"""BitNet + Residual: ternary weights with element-level dense residual.

R&D round 24 (2026-08-30). Validated by scripts/test_real_ternary_residual.py:
  - Pure ternary: 0.80-0.96 error on REAL LFM2.5 weights (too lossy)
  - +10% element residual: 0.31-0.33 error (best weight compression found)
  - Element-level residual wins over row/col residual (error is distributed)

Key insight: real trained weights have NO concentrated outliers (top-1% rows
carry only 1-2% of error). The ternary error is uniformly distributed, so
element-level sparse residual is the right granularity.

Compression: ~1.8× (10% bf16 + 90% ternary at 2 bits/elem packed in int8).
This is the best weight compression for near-full-rank weights (§14.2 showed
SVD/NLRQ can't compress them, §15.3 showed DCT can't either).

Two components:
  1. BitNetResidualLinear: nn.Module with ternary weight + element residual
  2. BitNetResidualKey: Key class for the key system
"""
from __future__ import annotations

import math
import torch
import torch.nn as nn
import torch.nn.functional as F

from research.keys.misc.base import Key, KeyClass, KeyResult

_TERNARY_EPS = 1e-8


def ternary_quantize(w: torch.Tensor, scale: float | None = None
                     ) -> tuple[torch.Tensor, torch.Tensor]:
    """BitNet b1.58 ternary quantize: W → {-1, 0, +1}."""
    w_abs = w.abs()
    if scale is None:
        scale = w_abs.mean().clamp(min=_TERNARY_EPS) / 0.7
    if not isinstance(scale, torch.Tensor):
        scale = torch.tensor(scale, dtype=w.dtype, device=w.device)
    q = torch.where(w_abs < 0.5 * scale, torch.zeros_like(w), torch.sign(w))
    return q, scale


def compute_residual(w: torch.Tensor, residual_frac: float
                     ) -> tuple[torch.Tensor, torch.Tensor, torch.Tensor]:
    """Compute ternary weight + element-level residual.

    Args:
        w: full-precision weight [out, in]
        residual_frac: fraction of elements to keep dense (0.0-1.0)

    Returns:
        w_ternary: ternary weight [out, in] (values in {-1, 0, +1})
        residual_mask: bool mask [out, in] (True = dense residual)
        residual_values: bf16 values for masked elements [n_residual]
    """
    w_t, scale = ternary_quantize(w)
    err = (w - w_t).abs()
    k = int(w.numel() * residual_frac)
    if k == 0:
        mask = torch.zeros_like(w, dtype=torch.bool)
        return w_t, mask, torch.empty(0, dtype=w.dtype, device=w.device)
    flat_err = err.flatten()
    top_idx = flat_err.topk(k).indices
    mask = torch.zeros_like(w, dtype=torch.bool)
    mask.flatten()[top_idx] = True
    # Apply residual: ternary + dense correction at masked positions
    w_t[mask] = w[mask]
    residual_values = w[mask]  # store the full-precision values at masked positions
    return w_t, mask, residual_values


class BitNetResidualLinear(nn.Module):
    """Linear layer with ternary weights + element-level dense residual.

    QAT semantics (matches BitNetLinear):
      - training forward: ternary weights + STE + residual (master weights fp).
      - eval forward: full-precision master weights by default; set force_quant=True
        for deployment with ternary + residual.
      - The residual is a fixed mask (computed at init or conversion time),
        not learned during training.

    Storage:
      - weight: full-precision master [out, in] (for QAT)
      - residual_mask: bool buffer [out, in] (which elements are dense)
      - At deploy: ternary weight stored as int8 + residual values as bf16

    Args:
        in_features, out_features: as nn.Linear.
        residual_frac: fraction of elements to keep dense (default 0.10).
        quantize: True = ternary forward during training (QAT).
        force_quant: also quantize in eval (deployment mode).
        learned_scale: learn a per-layer scale (param ``qscale``).
    """

    def __init__(self, in_features: int, out_features: int,
                 bias: bool = False, residual_frac: float = 0.10,
                 quantize: bool = False, force_quant: bool = False,
                 learned_scale: bool = True):
        super().__init__()
        self.in_features = in_features
        self.out_features = out_features
        self.residual_frac = residual_frac
        self.quantize = quantize
        self.force_quant = force_quant
        self.learned_scale = learned_scale
        self._prequantized = False

        # Master weight (full precision, for QAT)
        self.weight = nn.Parameter(torch.empty(out_features, in_features))
        nn.init.kaiming_uniform_(self.weight, a=math.sqrt(5))

        self.bias = None
        if bias:
            self.bias = nn.Parameter(torch.empty(out_features))
            bound = 1.0 / math.sqrt(in_features)
            nn.init.uniform_(self.bias, -bound, bound)

        self.qscale = None
        if learned_scale:
            with torch.no_grad():
                scale = self.weight.abs().mean().clamp(min=_TERNARY_EPS) / 0.7
            self.qscale = nn.Parameter(scale)

        # Residual mask (computed at conversion time, not init)
        self.register_buffer("residual_mask",
                             torch.zeros(out_features, in_features, dtype=torch.bool))

    def _compute_residual_mask(self):
        """Compute the element-level residual mask from current weights."""
        with torch.no_grad():
            w_t, scale = ternary_quantize(self.weight.data.float())
            err = (self.weight.data.float() - w_t).abs()
            k = int(self.weight.numel() * self.residual_frac)
            if k == 0:
                self.residual_mask.fill_(False)
                return
            flat_err = err.flatten()
            top_idx = flat_err.topk(k).indices
            self.residual_mask.fill_(False)
            self.residual_mask.flatten()[top_idx] = True

    def _ternary_forward(self, x: torch.Tensor) -> torch.Tensor:
        """Forward with ternary weights + residual (STE)."""
        scale = self.qscale if self.qscale is not None else None
        w_q, s = ternary_quantize(self.weight.float(), scale)
        # Apply residual: use full-precision values at masked positions
        w_q = w_q.to(self.weight.dtype)
        if self.residual_mask.any():
            w_q[self.residual_mask] = self.weight[self.residual_mask]
        # STE: gradient flows through master weight
        w_eff = self.weight + (w_q - self.weight).detach()
        out = F.linear(x, w_eff, self.bias)
        return out

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        if self._prequantized:
            # Deployment: use stored int8 ternary + residual buffer
            w_q = self.weight_int8.to(x.dtype) * self.qscale_buf
            if hasattr(self, "residual_values") and self.residual_values.numel() > 0:
                w_q[self.residual_mask] = self.residual_values.to(x.dtype)
            return F.linear(x, w_q, self.bias)

        if self.quantize or (self.force_quant and not self.training):
            return self._ternary_forward(x)
        # Full-precision forward (warm-start / pre-QAT)
        return F.linear(x, self.weight, self.bias)

    def convert_to_int8_storage(self):
        """Convert to int8 ternary storage + bf16 residual for deployment."""
        if self._prequantized:
            return
        with torch.no_grad():
            self._compute_residual_mask()
            scale = self.qscale if self.qscale is not None else None
            w_q, s = ternary_quantize(self.weight.data.float(), scale)
            w_int8 = w_q.to(torch.int8)
            device = self.weight.device
            dtype = self.weight.dtype

            # Store residual values (full precision at masked positions)
            if self.residual_mask.any():
                residual_values = self.weight.data[self.residual_mask].clone()
            else:
                residual_values = torch.empty(0, dtype=dtype, device=device)

            del self.weight
            self.register_buffer("weight_int8", w_int8.to(device))
            if isinstance(s, torch.Tensor):
                self.register_buffer("qscale_buf", s.to(device).to(dtype))
            else:
                self.register_buffer("qscale_buf",
                                     torch.tensor(s, device=device, dtype=dtype))
            self.register_buffer("residual_values", residual_values)
            if self.qscale is not None:
                del self.qscale
                self.qscale = None
            self._prequantized = True

    def _load_from_state_dict(self, state_dict, prefix, local_metadata, strict,
                              missing_keys, unexpected_keys, error_msgs):
        """Custom load: handle both pre-quantized and full-precision checkpoints."""
        if self._prequantized:
            # Pre-quantized: load int8 + residual buffers
            for name in ["weight_int8", "qscale_buf", "residual_mask", "residual_values"]:
                key = prefix + name
                if key in state_dict:
                    buf = getattr(self, name)
                    buf.copy_(state_dict[key])
        else:
            # Full-precision: load weight + qscale + residual_mask
            weight_key = prefix + "weight"
            if weight_key in state_dict:
                self.weight.data.copy_(state_dict[weight_key])
            qscale_key = prefix + "qscale"
            if qscale_key in state_dict and self.qscale is not None:
                self.qscale.data.copy_(state_dict[qscale_key])
            mask_key = prefix + "residual_mask"
            if mask_key in state_dict:
                self.residual_mask.copy_(state_dict[mask_key])
            else:
                # Compute mask from loaded weights
                self._compute_residual_mask()
            bias_key = prefix + "bias"
            if bias_key in state_dict and self.bias is not None:
                self.bias.data.copy_(state_dict[bias_key])


def apply_bitnet_residual(state: dict[str, torch.Tensor],
                          residual_frac: float = 0.10) -> dict[str, torch.Tensor]:
    """Apply ternary+residual quantization to all .weight tensors in state.

    For each weight, computes ternary quantization + element-level residual mask.
    Stores: ternary weight (as float for compatibility) + residual_mask + residual_values.
    """
    out = {}
    for k, v in state.items():
        if isinstance(v, torch.Tensor) and k.endswith(".weight") and v.ndim == 2:
            w_t, mask, res_vals = compute_residual(v.float(), residual_frac)
            # Save ternary weights as int8 (1 byte/param) + qscale
            from research.keys.quantization.bitnet_b158_key import ternary_quantize
            q, s = ternary_quantize(w_t.float())
            out[k] = q.to(torch.int8)
            out[k.replace(".weight", ".qscale")] = torch.tensor([s], dtype=torch.float32)
            out[k.replace(".weight", ".residual_mask")] = mask
            out[k.replace(".weight", ".residual_values")] = res_vals.to(torch.bfloat16)
        else:
            out[k] = v
    return out


class BitNetResidualKey(Key):
    """BitNet + Residual key — ternary weights with element-level dense residual.

    Key class: PARTIAL — the ternary transform is not invertible.
    The residual reduces error from 0.80 → 0.33 on real LFM2.5 weights (§15.2).
    """

    def __init__(self, residual_frac: float = 0.10):
        self.residual_frac = residual_frac

    @property
    def name(self) -> str:
        return "bitnet_residual"

    @property
    def description(self) -> str:
        return f"Ternary QAT + {self.residual_frac*100:.0f}% element residual"

    def key_class(self) -> KeyClass:
        return KeyClass.PARTIAL

    def forward(self, data: dict[str, torch.Tensor]) -> KeyResult:
        try:
            weights = apply_bitnet_residual(dict(data), self.residual_frac)
            n = sum(1 for k in weights if k.endswith(".weight"))
            return KeyResult(success=True, weights=weights,
                             metadata={"n_quantized": n,
                                       "residual_frac": self.residual_frac})
        except Exception as e:
            return KeyResult(success=False, error=str(e))

    def reverse(self, weights: dict[str, torch.Tensor]) -> KeyResult:
        return KeyResult(
            success=True, data=weights,
            metadata={"note": "Ternary+residual weights cannot be un-quantized"})


def build_bitnet_residual_linear(config, in_features: int, out_features: int,
                                  bias: bool = False) -> nn.Module:
    """Build a BitNetResidualLinear honoring the model config."""
    return BitNetResidualLinear(
        in_features, out_features, bias=bias,
        residual_frac=getattr(config, "bitnet_residual_frac", 0.10),
        quantize=bool(getattr(config, "use_bitnet", False)),
        force_quant=bool(getattr(config, "bitnet_force_quant", False)),
        learned_scale=bool(getattr(config, "bitnet_learned_scale", True)),
    )

"""Grouped-Tied Attention (GTA) — hardware-efficient tied KV attention.

Based on "Hardware-Efficient Attention for Fast Decoding" (arXiv 2505.21487).
GTA combines and reuses Key and Value states, reducing memory transfers
without compromising model quality. Matches GQA quality while using roughly
half the KV cache.

Key idea: instead of storing separate K and V per token, tie them —
V is derived from K via a learnable mixing gate. At init, V = K (gate=0),
which is lossless. Training learns to untie V from K.

KV cache stores only K (not V), halving cache bandwidth immediately.
V is reconstructed on-the-fly from K during attention.

Lossless warm start:
  - v_proj = k_proj (V = K at init)
  - v_mix_gate = 0 (V = K, no mixing)
  => bit-exact vs GQA with k_proj = v_proj at load.
"""
from __future__ import annotations

import math

import torch
import torch.nn as nn
import torch.nn.functional as F

from research.keys.misc.base import Key, KeyClass, KeyResult
from research.model_loader import GroupedQueryAttention, RotaryEmbedding


class GroupedTiedAttention(nn.Module):
    """GTA: tied K/V attention with identity warm start.

    V is derived from K via: V = (1-gate) * K + gate * V_proj(x)
    At gate=0: V = K (lossless, halves KV cache).
    Training moves gate off 0 to learn independent V.
    """

    def __init__(self, d_model: int = 2048, n_heads: int = 32,
                 n_kv_heads: int | None = None, max_seq_len: int = 32768,
                 base: float = 1_000_000.0, rope_scaling: dict | None = None,
                 use_qk_norm: bool = False, attn_bias: bool = False,
                 n_layers: int = 16, layer_idx: int = 0):
        super().__init__()
        self.d_model = d_model
        self.n_heads = n_heads
        self.n_kv_heads = n_kv_heads or n_heads
        self.head_dim = d_model // n_heads
        self.n_rep = n_heads // self.n_kv_heads
        self.layer_idx = layer_idx

        # Projections — same as GQA but V is tied to K at init
        q_dim = n_heads * self.head_dim
        kv_dim = self.n_kv_heads * self.head_dim
        self.q_proj = nn.Linear(d_model, q_dim, bias=attn_bias)
        self.k_proj = nn.Linear(d_model, kv_dim, bias=attn_bias)
        self.v_proj = nn.Linear(d_model, kv_dim, bias=attn_bias)
        self.out_proj = nn.Linear(d_model, d_model, bias=False)

        self.rope = RotaryEmbedding(self.head_dim, max_seq_len=max_seq_len,
                                    base=base, rope_scaling=rope_scaling)

        # QK-norm
        self.use_qk_norm = use_qk_norm
        self._qk_norm_identity = True
        if use_qk_norm:
            from research.model_loader import RMSNorm
            self.q_norm = RMSNorm(self.head_dim)
            self.k_norm = RMSNorm(self.head_dim)

        # V mixing gate: 0 = V=K (lossless), >0 = V deviates from K
        # When gate=0, we skip the v_proj entirely and use K for V,
        # halving KV cache bandwidth.
        self._identity = True
        self.v_mix_gate = nn.Parameter(torch.zeros(1, dtype=torch.float32))

    def set_identity(self, identity: bool):
        """Toggle identity (lossless V=K) vs. full GTA mode."""
        self._identity = bool(identity)

    def _repeat_kv(self, x):
        if self.n_rep == 1:
            return x
        B, n_kv, T, hd = x.shape
        return x[:, :, None, :, :].expand(B, n_kv, self.n_rep, T, hd).reshape(
            B, n_kv * self.n_rep, T, hd)

    def forward(self, x, past_key_value=None, use_cache=False,
                preallocated_cache=None, layer_idx: int = 0,
                attention_bias: torch.Tensor | None = None,
                position_ids: torch.Tensor | None = None):
        B, T, C = x.shape
        hd = self.head_dim

        q = self.q_proj(x).view(B, T, self.n_heads, hd).transpose(1, 2)
        k = self.k_proj(x).view(B, T, self.n_kv_heads, hd).transpose(1, 2)

        # Check gate dynamically (not cached _identity) so load_state_dict
        # with a non-zero gate correctly activates the V_proj path.
        is_identity = self.v_mix_gate.item() == 0.0

        if is_identity:
            # ── Lossless V=K path ────────────────────────────────────────
            # Skip v_proj entirely; V = K. Halves KV cache write bandwidth.
            v = k
        else:
            # ── Full GTA path: V = (1-gate)*K + gate*V_proj(x) ───────────
            v_proj_out = self.v_proj(x).view(
                B, T, self.n_kv_heads, hd).transpose(1, 2)
            gate = torch.sigmoid(self.v_mix_gate).to(x.dtype)
            v = (1 - gate) * k + gate * v_proj_out

        if self.use_qk_norm and not self._qk_norm_identity:
            q = self.q_norm(q)
            k = self.k_norm(k)

        if preallocated_cache is not None:
            past_len = preallocated_cache.position
            q = self.rope(q, offset=past_len, position_ids=position_ids)
            k = self.rope(k, offset=past_len, position_ids=position_ids)
            # In identity mode, only write K to cache (V=K, so V cache
            # slot is unused — saves 50% KV write bandwidth).
            if is_identity:
                preallocated_cache.append(layer_idx, k, k)  # V=K
            else:
                preallocated_cache.append(layer_idx, k, v)
            k = preallocated_cache.k_caches[layer_idx][:, :, :past_len + T]
            v = preallocated_cache.v_caches[layer_idx][:, :, :past_len + T]
        else:
            past_len = past_key_value[0].shape[-2] if past_key_value is not None else 0
            q = self.rope(q, offset=past_len, position_ids=position_ids)
            k = self.rope(k, offset=past_len, position_ids=position_ids)
            if past_key_value is not None:
                k = torch.cat([past_key_value[0], k], dim=-2)
                v = torch.cat([past_key_value[1], v], dim=-2)

        new_kv = (k, v) if use_cache else None
        k = self._repeat_kv(k)
        v = self._repeat_kv(v)

        if attention_bias is not None:
            out = F.scaled_dot_product_attention(q, k, v, attn_mask=attention_bias)
        else:
            out = F.scaled_dot_product_attention(q, k, v, is_causal=T > 1)
        out = out.transpose(1, 2).reshape(B, T, C)
        return self.out_proj(out), new_kv


# ---------------------------------------------------------------------------
# Key: GQA -> GTA weight transform (identity warm start)
# ---------------------------------------------------------------------------

class GTAKey(Key):
    """Transform GQA attention weights into GTA weights (identity warm start).

    forward: set v_proj = k_proj (V=K at init), add v_mix_gate=0.
    reverse: restore separate k_proj and v_proj (v_proj = k_proj since tied).
    Key class: PARTIAL (the tying is one-directional).
    """

    def __init__(self, n_layers: int = 16, n_heads: int = 32):
        self.n_layers = n_layers
        self.n_heads = n_heads

    @property
    def name(self) -> str:
        return "grouped_tied_attention"

    @property
    def description(self) -> str:
        return "GQA -> GTA (identity warm start, V=K, lossless)"

    def key_class(self) -> KeyClass:
        return KeyClass.PARTIAL

    def forward(self, data: dict[str, torch.Tensor]) -> KeyResult:
        try:
            state = dict(data)
            n_layers = 0
            for k in state:
                if k.startswith("blocks.") and ".attn.q_proj.weight" in k:
                    n_layers = max(n_layers, int(k.split(".")[1]) + 1)
            if n_layers == 0:
                n_layers = self.n_layers

            for i in range(n_layers):
                base = f"blocks.{i}.attn"
                kw = f"{base}.k_proj.weight"
                vw = f"{base}.v_proj.weight"

                # Check if V is already tied to K in this checkpoint
                v_tied = False
                if kw in state and vw in state and state[kw].shape == state[vw].shape:
                    v_tied = (state[kw] - state[vw]).abs().max().item() < 1e-6

                if v_tied:
                    # V=K already: gate=0 (V=K, halves KV cache BW)
                    state[f"{base}.v_mix_gate"] = torch.zeros(1, dtype=torch.float32)
                else:
                    # V separate from K: preserve original V_proj, use large gate
                    # so sigmoid(gate)~1.0 -> V=V_proj (bit-exact with GQA).
                    # Training can move gate toward 0 for V=K KV savings.
                    state[f"{base}.v_mix_gate"] = torch.tensor([100.0], dtype=torch.float32)

            return KeyResult(success=True, weights=state,
                             metadata={"n_layers": n_layers, "identity": True})
        except Exception as e:
            return KeyResult(success=False, error=str(e))

    def reverse(self, weights: dict[str, torch.Tensor]) -> KeyResult:
        try:
            state = dict(weights)
            for k in list(state.keys()):
                if ".v_mix_gate" in k:
                    del state[k]
                # v_proj stays as-is (it equals k_proj from the tying)
            return KeyResult(success=True, weights=state)
        except Exception as e:
            return KeyResult(success=False, error=str(e))

"""Unit test for the cu_seqlens fix in FusedQKNormRopeCacheWrapper.

Bug (2026-08-31, found while preparing V10 self-play):
  FusedQKNormRopeCacheWrapper.fused_forward did not accept the ``cu_seqlens``
  kwarg, but the block forward passes it for varlen packed sequences. Any
  wrapper that patches ``attn.forward`` with a fixed signature crashed with
  ``TypeError: ... got an unexpected keyword argument 'cu_seqlens'``.

Fix:
  - fused_forward now accepts ``cu_seqlens=None`` and delegates to the
    original forward when it is set (varlen is training-only; the fused path
    is inference-only — orthogonal, safe fallback).
  - Block inference path (model_loader.py) only passes cu_seqlens when not
    None, so patched forwards never see the unexpected kwarg at inference.

This test verifies the wrapper-level delegation: when cu_seqlens is provided,
the original (un-patched) forward is called with it, and no TypeError is
raised. CPU-only, no real weights.
"""
import torch
import torch.nn as nn
import pytest

from research.inference.attention.fused_qk_norm_rope_cache import (
    FusedQKNormRopeCacheWrapper,
)


class _MockAttention(nn.Module):
    """Minimal stand-in for GroupedQueryAttention.

    Exposes the attributes the wrapper inspects (use_qk_norm) and a recording
    forward so we can assert the delegation path was taken.
    """

    def __init__(self, head_dim=64, n_heads=32, n_kv_heads=8):
        super().__init__()
        self.head_dim = head_dim
        self.n_heads = n_heads
        self.n_kv_heads = n_kv_heads
        self.n_rep = n_heads // n_kv_heads
        self.use_qk_norm = True
        # Tiny real projections so the fused path could run if reached.
        self.q_proj = nn.Linear(n_heads * head_dim, n_heads * head_dim, bias=False)
        self.k_proj = nn.Linear(n_heads * head_dim, n_kv_heads * head_dim, bias=False)
        self.v_proj = nn.Linear(n_heads * head_dim, n_kv_heads * head_dim, bias=False)
        self.out_proj = nn.Linear(n_heads * head_dim, n_heads * head_dim, bias=False)
        self.q_norm = nn.LayerNorm(head_dim)
        self.k_norm = nn.LayerNorm(head_dim)
        # RoPE stub with cos/sin caches the fused path reads.
        cos = torch.zeros(16, head_dim)
        sin = torch.zeros(16, head_dim)
        self.rope = type("_R", (), {
            "cos_cached": cos, "sin_cached": sin,
            "base": 10000.0, "dim": head_dim,
        })()
        # Record calls to the original forward.
        self.last_kwargs = None

    def forward(self, x, past_key_value=None, use_cache=False,
                preallocated_cache=None, layer_idx=0,
                attention_bias=None, position_ids=None,
                cu_seqlens=None):
        self.last_kwargs = {"cu_seqlens": cu_seqlens, "use_cache": use_cache}
        B, T, C = x.shape
        return x, (past_key_value if use_cache else None)


class _MockModel(nn.Module):
    """Container so wrapper.apply() can iterate named_modules()."""

    def __init__(self):
        super().__init__()
        self.attn = _MockAttention()


class TestFusedQKNormRopeCacheCuSeqlens:
    def _patched(self):
        """Build a mock model with the wrapper patched in directly.

        ``apply()`` only patches modules that are ``GroupedQueryAttention``
        instances or have specific class names, so we call ``_patch`` directly
        to exercise the patched ``fused_forward`` on the mock.
        """
        model = _MockModel()
        wrapper = FusedQKNormRopeCacheWrapper(kv_quant_bits=None)
        wrapper._patch(model.attn, "attn")
        return model, wrapper

    def test_cu_seqlens_delegates_to_original(self):
        """cu_seqlens set → original forward called with it (no TypeError)."""
        model, _ = self._patched()

        x = torch.randn(1, 4, 32 * 64)
        cu = torch.tensor([0, 2, 4], dtype=torch.int32)
        # Before the fix this raised:
        #   TypeError: fused_forward() got an unexpected keyword argument 'cu_seqlens'
        out, _ = model.attn(x, cu_seqlens=cu)
        assert out is not None
        # The original forward must have received cu_seqlens (delegation path).
        assert model.attn.last_kwargs is not None
        assert model.attn.last_kwargs["cu_seqlens"] is cu

    def test_cu_seqlens_none_does_not_delegate(self):
        """cu_seqlens=None → fused path runs, original forward NOT called."""
        model, _ = self._patched()

        x = torch.randn(1, 4, 32 * 64)
        # cu_seqlens=None should take the fused path (not delegate).
        # The fused path hits the known RoPE-convention shape bug on real
        # head_dim (RuntimeError 32-vs-64, documented in .devin/scratchpad.md,
        # disabled in the self-play loop default). The point of THIS test is
        # that cu_seqlens=None is ACCEPTED as a kwarg — no TypeError about an
        # unexpected 'cu_seqlens' argument. The RuntimeError is the separate
        # RoPE bug, not the cu_seqlens fix.
        try:
            model.attn(x, cu_seqlens=None)
        except TypeError as e:
            assert "cu_seqlens" not in str(e), f"cu_seqlens kwarg rejected: {e}"
        except RuntimeError:
            pass  # known RoPE-convention shape bug (separate, documented)
        # Delegation only happens when cu_seqlens is not None, so the original
        # forward should not have recorded a non-None cu_seqlens.
        if model.attn.last_kwargs is not None:
            assert model.attn.last_kwargs["cu_seqlens"] is None

    def test_revert_restores_original(self):
        """revert() restores the un-patched forward."""
        model, wrapper = self._patched()
        # Compare underlying functions, not bound-method objects (Python
        # creates a new bound method on each attribute access).
        original_fn = type(model.attn).forward
        assert model.attn.forward.__func__ is not original_fn  # patched
        wrapper.revert(model)
        assert model.attn.forward.__func__ is original_fn  # restored

"""Tests for HINT4-NLRQ (Hadamard-INT4 NLRQ factors).

Verifies:
  1. Hadamard matrix orthogonality (H @ H^T ≈ I)
  2. INT4 packing/unpacking round-trip
  3. Compression ratio: INT4 uses ~half the storage of INT8
  4. Reconstruction error: HINT4 < 2x INT8 error
  5. Forward pass: HINT4 output within 10% of dense
  6. from_dense_hadamard_int4 classmethod
"""
import pytest
import torch

from research.keys.compression.nlrq_ffn_key import (
    NLRQLinear,
    _hadamard_matrix,
    _apply_hadamard,
    _pack_int4,
    _unpack_int4,
)

CUDA_AVAILABLE = torch.cuda.is_available()
DEVICE = torch.device("cuda" if CUDA_AVAILABLE else "cpu")


# ── 1. Hadamard orthogonality ──────────────────────────────────────────────

@pytest.mark.parametrize("n", [1, 2, 4, 8, 16, 64, 256, 768])
def test_hadamard_orthogonality(n):
    """H @ H^T should be identity (orthogonal matrix)."""
    H = _hadamard_matrix(n, device=torch.device("cpu"), dtype=torch.float32)
    assert H.shape == (n, n)
    I = H @ H.t()
    eye = torch.eye(n, dtype=torch.float32)
    assert torch.allclose(I, eye, atol=1e-5), (
        f"Hadamard {n}x{n} not orthogonal: max diff {(I - eye).abs().max():.6e}"
    )


def test_hadamard_non_power_of_2():
    """Non-power-of-2 should still produce an exactly orthogonal matrix (via QR)."""
    H = _hadamard_matrix(768, device=torch.device("cpu"), dtype=torch.float32)
    assert H.shape == (768, 768)
    # After QR re-orthogonalization, should be exactly orthogonal
    I = H @ H.t()
    eye = torch.eye(768, dtype=torch.float32)
    assert torch.allclose(I, eye, atol=1e-4), (
        f"Hadamard 768x768 not orthogonal after QR: max diff {(I - eye).abs().max():.6e}"
    )
    assert torch.isfinite(H).all()


# ── 2. INT4 packing/unpacking ──────────────────────────────────────────────

def test_int4_pack_unpack_roundtrip():
    """Pack then unpack int4 values — should recover original."""
    q = torch.randint(-8, 8, (128, 256), dtype=torch.int8)
    packed = _pack_int4(q)
    assert packed.dtype == torch.int8
    # Packed last dim should be half (rounded up)
    assert packed.shape[-1] == (q.shape[-1] + 1) // 2
    unpacked = _unpack_int4(packed, q.shape[-1])
    assert unpacked.shape == q.shape
    assert torch.equal(unpacked, q), "INT4 pack/unpack round-trip failed"


# ── 3. Compression ratio ───────────────────────────────────────────────────

def test_compression_ratio_int4_vs_int8():
    """INT4 NLRQ should use approximately half the factor storage of INT8.

    Uses production-like dims where Hadamard overhead is relatively small.
    At small dims (rank=256), the 2×rank² Hadamard matrices dominate.
    """
    out_features, in_features, rank = 2048, 8192, 512

    layer_int8 = NLRQLinear(in_features, out_features, rank=rank, factor_bits=8)
    layer_hint4 = NLRQLinear(in_features, out_features, rank=rank,
                             factor_bits=4, use_hadamard=True)

    bytes_int8 = layer_int8.compressed_storage_bytes()
    bytes_hint4 = layer_hint4.compressed_storage_bytes()

    # INT4 factors are half the bytes of INT8 factors.
    # Hadamard matrices add overhead (2 × rank² × 2 bytes).
    # At rank=512: Hadamard = 1MB, factor savings = ~3MB → net ~1.5x
    ratio = bytes_int8 / max(bytes_hint4, 1)
    print(f"INT8 bytes: {bytes_int8}, HINT4 bytes: {bytes_hint4}, ratio: {ratio:.2f}")
    # Should be > 1.3x (Hadamard overhead reduces the theoretical 2x)
    assert ratio > 1.3, f"Expected >1.3x compression ratio, got {ratio:.2f}"


# ── 4. Reconstruction error ────────────────────────────────────────────────

def test_reconstruction_error():
    """Compare HINT4 vs INT8 reconstruction error.

    INT4 has 16 quantization levels vs INT8's 256 — a fundamental 16x gap.
    The Hadamard rotation spreads outliers but can't overcome the level gap.
    Expected: INT8 ~1% error, HINT4 ~15-20% error, HINT4 ~1.25x better CR.

    The HINT4 tradeoff: ~1.25x more compression for ~18x more error.
    This is viable for inference-only compression where the low-rank
    structure absorbs some of the quantization error, or when combined
    with an INT4 residual (future work).
    """
    torch.manual_seed(42)
    # Use smaller dims for test speed, but still representative
    out_features, in_features, rank = 1024, 4096, 384
    # Low-rank matrix so SVD truncation error is minimal
    W_low = torch.randn(out_features, rank, dtype=torch.float32, device=DEVICE) * 0.02
    W_high = torch.randn(rank, in_features, dtype=torch.float32, device=DEVICE) * 0.02
    W = W_low @ W_high  # rank-384 matrix

    # INT8 NLRQ
    layer_int8 = NLRQLinear.from_dense(W, rank=rank, factor_bits=8)
    W_int8 = layer_int8._dequantize_weight().float()
    err_int8 = (W - W_int8).norm() / W.norm()
    cr_int8 = layer_int8.compression_ratio()

    # HINT4 NLRQ (pure — no residual, to compare the INT4 factor floor)
    layer_hint4 = NLRQLinear.from_dense_hadamard_int4(W, rank=rank, use_residual=False)
    W_hint4 = layer_hint4._dequantize_weight().float()
    err_hint4 = (W - W_hint4).norm() / W.norm()
    cr_hint4 = layer_hint4.compression_ratio()

    print(f"\nINT8:  error={err_int8:.4f} ({err_int8*100:.2f}%), CR={cr_int8:.1f}x")
    print(f"HINT4: error={err_hint4:.4f} ({err_hint4*100:.2f}%), CR={cr_hint4:.1f}x")
    print(f"Error ratio (HINT4/INT8): {err_hint4/err_int8:.2f}x")
    print(f"Storage ratio (INT8/HINT4): {cr_hint4/cr_int8:.2f}x")

    # HINT4 error should be < 25% (INT4 quantization floor ~15-20%)
    assert err_hint4 < 0.25, (
        f"HINT4 error {err_hint4:.4f} >= 25% — too high even for INT4"
    )
    # HINT4 should have better compression (even with Hadamard overhead)
    assert cr_hint4 > cr_int8, (
        f"HINT4 CR {cr_hint4:.1f} not better than INT8 CR {cr_int8:.1f}"
    )


# ── 5. Forward pass ────────────────────────────────────────────────────────

def test_forward_pass_accuracy():
    """HINT4 NLRQ forward output should be within 20% of dense linear output.

    INT4 quantization (16 levels) inherently has ~6% per-element error.
    After matrix multiplication, errors compound. 20% is a realistic
    threshold for INT4 factors at rank=256 on a 512×2048 matrix.
    """
    torch.manual_seed(123)
    out_features, in_features, rank = 512, 2048, 256
    # Low-rank matrix so SVD truncation error is minimal
    W_low = torch.randn(out_features, rank, dtype=torch.float32, device=DEVICE) * 0.02
    W_high = torch.randn(rank, in_features, dtype=torch.float32, device=DEVICE) * 0.02
    W = W_low @ W_high  # rank-256 matrix
    bias = torch.randn(out_features, dtype=torch.float32, device=DEVICE) * 0.01

    # Dense reference
    x = torch.randn(4, in_features, dtype=torch.float32, device=DEVICE)
    y_dense = x @ W.t() + bias

    # HINT4 NLRQ
    layer = NLRQLinear.from_dense_hadamard_int4(W, rank=rank, bias=bias)
    layer.eval()
    with torch.no_grad():
        y_hint4 = layer(x)

    rel_err = (y_dense - y_hint4).norm() / y_dense.norm()
    print(f"Forward pass relative error: {rel_err:.4f} ({rel_err*100:.2f}%)")
    assert rel_err < 0.20, (
        f"Forward pass error {rel_err:.4f} >= 20%"
    )


# ── 6. from_dense_hadamard_int4 classmethod ────────────────────────────────

def test_from_dense_hadamard_int4_basic():
    """Verify from_dense_hadamard_int4 creates a valid layer with Hadamard buffers."""
    torch.manual_seed(99)
    out_features, in_features, rank = 256, 1024, 128
    # Low-rank matrix so SVD truncation is minimal
    W_low = torch.randn(out_features, rank, dtype=torch.float32, device=DEVICE) * 0.05
    W_high = torch.randn(rank, in_features, dtype=torch.float32, device=DEVICE) * 0.05
    W = W_low @ W_high  # rank-128 matrix

    layer = NLRQLinear.from_dense_hadamard_int4(W, rank=rank)

    # Check basic properties
    assert layer.factor_bits == 4
    assert layer.use_hadamard is True
    assert layer._max_val == 7
    assert layer._min_val == -8

    # Hadamard buffers should be set
    assert layer.hadamard_U is not None
    assert layer.hadamard_V is not None
    assert layer.hadamard_U.shape == (rank, rank)
    assert layer.hadamard_V.shape == (rank, rank)
    assert layer.hadamard_U.dtype == torch.bfloat16

    # Quantized factors should be in INT4 range
    assert layer.U_q.min() >= -8
    assert layer.U_q.max() <= 7
    assert layer.V_q.min() >= -8
    assert layer.V_q.max() <= 7

    # S should have the top singular values
    assert layer.S.shape == (rank,)

    # Reconstruction should be reasonable (INT4 is coarser than INT8)
    W_recon = layer._dequantize_weight().float()
    rel_err = (W - W_recon).norm() / W.norm()
    print(f"from_dense_hadamard_int4 reconstruction error: {rel_err:.4f}")
    assert rel_err < 0.30, f"Reconstruction error {rel_err:.4f} too high"


def test_from_dense_hadamard_int4_with_bias():
    """Verify from_dense_hadamard_int4 correctly stores bias."""
    out_features, in_features, rank = 128, 512, 64
    W = torch.randn(out_features, in_features, dtype=torch.float32, device=DEVICE) * 0.03
    bias = torch.randn(out_features, dtype=torch.float32, device=DEVICE) * 0.01

    layer = NLRQLinear.from_dense_hadamard_int4(W, rank=rank, bias=bias)
    assert layer.bias is not None
    assert layer.bias.shape == (out_features,)
    assert torch.allclose(layer.bias, bias, atol=1e-6)


# ── 7. Backward compatibility: INT8 still works ────────────────────────────

def test_int8_backward_compatibility():
    """Existing INT8 NLRQ must work unchanged."""
    torch.manual_seed(42)
    out_features, in_features, rank = 256, 1024, 128
    # Use a low-rank matrix so SVD truncation error is minimal
    # (random matrices have slow singular value decay → high truncation error)
    W_low = torch.randn(out_features, rank, dtype=torch.float32, device=DEVICE) * 0.02
    W_high = torch.randn(rank, in_features, dtype=torch.float32, device=DEVICE) * 0.02
    W = W_low @ W_high  # rank-128 matrix

    layer = NLRQLinear.from_dense(W, rank=rank, factor_bits=8)
    assert layer.factor_bits == 8
    assert layer.use_hadamard is False
    assert layer.hadamard_U is None
    assert layer.hadamard_V is None
    assert layer._max_val == 127
    assert layer._min_val == -128

    # INT8 factors should be in [-128, 127]
    assert layer.U_q.min() >= -128
    assert layer.U_q.max() <= 127

    # Reconstruction should work (low-rank matrix → minimal truncation error)
    W_recon = layer._dequantize_weight().float()
    rel_err = (W - W_recon).norm() / W.norm()
    print(f"INT8 backward compat reconstruction error: {rel_err:.4f}")
    assert rel_err < 0.05

    # Forward pass
    x = torch.randn(2, in_features, dtype=torch.float32, device=DEVICE)
    with torch.no_grad():
        y = layer(x)
    assert y.shape == (2, out_features)


# ── 8. Hadamard apply/inverse round-trip ───────────────────────────────────

def test_apply_hadamard_inverse():
    """Applying Hadamard then its inverse should recover the original."""
    torch.manual_seed(42)
    weight = torch.randn(64, 128, dtype=torch.float32, device=DEVICE)

    # Disable TF32 for exact float32 matmul precision (other tests may enable it)
    old_tf32 = torch.backends.cuda.matmul.allow_tf32
    torch.backends.cuda.matmul.allow_tf32 = False
    try:
        # Apply along dim=1 (columns)
        rotated, H = _apply_hadamard(weight, dim=1)
        assert rotated.shape == weight.shape
        # Inverse: weight = rotated @ H
        recovered = rotated @ H.to(rotated.dtype)
        assert torch.allclose(weight, recovered, atol=1e-5), (
            f"Hadamard dim=1 inverse failed: max diff {(weight - recovered).abs().max():.6e}"
        )

        # Apply along dim=0 (rows)
        rotated0, H0 = _apply_hadamard(weight, dim=0)
        assert rotated0.shape == weight.shape
        # Inverse: weight = H^T @ rotated
        recovered0 = H0.to(rotated0.dtype).t() @ rotated0
        assert torch.allclose(weight, recovered0, atol=1e-5), (
            f"Hadamard dim=0 inverse failed: max diff {(weight - recovered0).abs().max():.6e}"
        )
    finally:
        torch.backends.cuda.matmul.allow_tf32 = old_tf32


# ── 9. Adaptive rank ────────────────────────────────────────────────────────

class TestAdaptiveRank:
    def test_adaptive_rank_low_rank_matrix(self):
        """A rank-64 matrix should select rank ~64 at 99% energy."""
        torch.manual_seed(42)
        # Create a rank-64 matrix
        W_low = torch.randn(512, 64, dtype=torch.float32, device=DEVICE) * 0.02
        W_high = torch.randn(64, 2048, dtype=torch.float32, device=DEVICE) * 0.02
        W = W_low @ W_high  # rank-64

        layer, r = NLRQLinear.from_dense_adaptive(W, energy_threshold=0.99, min_rank=32)
        print(f"Adaptive rank for rank-64 matrix: {r}")
        # Should select a small rank (close to 64)
        assert r <= 100, f"Adaptive rank {r} too high for rank-64 matrix"
        assert r >= 32, f"Adaptive rank {r} below min_rank"

    def test_adaptive_rank_full_rank_matrix(self):
        """A full-rank random matrix should select a high rank."""
        torch.manual_seed(42)
        W = torch.randn(256, 512, dtype=torch.float32, device=DEVICE) * 0.02
        layer, r = NLRQLinear.from_dense_adaptive(W, energy_threshold=0.99, min_rank=32)
        print(f"Adaptive rank for full-rank matrix: {r}")
        # Random matrices have slow singular value decay → high rank
        assert r > 100, f"Adaptive rank {r} too low for full-rank matrix"

    def test_adaptive_rank_energy_threshold(self):
        """Lower energy threshold should select lower rank."""
        torch.manual_seed(42)
        W = torch.randn(256, 512, dtype=torch.float32, device=DEVICE) * 0.02
        _, r99 = NLRQLinear.from_dense_adaptive(W, energy_threshold=0.99, min_rank=16)
        _, r90 = NLRQLinear.from_dense_adaptive(W, energy_threshold=0.90, min_rank=16)
        print(f"99% energy: rank={r99}, 90% energy: rank={r90}")
        assert r90 <= r99, "Lower energy threshold should select lower rank"

    def test_adaptive_rank_reconstruction(self):
        """Adaptive rank layer should reconstruct well."""
        torch.manual_seed(42)
        W_low = torch.randn(512, 128, dtype=torch.float32, device=DEVICE) * 0.02
        W_high = torch.randn(128, 2048, dtype=torch.float32, device=DEVICE) * 0.02
        W = W_low @ W_high  # rank-128

        layer, r = NLRQLinear.from_dense_adaptive(W, energy_threshold=0.99, min_rank=32)
        W_recon = layer._dequantize_weight().float()
        err = (W - W_recon).norm() / W.norm()
        print(f"Adaptive rank={r}, reconstruction error: {err:.4f}")
        # Should have low error (we captured 99% of energy + INT8 quant noise)
        assert err < 0.10, f"Adaptive rank error {err:.4f} too high"

    def test_adaptive_rank_min_max(self):
        """min_rank and max_rank should clamp the selected rank."""
        torch.manual_seed(42)
        W = torch.randn(256, 512, dtype=torch.float32, device=DEVICE) * 0.02
        _, r_clamped = NLRQLinear.from_dense_adaptive(
            W, energy_threshold=0.99, min_rank=200, max_rank=250)
        assert r_clamped >= 200, "Should respect min_rank"
        assert r_clamped <= 250, "Should respect max_rank"

    def test_adaptive_rank_saves_storage(self):
        """Adaptive rank on a low-rank matrix should use less storage than fixed rank."""
        torch.manual_seed(42)
        W_low = torch.randn(512, 64, dtype=torch.float32, device=DEVICE) * 0.02
        W_high = torch.randn(64, 2048, dtype=torch.float32, device=DEVICE) * 0.02
        W = W_low @ W_high  # rank-64

        # Fixed rank=256 (overkill for a rank-64 matrix)
        layer_fixed = NLRQLinear.from_dense(W, rank=256, factor_bits=8)
        bytes_fixed = layer_fixed.compressed_storage_bytes()

        # Adaptive rank (should select ~64)
        layer_adaptive, r = NLRQLinear.from_dense_adaptive(
            W, energy_threshold=0.99, min_rank=32)
        bytes_adaptive = layer_adaptive.compressed_storage_bytes()

        print(f"Fixed rank=256: {bytes_fixed} bytes")
        print(f"Adaptive rank={r}: {bytes_adaptive} bytes")
        print(f"Storage savings: {bytes_fixed / bytes_adaptive:.2f}x")

        assert bytes_adaptive < bytes_fixed, "Adaptive should use less storage on low-rank matrix"


# ── 10. HINT4 + INT4 residual ───────────────────────────────────────────────

def test_hint4_with_residual_error():
    """HINT4 + INT4 residual should have much lower error than pure HINT4."""
    torch.manual_seed(42)
    out_features, in_features, rank = 1024, 4096, 384
    # Low-rank matrix
    W_low = torch.randn(out_features, rank, dtype=torch.float32, device=DEVICE) * 0.02
    W_high = torch.randn(rank, in_features, dtype=torch.float32, device=DEVICE) * 0.02
    W = W_low @ W_high

    # Pure HINT4 (no residual)
    layer_pure = NLRQLinear.from_dense_hadamard_int4(W, rank=rank, use_residual=False)
    W_pure = layer_pure._dequantize_weight().float()
    err_pure = (W - W_pure).norm() / W.norm()

    # HINT4 + residual
    layer_res = NLRQLinear.from_dense_hadamard_int4(W, rank=rank, use_residual=True)
    W_res = layer_res._dequantize_weight().float()
    err_res = (W - W_res).norm() / W.norm()

    print(f"\nPure HINT4: error={err_pure:.4f} ({err_pure*100:.2f}%)")
    print(f"HINT4+residual: error={err_res:.4f} ({err_res*100:.2f}%)")
    print(f"Error improvement: {err_pure/err_res:.2f}x")

    # Residual should significantly reduce error
    assert err_res < err_pure, "Residual should reduce error"
    # Should be under 10% (down from ~18%)
    assert err_res < 0.10, f"HINT4+residual error {err_res:.4f} >= 10%"


def test_hint4_residual_compression_ratio():
    """Compression tradeoff of HINT4+residual vs INT8 and pure HINT4.

    Math reality (do the math by hand): the residual is a FULL out×in INT4
    tensor (0.5 bytes/element). For HINT4+res to be smaller than INT8 NLRQ we
    would need  out*in < rank*(out+in) - 8*rank² , whose RHS maxes at
    (out+in)²/32 — far below out*in for any practical rank. So a dense INT4
    residual is ALWAYS larger than INT8 low-rank factors.

    The real tradeoff is: pure HINT4 beats INT8 on CR (2x factor savings) but
    has ~18% error; HINT4+residual trades that CR back for ~3-5% error. This
    test documents the honest relationship instead of asserting an impossible
    "HINT4+res < INT8" claim.
    """
    out_features, in_features, rank = 2048, 8192, 512
    torch.manual_seed(0)
    W = torch.randn(out_features, in_features, dtype=torch.float32, device=DEVICE) * 0.02

    layer_int8 = NLRQLinear(in_features, out_features, rank=rank, factor_bits=8)
    layer_hint4_pure = NLRQLinear.from_dense_hadamard_int4(W, rank=rank, use_residual=False)
    layer_hint4_res = NLRQLinear.from_dense_hadamard_int4(W, rank=rank, use_residual=True)

    bytes_int8 = layer_int8.compressed_storage_bytes()
    bytes_pure = layer_hint4_pure.compressed_storage_bytes()
    bytes_res = layer_hint4_res.compressed_storage_bytes()
    dense_bytes = layer_int8.dense_storage_bytes()

    print(f"Dense:       {dense_bytes}")
    print(f"INT8:        {bytes_int8}  (CR={dense_bytes/bytes_int8:.2f}x)")
    print(f"HINT4 pure:  {bytes_pure}  (CR={dense_bytes/bytes_pure:.2f}x)")
    print(f"HINT4+res:   {bytes_res}  (CR={dense_bytes/bytes_res:.2f}x)")

    # 1. Pure HINT4 beats INT8 on compression (the whole point of INT4 factors)
    assert bytes_pure < bytes_int8, "Pure HINT4 should be smaller than INT8"
    # 2. HINT4+residual still compresses vs dense (residual is INT4, not bf16)
    assert bytes_res < dense_bytes, "HINT4+residual should still beat dense bf16"
    # 3. Residual adds storage over pure HINT4 (documenting the tradeoff)
    assert bytes_res > bytes_pure, "Residual should add storage over pure HINT4"
    # 4. Residual buffers are actually populated
    assert layer_hint4_res.residual_q is not None
    assert layer_hint4_res.residual_scales is not None
    assert layer_hint4_res.residual_q.abs().sum() > 0, "Residual should be non-zero"


if __name__ == "__main__":
    pytest.main([__file__, "-v", "--tb=short"])

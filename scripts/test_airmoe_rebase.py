"""AirMoE LoRA rebase correctness test (plan §13.6). CUDA.

Tests whether a LoRA expert delta survives a parent update correctly.

LoRA: W_effective = W_parent + alpha * B @ A
Expert delta: D = alpha * B @ A (the LoRA adapter, independent of W_parent)

Question: when parent W_parent -> W_parent', does the expert delta need rebasing?

Hypothesis: NO — LoRA is additive and independent of W_parent. The expert's
contribution (B@A) is the same regardless of W_parent. Only direct weight
modifications (not LoRA) need rebasing.

Test:
  1. Create parent W, expert LoRA (B, A), compute W_eff = W + alpha*B@A
  2. Update parent W -> W' (simulate training: W' = W + delta_W)
  3. New effective: W'_eff = W' + alpha*B@A (same LoRA, new parent)
  4. Compare to "rebased" LoRA: does any rebase formula do better?
  5. Test with merge: if we merge expert into parent, then train parent, then
     want to recover the expert — does the delta survive?

Also tests: non-LoRA expert (direct weight modification) to show it DOES need
rebase (contrast case).

Runs on CUDA.
"""
import torch
import torch.nn.functional as F

DEV = torch.device('cuda' if torch.cuda.is_available() else 'cpu')
print(f"Device: {DEV}")


def rel_err(a, b):
    return (a.float() - b.float()).norm().item() / (a.float().norm().item() + 1e-12)


def test_lora_rebase():
    """Test 1: LoRA expert survives parent update without rebase."""
    torch.manual_seed(42)
    m, n, rank, alpha = 2048, 8192, 32, 16.0

    # Parent weight (trained-like)
    W = torch.randn(m, n, device=DEV) * 0.02

    # Expert LoRA: B [m, rank], A [rank, n]
    B = torch.randn(m, rank, device=DEV) * 0.01
    A = torch.randn(rank, n, device=DEV) * 0.01
    delta = alpha * B @ A  # the LoRA contribution

    # W with expert = W + delta
    W_with_expert = W + delta

    # Parent trains: W -> W' (small update)
    delta_W = torch.randn(m, n, device=DEV) * 0.005  # training update
    W_prime = W + delta_W

    # Option A: keep same LoRA on new parent
    W_prime_with_same_lora = W_prime + delta

    # Option B: "rebase" — subtract old parent's residual (wrong for LoRA?)
    # If expert was a DIRECT modification: expert_W = W_with_expert, rebase = W_with_expert - W_prime
    # For LoRA: the delta is independent, so rebase should be identity
    rebased_delta = delta  # no change needed for LoRA
    W_prime_with_rebased = W_prime + rebased_delta

    # They should be identical (LoRA is parent-independent)
    err_same_vs_rebased = rel_err(W_prime_with_same_lora, W_prime_with_rebased)

    # What we WANT: W_prime + delta should be close to "W_with_expert + delta_W"
    # (i.e., the expert's effect is preserved AND the parent's training is applied)
    ideal = W_with_expert + delta_W
    err_lora = rel_err(W_prime_with_same_lora, ideal)

    print(f"{'='*60}")
    print("Test 1: LoRA expert + parent update")
    print(f"{'='*60}")
    print(f"  LoRA delta norm: {delta.norm():.4f}")
    print(f"  Parent update norm: {delta_W.norm():.4f}")
    print(f"  Same-LoRA vs rebased-LoRA: {err_same_vs_rebased:.6f} (should be ~0)")
    print(f"  LoRA on new parent vs ideal: {err_lora:.6f} (should be ~0)")
    print(f"  VERDICT: LoRA is parent-independent, NO rebase needed. ✓")


def test_direct_mod_rebase():
    """Test 2: Direct weight modification DOES need rebase (contrast)."""
    torch.manual_seed(42)
    m, n = 2048, 8192

    W = torch.randn(m, n, device=DEV) * 0.02
    # Direct modification: expert modifies W directly
    expert_mod = torch.randn(m, n, device=DEV) * 0.01
    W_with_expert = W + expert_mod  # the "expert" is baked into W

    # Parent trains: W -> W' (but expert was on OLD W)
    delta_W = torch.randn(m, n, device=DEV) * 0.005
    W_prime = W + delta_W

    # If we just apply expert_mod to W_prime, we get W_prime + expert_mod
    # But the "correct" answer is W_with_expert + delta_W = W + expert_mod + delta_W
    # = W_prime + expert_mod. So actually... it's the same!
    naive = W_prime + expert_mod
    ideal = W_with_expert + delta_W
    err = rel_err(naive, ideal)

    print(f"\n{'='*60}")
    print("Test 2: Direct modification + parent update")
    print(f"{'='*60}")
    print(f"  Naive (apply old mod to new parent) vs ideal: {err:.6f}")
    print(f"  VERDICT: Direct mod is ALSO parent-independent (additive).")
    print(f"  Rebase is only needed if expert REPLACES weights, not ADDS.")


def test_merge_then_recover():
    """Test 3: Merge expert into parent, train parent, recover expert."""
    torch.manual_seed(42)
    m, n, rank, alpha = 2048, 8192, 32, 16.0

    W = torch.randn(m, n, device=DEV) * 0.02
    B = torch.randn(m, rank, device=DEV) * 0.01
    A = torch.randn(rank, n, device=DEV) * 0.01
    delta = alpha * B @ A

    # Merge expert into parent
    W_merged = W + delta

    # Train the merged parent (changes ALL of W_merged, including the delta region)
    delta_train = torch.randn(m, n, device=DEV) * 0.003
    W_trained = W_merged + delta_train

    # Now we want to "recover" the expert: extract the expert's contribution
    # The expert was delta = alpha*B@A. After training, W_trained = W + delta + delta_train
    # To recover the expert, we need to separate delta from delta_train.
    # We can't — they're entangled. But we can re-extract the LoRA by projecting:
    # delta_recovered = W_trained - W_original (but we don't have W_original in practice)
    # In practice: delta_recovered = W_trained - W (if we kept the pre-merge parent)

    # If we kept pre-merge parent W:
    delta_recovered = W_trained - W  # = delta + delta_train
    err_recovery = rel_err(delta_recovered, delta)

    # The recovered delta includes training noise. Project onto LoRA rank-r subspace:
    U, S, Vh = torch.linalg.svd(delta_recovered.float(), full_matrices=False)
    delta_projected = (U[:, :rank] * S[:rank]) @ Vh[:rank, :]
    err_projected = rel_err(delta_projected, delta)

    print(f"\n{'='*60}")
    print("Test 3: Merge expert → train parent → recover expert")
    print(f"{'='*60}")
    print(f"  Original delta norm: {delta.norm():.4f}")
    print(f"  Training noise norm: {delta_train.norm():.4f}")
    print(f"  Recovered (W_trained - W) err vs original: {err_recovery:.4f}")
    print(f"  Projected to rank-{rank} err vs original: {err_projected:.4f}")
    print(f"  VERDICT: Recovery is lossy (training noise entangled).")
    print(f"  Rank-{rank} projection recovers {'well' if err_projected < 0.3 else 'poorly'}.")
    print(f"  BETTER APPROACH: don't merge experts into parent. Keep them as")
    print(f"  separate LoRA adapters. Parent trains independently, experts stay intact.")


def test_rebase_when_parent_absorbs():
    """Test 4: The real rebase scenario — parent absorbs expert knowledge via merge,
    then we want to extract the RESIDUAL expert (what the expert adds beyond
    what the parent now knows)."""
    torch.manual_seed(42)
    m, n, rank, alpha = 2048, 8192, 32, 16.0

    W = torch.randn(m, n, device=DEV) * 0.02
    B = torch.randn(m, rank, device=DEV) * 0.01
    A = torch.randn(rank, n, device=DEV) * 0.01
    delta = alpha * B @ A

    # Merge expert into parent (parent absorbs the knowledge)
    W_absorbed = W + delta

    # Now the expert's knowledge is in the parent. The expert should become
    # the RESIDUAL: what it adds on top of the NEW parent.
    # New expert delta = old_delta - (W_absorbed - W) = old_delta - old_delta = 0
    # This is correct: once merged, the expert adds nothing (it's in the parent).

    # But if parent trains FURTHER after absorbing:
    delta_train = torch.randn(m, n, device=DEV) * 0.002
    W_trained = W_absorbed + delta_train

    # The expert's knowledge is now W_trained - W (approximately delta + delta_train)
    # To get the "pure" expert back, project onto LoRA rank-r:
    full_delta = W_trained - W
    U, S, Vh = torch.linalg.svd(full_delta.float(), full_matrices=False)
    delta_pure = (U[:, :rank] * S[:rank]) @ Vh[:rank, :]
    err_pure = rel_err(delta_pure, delta)

    print(f"\n{'='*60}")
    print("Test 4: Rebase after parent absorbs expert (the real scenario)")
    print(f"{'='*60}")
    print(f"  After merge + train, rank-{rank} projection of full delta:")
    print(f"    err vs original expert: {err_pure:.4f}")
    print(f"  VERDICT: Rebase via rank-r projection recovers the expert")
    print(f"  {'well' if err_pure < 0.2 else 'poorly'} (training noise is higher-rank,")
    print(f"  projects out). This is the correct rebase protocol for AirMoE.")

    if DEV.type == 'cuda':
        torch.cuda.empty_cache()


if __name__ == "__main__":
    print("=" * 70)
    print("AirMoE LoRA rebase correctness test (plan §13.6)")
    print("=" * 70)
    test_lora_rebase()
    test_direct_mod_rebase()
    test_merge_then_recover()
    test_rebase_when_parent_absorbs()
    print(f"\n{'='*70}")
    print("CONCLUSION:")
    print("1. LoRA experts are parent-INDEPENDENT (additive). No rebase needed")
    print("   when parent trains — the LoRA delta stays valid.")
    print("2. Don't merge experts into parent (entangles delta with training).")
    print("3. If merge happens, rank-r projection recovers the expert (rebase).")
    print("4. AirMoE design: keep experts as separate LoRA adapters, never merge.")
    print("   Parent trains freely, experts stay valid. ✓")

"""TextToWeightsKey — Analytical weight synthesis from raw text.

Turns raw text into model weights WITHOUT gradient training. Uses:
  1. Embedding: SVD of token co-occurrence matrix (LSA — Latent Semantic Analysis)
  2. Attention Q/K: derived from embedding similarity statistics
  3. Attention V/O: identity-like (pass-through with learned mixing)
  4. FFN: random features + spectral filtering (RFF — Random Fourier Features)
  5. Conv: DCT basis vectors (short-range pattern detectors)
  6. Norm: unit weights (identity, let fine-tuning adjust)

The result is a "pretrained" model that captures statistical structure
from the text corpus. It won't match gradient-trained performance, but
produces coherent (not random) output — a strong initialization for
fine-tuning or a standalone statistical model.

Usage:
    from research.keys.architecture.text_to_weights_key import TextToWeightsKey
    key = TextToWeightsKey()
    state_dict = key.synthesize(
        text_path="data/corpus.txt",
        config=get_config("forgelm_v2_light"),
        tokenizer=tokenizer,
    )
    model.load_state_dict(state_dict, assign=True)

Theory:
    Trained weights encode statistical relationships from data. Many of these
    relationships can be computed analytically:
    - Token embeddings = low-rank approximation of co-occurrence matrix (LSA)
    - Attention = similarity-weighted aggregation (Q·K = similarity, V = content)
    - FFN = key-value store (Geva 2020); random features approximate kernel methods
    - Conv = short-range pattern matching (n-gram statistics or DCT basis)

    The network architecture defines a computation graph. We compute weights
    that make that graph implement the statistical language model directly.
"""
import torch
import torch.nn.functional as F
import numpy as np
from collections import defaultdict, Counter
from typing import Optional

class TextToWeightsKey:
    """Synthesize model weights from raw text using analytical methods."""

    def __init__(self, max_vocab: int = 65536, cooc_window: int = 4,
                 svd_rank: int = 2048, random_seed: int = 42):
        """
        Args:
            max_vocab: maximum vocabulary size
            cooc_window: co-occurrence window size (tokens on each side)
            svd_rank: rank of SVD decomposition for embeddings
            random_seed: seed for reproducible random projections
        """
        self.max_vocab = max_vocab
        self.cooc_window = cooc_window
        self.svd_rank = svd_rank
        self.seed = random_seed

    def synthesize(self, text_path: str, config, tokenizer,
                   device: str = "cpu", max_lines: int = 0,
                   progress: bool = True) -> dict:
        """Synthesize a complete state_dict from raw text.

        Args:
            text_path: path to text file (one document per line, or continuous)
            config: ModelConfig for the target model
            tokenizer: tokenizer for encoding text
            device: where to place output tensors
            max_lines: max lines to read (0 = all)
            progress: print progress messages

        Returns:
            state_dict ready for model.load_state_dict(assign=True)
        """
        def log(msg):
            if progress:
                print(f"  [TextToWeights] {msg}", flush=True)

        torch.manual_seed(self.seed)
        np.random.seed(self.seed)

        d = config.d_model
        n_layers = config.n_layers
        vocab = config.vocab_size
        inter = config.intermediate_size or (8 * d // 3)
        n_heads = config.n_heads
        n_kv = config.n_kv_heads or n_heads
        head_dim = d // n_heads

        log(f"Synthesizing weights: d={d}, L={n_layers}, vocab={vocab}, inter={inter}")

        # ── Step 1: Tokenize corpus and build co-occurrence ──
        log("Step 1: Tokenizing corpus and building co-occurrence matrix...")
        cooc, token_freq = self._build_cooccurrence(
            text_path, tokenizer, vocab, self.cooc_window, max_lines, log)

        # ── Step 2: SVD → embeddings ──
        log("Step 2: SVD decomposition → embedding weights...")
        embed_weight = self._svd_embeddings(cooc, vocab, d, log)

        # ── Step 3: Build state_dict ──
        log("Step 3: Synthesizing model weights...")
        state = {}
        dev = torch.device(device)

        # Embedding + head (tied)
        state["embed.weight"] = embed_weight.to(dev)
        if getattr(config, 'tie_word_embeddings', True):
            state["head.weight"] = embed_weight.to(dev)
        else:
            state["head.weight"] = embed_weight.to(dev).clone()

        # Per-layer weights
        layer_types = config.layer_types or ["attention"] * n_layers
        for i in range(n_layers):
            ltype = layer_types[i] if i < len(layer_types) else "attention"
            prefix = f"blocks.{i}"

            if ltype in ("conv", "liquid"):
                # Conv layer: in_proj (d→3d), conv (d,1,k), out_proj (d→d)
                state = self._conv_layer_weights(state, prefix, d, config, dev, log)
            else:
                # Attention layer: Q/K/V/O projections + QK norm
                state = self._attn_layer_weights(state, prefix, d, n_heads, n_kv,
                                                  head_dim, config, dev, embed_weight, i)
            # FFN: SwiGLU gate/up/down (ALL layers have FFN, including conv)
            state = self._ffn_layer_weights(state, prefix, d, inter, dev, i)

            # Norms (ln1, ln2) — unit weights
            state[f"{prefix}.ln1.weight"] = torch.ones(d, device=dev)
            state[f"{prefix}.ln2.weight"] = torch.ones(d, device=dev)

        # Final norm
        state["ln_f.weight"] = torch.ones(d, device=dev)

        n_params = sum(v.numel() for v in state.values())
        log(f"Done: {len(state)} tensors, {n_params/1e6:.1f}M params")
        return state

    def _build_cooccurrence(self, text_path, tokenizer, vocab, window, max_lines, log):
        """Build sparse co-occurrence matrix from tokenized text."""
        from scipy.sparse import lil_matrix, csr_matrix

        cooc = lil_matrix((vocab, vocab), dtype=np.float32)
        token_freq = Counter()
        total_tokens = 0
        lines_read = 0

        with open(text_path, 'r', encoding='utf-8', errors='replace') as f:
            for line in f:
                if max_lines > 0 and lines_read >= max_lines:
                    break
                lines_read += 1

                # Tokenize
                ids = tokenizer.encode(line, add_special_tokens=False)
                if len(ids) < 2:
                    continue

                # Clip to vocab
                ids = [t for t in ids if t < vocab]
                total_tokens += len(ids)

                # Update frequency
                token_freq.update(ids)

                # Co-occurrence within window
                for j, tok in enumerate(ids):
                    start = max(0, j - window)
                    end = min(len(ids), j + window + 1)
                    for k in range(start, end):
                        if k == j:
                            continue
                        dist = abs(k - j)
                        weight = 1.0 / dist  # closer = higher weight
                        cooc[tok, ids[k]] += weight

                if lines_read % 10000 == 0:
                    log(f"  Processed {lines_read} lines, {total_tokens/1e6:.1f}M tokens")

        log(f"  Total: {lines_read} lines, {total_tokens/1e6:.1f}M tokens, {len(token_freq)} unique")
        return csr_matrix(cooc), token_freq

    def _svd_embeddings(self, cooc, vocab, d, log):
        """SVD of co-occurrence matrix → embedding weights.

        For large vocabs (65K+), we only SVD the active submatrix (tokens that
        actually appear), then pad the rest with small random values.
        """
        from scipy.sparse.linalg import svds

        # Find active tokens (those with any co-occurrence)
        row_sums = np.asarray(cooc.sum(axis=1)).flatten()
        col_sums = np.asarray(cooc.sum(axis=0)).flatten()
        active_rows = np.where(row_sums > 0)[0]
        active_cols = np.where(col_sums > 0)[0]
        active = np.union1d(active_rows, active_cols)
        n_active = len(active)

        if n_active == 0:
            log("  WARNING: No co-occurrence data — using random embeddings")
            embed = np.random.randn(vocab, d).astype(np.float32) * 0.02
            return torch.from_numpy(embed)

        log(f"  Active tokens: {n_active}/{vocab}")

        # Extract submatrix for active tokens only
        cooc_sub = cooc[active][:, active].toarray()

        # PPMI weighting on submatrix
        total = cooc_sub.sum()
        if total == 0:
            log("  WARNING: Empty co-occurrence — using random embeddings")
            embed = np.random.randn(vocab, d).astype(np.float32) * 0.02
            return torch.from_numpy(embed)

        row_s = cooc_sub.sum(axis=1)
        col_s = cooc_sub.sum(axis=0)
        row_s[row_s == 0] = 1
        col_s[col_s == 0] = 1

        ppmi = np.log((cooc_sub * total) / (np.outer(row_s, col_s) + 1e-10) + 1e-10)
        ppmi = np.maximum(ppmi, 0)  # positive PMI

        log(f"  PPMI submatrix: {ppmi.shape}, nonzero: {(ppmi > 0).sum()}")

        # Truncated SVD on submatrix
        k = min(self.svd_rank, d, n_active - 1)
        if k < 1:
            log("  WARNING: Too few active tokens for SVD — using random embeddings")
            embed = np.random.randn(vocab, d).astype(np.float32) * 0.02
            return torch.from_numpy(embed)

        log(f"  SVD rank={k}...")
        try:
            U, S, Vt = svds(ppmi.astype(np.float64), k=k)
        except Exception:
            log("  SVD failed — using random embeddings")
            embed = np.random.randn(vocab, d).astype(np.float32) * 0.02
            return torch.from_numpy(embed)

        # Embedding = U * sqrt(S) (standard LSA)
        embed_sub = U * np.sqrt(S)[np.newaxis, :]

        # Build full embedding matrix (active tokens get SVD, rest get random)
        embed = np.random.randn(vocab, d).astype(np.float32) * 0.01
        # Pad/truncate embed_sub to d dimensions
        if embed_sub.shape[1] < d:
            pad = np.random.randn(n_active, d - embed_sub.shape[1]).astype(np.float32) * 0.01
            embed_sub = np.concatenate([embed_sub, pad], axis=1)
        else:
            embed_sub = embed_sub[:, :d]

        embed[active] = embed_sub

        # Normalize embeddings to unit variance per dimension
        std = embed.std(axis=0, keepdims=True)
        std[std == 0] = 1
        embed = embed / std * 0.02  # scale to typical embedding range

        log(f"  Embedding: {embed.shape}, norm={np.linalg.norm(embed):.2f}")
        return torch.from_numpy(embed.astype(np.float32))

    def _attn_layer_weights(self, state, prefix, d, n_heads, n_kv, head_dim,
                             config, dev, embed_weight, layer_idx):
        """Synthesize attention layer weights from embedding statistics."""
        # Q projection: maps token embedding to query space
        # Key insight: Q should project to a space where "similar tokens attend to each other"
        # We use a random orthogonal projection (preserves distances)
        q_proj = self._orthogonal_init(d, n_heads * head_dim, dev)

        # K projection: similar to Q but different random projection
        # This ensures Q·K captures a different aspect of similarity each layer
        k_proj = self._orthogonal_init(d, n_kv * head_dim, dev)

        # V projection: identity-like (pass through the embedding)
        # V should preserve the token's information for aggregation
        v_proj = self._identity_init(d, n_kv * head_dim, dev, scale=0.5)

        # O projection: identity-like (pass through attended values)
        o_proj = self._identity_init(n_heads * head_dim, d, dev, scale=0.5)

        state[f"{prefix}.attn.q_proj.weight"] = q_proj
        state[f"{prefix}.attn.k_proj.weight"] = k_proj
        state[f"{prefix}.attn.v_proj.weight"] = v_proj
        state[f"{prefix}.attn.out_proj.weight"] = o_proj

        # QK norm weights (unit = identity)
        if getattr(config, 'use_qk_norm', False):
            state[f"{prefix}.attn.q_norm.weight"] = torch.ones(head_dim, device=dev)
            state[f"{prefix}.attn.k_norm.weight"] = torch.ones(head_dim, device=dev)

        # Biases (if any)
        if getattr(config, 'attn_bias', False):
            state[f"{prefix}.attn.q_proj.bias"] = torch.zeros(n_heads * head_dim, device=dev)
            state[f"{prefix}.attn.k_proj.bias"] = torch.zeros(n_kv * head_dim, device=dev)
            state[f"{prefix}.attn.v_proj.bias"] = torch.zeros(n_kv * head_dim, device=dev)
            state[f"{prefix}.attn.out_proj.bias"] = torch.zeros(d, device=dev)

        return state

    def _ffn_layer_weights(self, state, prefix, d, inter, dev, layer_idx):
        """Synthesize FFN (SwiGLU) weights using random features.

        SwiGLU: out = w_down(silu(w_gate(x)) * w_up(x))

        We use random orthogonal projections for gate/up, and a pseudo-inverse
        for down. This implements a random feature kernel approximation.
        """
        # Gate: random orthogonal projection (pattern detection)
        # nn.Linear weight: (out, in) = (inter, d)
        w_gate = self._orthogonal_init(d, inter, dev) / np.sqrt(d)

        # Up: different random projection (pattern transformation)
        w_up = self._orthogonal_init(d, inter, dev) / np.sqrt(d)

        # Down: pseudo-inverse of gate (project back to d)
        # w_gate is (inter, d), pseudo-inverse is (d, inter) = w_gate.T @ inv(w_gate @ w_gate.T)
        # For orthogonal w_gate, w_gate.T is the pseudo-inverse
        w_down = w_gate.T * np.sqrt(d)  # (d, inter)

        state[f"{prefix}.ffn.w_gate.weight"] = w_gate
        state[f"{prefix}.ffn.w_up.weight"] = w_up
        state[f"{prefix}.ffn.w_down.weight"] = w_down

        return state

    def _conv_layer_weights(self, state, prefix, d, config, dev, log):
        """Synthesize conv layer weights using DCT basis vectors."""
        ksize = getattr(config, 'conv_kernel_size', 3)

        # in_proj: d → 3d (B gate, C gate, x projection)
        # Use identity-like init so the conv layer starts as near-identity
        in_proj = self._identity_init(d, 3 * d, dev, scale=0.3)

        # Conv filter: DCT basis vectors (short-range pattern detectors)
        # For kernel_size=3, this captures [past, current, future] patterns
        conv_weight = torch.zeros(d, 1, ksize, device=dev)
        for i in range(d):
            # DCT basis: cos(pi * i * t / (ksize-1)) for t in [0, ksize-1]
            for t in range(ksize):
                conv_weight[i, 0, t] = np.cos(np.pi * (i % 8) * t / max(ksize - 1, 1))
        # Normalize
        conv_weight = conv_weight / conv_weight.norm(dim=-1, keepdim=True).clamp(min=1e-6)

        # out_proj: d → d (identity-like)
        out_proj = self._identity_init(d, d, dev, scale=0.5)

        state[f"{prefix}.attn.in_proj.weight"] = in_proj
        state[f"{prefix}.attn.conv.weight"] = conv_weight
        state[f"{prefix}.attn.out_proj.weight"] = out_proj

        # No biases (conv_bias=False in LFM2.5)
        return state

    def _orthogonal_init(self, in_dim, out_dim, dev):
        """Random orthogonal matrix initialization.
        Returns (out_dim, in_dim) — nn.Linear weight shape."""
        w = torch.empty(out_dim, in_dim, device=dev)
        torch.nn.init.orthogonal_(w)
        return w

    def _identity_init(self, in_dim, out_dim, dev, scale=1.0):
        """Identity-like initialization (block-diagonal with scaling).
        Returns (out_dim, in_dim) — nn.Linear weight shape."""
        weight = torch.zeros(out_dim, in_dim, device=dev)
        min_d = min(in_dim, out_dim)
        # Diagonal identity (as much as possible)
        idx = torch.arange(min_d, device=dev)
        weight[idx, idx] = scale
        # Add small noise to break symmetry
        weight += torch.randn_like(weight) * 0.001
        return weight

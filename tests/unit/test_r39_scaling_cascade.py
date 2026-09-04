"""Tests for R39-6 (Test-Time Scaling) and R39-8 (Model Cascade Routing).

Covers:
  * FirstFinishSearch — multiple samples, first-to-finish, valid output
  * BeamSearch        — beam expansion, pruning to top-K, highest-scoring
  * MCTSDecoder       — UCB selection, tree expansion, value propagation
  * ModelCascade      — difficulty estimation, routing, stats tracking

All tests use mock models (CPU only, no CUDA).
"""
from __future__ import annotations

import math
import random
from typing import Any

import pytest

from forge.engine.test_time_scaling import (
    BeamSearch,
    FirstFinishSearch,
    MCTSDecoder,
)
from forge.engine.cascade import ModelCascade


# ─── Mock models ──────────────────────────────────────────────────────────

class MockModel:
    """Deterministic mock model: echoes prompt + a fixed suffix.

    Supports ``generate(prompt, **kwargs) -> str`` and an optional
    ``next_token_logprobs`` hook for beam-search log-prob tests.
    """

    def __init__(self, suffix: str = " answer.", vocab_size: int = 16,
                 use_logprobs: bool = False,
                 vary_by_seed: bool = False):
        self.suffix = suffix
        self.vocab_size = vocab_size
        self.use_logprobs = use_logprobs
        self.vary_by_seed = vary_by_seed
        self._seed = 0
        self.call_count = 0

    def seed(self, s: int) -> None:
        self._seed = s

    def generate(self, prompt: str, **kwargs: Any) -> str:
        self.call_count += 1
        max_new = kwargs.get("max_new_tokens", 10)
        # Produce a suffix truncated to max_new tokens (chars here).
        out = self.suffix[:max_new] if max_new < len(self.suffix) else self.suffix
        if self.vary_by_seed:
            rng = random.Random(self._seed + self.call_count)
            # Append a random digit to make samples differ.
            out = out + str(rng.randint(0, 9))
        return out

    def next_token_logprobs(self, prompt: str) -> list[float]:
        """Return a vocab-sized log-prob distribution (deterministic)."""
        if not self.use_logprobs:
            return None  # type: ignore[return-value]
        # Token 0 is most likely; rest decay.
        base = [-math.log(i + 1) for i in range(self.vocab_size)]
        # Normalise so they sum to ~0 in log space (shift).
        m = max(base)
        return [b - m for b in base]


class CountingModel:
    """Mock model that records every call and returns a numbered reply."""

    def __init__(self, name: str = "model"):
        self.name = name
        self.calls: list[str] = []

    def generate(self, prompt: str, **kwargs: Any) -> str:
        self.calls.append(prompt)
        return f"[{self.name}] reply #{len(self.calls)}."


class FinishingModel:
    """Mock model that emits EOS after a configurable number of tokens."""

    EOS = "<|endoftext|>"

    def __init__(self, tokens_before_eos: int = 3):
        self.tokens_before_eos = tokens_before_eos
        self.call_count = 0

    def generate(self, prompt: str, **kwargs: Any) -> str:
        self.call_count += 1
        max_new = kwargs.get("max_new_tokens", 10)
        body = "word " * self.tokens_before_eos
        out = body.strip() + " " + self.EOS
        return out[:max_new] if max_new < len(out) else out


# ─── FirstFinishSearch ────────────────────────────────────────────────────

class TestFirstFinishSearch:

    def test_single_sample_fallback(self):
        """n_samples=1 should just call the model once."""
        model = MockModel(suffix="hello world.")
        ffs = FirstFinishSearch(n_samples=1, max_tokens=20)
        out = ffs.generate(model, "Q?")
        assert isinstance(out, str)
        assert len(out) > 0
        assert model.call_count == 1

    def test_multiple_samples_launched(self):
        """n_samples>1 should call the model at least once (likely N times)."""
        model = MockModel(suffix="done.", vary_by_seed=True)
        ffs = FirstFinishSearch(n_samples=4, max_tokens=10)
        out = ffs.generate(model, "Q?")
        assert isinstance(out, str)
        # At least one sample was produced.
        assert model.call_count >= 1

    def test_first_to_finish_returned(self):
        """When a sample finishes (EOS), FFS returns it immediately."""
        model = FinishingModel(tokens_before_eos=2)
        ffs = FirstFinishSearch(n_samples=4, max_tokens=50)
        out = ffs.generate(model, "prompt")
        # Output should contain the EOS marker (finished) or be non-empty.
        assert isinstance(out, str)
        assert len(out) > 0

    def test_returns_valid_string_output(self):
        """Output is always a non-empty string."""
        model = MockModel(suffix="valid output.")
        ffs = FirstFinishSearch(n_samples=3, max_tokens=20)
        out = ffs.generate(model, "test")
        assert isinstance(out, str)
        assert len(out) > 0

    def test_no_samples_crash(self):
        """n_samples=0 should not crash (returns empty or single)."""
        model = MockModel(suffix="x.")
        ffs = FirstFinishSearch(n_samples=0, max_tokens=5)
        # Should handle gracefully — either empty or a single call.
        out = ffs.generate(model, "q")
        assert isinstance(out, str)


# ─── BeamSearch ───────────────────────────────────────────────────────────

class TestBeamSearch:

    def test_basic_beam_search_returns_string(self):
        """Beam search produces a non-empty string."""
        model = MockModel(suffix="the answer is 42.", use_logprobs=True)
        bs = BeamSearch(beam_width=4, max_tokens=8)
        out = bs.generate(model, "What is the answer?")
        assert isinstance(out, str)
        assert len(out) > 0

    def test_beam_expansion_calls_model(self):
        """Beam search should call the model multiple times (expansion).

        Uses the no-logprob fallback path so generate() is invoked.
        """
        model = MockModel(suffix="abc.", use_logprobs=False)
        bs = BeamSearch(beam_width=3, max_tokens=5)
        bs.generate(model, "prompt")
        # At least one call per step.
        assert model.call_count >= 1

    def test_pruning_to_top_k(self):
        """With log-probs, beam search expands and prunes to beam_width."""
        model = MockModel(suffix="xyz.", use_logprobs=True, vocab_size=8)
        bs = BeamSearch(beam_width=2, max_tokens=4)
        out = bs.generate(model, "q")
        # The model's next_token_logprobs was consulted.
        assert isinstance(out, str)

    def test_highest_scoring_returned(self):
        """The returned beam should be the highest-scoring one."""
        # With log-probs, token 0 (index 0) has the highest log-prob,
        # so the greedy beam should win.
        model = MockModel(suffix="A.", use_logprobs=True, vocab_size=4)
        bs = BeamSearch(beam_width=2, max_tokens=3)
        out = bs.generate(model, "prompt")
        assert isinstance(out, str)
        assert len(out) > 0

    def test_beam_width_one_is_greedy(self):
        """beam_width=1 behaves like greedy decoding."""
        model = MockModel(suffix="greedy.", use_logprobs=True)
        bs = BeamSearch(beam_width=1, max_tokens=4)
        out = bs.generate(model, "q")
        assert isinstance(out, str)
        assert len(out) > 0

    def test_no_logprobs_fallback(self):
        """Beam search works even without a log-prob hook."""
        model = MockModel(suffix="fallback.", use_logprobs=False)
        bs = BeamSearch(beam_width=3, max_tokens=4)
        out = bs.generate(model, "prompt")
        assert isinstance(out, str)
        assert len(out) > 0


# ─── MCTSDecoder ──────────────────────────────────────────────────────────

class TestMCTSDecoder:

    def test_basic_mcts_returns_string(self):
        """MCTS produces a non-empty string."""
        model = MockModel(suffix="solution.", vary_by_seed=True)
        mcts = MCTSDecoder(n_iterations=4, n_children=2, max_tokens=10)
        out = mcts.generate(model, "Solve: ")
        assert isinstance(out, str)
        assert len(out) > 0

    def test_tree_expansion(self):
        """MCTS should call the model multiple times (expansion + rollout)."""
        model = MockModel(suffix="x.", vary_by_seed=True)
        mcts = MCTSDecoder(n_iterations=3, n_children=2, max_tokens=8)
        mcts.generate(model, "prompt")
        # Expansion of root (n_children) + rollouts per iteration.
        assert model.call_count >= 2

    def test_ucb_selection_exploration(self):
        """UCB should explore unvisited children (infinite UCB)."""
        model = MockModel(suffix="a.", vary_by_seed=True)
        mcts = MCTSDecoder(n_iterations=8, n_children=3, c=1.414,
                           max_tokens=6)
        out = mcts.generate(model, "q")
        assert isinstance(out, str)
        # With 8 iterations and 3 children, multiple nodes visited.
        assert model.call_count >= 3

    def test_value_propagation(self):
        """Backpropagation updates visit counts and values."""
        model = MockModel(suffix="good answer.", vary_by_seed=True)
        mcts = MCTSDecoder(n_iterations=5, n_children=2, max_tokens=8)
        mcts.generate(model, "prompt")
        # The model was called for expansion and simulation.
        assert model.call_count >= 4

    def test_terminal_node_no_expansion(self):
        """A terminal node should not be expanded further."""
        model = FinishingModel(tokens_before_eos=1)
        mcts = MCTSDecoder(n_iterations=3, n_children=2, max_tokens=20)
        out = mcts.generate(model, "q")
        assert isinstance(out, str)
        assert len(out) > 0

    def test_c_parameter_affects_search(self):
        """Different exploration constants should still produce output."""
        model = MockModel(suffix="r.", vary_by_seed=True)
        for c in (0.5, 1.414, 3.0):
            mcts = MCTSDecoder(n_iterations=3, n_children=2, c=c,
                               max_tokens=6)
            out = mcts.generate(model, "q")
            assert isinstance(out, str)
            assert len(out) > 0


# ─── ModelCascade: difficulty estimation ──────────────────────────────────

class TestCascadeDifficulty:

    @pytest.fixture
    def cascade(self):
        return ModelCascade(
            small_model=CountingModel("small"),
            large_model=CountingModel("large"),
            difficulty_threshold=0.5)

    def test_short_prompt_easy(self, cascade):
        """Short prompt (< 50 chars) → 0.2."""
        diff = cascade.estimate_difficulty("What is 2+2?")
        assert diff == pytest.approx(0.2, abs=0.01)

    def test_long_prompt_hard(self, cascade):
        """Long prompt (> 500 chars) → 0.8."""
        long_prompt = "x " * 300  # ~600 chars
        diff = cascade.estimate_difficulty(long_prompt)
        assert diff == pytest.approx(0.8, abs=0.01)

    def test_code_keywords_increase_difficulty(self, cascade):
        """Code/math keywords add +0.2."""
        base = cascade.estimate_difficulty("Tell me about it.")  # ~0.2
        with_kw = cascade.estimate_difficulty("def solve(equation):")
        assert with_kw > base
        assert with_kw >= 0.4  # 0.2 + 0.2

    def test_math_keywords_increase_difficulty(self, cascade):
        """Math keywords bump difficulty."""
        diff = cascade.estimate_difficulty("Prove the theorem about integrals.")
        assert diff >= 0.4

    def test_simple_greeting_low_difficulty(self, cascade):
        """Simple greeting → 0.1."""
        diff = cascade.estimate_difficulty("Hi!")
        assert diff == pytest.approx(0.1, abs=0.01)

    def test_hello_greeting(self, cascade):
        diff = cascade.estimate_difficulty("Hello")
        assert diff == pytest.approx(0.1, abs=0.01)

    def test_trivial_reply(self, cascade):
        """Trivial one-word reply → 0.05."""
        diff = cascade.estimate_difficulty("ok")
        assert diff == pytest.approx(0.05, abs=0.01)

    def test_empty_prompt(self, cascade):
        """Empty prompt → 0.0."""
        assert cascade.estimate_difficulty("") == 0.0
        assert cascade.estimate_difficulty("   ") == 0.0

    def test_difficulty_in_range(self, cascade):
        """Difficulty is always in [0, 1]."""
        prompts = [
            "hi", "a", "x" * 1000,
            "def f(x): return x**2",
            "Prove that the integral converges.",
            "What is the meaning of life? " * 50,
        ]
        for p in prompts:
            d = cascade.estimate_difficulty(p)
            assert 0.0 <= d <= 1.0, f"difficulty {d} out of range for {p!r}"

    def test_medium_prompt_interpolated(self, cascade):
        """Medium-length prompt is interpolated between 0.2 and 0.8."""
        # ~200 chars, no keywords.
        med = "word " * 40
        diff = cascade.estimate_difficulty(med)
        assert 0.2 < diff < 0.8


# ─── ModelCascade: routing ────────────────────────────────────────────────

class TestCascadeRouting:

    @pytest.fixture
    def cascade(self):
        return ModelCascade(
            small_model=CountingModel("small"),
            large_model=CountingModel("large"),
            difficulty_threshold=0.5)

    def test_easy_routes_to_small(self, cascade):
        """Easy prompt routes to 'small'."""
        assert cascade.route("Hi!") == "small"
        assert cascade.route("ok") == "small"

    def test_hard_routes_to_large(self, cascade):
        """Hard prompt routes to 'large'."""
        long_hard = "def solve(equation): " + "x " * 300
        assert cascade.route(long_hard) == "large"

    def test_code_keyword_routes_to_large(self, cascade):
        """Code keyword + medium length can cross threshold."""
        # 0.2 (short) + 0.2 (keyword) = 0.4 < 0.5 → still small.
        # Use a longer prompt with keywords to exceed 0.5.
        prompt = "def solve(equation): " + "detail " * 20
        assert cascade.route(prompt) == "large"

    def test_threshold_boundary(self):
        """At exactly the threshold, routes to large (>=)."""
        small = CountingModel("small")
        large = CountingModel("large")
        cascade = ModelCascade(small, large, difficulty_threshold=0.2)
        # Short prompt = 0.2 → >= 0.2 → large.
        assert cascade.route("short q") == "large"

    def test_custom_threshold(self):
        """A low threshold routes more to large."""
        small = CountingModel("small")
        large = CountingModel("large")
        cascade_low = ModelCascade(small, large, difficulty_threshold=0.1)
        # Greeting = 0.1 → >= 0.1 → large.
        assert cascade_low.route("Hi!") == "large"

    def test_invalid_threshold_raises(self):
        """Threshold outside [0, 1] raises ValueError."""
        small = CountingModel("small")
        large = CountingModel("large")
        with pytest.raises(ValueError):
            ModelCascade(small, large, difficulty_threshold=-0.1)
        with pytest.raises(ValueError):
            ModelCascade(small, large, difficulty_threshold=1.5)


# ─── ModelCascade: generate + stats ───────────────────────────────────────

class TestCascadeGenerate:

    @pytest.fixture
    def cascade(self):
        return ModelCascade(
            small_model=CountingModel("small"),
            large_model=CountingModel("large"),
            difficulty_threshold=0.5)

    def test_generate_easy_uses_small(self, cascade):
        """Easy prompt → small model generates."""
        out = cascade.generate("Hi!")
        assert "small" in out
        assert cascade.stats()["n_small"] == 1
        assert cascade.stats()["n_large"] == 0

    def test_generate_hard_uses_large(self, cascade):
        """Hard prompt → large model generates."""
        out = cascade.generate("def solve(equation): " + "x " * 300)
        assert "large" in out
        assert cascade.stats()["n_large"] == 1
        assert cascade.stats()["n_small"] == 0

    def test_generate_passes_kwargs(self):
        """kwargs are forwarded to the underlying model."""
        received: dict[str, Any] = {}

        class KwargModel:
            def generate(self, prompt: str, **kwargs: Any) -> str:
                received.update(kwargs)
                return "ok"

        cascade = ModelCascade(
            KwargModel(), KwargModel(), difficulty_threshold=0.5)
        cascade.generate("Hi!", max_new_tokens=99, temperature=0.3)
        assert received.get("max_new_tokens") == 99
        assert received.get("temperature") == 0.3

    def test_stats_tracking_multiple_calls(self, cascade):
        """Stats accumulate across multiple calls."""
        cascade.generate("Hi!")                         # small
        cascade.generate("ok")                          # small
        cascade.generate("def solve(equation): " + "x " * 300)  # large
        s = cascade.stats()
        assert s["n_small"] == 2
        assert s["n_large"] == 1
        assert s["n_total"] == 3
        assert 0.0 <= s["avg_difficulty"] <= 1.0

    def test_stats_avg_difficulty(self, cascade):
        """avg_difficulty is the mean of all difficulties."""
        cascade.generate("Hi!")   # 0.1
        cascade.generate("ok")    # 0.05
        s = cascade.stats()
        assert s["avg_difficulty"] == pytest.approx(0.075, abs=0.01)

    def test_stats_empty(self):
        """Stats on a fresh cascade are zeroed."""
        cascade = ModelCascade(
            CountingModel("s"), CountingModel("l"))
        s = cascade.stats()
        assert s["n_small"] == 0
        assert s["n_large"] == 0
        assert s["n_total"] == 0
        assert s["avg_difficulty"] == 0.0

    def test_reset_stats(self, cascade):
        """reset_stats zeroes everything."""
        cascade.generate("Hi!")
        cascade.generate("def solve(equation): " + "x " * 300)
        assert cascade.stats()["n_total"] == 2
        cascade.reset_stats()
        s = cascade.stats()
        assert s["n_small"] == 0
        assert s["n_large"] == 0
        assert s["n_total"] == 0
        assert s["avg_difficulty"] == 0.0

    def test_stats_keys(self, cascade):
        """stats() returns the expected keys."""
        s = cascade.stats()
        assert "n_small" in s
        assert "n_large" in s
        assert "avg_difficulty" in s


# ─── ForgeEngine integration (R39 wiring) ──────────────────────────────────

class _MockEngine:
    """Minimal stand-in for ForgeEngine with a string generate().

    ForgeEngine.generate(prompt, max_new_tokens=..., temperature=...,
    top_p=...) -> str is the only interface the scaling/cascade code
    needs, so a lightweight mock suffices for integration tests.
    """

    def __init__(self, name: str = "engine", suffix: str = " result."):
        self.name = name
        self.suffix = suffix
        self.calls: list[str] = []
        # Expose a fake tokenizer attribute (BeamSearch may inspect it).
        self.tokenizer = None

    def generate(self, prompt: str, **kwargs: Any) -> str:
        self.calls.append(prompt)
        max_new = kwargs.get("max_new_tokens", 100)
        out = f"[{self.name}]{self.suffix}"
        return out[:max_new] if max_new < len(out) else out


class TestEngineScalingIntegration:
    """Integration: ForgeEngine.generate_with_scaling / generate_cascade.

    These exercise the wiring in forge_engine.py using mock engines so
    no real model / CUDA is required.
    """

    def test_generate_with_scaling_ffs_returns_string(self):
        """generate_with_scaling(strategy='ffs') returns a string."""
        from forge.engine.forge_engine import _ScalingModelAdapter
        engine = _MockEngine(name="ffs", suffix=" done.")
        # Simulate the method logic using the adapter directly (avoids
        # needing a full ForgeEngine instance).
        adapter = _ScalingModelAdapter(engine)
        ffs = FirstFinishSearch(n_samples=3, max_tokens=10)
        out = ffs.generate(adapter, "question?")
        assert isinstance(out, str)
        assert len(out) > 0

    def test_generate_with_scaling_beam_returns_string(self):
        """generate_with_scaling(strategy='beam') returns a string."""
        from forge.engine.forge_engine import _ScalingModelAdapter
        engine = _MockEngine(name="beam", suffix=" beam answer.")
        adapter = _ScalingModelAdapter(engine)
        bs = BeamSearch(beam_width=3, max_tokens=6)
        out = bs.generate(adapter, "prompt")
        assert isinstance(out, str)
        assert len(out) > 0

    def test_generate_with_scaling_mcts_returns_string(self):
        """generate_with_scaling(strategy='mcts') returns a string."""
        from forge.engine.forge_engine import _ScalingModelAdapter
        engine = _MockEngine(name="mcts", suffix=" mcts solution.")
        adapter = _ScalingModelAdapter(engine)
        mcts = MCTSDecoder(n_iterations=4, n_children=2, max_tokens=8)
        out = mcts.generate(adapter, "solve: ")
        assert isinstance(out, str)
        assert len(out) > 0

    def test_generate_cascade_routes_easy_to_small(self):
        """generate_cascade routes easy prompts to the small model."""
        from forge.engine.forge_engine import _ScalingModelAdapter
        small = _MockEngine(name="small", suffix=" small reply.")
        large = _MockEngine(name="large", suffix=" large reply.")
        small_adapter = _ScalingModelAdapter(small)
        large_adapter = _ScalingModelAdapter(large)
        cascade = ModelCascade(
            small_model=small_adapter,
            large_model=large_adapter,
            difficulty_threshold=0.5)
        out = cascade.generate("Hi!")
        assert "small" in out
        assert len(small.calls) == 1
        assert len(large.calls) == 0

    def test_generate_cascade_routes_hard_to_large(self):
        """generate_cascade routes hard prompts to the large model."""
        from forge.engine.forge_engine import _ScalingModelAdapter
        small = _MockEngine(name="small", suffix=" small reply.")
        large = _MockEngine(name="large", suffix=" large reply.")
        small_adapter = _ScalingModelAdapter(small)
        large_adapter = _ScalingModelAdapter(large)
        cascade = ModelCascade(
            small_model=small_adapter,
            large_model=large_adapter,
            difficulty_threshold=0.5)
        hard_prompt = "def solve(equation): " + "x " * 300
        out = cascade.generate(hard_prompt)
        assert "large" in out
        assert len(large.calls) == 1
        assert len(small.calls) == 0

    def test_scaling_adapter_forwards_kwargs(self):
        """The adapter merges default kwargs with per-call kwargs."""
        from forge.engine.forge_engine import _ScalingModelAdapter
        engine = _MockEngine(name="kw", suffix=" x.")
        adapter = _ScalingModelAdapter(engine, temperature=0.5)
        adapter.generate("p", max_new_tokens=5)
        # The mock just records the prompt; verify it didn't crash.
        assert len(engine.calls) == 1

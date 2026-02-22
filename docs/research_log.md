# RLM Research Log

## Status: Active — Iteration 1 Complete

## Research Thrusts

### Thrust 1: Fine-Tuning Exploration
Explore fine-tuning open models to find ideal tuning methodologies and model choices.

### Thrust 2: Dynamic/Incremental RLM (Novel Contribution)
Architect an RLM that doesn't re-read the whole context every turn. Stateful Python objects, delta-based updates, incremental computation.

### Key Observation: The Dynamic Metrics Gap
Current benchmarks (OOLONG, S-NIAH) only test static context — paste a big document, ask a question. But the core thesis is that real-world context is *dynamic*: built up over many turns, changing incrementally. No existing benchmark tests this. This is both a problem (we can't measure our improvement) and an opportunity (filling this gap is itself a contribution). Exploring dynamic benchmarks is a high-priority research direction.

---

## Research Principles

1. **Kill dead ends fast.** If an approach hasn't shown progress after 2-3 iterations, stop. Analyze why it failed and pivot.
2. **Reason from results.** Failed experiments are data. Use them to infer what would work, not just try the next random thing.
3. **Extrapolate across experiments.** Look for patterns. If multiple approaches fail for the same reason, that reason is a finding.
4. **Every experiment needs a hypothesis.** "I'm trying X because results from Y suggest Z." Not "let's try X and see."

---

## Experiment Log

### Experiment 1: OOLONG-Pairs Token Cost & Failure Analysis
**Date**: 2026-02-22
**Hypothesis**: The 77.8% F1 result has hidden cost structure and failure patterns that inform the dynamic RLM design.

**Results — Token Costs**:
- Total tokens: 4,052,068 (2.49M input + 1.56M output)
- Estimated cost: $17.46 ($0.87/task)
- Cost per F1 point: $22.44
- Model breakdown:
  - gpt-5 (root): 723K input + 161K output
  - gpt-5-mini (sub-calls): 1.77M input + 1.40M output
- **Finding**: Sub-model (gpt-5-mini) dominates token usage at 78% of all tokens. Root model is relatively cheap. This means incremental computation should focus on reducing sub-model re-invocations.

**Results — Per-Task F1**:
- Symmetric tasks (1-10) avg: **84.3%** F1
- Asymmetric tasks (11-20) avg: **71.4%** F1
- Worst: Task 19 (0.443 F1) — complex "exactly one" condition, low precision (0.357)
- Best: Task 1 (0.984 F1) — simple "at least one" condition, perfect precision

**Failure Mode Analysis**:
| Failure Mode | Tasks | Pattern |
|---|---|---|
| Low precision | 19 | Complex asymmetric conditions with "exactly N" constraints |
| Low recall | 3 | Large gold set (10,440 pairs), model finds only 38.4% |
| Moderate both | 2, 9, 11, 13, 14, 15, 16, 18, 20 | Mix of precision/recall issues |

**Key Insight**: Asymmetric tasks are harder because the model must track which user satisfies which role. This is exactly the kind of structured computation that benefits from incremental processing — once you've classified users by role, that classification is reusable.

---

### Experiment 2: Streaming OOLONG-Pairs — Ground Truth Simulation
**Date**: 2026-02-22
**Hypothesis**: When context arrives incrementally, the number of discoverable pairs grows quadratically (O(n²)) with users, creating an opportunity for incremental computation.

**Setup**: Split OOLONG-Pairs context into 3/5/10 chunks at user boundaries. Computed ground-truth gold pairs at each cumulative chunk level.

**Results (5 chunks, Task 1)**:
| Chunk | Users | Discoverable Pairs | Fraction |
|-------|-------|-------------------|----------|
| 1 | 98 | 1,326 | 16.6% |
| 2 | 143 | 3,403 | 42.5% |
| 3 | 168 | 4,656 | 58.2% |
| 4 | 195 | 5,995 | 74.9% |
| 5 | 231 | 8,001 | 100.0% |

**Key Findings**:
1. **Pairs grow super-linearly** with users seen, confirming the O(n²) structure.
2. **Asymmetric tasks (11, 13, 19) show 0 discoverable pairs in chunk 1** — complex conditions require diversity in the user pool.
3. **Task 19 exhibits non-monotonic discovery** (0% → 15% → 98.3% → 40% → 100% over 5 chunks). The "exactly one" constraints mean new data can *invalidate* previously valid pairs. This is a genuine challenge for incremental systems.
4. **Novel finding for potential paper**: Non-monotonic discoverability under "exactly N" constraints is a previously uncharacterized phenomenon in incremental computation. It means incremental updates aren't always additive — sometimes delta processing must include "retraction" of previously computed results.

---

### Experiment 3: Incremental Advantage — Computation Savings Analysis
**Date**: 2026-02-22
**Hypothesis**: Incremental computation (process only new users, check pairs against cached classifications) achieves sub-linear cost scaling vs. full recomputation.

**Method**: For each chunk arrival, counted:
- Full recompute: parse ALL users, check ALL C(n,2) pairs
- Incremental: parse only NEW users, check (new × existing) + C(new, 2) pairs

**Results**:
| Chunks | Full Pair Checks | Incremental Checks | Savings | Est. Full Tokens | Est. Incr. Tokens | Token Savings |
|--------|-----------------|-------------------|---------|-----------------|------------------|--------------|
| 3 | 403,176 | 212,520 | 47.3% | 4.5M | 2.4M | **45.7%** |
| 5 | 595,312 | 212,520 | 64.3% | 6.6M | 2.5M | **62.3%** |
| 10 | 1,076,640 | 212,520 | 80.3% | 12.0M | 2.6M | **78.4%** |

**Critical Finding**: **Incremental cost is essentially constant (~212K pair checks, ~2.5M estimated tokens) regardless of chunk count**, while full recompute grows linearly with chunks. This is the O(k·n) vs O(n²) advantage the thesis claims.

**Per-chunk detail (5 chunks, Task 1)**:
| Chunk | New Users | Total Users | Full Checks | Incr. Checks | Savings |
|-------|-----------|-------------|-------------|--------------|---------|
| 1 | 98 | 98 | 4,753 | 4,753 | 0.0% |
| 2 | 45 | 143 | 10,153 | 5,400 | 46.8% |
| 3 | 25 | 168 | 14,028 | 3,875 | 72.4% |
| 4 | 27 | 195 | 18,915 | 4,887 | 74.2% |
| 5 | 36 | 231 | 26,565 | 7,650 | 71.2% |

**Implication**: The savings increase with each chunk because the ratio of new-to-existing users shrinks. By chunk 5, incremental processing is 71% cheaper than full recompute. At 10 chunks, it's 87% cheaper.

---

### Bug Fixes (Iteration 1)
1. **`_default_answer` wrong message role**: Changed `"role": "assistant"` to `"role": "user"` in `rlm.py:329`. The old code put a final-answer request as an assistant message, violating LLM API expectations.
2. **`REPLResult` field name mismatch**: Changed dataclass field from `llm_calls` to `rlm_calls` in `types.py:126` to match the `__init__` parameter.

---

### Architecture Changes (Iteration 1)

#### Incremental State Awareness
**Files modified**: `rlm/utils/prompts.py`, `rlm/core/rlm.py`

Added `cached_vars` parameter to `build_user_prompt()`. When persistent mode enters a non-first turn, the prompt now includes an **INCREMENTAL STATE** section listing all cached REPL variables from prior turns. This tells the model what's already been computed so it can build on cached results instead of re-computing from scratch.

Added `_get_cached_vars()` static method to `RLM` class that inspects the environment's locals, filtering out internal/context/history variables, and returns `{name: type_name}` for user-defined variables.

**Test coverage**: 9 new tests in `tests/test_incremental_state.py` covering variable detection, context/history exclusion, prompt generation, and state persistence.

---

### New Files Created (Iteration 1)
| File | Purpose |
|------|---------|
| `eval/analyze_results.py` | Token cost analysis, per-task F1, failure categorization |
| `eval/streaming_benchmark.py` | Streaming OOLONG-Pairs benchmark (simulate/persistent/non-persistent modes) |
| `eval/incremental_advantage.py` | Theoretical incremental vs full-recompute cost analysis |
| `tests/test_incremental_state.py` | Tests for incremental state awareness feature |
| `results/oolong_pairs/analysis.json` | Token/F1 analysis results |
| `results/streaming/simulation.json` | 5-chunk streaming simulation ground truth |
| `results/streaming/simulation_3chunks.json` | 3-chunk streaming simulation ground truth |
| `results/streaming/incremental_advantage.json` | Incremental computation savings analysis |

---

## Next Steps (Iteration 2)

1. **Run live streaming benchmark** with API keys: persistent vs non-persistent mode on 2-3 tasks × 3 chunks. This would produce the first real token measurements comparing incremental vs full recompute.
2. **Implement delta-aware prompt engineering**: The current system prompt doesn't tell the model to specifically build data structures that cache user classifications. A "delta-aware" system prompt for streaming mode would instruct the model to maintain a `user_profiles` dict and only classify new users per chunk.
3. **Non-monotonic discovery handling**: Task 19's non-monotonic pattern suggests we need a "retraction" mechanism. When new data invalidates a cached result, the model needs to know which cached computations are affected.
4. **Message history pruning**: The critiquer correctly identified unbounded message history. For persistent mode with many chunks, implement a pruning strategy that keeps only the most recent N messages plus a summary.
5. **Error analysis on worst tasks**: Deep-dive into Task 19 and Task 3 log trajectories to understand the specific failure mechanisms.

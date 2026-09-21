# WAL 11 — Negative sampling + audit fixes (2026-09-04 22:21)

**Date:** 2026-09-18
**Branch:** `main`
**Focus:** Negative sampling + audit fixes (2026-09-04 22:21)

## Extracted from WAL.md

This wave was automatically extracted from the monolithic WAL.md file.

— Negative sampling + audit fixes (2026-09-04 22:21)

### What changed
- `LmHead.update(chainOutput, token, nNegatives)` — added negative sampling. Default K=5 in `LmHeadTrainer.train()`. For each positive (fingerprint, token) update, K random other tokens are decremented for the same fingerprint. Prevents mode collapse on common tokens (e.g., `:`).
- `LmHeadTrainer.train(limit, epochs)` now delegates to `train(limit, epochs, 5)`.
- `LmHeadTrainer.trainOne(q, a)` now delegates to `trainOne(q, a, 0)`.

### Audit findings fixed (Goal Guard review cycle #0)
1. Doc-vs-code lie: removed dangling `{@link #updateConcurrent}` reference in `LmHead.update()` Javadoc.
2. Thread-safety regression: restored `synchronized (tw)` blocks in `update`, `score`, and `save` after RUN 11's first pass had stripped them.
3. Non-deterministic RNG: replaced `new Random(targetToken * 31L ^ System.nanoTime())` with `new Random((long) targetToken * 0x9E3779B97F4A7C15L)` — deterministic across runs, no wall-clock in decision path (AGENTS.md compliant).

### Verification
- `./gradlew :matrix-core:test --rerun-tasks --tests "io.matrix.api.LmHeadTest"` → 7/7 PASS in 0.281s
- 2 new tests: `negativeSamplingAddsNegativeTokensToVocab`, `negativeSamplingPreservesPositiveSignal`
- 5 prior tests still green

### Honest framing
Negative sampling is small and tested at the unit level. Full-bench re-measure (HellaSwag / ARC-Easy with new LM head scoring) is NOT in this RUN — that's a future scope.

---

**Checkpoint Hash:** `430de111` (current HEAD at extraction time)
**Previous Checkpoint:** see git log -1
**Next Wave:** W12

*Auto-extracted by extract-waves.py*

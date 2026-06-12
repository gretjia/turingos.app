# Hypothesis: TuringOS replaces model internal CoT (chat > reasoner)

**Proposed by**: User (2026-04-15 ~04:30 UTC)  
**Status**: Queued for v3.2 experiment post-M4

## Claim

TuringOS architecture (tape, market, Boltzmann routing, recent_errors broadcast, wallet) is an externalized Chain-of-Thought. Running reasoning models (deepseek-reasoner, GPT-o1, Claude Opus thinking) inside TuringOS is double-reasoning: internal CoT + external scaffold = redundant.

Therefore: **prefer chat models** for TuringOS agents. Cheaper (~4-8×), faster (~5-10×), and the architecture compensates for lower per-call reasoning depth.

## Mapping (TuringOS ↔ CoT)

| Architectural component | CoT analog |
|---|---|
| Tape (linear nodes) | Thought steps |
| Market (node prices) | Beam-search / heuristic eval |
| Recent_errors broadcast | Self-correction |
| Boltzmann routing | Temperature / exploration |
| Wallet (Coin budget) | Token budget |
| Multi-agent | Multi-sampling |

## Testable prediction (pre-registration)

**v3.2 binary verdict** uses ONLY SolveRate pairwise rule (see PLAN_V3_2_2026-04-15.md §Expected outcomes). Concrete decision boundary:
- CONFIRMED: `|n1_chat − n1_reasoner|` ≤ 1 (i.e., `n1_chat` ∈ [29, 31]) OR strict win (≥33)
- FALSIFIED: `n1_reasoner − n1_chat` ≥ 3 (i.e., `n1_chat` ≤ 27)
- GRAY: difference of exactly 2

**Append-rate is informational only** in v3.2. *Earlier framing of "append_rate(chat) > append_rate(reasoner) → confirmed" is RETRACTED* per post-audit discipline — it was a secondary hypothesis inappropriate as primary decision criterion. Append-rate remains a generator for future v3.3+ hypotheses, not a v3.2 verdict input.

## Constitutional framing

- **C-034 "mechanism > prompt"**: model choice is a mechanism. Selecting chat-model forces collective machinery to earn its keep.
- **C-033 emergence requires causal proof**: chat-model test distinguishes "scaffold contributes" from "reasoner carries".
- **C-031 institution > tuning**: model choice is institution-level, not parameter-tweaking.
- **Art. II.2 broadcast price signals + II.2.1 exploration**: these mechanisms are designed to aid *cooperation among limited agents*, not to coordinate already-complete individual reasoners.

## Proposed v3.2 design

- **Sample**: identical (seed=74677, N=50, fingerprint=796ead6c40351ae9) — enables direct paired comparison
- **Conditions**: oneshot, n1, n3 (same three)
- **Model**: `ACTIVE_MODEL=deepseek-chat` (only change vs v3.1)
- **Prompt/schema/timeout**: unchanged
- **Abort gate**: unchanged (10-problem / 3-timeout)

### Informational-only observables (v3.2 diagnostic)

Append-usage rate: `tape_depth_at_OMEGA / total_solves`. Descriptive only in v3.2 — tracked to inform FUTURE hypotheses.

**NOT a decision criterion for v3.2 verdict** (see §Testable prediction above for the actual pre-registered rule). Append-rate observations in v3.2 feed exclusively into post-hoc hypothesis generation for v3.3+, which would need to pre-register append as primary/secondary in its own metrics freeze before running.

Retracted framing (preserved for audit trail): an earlier draft listed append_rate comparison as confirm/falsify input. That was inconsistent with the SolveRate-primary v3.2 decision rule and is superseded. Do not re-introduce binary append rules without fresh pre-registration.

## Expected wall time + cost

- reasoner v3.1 (ongoing): ~12h, ~$25 API
- chat v3.2 (planned): ~75 min, ~$4 API

**10× efficiency gain at equal sample size.** If SolveRate holds up, thesis is confirmed and TuringOS becomes dramatically cheaper.

## Decision gate

v3.2 executes only if:
1. v3.1 M4 audit = PASS (Codex + Gemini)
2. v3.2 plan passes dual audit
3. No unresolved URGENT_*.md in handover

## Side implications if thesis confirmed

- All future TuringOS benchmarks should use chat models as default
- Reasoner is an upper-bound control, not production choice
- C-031 precedent extends: model-class selection is institutional design

## Side implications if thesis falsified

- TuringOS scaffold is INSUFFICIENT to replace internal CoT
- Architecture engineering should focus on making tape/market actually contribute (append incentives per C-034)
- Current reasoner+TuringOS "+33% PPUT" was likely just k-sample advantage, not architecture value

# Tuberosa Knowledge-Quality Overhaul — Detailed Plan

## Context

Tuberosa already has the right core shape: classify → search (lexical/vector/metadata/memory/graph) → fuse → rerank → context-fit → context-pack. The current weakness is **not** missing features — it's that **knowledge quality is undermeasured and several pipeline stages have known gaps** that the deterministic fixture is too small to catch:

- **Classifier verb noise** — `Analyze`, `Investigate`, `Improve` leak into the symbols set (`src/retrieval/classifier.ts:544-675`), polluting downstream matching.
- **Domain inferred but not labelled** — `inferDomain` produces a field but `labelsFromClassification` never emits it (`classifier.ts:114-147`).
- **Query rewrite augments without validating** — `applyQueryRewrite` (`service.ts:108`) merges new terms into the old ones with no check that the rewrite improved retrieval; no caching of rewrite outcomes.
- **Fusion divisor hardcoded** — `(60 + rank)` in `fusion.ts` is not tunable per task; the calibrator only tunes weights, not k.
- **Feedback aggregates but doesn't move scores** — 11 feedback types exist, `KnowledgeFeedbackSummary` counts them, but **no per-knowledge penalty is applied during fusion**. Rejected memories keep ranking high until someone manually marks them stale.
- **Suppression penalties cumulate linearly without normalization** — a candidate hit by stale + rejected + domain-mismatch can drop >0.5 with no clipping (`service.ts:1457-1592`).
- **Context-fit computed late** — `fitStatus` is set after rerank; rerank failures bubble up silently and trust decays to 0 with no fallback.
- **Worktree is not a first-class source** — live files / prompt-named files / current handoff have no producer in `KnowledgeStore`; durable memory competes with itself instead of with live truth.
- **Atomizer loses cross-chunk context** — `document-atomizer.ts` splits Markdown by heading with no breadcrumb prefix; a chunk reading "this section adds X" is unmoored after embedding.
- **Eval coverage is shallow** — fixture has ~14 cases (`eval/retrieval-fixtures.json`), no entity-recall, no noise-sensitivity, no per-task-type taxonomy, no feedback-→-ranking regression case.

**Intended outcome:** Tuberosa becomes measurably better at putting **on-point** evidence in front of fresh agents while staying **offline-capable**, **backwards-compatible at the MCP surface**, and **dependency-light by default**. Every phase below ships the regression fixture FIRST, then the fix. Eval stays green at every step.

---

## Why not just integrate Mem0?

Mem0 is great but conflicts with all four locked-in constraints: it's Python-first (no Node SDK), calls GPT-4o-mini on every memory write (not offline), requires Neo4j (heavy infra), duplicates Tuberosa's vector store, overrides the review-gated trust model, and is shaped for chat memory not project knowledge. **We borrow the patterns (4-way write gate, time-stamped edges, entity-centric expansion) but implement them locally with vector cosine + label/reference overlap — no LLM call, no Neo4j.**

---

## Current quality assessment (baseline before any change)

| Dimension | Current state | Evidence |
|---|---|---|
| **Helpfulness** | Moderate. Hash reranker is a placeholder; `bge-reranker-v2-m3` only loads with `TUBEROSA_MODEL_PROVIDER=local`. Most users run pure hash. | `local-provider.ts:52`, `provider.ts:31-47` |
| **Coverage** | 5 sources fused (metadata, lexical, vector, memory, graph). **No worktree source.** Classifier emits domain field but not as label, so domain-scoped retrieval underperforms. | `fusion.ts`, `classifier.ts:114-147` |
| **Completeness ratio** | Feedback aggregates exist (`KnowledgeFeedbackSummary`) but don't feed back into fused score. Stale/rejected items ride along until manually superseded. | `service.ts:1386-1592` |
| **Effectiveness (measured)** | `pnpm run eval:retrieval` passes at 100% on 14 hand-picked cases. Sandbox adds tiered corpus + ablation. **No entity recall, no noise-sensitivity, no CoIR-style task taxonomy.** | `eval/retrieval-fixtures.json`, `scripts/sandbox.ts` |
| **Rewrite flow** | Conditional on OpenAI provider (`provider.ts:123-159`); augments lexical query, doesn't replace, doesn't validate. No diverse-angle prompts. No gating on confidence. | `service.ts:105-129` |
| **Categorization** | Item types: spec/workflow/memory/bugfix/code_ref/rule/wiki/conversation. Labels: technology/business_area/task_type/file/symbol/project. **Domain inferred from `src/X/` but not emitted as label.** No label provenance/confidence. | `classifier.ts`, `relations/inference.ts` |
| **Knowledge safety** | Secrets + prompt-injection blocked at ingestion. **False-positive rate unmeasured** — regex `api[_-]?key\s*[:=]` matches legitimate config keys. | `security/knowledge-safety.ts:60-100` |

---

## Approach

Ten phases, each independently mergeable, each behind a flag if behavior changes externally. Pre-commit invariant for every phase:

```bash
pnpm run build && pnpm test && pnpm run eval:retrieval && pnpm run sandbox
```

Each phase **adds the regression fixture before** writing the fix, so the test goes red → green inside the same PR.

---

## Phase 0 — Evaluation expansion (foundation; everything else depends on this)

**Why first:** every later phase claims to improve quality. We need metrics that can prove or disprove that, beyond the 14-case fixture.

**Status: ✅ DONE (2026-05-21)**

**Implemented:**
- ✅ New fixture: `eval/context-mapping-fixtures.json` — 12 approved knowledge items + 3 distractors + 2 feedback events + 3 relations + 7 cases spanning all four taxons.
- ✅ New evaluator: `src/evaluation/context-mapping-evaluator.ts` — computes Context Precision @ k, Context Recall, Context Entities Recall, Noise Sensitivity, Direct-evidence Placement, Fit Calibration, Forbidden-item Rate, plus CoIR-style per-taxon breakdowns. Deterministic — no LLM calls, hash provider only.
- ✅ New fixture loader: `src/evaluation/context-mapping-fixture-loader.ts` — parallel to the existing retrieval-fixtures loader; validates the taxon enum.
- ✅ New script: `scripts/eval-context-mapping.ts` and npm script `pnpm run eval:context-mapping` with `--write-baseline` plus six threshold flags (`--fail-under-precision`, `--fail-under-recall`, `--fail-under-entities-recall`, `--fail-under-noise-sensitivity`, `--fail-under-fit-calibration`, `--fail-over-forbidden-rate`).
- ✅ Extended `eval/retrieval-fixtures.json`: every existing case now has `taxon` + `expectedEntities` fields.
- ✅ Baseline captured: `eval/baseline-context-mapping.json` — current hash-provider numbers are now the reference for every subsequent phase.

**Baseline numbers (2026-05-21, hash provider):**

| Metric | All cases | nl_to_code | code_to_code | text_to_text_doc | hybrid |
|---|---|---|---|---|---|
| Context Precision @ 5 | 25.7% | 20% | 40% | 20% | 40% |
| Context Recall | 100% | 100% | 100% | 100% | 100% |
| Context Entities Recall | 100% | 100% | 100% | 100% | 100% |
| Noise Sensitivity | 71.4% | 50% | 100% | 66.7% | 100% |
| Direct-evidence Placement | 100% | 100% | 100% | 100% | 100% |
| Fit Calibration | 100% | 100% | 100% | 100% | 100% |
| Forbidden-item Rate | 16.7% | 0% | n/a | 33.3% | 0% |

**What this confirms about the current state:** precision and noise resistance are the weakest dimensions today. Adjacent-but-unrelated workflow docs (`current-deploy-runbook`, `current-rate-limit-policy`) flood the top-5 even when the query is about something else; semantically-similar distractors leak into top-5 on 28.6% of cases; one legacy item (`legacy-deploy-runbook`) bubbles up alongside its supersession. These are precisely the failure modes Phases 1, 2, 4, and 5 will attack.

**Deviations from the original Phase 0 spec (recorded here so they aren't lost):**
- **Worktree field in the fixture schema:** the spec listed `worktree` as a top-level fixture field (current/changed/missing files). It is **omitted from this iteration** because the worktree provider doesn't land until Phase 5 and parsing fields no producer consumes invites schema drift. When Phase 5 ships, add the field to `ContextMappingFixture` + loader + evaluator alongside the worktree-precedence metric.
- **Noise-sensitivity implementation:** spec said "inject N distractor chunks per case; fitStatus must degrade to `needs_confirmation`". Implemented as a **single-pass case evaluation** where distractors are seeded once into the store, and the metric measures whether they leak into top-K. FitStatus degradation under noise is **not** measured per-case yet — adding a second-pass run with a noise-amplified prompt was deferred to keep the runner offline-fast (one pass per case, no re-seeding). Re-evaluate once Phase 3 ships the structured `fitDiagnostics`.
- **`taxon` + `expectedEntities` on `RetrievalEvalCase` type:** the JSON fields are present on every case in `eval/retrieval-fixtures.json`, but the existing `RetrievalEvalCase` TypeScript type and `fixture-loader.ts` were **deliberately not extended**. They're documentation-only data, ready for the phase that actually consumes them (Phase 1 for the classifier hygiene work; Phase 5 for worktree). The legacy loader silently ignores unknown JSON fields, so `pnpm run eval:retrieval` stays green without churn.
- **CoIR taxonomy coverage:** only 7 cases across 4 taxons in this fixture (2/1/3/1). Sufficient for baseline measurement but thin. When Phase 1 lands (classifier verb hygiene + domain labels) and we want stronger per-taxon signal, expand to ~16 cases (4 per taxon) so per-taxon deltas are meaningful.

**Files added:**
- `src/evaluation/context-mapping-evaluator.ts` (~420 lines)
- `src/evaluation/context-mapping-fixture-loader.ts` (~175 lines)
- `scripts/eval-context-mapping.ts` (~230 lines)
- `eval/context-mapping-fixtures.json` (7 cases)
- `eval/baseline-context-mapping.json` (locked baseline metrics)

**Files modified:**
- `package.json` — added `eval:context-mapping` script.
- `eval/retrieval-fixtures.json` — added `taxon` + `expectedEntities` on every case (data-only, no type/loader changes).
- `implements/enhance_rewrite/tuberosa-enhance-knowledge-quality.md` — this status block.

**Verification (all green):**
- `pnpm run build` ✅
- `pnpm test` ✅ — 224/224 pass
- `pnpm run eval:retrieval` ✅ — hit@5 100%, MRR 1.0, all classification rates 100%
- `pnpm run eval:agent-context` ✅
- `pnpm run eval:context-mapping` ✅ — runs, prints metrics, writes baseline

**Tried but not done (deliberate carry-overs):**
- A "noise variant" second pass per case to measure fitStatus degradation under injected distractors — deferred until Phase 3's `fitDiagnostics` block lands so the assertion has structured signal to bind to.
- Extending `RetrievalEvalCase` to type-check `taxon`/`expectedEntities` — deferred to the first phase that consumes the fields programmatically (likely Phase 1).
- The `--fail-*` threshold flags exist but are **not wired into CI yet**; the baseline file is the regression reference. Wire thresholds once Phase 1's targets are agreed on.

---

## Phase 1 — Classifier + label hygiene (cheap, high signal)

**Why:** noise at the front of the pipeline poisons every downstream stage. Roadmap explicitly flagged this.

**Status: ✅ DONE (2026-05-21)**

**Implemented:**
- ✅ `src/retrieval/classifier.ts`:
  - `SYMBOL_STOP_WORDS` expanded with the roadmap's task verbs + conjugations: `Analyze/Analyse/Analyzing/Analyzed/Analysed`, `Answer/Answers/Answering/Answered`, `Investigate/Investigates/Investigating/Investigated/Investigation`, `Improving/Improved/Improvement`, `Implementing/Implementation`, `Fixed/Fixes/Fixing`, `Adding/Adds`, `Refactoring/Refactored`, `Reviewing/Reviewed`, `Audit/Audits/Auditing/Audited`, `Map/Maps/Mapping/Mapped`, `Tracing/Traced`, `Plan/Plans/Planning/Planned`, `Building/Built`, `Testing/Tested`, `Verifying`, `Validate/Validates/Validating/Validated`, `Identify/Identifies/Identifying/Identified`, `Document/Documents/Documenting/Documented`, `Expand/Expands/Expanding/Expanded`, `Ensure/Ensures/Ensuring/Ensured`, `Confirm/Confirms/Confirming/Confirmed`, `Propose/Proposes/Proposing/Proposed`. User-supplied symbols via the `symbols:` input bypass the filter — caller authority wins (this already worked by construction; the new test pins it down).
  - `labelsFromClassification` now emits a `domain` label (weight 0.85, classifier-confidence 0.7) whenever `classified.domain` is set, AND stamps every classifier-emitted label with `provenance: { source: 'classifier', confidence: … }`. The existing `LabelProvenance` shape already existed on `LabelInput` (`src/types.ts:92-97`) — see the deviation note below for why we re-used `source` rather than the plan's `explicit | inferred | reviewed | feedback_proposed | worktree_detected` vocabulary.
  - `hasDomainMismatch` tightened: only **explicit** (non-`classifier`-source) domain labels participate in mismatch. Classifier-inferred labels alone don't trigger mismatch suppression, since one file's path is heuristic and would create false positives for every candidate that simply lives in a different `src/X/`.
- ✅ `src/ingest/label-enricher.ts`: when the user supplies a `domain` label, drop the classifier-emitted one (`dropInferredDomainIfUserSupplied`). User authority wins on domain typing.
- ✅ `src/retrieval/service.ts`: the domain-mismatch suppression block uses the **explicit-only** filter for the penalty branch while keeping the **permissive** filter for the matching-boost branch (an inferred match is still useful).
- ✅ `src/storage/postgres-store.ts`: provenance round-trips through Postgres by persisting a `metadata.labelProvenance` index keyed by `${type}:${normalizedValue}` (no schema migration — uses the existing JSONB column). `mapKnowledgeRow` hydrates it back. Memory store is transparent (it stores labels as-is).
- ✅ `test/classifier-phase1.test.ts`: 5 dedicated regression tests covering the stopword set, the `symbols:` bypass, the new `domain` label + provenance, and the no-domain-label-when-no-`src/X/` case. All green.
- ✅ `eval/context-mapping-fixtures.json`: added one new case (`article-search-domain-routing`) + two supporting knowledge items (`article-search-handler` in `src/retrieval/`, `email-thumbnail-search-helper` in `src/email/`) that exercise the new domain-label routing. New case PASSES at 100% precision (top-1 = direct evidence).

**Baseline deltas (hash provider, 2026-05-21):**

| Metric | Phase 0 baseline | Post Phase 1 | Δ |
|---|---|---|---|
| Cases | 7 | 8 (+1 domain-routing case) | +1 |
| Context Precision @ 5 | 25.7% | 25.0% | −0.7pp (one extra weak case dragged the mean — 7-of-8 unchanged) |
| Context Recall | 100% | 100% | — |
| Context Entities Recall | 100% | 100% | — |
| Noise Sensitivity | 71.4% | 75.0% | +3.6pp |
| Direct-evidence Placement | 100% | 100% | — |
| Fit Calibration | 100% | 100% | — |
| Forbidden-item Rate | 16.7% | 14.3% | −2.4pp (improvement) |
| `eval:retrieval` | 14/14 green | 14/14 green | — |
| `eval:agent-context` | green | green | — |
| `pnpm test` | 224/224 | 229/229 (+5 phase-1 tests) | +5 |

`sender-queue-refactor` flipped FAIL → PASS during Phase 1 — the `ops-noisy-with-symbol` candidate (whose user-supplied `domain=operations` correctly conflicts with the query's inferred `domain=email`) is now suppressed deterministically by the explicit-domain mismatch rule.

**Deviations from the original Phase 1 spec (recorded so they aren't lost):**
- **Provenance vocabulary:** the spec named five sources — `explicit | inferred | reviewed | feedback_proposed | worktree_detected` — and said they'd live in `labels[].metadata.provenance`. The existing codebase already had a `LabelProvenance` interface with `source: 'prompt' | 'classifier' | 'ontology' | 'reviewer' | 'llm' | 'ast' | 'heuristic'` and `confidence` (`src/types.ts:85-90`). Phase 1 **re-used the existing shape** and mapped intent → existing values: `explicit ≈ 'prompt'`, `inferred ≈ 'classifier'`, `reviewed ≈ 'reviewer'`. `feedback_proposed` and `worktree_detected` are deferred to Phases 2 (feedback) and 5 (worktree) which will introduce them as new `LabelProvenanceSource` values.
- **`labels[].metadata.provenance` path:** spec called for provenance inside `metadata`. The codebase carries it as a top-level `provenance` field on `LabelInput` directly. We left that location alone — adding a metadata sub-key would have been a churn-only rename. The intent (per-label source + confidence) is satisfied.
- **No new migration:** spec mentioned `migrations/00Y_label_provenance.sql` as a possible storage-side support file. We did **not** add it. Postgres persistence is done via a `metadata.labelProvenance` JSONB index on `knowledge_items` (already-existing column), which is migration-free and round-trips correctly through `upsertKnowledge` / `updateKnowledge` / `mapKnowledgeRow`. If a future phase needs per-`knowledge_labels`-row provenance (e.g., for SQL filtering by confidence) we can add the column then.
- **`hasDomainMismatch` semantics change:** the spec did not explicitly call out that the existing mismatch check would over-fire on classifier-inferred domains. During verification this surfaced as a regression (`sender-queue-refactor` failing, `domain-scope-suppresses-off-domain` failing on the retrieval eval). The fix — split into "permissive boost / explicit-only penalty" — is a **semantics tightening** beyond the spec text. Both evals green afterwards.
- **`SYMBOL_STOP_WORDS` includes more variants than the spec listed:** added `Validate*`, `Identify*`, `Document*`, `Ensure*`, `Confirm*`, `Propose*` and full conjugation sets. These appeared empirically in the agent prompts being processed and would otherwise leak as symbols.
- **`TUBEROSA_DOMAIN_LABELS_ENABLED` flag:** spec lists this in the cross-cutting flags table (default `true`). Phase 1 ships it as **always-on** — no env flag was added. Rationale: the failure-mode caught during verification was *not* in domain-label emission itself but in the downstream suppression check; making the emission flag-gated would have hidden, not fixed, that downstream behavior. The fix lives in `hasDomainMismatch` + service.ts, not in a kill-switch.

**Files added:**
- `test/classifier-phase1.test.ts` (5 tests, all green)

**Files modified:**
- `src/retrieval/classifier.ts` — `SYMBOL_STOP_WORDS` expansion, domain label emission, classifier provenance on every emitted label, tightened `hasDomainMismatch`.
- `src/retrieval/service.ts` — `applyIntentSuppression` domain-mismatch branch now uses explicit-only filter for the penalty, permissive filter for the boost. Adds `isExplicitDomainCandidateLabel` helper. Imports `LabelInput`.
- `src/ingest/label-enricher.ts` — `dropInferredDomainIfUserSupplied` to honor user-supplied `domain` over classifier-inferred.
- `src/storage/postgres-store.ts` — `withLabelProvenanceMetadata`, `mergeLabelProvenanceIntoMetadata`, `buildLabelProvenanceMap`, `hydrateLabelProvenance` helpers. `upsertKnowledge` + `updateKnowledge` weave provenance into the row's `metadata` JSONB. `mapKnowledgeRow` hydrates it back into `labels[].provenance`.
- `eval/context-mapping-fixtures.json` — added `article-search-handler`, `email-thumbnail-search-helper`, `article-search-domain-routing` case.
- `implements/enhance_rewrite/tuberosa-enhance-knowledge-quality.md` — this status block.

**Verification (all green):**
- `pnpm run build` ✅
- `pnpm test` ✅ — 229/229 pass (was 224/224; +5 from the new phase-1 test file)
- `pnpm run eval:retrieval` ✅ — hit@5 100%, MRR 1.0, all classification rates 100%, all 14 cases pass
- `pnpm run eval:agent-context` ✅
- `pnpm run eval:context-mapping` ✅ — runs, prints metrics, 8 cases total; noise sensitivity +3.6pp, forbidden rate −2.4pp; no regressions vs Phase 0 baseline

**Tried but not done (deliberate carry-overs):**
- The plan's `LabelProvenanceSource` vocabulary expansion (`feedback_proposed`, `worktree_detected`) — deferred to Phases 2 and 5 which actually produce those sources.
- The `TUBEROSA_DOMAIN_LABELS_ENABLED` env flag — not added; see deviation above. If a future phase needs a quick kill switch, add it then.
- Re-baseline `eval/baseline-context-mapping.json` — kept the Phase 0 baseline (7 cases) as the locked reference. Once Phase 2 lands and we want to roll Phase 1's behavior into the regression target, regenerate with `pnpm run eval:context-mapping -- --write-baseline`.

---

## Phase 2 — Feedback → ranking translation (closes the loop)

**Why:** the system already collects 11 feedback types but doesn't act on them at retrieval time. Memories stay high-ranked even after multiple rejections.

**Status: ✅ DONE (2026-05-22)**

**Implemented:**
- ✅ New module `src/retrieval/feedback-scorer.ts`: `computeFeedbackPenalty(summary, now)` returns a multiplicative factor in `[FEEDBACK_FACTOR_FLOOR=0.3, FEEDBACK_FACTOR_CEILING=1.0]`. Distinct per-type weights: `stale` (0.22), `rejected` (0.18), `irrelevant` (0.08), `selected_but_noisy` (0.04), `selected` (-0.06, lifts the factor back toward 1). Exponential recency decay anchored at `FEEDBACK_DECAY_HALF_LIFE_DAYS_ANCHOR=60` days via `recency = exp(-Δdays / 60)`. Smooth exponential damping `factor = floor + (1-floor) * exp(-mass * recency)` so cumulative penalties asymptote toward the floor rather than crashing through it. Also exports `multiplicativeDeltaWithFloor` helper for the suppression refactor.
- ✅ `src/retrieval/fusion.ts`: `FuseOptions` now accepts `feedbackSummaries: Map<string, KnowledgeFeedbackSummary>` and `now: Date`. Inside `fuseCandidates`, after RRF normalization, every candidate's `fusedScore` is multiplied by `computeFeedbackPenalty(summary)`. This puts feedback **before rerank** as specified.
- ✅ `src/retrieval/service.ts`: `rankCandidates` now collects all candidate ids before fusion, fetches the feedback summary map via `this.store.getFeedbackSummaries`, and threads it into `fuseCandidates({ feedbackSummaries, collectBreakdown: true })`. Always uses the `FuseResult` form (avoids the runtime overload-mismatch trap where passing options-without-breakdown returned a bare array).
- ✅ `src/retrieval/service.ts`: refactored `intentSuppressionAdjustment` from accumulating an additive `score` to accumulating a multiplicative `factor` (penalty contributions) plus a separate additive `boost` (positive contributions like domain-match). Each prior linear delta (`-0.28 / -0.14 / -0.10 / -0.08`) now maps to a factor via `penaltyDeltaToFactor(delta) = clamp(exp(2.2 * delta), 0.4, 1)`. Cumulative penalties multiply (order-independent product), then `applyIntentSuppression` applies the factor with a hard floor: `dampedBase = base > SUPPRESSION_FLOOR ? max(base * factor, SUPPRESSION_FLOOR) : base * factor`. Positive boosts (domain_match) add on top. Result clamped to [0, 1]. The per-event `deltaScore` reporting for `SuppressionEvent` keeps its original linear value so existing event traceability is preserved.
- ✅ Constants: `SUPPRESSION_FLOOR = 0.1` (hard floor for cumulative damping). Per-event `deltaScore` values continue to flow into `onSuppression` callbacks unchanged for telemetry compatibility.
- ✅ `test/feedback-scorer-phase2.test.ts` (new, 7 tests): unit tests for `computeFeedbackPenalty` (shape/bounds/decay/per-type weighting/floor) plus two end-to-end regression tests pinning down the plan's two fixtures (K vs K' ranking, cumulative damping floor). All green.
- ✅ `test/retrieval.test.ts:1762` updated — the pre-Phase-2 "feedback history adjusts later retrieval ranking" test was asserting that a stale-marked candidate would still appear in the pack with feedback annotations. Post-Phase-2 the cumulative damping correctly drops it below the pack assembly threshold (it now never reaches the user). The test now allows either outcome and asserts the load-bearing invariant: selected outranks stale, and if stale survives, it still carries the feedback reasons.

**Baseline deltas (hash provider, 2026-05-22):**

| Metric | Post Phase 1 | Post Phase 2 | Δ |
|---|---|---|---|
| Cases (context-mapping) | 8 | 8 | — |
| Context Precision @ 5 | 25.0% | 25.0% | — |
| Context Recall | 100% | 100% | — |
| Context Entities Recall | 100% | 100% | — |
| Noise Sensitivity | 75.0% | 75.0% | — |
| Direct-evidence Placement | 100% | 100% | — |
| Fit Calibration | 100% | 100% | — |
| **Forbidden-item Rate** | **14.3%** | **0.0%** | **−14.3pp** (Phase 2 target hit) |
| `eval:retrieval` | 14/14 green | 14/14 green | — |
| `eval:agent-context` | green | green | — |
| `pnpm test` | 229/229 | 236/236 (+7 phase-2 tests) | +7 |

`deploy-runbook-current` flipped FAIL → PASS — the cumulative damping (stale-freshness × feedback × evidence-mismatch) finally pushes `legacy-deploy-runbook` below the pack threshold, where multi-source linear subtraction couldn't quite get there in the prior phase. Forbidden-item rate is now 0% on the context-mapping fixture (was 14.3% post Phase 1; 16.7% in the Phase 0 baseline).

**Deviations from the original Phase 2 spec (recorded so they aren't lost):**
- **Decay anchor:** spec called for `weight = exp(-Δdays / 60)` per-event. The `KnowledgeFeedbackSummary` interface only exposes aggregate counts plus `latestFeedbackAt` (not per-event timestamps), so the decay multiplier in `computeFeedbackPenalty` uses `latestFeedbackAt` as the **summary-level recency proxy**: `recency = exp(-Δdays / 60)`. This approximates per-event decay without requiring a schema change. To get true per-event decay later, extend `KnowledgeFeedbackSummary` (or load `FeedbackEvent[]` directly in the service) — deferred until a future phase that needs that resolution.
- **Distinct per-type weights:** spec mentioned that `too_much_adjacent_context` should weakly raise the factor. `KnowledgeFeedbackSummary` doesn't track that type (it's a context-quality signal not aggregated into the summary today), so it's currently inert in `computeFeedbackPenalty`. The function still supports the other five named types (`rejected`, `stale`, `irrelevant`, `selected_but_noisy`, `selected`). Adding `tooMuchAdjacentContextCount` to the summary is a small change for a future phase.
- **Penalty → factor mapping:** spec said "convert linear `-0.28 / -0.14 / -0.10` subtractions to multiplicative damping". The mapping is `penaltyDeltaToFactor(delta) = clamp(exp(2.2 * delta), 0.4, 1)` — empirically chosen so the strongest single penalty (-0.28) maps to factor ~0.54 (≈46% reduction) and the weakest (-0.08) maps to ~0.84 (≈16% reduction). The exact slope (2.2) was hand-picked to make the cumulative product land in a reasonable mid-range when 2-3 penalties stack; if a future calibration phase wants to tune it, expose it via `config/retrieval-policy.json` then.
- **Hard floor application:** spec said "hard floor at 0.1". Implemented in `applyIntentSuppression`, NOT in `intentSuppressionAdjustment` — i.e., the floor is applied *when* the factor is multiplied onto the base score, not as a constraint on the factor itself. The factor can be very small; the floor protects positive scores from cumulative penalties pushing them below 0.1. Scores already below the floor are still allowed to be damped further (they were never trustworthy).
- **`SuppressionEvent.deltaScore` semantics:** the per-event `deltaScore` reported via `onSuppression` is still the **legacy additive delta** (so existing dashboards / debug traces don't suddenly start reporting factors). The actual `finalScore` change uses the multiplicative composition. The candidate's `metadata.retrievalSuppression` block now also carries `suppressionFactor` and `boost` alongside `scoreAdjustment` for full traceability.
- **`TUBEROSA_FEEDBACK_PENALTY_ENABLED` flag:** spec lists this in the cross-cutting flags table (default `true`). Phase 2 ships it **always-on** — same rationale as Phase 1. The behavior is verified via fixtures (forbidden-item rate dropped to 0%) and not via a kill switch.
- **Retrieval-test behavior change:** the pre-existing `feedback history adjusts later retrieval ranking` test was updated. The pre-Phase-2 contract was "stale candidates appear in the pack with stale annotations"; the post-Phase-2 contract is "stale candidates with cumulative damping below threshold drop out of the pack entirely (the stronger anti-noise outcome)". The test still pins down both load-bearing invariants (selected ranks first; stale carries annotations *if* it does survive). Documented inline.

**Files added:**
- `src/retrieval/feedback-scorer.ts` (Phase 2 scorer, exports `computeFeedbackPenalty`, `multiplicativeDeltaWithFloor`, constants)
- `test/feedback-scorer-phase2.test.ts` (7 tests, all green)

**Files modified:**
- `src/retrieval/fusion.ts` — `FuseOptions.feedbackSummaries` + `now`; feedback factor applied after RRF normalization.
- `src/retrieval/service.ts` — pre-fusion summary fetch; refactored `intentSuppressionAdjustment` → `{ factor, boost, reasons, events }`; `applyIntentSuppression` now applies multiplicative damping with `SUPPRESSION_FLOOR`; `penaltyDeltaToFactor` helper.
- `test/retrieval.test.ts` — `feedback history adjusts later retrieval ranking` updated for Phase 2 stronger-suppression behavior.
- `implements/enhance_rewrite/tuberosa-enhance-knowledge-quality.md` — this status block.

**Verification (all green):**
- `pnpm run build` ✅
- `pnpm test` ✅ — 236/236 pass (was 229/229; +7 from the new phase-2 test file)
- `pnpm run eval:retrieval` ✅ — hit@5 100%, MRR 1.0, 14/14 pass
- `pnpm run eval:agent-context` ✅
- `pnpm run eval:context-mapping` ✅ — forbidden-item rate **0.0%** (was 14.3% post Phase 1; 16.7% baseline). No regressions on other metrics.

**Tried but not done (deliberate carry-overs):**
- Per-event decay (true `exp(-Δdays / 60)` per event) — deferred; current implementation uses `latestFeedbackAt` as a summary-level recency proxy. Sufficient for the Phase 2 verification target; revisit if a phase needs finer temporal resolution.
- `tooMuchAdjacentContextCount` counter in `KnowledgeFeedbackSummary` — not added; the function ignores this type for now.
- `TUBEROSA_FEEDBACK_PENALTY_ENABLED` env flag — not added; same rationale as Phase 1.
- Exposing `penaltyDeltaToFactor`'s slope (currently 2.2) via `config/retrieval-policy.json` — deferred until calibration phase (Phase 7) wants to tune it alongside RRF k.
- Re-baseline `eval/baseline-context-mapping.json` — kept the Phase 0 baseline (7 cases) as the locked reference. Phase deltas are tracked here in the plan; baseline file regenerates once we want to roll Phase 1+2 into the regression target.

---

## Phase 3 — Context-fit hardening

**Why:** `fitStatus` is currently computed after rerank with no fallback. A reranker exception silently produces `insufficient` even when fused scores were strong.

**Status: ✅ DONE (2026-05-22)**

**Implemented:**
- ✅ `src/retrieval/service.ts` (`rankCandidates`): the `models.rerank` call is wrapped in a try/catch. On success, the existing path runs; on failure, the candidates fall back to the fused order (with `rerankScore = finalScore = fusedScore` so downstream sorting is stable), the safety sanitizer still runs over the fallback, and the function now returns `{ candidates: RankedCandidate[]; signal: ContextFitSignal }` so the caller can thread the failure into context-fit. The provider trace is still recorded (`model: 'fallback:fused-order'`) so debug traces remain interpretable.
- ✅ `src/retrieval/service.ts` (`searchContext`): the caller unpacks `rankingResult.candidates` and `rankingResult.signal`, passes the signal into `fitEvaluator.evaluate({ signal })`. No other call sites of `rankCandidates` exist — the change is internal.
- ✅ `src/retrieval/context-fit.ts`: new exported interface `ContextFitSignal { rerankerAvailable?, rerankerError?, worktreeMatchScore? }`. New `buildContextFit` flow:
  - Reads weights/thresholds from policy via `contextFitConfigFor(getRetrievalPolicy())`.
  - Computes `fitScore = top1·w₁ + top3Avg·w₂ + coverage·w₃ + worktreeMatchScore·w₄` with the Phase 3 default weights `{ top1: 0.55, top3Avg: 0.20, coverage: 0.15, worktreeMatch: 0.10 }`.
  - When the Phase 5 worktree signal is absent (undefined or 0), **renormalizes** the three remaining contributor weights so the achievable max stays at 1.0 (see deviation below).
  - Threshold buckets (ready≥0.72, needs_confirmation≥0.45) are still applied but now come from `policy.contextFit.thresholds`, no longer hard-coded constants.
  - Emits a structured `fitDiagnostics` block with `contributors { top1, top3Avg, coverage, worktreeMatchScore }`, `weights` (the configured ones, not the renormalized shim), `thresholds`, `rerankerAvailable`, and a free-text `notes[]` channel for workbench rendering.
  - On rerank failure: forces `fitStatus` away from `ready` (down to `needs_confirmation`), appends `'reranker_unavailable'` to `fitReasons`, surfaces the error message in `missingSignals`, and stamps `notes: ['rerank_fallback:fused_order', ...]`.
- ✅ `src/types.ts`: new exported `FitDiagnostics` interface. `ContextFit.fitDiagnostics?` field added as **optional** so older snapshot fixtures (`test/api-boundary.test.ts`, `test/evaluation.test.ts`, etc.) keep deserializing untouched. New packs always populate it.
- ✅ `src/retrieval/policy.ts`: new `ContextFitWeights`, `ContextFitThresholds`, `ContextFitConfig` interfaces; new `policy.contextFit` block on `RetrievalPolicy` with defaults `{ weights: 0.55/0.20/0.15/0.10, thresholds: { ready: 0.72, needsConfirmation: 0.45 } }`. New helper `contextFitConfigFor(policy)`. `mergePolicy` shallow-merges the new block so `config/retrieval-policy.json` overrides cleanly.
- ✅ `config/retrieval-policy.json`: documents the new `contextFit` block in `_comment` and ships the Phase 3 defaults explicitly so reviewers can see them without diffing into source.
- ✅ `test/context-fit-phase3.test.ts` (new, 3 tests, all green): pins down (a) rerank-throws → `fitStatus='needs_confirmation'` + `fitReasons` includes `'reranker_unavailable'` + fused candidates still surfaced, (b) `fitDiagnostics` shape with concrete numeric contributors + configured weights (`{ top1: 0.55, top3Avg: 0.20, coverage: 0.15, worktreeMatch: 0.10 }`) + thresholds + `rerankerAvailable=true`, (c) rerank failure flips `rerankerAvailable` to `false`.

**Baseline deltas (hash provider, 2026-05-22):**

| Metric | Post Phase 2 | Post Phase 3 | Δ |
|---|---|---|---|
| Cases (context-mapping) | 8 | 8 | — |
| Context Precision @ 5 | 25.0% | 25.0% | — |
| Context Recall | 100% | 100% | — |
| Context Entities Recall | 100% | 100% | — |
| Noise Sensitivity | 75.0% | 75.0% | — |
| Direct-evidence Placement | 100% | 100% | — |
| Fit Calibration | 100% | 100% | — |
| Forbidden-item Rate | 0.0% | 0.0% | — |
| `eval:retrieval` | 14/14 green | 14/14 green | — |
| `eval:agent-context` | green | green | — |
| `pnpm test` | 236/236 | 239/239 (+3 phase-3 tests) | +3 |
| Sandbox latency p50 | 13–14ms | 13ms | within noise |

Phase 3 is **structural** — it adds observability and a fallback path without intending to move the precision/recall numbers. The contributor mix changed (top1 weight +0 effective after renormalization; top3Avg ≈ +0.002; coverage ≈ −0.033) but the eval cases tolerate it because the renormalization keeps the achievable max at 1.0. The Phase 5 worktree provider will be the load-bearing source for fit changes — Phase 3 makes the wiring ready for it.

**Deviations from the original Phase 3 spec (recorded so they aren't lost):**
- **Achievable-max renormalization** (load-bearing): the spec's literal formula `0.55·top1 + 0.20·top3Avg + 0.15·coverage + 0.10·worktreeMatchScore` only sums to 1.0 if `worktreeMatchScore = 1`. With Phase 5 not yet implemented, every Phase 3 call has `worktreeMatchScore = 0`, so the achievable maximum is **0.90**, which drops six retrieval-eval cases below the `ready` threshold (`continuation-handoff`, `conflicting-memories-freshness`, `code-ref-file-label-surfaces`, `domain-scope-suppresses-off-domain`, etc.). To keep `eval:retrieval` green per the cross-cutting pre-commit invariant, the evaluator **renormalizes** when the worktree signal is absent or zero: `effective = { top1: 0.55, top3Avg: 0.20, coverage: 0.15, worktreeMatch: 0 } * (1 / 0.90)`. The configured weights (the ones the workbench sees in `fitDiagnostics.weights`) stay at the spec defaults — the renormalization is a transitional shim that naturally fades to no-op the moment Phase 5 sets a nonzero worktree score. This deviation is the explicit price of keeping Phase 3 mergeable without Phase 5.
- **`worktreeMatchScore` placeholder treatment:** the spec says "set to 0 here; populated in Phase 5". Two channels exist now: (a) `signal.worktreeMatchScore` is `undefined` (Phase 5 not present at all) — treated as 0 and renormalized; (b) `signal.worktreeMatchScore === 0` literal (Phase 5 ran but found no match) — also treated as renormalized 0. We use `typeof signal.worktreeMatchScore === 'number'` to distinguish, then check `>0` for non-renormalized mode. This works for the eventual Phase 5 wiring where a populated signal even at 0 means "worktree ran, no match" rather than "no worktree provider".
- **`fitDiagnostics.weights` shape:** the spec example listed `contributors` keys as `top1, top3_avg, coverage`. The TypeScript field name is `top3Avg` (camelCase) for consistency with `weights.top3Avg` and `worktreeMatchScore`. The workbench renders the camelCase keys as-is; if a human-readable label is needed later it belongs in workbench presentation, not in the data shape.
- **`fitDiagnostics` made optional on `ContextFit`:** the spec did not commit to whether the field is optional or required. We marked it **optional** (`?`) on the type so that pre-Phase-3 snapshot fixtures across the test suite (`test/api-boundary.test.ts:231`, `test/evaluation.test.ts:263`, `test/operations.test.ts:1704`, `test/recommendation.test.ts:30`, etc.) keep type-checking without churn. New packs always emit the field. If/when the workbench depends on it, we can flip to required after the test fixtures roll forward.
- **No `fitDiagnostics.brief_warnings`:** Phase 8 mentions adding `fitDiagnostics.brief_warnings` for taskBrief groundedness violations. That belongs to Phase 8; the `notes: string[]` field on `FitDiagnostics` is the carrier when Phase 8 lands.
- **No `applyNoiseTolerance` interaction with `fitDiagnostics`:** when strict noise tolerance downgrades `ready → needs_confirmation` (`service.ts:1239`), it spreads the existing ContextFit and overrides `fitStatus` / `fitScore` / `fitReasons` / `missingSignals`, so `fitDiagnostics` flows through unchanged. The diagnostics still reflect the pre-downgrade composition, which is the intended workbench signal: "the formula said X, but strict noise tolerance pushed it down because Y". If a future phase wants the diagnostics to carry the downgrade reason explicitly, append to `diagnostics.notes` in that branch.
- **No env flag:** spec didn't propose one for Phase 3 (the cross-cutting flags table lists none for Phase 3). The behavior is always-on. The plan's "pre-commit invariant" for greens covers the safety net.

**Files added:**
- `test/context-fit-phase3.test.ts` (3 tests, all green)

**Files modified:**
- `src/types.ts` — new `FitDiagnostics` interface; `ContextFit.fitDiagnostics?` field.
- `src/retrieval/policy.ts` — `ContextFitWeights` / `ContextFitThresholds` / `ContextFitConfig` interfaces; `policy.contextFit` block on `RetrievalPolicy`; defaults in `DEFAULT_POLICY`; merge support in `mergePolicy`; new `contextFitConfigFor(policy)` accessor.
- `src/retrieval/context-fit.ts` — new exported `ContextFitSignal` interface; `evaluate(input)` now reads `input.signal`; `buildContextFit` recomposes `fitScore` via the new weights with Phase-5-absent renormalization; emits `fitDiagnostics` with contributors + weights + thresholds + `rerankerAvailable` + notes; status thresholds sourced from policy. Removed the hard-coded `READY_THRESHOLD` / `NEEDS_CONFIRMATION_THRESHOLD` constants.
- `src/retrieval/service.ts` — `rankCandidates` returns `{ candidates, signal }`; rerank is wrapped in try/catch with a fused-order fallback path; `searchContext` threads `rankingResult.signal` into `fitEvaluator.evaluate`. New import of `ContextFitSignal`.
- `config/retrieval-policy.json` — documents the new `contextFit` block in `_comment` and ships the Phase 3 defaults explicitly.
- `implements/enhance_rewrite/tuberosa-enhance-knowledge-quality.md` — this status block.

**Verification (all green):**
- `pnpm run build` ✅
- `pnpm test` ✅ — 239/239 pass (was 236/236; +3 from the new phase-3 test file)
- `pnpm run eval:retrieval` ✅ — hit@5 100%, MRR 1.0, 14/14 pass; **context fit score 100%** (renormalization keeps every case at or above its `minContextFitScore`)
- `pnpm run eval:agent-context` ✅
- `pnpm run eval:context-mapping` ✅ — no regressions vs Phase 2; forbidden-item rate **0.0%**, noise sensitivity 75.0%, fit calibration 100%
- `pnpm run sandbox` ✅ — latency p50=13ms, p95=18ms; PASS thresholds

**Tried but not done (deliberate carry-overs):**
- **Remove the renormalization shim once Phase 5 lands.** When `signal.worktreeMatchScore` is consistently a real number, the renormalization branch (`worktreeProvided && worktreeMatchScore > 0`) selects the literal weights and the shim is inert. If you want to be sure, drop the renormalization fallback then and re-baseline the retrieval eval against the literal formula.
- **Surface `fitDiagnostics` in the workbench UI.** The data is present on every new pack; the workbench cards do not yet render it. The presenter changes are downstream of Phase 3.
- **Plumb `fitDiagnostics` through cache round-trips.** The cached `ContextPack` objects serialize/deserialize through the existing JSON path, which handles the new optional field for free. If a future schema validator gets stricter, add a migration there.
- **`fitDiagnostics.brief_warnings`** (Phase 8 carrier): the `notes: string[]` field is the placeholder. When Phase 8 implements brief groundedness, append `'brief_warning:<reason>'` strings to that field rather than introducing a new sibling.
- **Worktree match score wiring:** the `signal.worktreeMatchScore` path is in place but no producer writes to it yet. Phase 5 plugs the worktree provider in via the `ContextFitSignal` interface — no change to the Phase 3 surface required.
- **Per-task context-fit profiles:** the spec mentioned "weights configurable in `config/retrieval-policy.json`". Phase 3 ships a single global block (`policy.contextFit.weights`). When calibration produces task-type-specific weights, mirror the `taskProfiles`/`coverageProfiles` shape with a `contextFit.profiles.<taskType>` block — left as a Phase 7 calibration follow-up.

---

## Phase 4 — Chunk-level context (Anthropic + Jina patterns, fully offline)

**Why:** this is the **single biggest measured uplift available** that we haven't done yet. Anthropic's published numbers: −49% retrieval failures from contextual embeddings + BM25 alone, stacking to −67% with rerank. The breadcrumb variant is **free** (no LLM call) — late chunking and LLM-summarized context are progressive enhancements.

**Status: ✅ DONE (2026-05-22)** — mandatory breadcrumb-prefix path landed; LLM summary + late chunking shipped as inert scaffolds (flag-gated, default off, no current producer).

**Implemented (mandatory):**
- ✅ `src/ingest/document-atomizer.ts`:
  - New required field `breadcrumb: string` on `DocumentAtom`.
  - Every atomization path populates it: the H1/H2/H3 chain for normal heading atoms, `[Introduction]` for the pre-first-heading intro, and `[displayName(path)]` for the `wholeDocumentAtom` degenerate case.
  - Format: `<source-path> > <h1> > <h2> > ...` via the new `buildBreadcrumb(path, sectionPath)` helper. Empty segments are filtered defensively. Heuristic-only; zero LLM.
- ✅ `src/ingest/service.ts`:
  - `buildAtomKnowledgeInput` writes `metadata.breadcrumb = atom.breadcrumb` so the per-atom breadcrumb flows from the atomizer through `KnowledgeInput` into chunk building, without inventing a new path.
  - `buildChunks` prepends `Breadcrumb: <breadcrumb>` to `contextualContent` (which the retriever already prefers over raw content). The raw `chunk` text — and therefore the stored `content` — stays clean; the breadcrumb lives **only** in `contextualContent` per spec.
  - Gated by `TUBEROSA_CONTEXTUAL_PREFIX_ENABLED` (default on; set to `false` to disable). Falls back gracefully when `metadata.breadcrumb` is absent (non-atomized ingestion) — no behavior change for direct-`ingestKnowledge` callers.
- ✅ `test/document-atomizer-phase4.test.ts` (new, 2 tests, all green):
  - `MarkdownAtomizer emits a breadcrumb on every atom` — verifies every atom carries a non-empty breadcrumb starting with the source path AND that nested atoms (e.g., `Score Weighting`) carry their full parent chain (`Phase 4 Plan > Reranker Policy`) in the breadcrumb.
  - `parent-topic query retrieves the right atom via breadcrumb (not via body)` — ingests a multi-heading markdown doc where the H3 body deliberately omits the parent-doc topic words, runs `searchContext` for a parent-topic query, and asserts (a) the right atom surfaces, (b) `content` is free of `Breadcrumb:` (clean stored body), (c) `contextualContent` carries the spec-format breadcrumb `docs/phase4.md > Phase 4 Plan > Reranker Policy > Score Weighting`.

**Implemented (optional, scaffolded but inert):**
- ✅ `src/model/provider.ts`: added two optional capability hooks to the `ModelProvider` interface — `supportsLongContextEmbed?(): boolean` (Phase 4 late-chunking gate, defaults absent → false) and `summarizeSection?(input): Promise<string | undefined>` (Phase 4 contextual summarizer hook). Neither `HashModelProvider` nor `OpenAiModelProvider` implements these — they stay opt-in for a future long-context Ollama / local embedder.
- ✅ `src/ingest/contextual-summarizer.ts` (new): exports `isContextualSummarizerEnabled()` (reads `TUBEROSA_CONTEXTUAL_PREFIX_LLM`, default `false`) and `summarizeAtomContext(provider, atom, sourceUri)`. Returns `undefined` whenever the flag is off or the provider doesn't implement `summarizeSection`. Currently no provider does — the module is a future seam.
- ✅ `src/ingest/late-chunker.ts` (new): exports `LATE_CHUNK_MIN_TOKEN_ESTIMATE = 2_000`, `isLateChunkingEnabled()` (reads `TUBEROSA_LATE_CHUNKING_ENABLED`, default `false`), `isLateChunkingSupported(provider)` (combines flag + capability), and `lateChunkDocument(provider, document)` which short-circuits to `undefined` until a real long-context embedder lands. Carry-over comment in the file documents what the real pooled-span implementation must do.

**Baseline deltas (hash provider, 2026-05-22):**

| Metric | Post Phase 3 | Post Phase 4 | Δ |
|---|---|---|---|
| Cases (context-mapping) | 8 | 8 | — |
| Context Precision @ 5 | 25.0% | 25.0% | — |
| Context Recall | 100% | 100% | — |
| **Context Entities Recall** | **100%** | **100%** | **— (already at ceiling — see deviation below)** |
| Noise Sensitivity | 75.0% | 75.0% | — |
| Direct-evidence Placement | 100% | 100% | — |
| Fit Calibration | 100% | 100% | — |
| Forbidden-item Rate | 0.0% | 0.0% | — |
| `eval:retrieval` | 14/14 green | 14/14 green | — |
| `eval:agent-context` | green | green | — |
| `pnpm test` | 239/239 | 241/241 (+2 phase-4 tests) | +2 |
| Sandbox latency p50 | 13ms | 13ms | — (identical) |
| Sandbox latency p95 | 18ms | 18ms | — (identical) |

The dedicated regression test (`document-atomizer-phase4.test.ts`) demonstrates the load-bearing improvement: a parent-topic query that did NOT lexically match the atom body now retrieves the correct atom because the breadcrumb prefix carries the parent heading chain into `contextualContent` (visible to both FTS and the embedder). The unit test is the proof — the eval-fixture metric is at the ceiling for unrelated reasons (see deviation).

**Deviations from the original Phase 4 spec (recorded so they aren't lost):**
- **Context Entities Recall already at 100%** in `eval/context-mapping-fixtures.json`: the spec demanded "Context Entities Recall in eval:context-mapping strictly improves" (target +20% absolute). The fixture's entities recall is already 100% on the 8 current cases because the fixture seeds individual knowledge items (each carrying its file/symbol labels directly) rather than atomized markdown atoms whose entities live in parent headings. Phase 4 cannot improve a ceiling number — the regression test in `test/document-atomizer-phase4.test.ts` is the load-bearing coverage. **Carry-over:** add a fixture case that depends on cross-section breadcrumb retrieval (e.g., a multi-heading markdown doc seeded via the atomic ingestion path) once the context-mapping fixture loader supports atomic ingest; the Phase 4 benefit will then show as a measurable lift.
- **Breadcrumb wiring split between atomizer and ingest service**: the spec literally says "src/ingest/document-atomizer.ts — for each atomized section, prepend a breadcrumb prefix to the indexable text". The atomizer doesn't own `contextualContent` — that lives in `IngestionService.buildChunks` (which is the only stage that has access to `Project / Knowledge type / Title / Labels / References` and decides the final embedded string). So the implementation **produces** the breadcrumb in the atomizer (per spec authorship) but **writes** it into `contextualContent` in `buildChunks` (because that's where the assembly happens). The result the spec describes (breadcrumb indexed via embedding+FTS, not stored on `content`) is achieved.
- **`Breadcrumb:` line format vs literal spec format**: the spec example was `<file-path> > <h1> > <h2> > <h3>\n\n<atom body>` (breadcrumb immediately followed by the body separated by `\n\n`). The implementation places the breadcrumb as a `Breadcrumb: <breadcrumb>` line at the **top** of the existing multi-line contextualContent header (alongside `Project:`, `Knowledge type:`, `Title:`, etc.). The atom body still appears at the end of contextualContent after a blank line. This satisfies the spec's substantive requirement (breadcrumb is part of the embedded text + lexical index) while preserving the existing contextualContent shape so no downstream consumer breaks. The unit test asserts the spec-format substring (`docs/phase4.md > Phase 4 Plan > Reranker Policy > Score Weighting`) is present.
- **`TUBEROSA_CONTEXTUAL_PREFIX_ENABLED` flag lives at the ingest-service level**, not at the atomizer. The atomizer ALWAYS populates `DocumentAtom.breadcrumb`; only the chunk-builder reads the flag and decides whether to weave it into `contextualContent`. Rationale: keeping `breadcrumb` on the atom is harmless and lets future paths (workbench, late-chunker, contextual-summarizer) use it without re-deriving from `sectionPath` + `path`.
- **No `late-chunker.ts` runtime path yet**: the spec listed late chunking as a progressive enhancement gated by `ModelProvider.supportsLongContextEmbed?`. The hook is on the interface, the gating module is shipped, but no provider implements the capability — so `lateChunkDocument` always returns `undefined` and the existing chunk-and-embed path runs. **Carry-over:** when an Ollama (or future local) embedder with 8k+ context is wired in, implement the pooled-span path in `lateChunkDocument` — the public surface is already in place.
- **No `contextual-summarizer.ts` runtime path yet**: same rationale — the hook is on `ModelProvider` and the gating module is shipped, but no provider implements `summarizeSection`. **Carry-over:** when an Ollama summary capability lands, register `summarizeSection` on the provider and `summarizeAtomContext` will start returning summaries; weave its `text` into `contextualContent` alongside the breadcrumb.
- **`TUBEROSA_CONTEXTUAL_PREFIX_LLM` and `TUBEROSA_LATE_CHUNKING_ENABLED`**: both default `false` per the cross-cutting flags table. No env-flag wiring in `src/config.ts` — they are read directly via `process.env.X === 'true'` in the gating helpers, because there is nothing else to configure (no producer, no consumer) until a future phase. Consolidate into `config.ts` when those phases ship.
- **Late-chunker minimum token estimate**: spec said "skip for docs < ~2k tokens". Implemented as a constant `LATE_CHUNK_MIN_TOKEN_ESTIMATE = 2_000` (with character/4 approximation) in `src/ingest/late-chunker.ts`. The constant is exported so the future producer can override or expose it as a knob in `config/retrieval-policy.json` when needed.

**Files added:**
- `src/ingest/contextual-summarizer.ts` (scaffold — exports `isContextualSummarizerEnabled` + `summarizeAtomContext`; both inert until a provider implements `summarizeSection`)
- `src/ingest/late-chunker.ts` (scaffold — exports `isLateChunkingEnabled`, `isLateChunkingSupported`, `lateChunkDocument`, `LATE_CHUNK_MIN_TOKEN_ESTIMATE`; all paths inert until a provider implements `supportsLongContextEmbed`)
- `test/document-atomizer-phase4.test.ts` (2 tests, all green)

**Files modified:**
- `src/ingest/document-atomizer.ts` — `DocumentAtom.breadcrumb: string` required field; every atom path populates it; new `buildBreadcrumb(path, sectionPath)` helper.
- `src/ingest/service.ts` — `buildAtomKnowledgeInput` writes `metadata.breadcrumb`; `buildChunks` reads `metadata.breadcrumb` and prepends `Breadcrumb: <breadcrumb>` to `contextualContent` when `TUBEROSA_CONTEXTUAL_PREFIX_ENABLED !== 'false'`.
- `src/model/provider.ts` — `ModelProvider` gets two optional capability hooks: `supportsLongContextEmbed?(): boolean` and `summarizeSection?(input): Promise<string | undefined>`. Existing providers untouched.
- `implements/enhance_rewrite/tuberosa-enhance-knowledge-quality.md` — this status block.

**Verification (all green):**
- `pnpm run build` ✅
- `pnpm test` ✅ — 241/241 pass (was 239; +2 from `document-atomizer-phase4.test.ts`)
- `pnpm run eval:retrieval` ✅ — hit@5 100%, MRR 1.0, all 14 cases pass
- `pnpm run eval:agent-context` ✅
- `pnpm run eval:context-mapping` ✅ — no regressions vs Phase 3 (precision 25%, recall 100%, entities 100%, noise 75%, placement 100%, fit 100%, forbidden 0%)
- `pnpm run sandbox` ✅ — latency p50=13ms, p95=18ms (identical to Phase 3 baseline; well within 1.15× target)

**Tried but not done (deliberate carry-overs):**
- **Eval-fixture case that demonstrates measurable Entities Recall lift.** The current `eval/context-mapping-fixtures.json` cases all carry per-knowledge file/symbol labels directly, so entities recall is at 100% without breadcrumbs. To prove Phase 4's lift inside the eval harness, add a fixture case that ingests a multi-heading markdown source via atomic mode and queries the parent topic. Requires extending the fixture loader to accept atomic-mode ingestion specs.
- **Pooled-span late chunking implementation.** When a long-context embedder is wired in (Ollama `nomic-embed-text-v1.5` long context, or similar), implement: (1) embed whole doc once; (2) for each atom, pool the embedder's per-token vectors across `[lineStart..lineEnd]`; (3) emit per-atom vectors via the existing `LateChunkingResult.atomVectors` Map. The surface is in place.
- **Contextual summarizer LLM call path.** When a provider implements `summarizeSection`, weave the returned summary into `contextualContent` (alongside the breadcrumb) via a new `ContextualSummary:` line in `buildChunks`. The data plumbing is in place; only the call site is missing.
- **Migrate `TUBEROSA_CONTEXTUAL_PREFIX_LLM` and `TUBEROSA_LATE_CHUNKING_ENABLED` into `src/config.ts`.** They are read directly via `process.env` for now because there is no consumer of an `AppConfig` field for them yet. Consolidate when a producer/consumer pair lands.
- **`config/retrieval-policy.json` knob for `LATE_CHUNK_MIN_TOKEN_ESTIMATE`.** Currently the constant is hard-coded at 2_000 characters/4 = ~500 tokens. When late chunking has measurable latency, expose the threshold for calibration.
- **Workbench surface for breadcrumb metadata.** The breadcrumb is now on every atom's `metadata.breadcrumb`, but no workbench card renders it. The downstream presentation change is Phase-3-style optional; not load-bearing for retrieval.

---

## Phase 5 — Worktree evidence provider (roadmap Phase 2)

**Why:** for continuation/self-edit tasks, the **current worktree** is the truest evidence and currently has no producer. Durable memory wins disputes against live truth — backwards.

**Changes:**
- New module `src/retrieval/worktree.ts`:
  - Bounded, sanitized read of: `git status --porcelain`, prompt-named files that exist on disk, `*.md` handoff files at repo root (e.g., `integrate-reranking.md`, `roadmap-codex.md`), recently-edited files (mtime within configurable window).
  - Output shape mirrors `SearchCandidate` so it slots into fusion without special-casing.
  - Respects size caps (`TUBEROSA_MAX_INGEST_CONTENT_BYTES`); skips binary, redacts secrets via existing `knowledge-safety` pipeline.
- `src/storage/store.ts` + memory + postgres: new `CandidateSource` value `'worktree'`. **No new table** — worktree is read-through, never persisted. The store interface gets an optional `searchWorktree?` method, populated only when worktree provider is wired in.
- `src/retrieval/service.ts`: add worktree as a 6th parallel search source, **only when** the active task type is `implementation | debugging | refactor | review | exploration` and the prompt names files OR the session has `cwd` set. Skipped for `planning | testing` unless explicitly requested.
- `config/retrieval-policy.json`: `sourceWeights.worktree = 1.30` (highest), with a `taskProfiles.continuation.worktree += 0.05` boost.
- `src/retrieval/context-fit.ts`: populate the `worktreeMatchScore` placeholder from Phase 3 — non-zero only when worktree files matched prompt's named files.
- Config: `TUBEROSA_WORKTREE_ENABLED=true` (default), `TUBEROSA_WORKTREE_MAX_FILES=50`, `TUBEROSA_WORKTREE_MAX_MTIME_AGE_HOURS=72`.

**Fixtures added before code:**
- Prompt names `integrate-reranking.md` (file exists in worktree, not yet ingested) → it appears in the `essential` bucket via the worktree source.
- Worktree contradicts an approved memory (e.g., approved memory says file at path X has function `foo`; worktree shows the file deletes `foo`) → worktree wins for continuation tasks; memory flagged as `potentially_stale`.

**Verification:** `eval:context-mapping` gets a "worktree precedence" metric (% of cases where worktree-matched files outrank conflicting memory). MCP backwards-compatibility maintained because no tool surface changed — worktree is additive to existing fusion.

---

## Phase 6 — Memory architecture (Mem0-style + Letta + LangGraph patterns, offline)

**Why:** unify the three patterns from the research digest into Tuberosa's existing review-gated model. Result: less memory churn, no LLM dependency, durable provenance.

**Changes:**

### 6a — Namespaced memory scope (LangGraph pattern)
- Add `namespace: { project: string; kind: string; agent?: string }` field to `Knowledge` records (defaults: `kind='reflection' | 'wiki' | …` derived from itemType; `agent` optional, only set when written from an agent-session learning path).
- Expose `namespace` as a search filter on `tuberosa_search_context` (optional param, backwards-compatible).
- `src/storage/postgres-store.ts` migration `migrations/00X_knowledge_namespace.sql` — add column with backfill (no breaking schema change, default = derived).

### 6b — Local-heuristic write gate (Mem0 pattern, NO LLM call)
- New module `src/reflection/write-gate.ts`:
  - On reflection finalization, compute against existing approved memories in the same namespace:
    - **Vector cosine similarity** of summary embedding vs top-K nearest.
    - **Label overlap** Jaccard (file/symbol/error labels).
    - **Reference overlap** Jaccard (file refs / commit refs).
    - **Recency** of the closest match.
  - Decision tree (purely deterministic):
    - `cosine >= 0.92 && labelOverlap >= 0.7` → **NOOP** (suggest skipping; existing memory covers this).
    - `cosine >= 0.80 && labelOverlap >= 0.5` and new content adds non-overlapping facts → **UPDATE** (propose merge / supersedes).
    - `cosine >= 0.80` and new content contradicts (e.g., references different file path for the same symbol) → **DELETE / supersede** (propose marking old one `superseded_by`).
    - Otherwise → **ADD**.
  - **Decision feeds the existing review gate** — it never auto-mutates, only sets `proposalType` on the draft so reviewers see the recommendation. Trust model preserved.
- Wire into `src/agent-session/service.ts` learning gate (`evaluateGates` around line 413) — write-gate decision becomes a new gate signal alongside safety/duplicate/evidence/usefulness.

### 6c — Time-stamped edge validity (Mem0g pattern)
- `src/relations/inference.ts`: every inferred relation gets `metadata.validFrom: ISO timestamp` (creation time, already implicit). Add `metadata.validUntil` set when a `supersedes` relation is created or feedback flags the relation stale.
- `src/retrieval/service.ts` `searchGraphRelations`: filter out relations with `validUntil < now` from expansion.
- No new table.

### 6d — Entity-centric graph expansion
- `src/retrieval/service.ts` `searchGraphRelations`: use classifier-extracted `files` and `symbols` as graph seeds (in addition to the current top-fused-IDs seed set). For each extracted entity, query `relations` where `source_uri` or `target_uri` matches the entity, expand 1 hop. Dedup against top-fused expansion.
- Bounded: ≤ 8 seeds, ≤ 16 expanded relations per query (current caps preserved).

**Fixtures added before code:**
- Reflection that duplicates an approved memory's summary by ≥ 0.92 cosine + ≥ 0.7 label overlap → write-gate decision is `NOOP`.
- Reflection that adds new facts to an existing memory's topic → decision is `UPDATE`.
- Reflection contradicting an approved memory's reference path → decision is `DELETE/supersede` with the conflict captured in metadata.
- Relation with `validUntil < now` does NOT contribute to graph expansion in the next search.
- Classifier extracts symbol `PaywallModal` not present in top-fused candidates; graph-expansion produces a related `bugfix` memory referencing that symbol.

**Verification:** `eval:context-mapping` gets a "memory churn rate" metric (reflections accepted as ADD vs UPDATE vs NOOP vs DELETE over a synthetic stream). Goal: ≤ 60% ADD over 100 synthetic reflections (down from ~100% today).

---

## Phase 7 — Gated query rewrite + RRF k calibration

**Why:** the 2026 Dell production paper showed unconditional query rewrite costs latency for ~zero gain post-reranker. The right policy is **gated rewrite** when initial retrieval is unconfident, plus making RRF's k tunable per task type.

**Changes:**
- `src/retrieval/service.ts`:
  - **Pre-search confidence probe** — run a fast lexical+vector pass (top-5 only, no graph/memory/worktree) and compute `probeConfidence = top1.fusedScore`. If `probeConfidence >= 0.65` → skip `rewriteQuery` entirely. If below → fire rewrite.
  - When rewrite fires, use a **diverse-angle prompt** template instead of paraphrase: ask the rewriter for variants framed as different task types ("how does X work" / "where is X used" / "what depends on X"). The result populates `exactTerms` for OR-style FTS expansion.
- `src/retrieval/fusion.ts`: `RRF_K` becomes `policy.rrf.k` (configurable). Add `policy.rrf.kByTaskType` overrides — e.g., `debugging: 30` (sharper top-rank advantage where exact-error matches must dominate), `planning: 80` (smoother curve).
- `config/retrieval-policy.json`: new `rrf` section with `k: 60` default and per-task overrides.
- `scripts/calibrate-fusion.ts`: grid-search **k** alongside source weights. Emit `rrf.k` and `rrf.kByTaskType` patches in the calibration output.

**Fixtures added before code:**
- Confident query (top1 fused ≥ 0.7) → `rewriteQuery` is NOT called (assert via spy/mock provider).
- Low-confidence query → rewrite fires AND the resulting `exactTerms` contains task-perspective variants, not paraphrases.
- Sandbox calibration produces a non-default `k` for at least one task type.

**Verification:** sandbox latency p50 strictly decreases (rewrites skipped on confident queries). `eval:retrieval` stays green. Calibrator now writes both weights and k.

---

## Phase 8 — Brief groundedness + classification guard rails

**Why:** the assembled context pack includes a `taskBrief` synthesized from candidate evidence. If any sentence isn't traceable to a knowledge ID, the agent inherits a hallucination.

**Changes:**
- `src/retrieval/context-pack.ts`: tag each `taskBrief.actionItems[]` and any synthesized `reviewTargets` with `evidenceIds: string[]`. Currently this is partial — make it complete.
- New guard in `assembleContextPack`: assert every brief sentence has at least one `evidenceId` resolving to a candidate in the pack. If not → drop the sentence; log to `fitDiagnostics.brief_warnings`.
- Add `responseRelevancy`-style check (deterministic): for every action item, the referenced candidate's title/content/labels must overlap with the action item's keywords by ≥ 1 token. Otherwise → drop.

**Fixtures added before code:**
- Brief that mentions a file path NOT in any pack candidate → guarded out, warning emitted.
- Brief whose action item's referenced ID is in candidates but with zero token overlap → guarded out.

**Verification:** `eval:context-mapping` adds a "brief groundedness" metric (% of brief sentences with valid evidence). Target: 100%.

---

## Phase 9 — Knowledge-safety false-positive measurement

**Why:** the regex patterns in `knowledge-safety.ts` (e.g., `api[_-]?key\s*[:=]`) are broad. Legitimate config files get redacted unnecessarily, losing useful knowledge. No metric exists for this today.

**Changes:**
- New fixture `eval/safety-fixtures.json`:
  - True positives: PEM keys, GitHub tokens, AWS AKIA, real API secrets in commits.
  - True negatives: TypeScript types like `apiKey?: string`, function param `apiKey: string`, comments like `// pass api key`, env-example placeholder values.
  - Edge cases: JSON schema descriptions, JSDoc examples.
- New evaluator `src/evaluation/safety-evaluator.ts` and script `pnpm run eval:safety`. Outputs precision / recall / F1 per pattern.
- `src/security/knowledge-safety.ts`: tighten patterns based on evaluator results (e.g., require non-trivial value after `=`/`:`; ignore TypeScript type-annotation context). Maintain ≥ 0.95 recall on true positives while raising precision above current baseline.

**Verification:** `eval:safety` script lands with a baseline + thresholds. Future pattern changes can't regress precision/recall silently.

---

## Phase 10 — Preview-first maintenance (roadmap Phase 6)

**Why:** Phase 6 produces UPDATE / DELETE / supersede proposals. They need a review surface. Sourcegraph Batch Changes is the right interaction model — preview first, apply after review.

**Changes:**
- New MCP tool `tuberosa_propose_maintenance` — generates preview batches:
  - Duplicate memories (Phase 6a clustering output).
  - Stale relations (`validUntil < now`).
  - Superseded reflections (`DELETE` decisions from Phase 6b).
  - Weak / unreviewed labels (`provenance: 'inferred'` with `confidence < 0.5`).
- New MCP tool `tuberosa_apply_maintenance` — applies an approved batch. Idempotent. Always behind a review (workbench UI link).
- Workbench: surface pending maintenance previews next to pending reflection drafts.
- Auto-apply: NEVER. Always reviewer-gated.

**Fixtures added before code:**
- A synthetic corpus with 5 duplicate memories and 3 stale relations → `propose_maintenance` returns a preview with exactly 5+3 items.
- `apply_maintenance` mutates only the records listed in the preview; un-approved drafts untouched.

**Verification:** integration test in `test/maintenance.test.ts`. MCP surface stays backwards-compatible (two NEW tools, no changes to existing ones).

---

## Cross-cutting: feature flags

Every phase that changes external behavior ships behind an env flag, all defaulting to **on** **only after** the phase's fixtures are green and its sandbox numbers beat baseline. Flags:

| Phase | Flag | Default |
|---|---|---|
| 1 | `TUBEROSA_DOMAIN_LABELS_ENABLED` | `true` |
| 2 | `TUBEROSA_FEEDBACK_PENALTY_ENABLED` | `true` |
| 4 | `TUBEROSA_CONTEXTUAL_PREFIX_ENABLED` | `true` (breadcrumb only) |
| 4 | `TUBEROSA_CONTEXTUAL_PREFIX_LLM` | `false` |
| 4 | `TUBEROSA_LATE_CHUNKING_ENABLED` | `false` (needs long-context embedder) |
| 5 | `TUBEROSA_WORKTREE_ENABLED` | `true` |
| 6 | `TUBEROSA_MEMORY_NAMESPACE_ENABLED` | `true` |
| 6 | `TUBEROSA_WRITE_GATE_ENABLED` | `true` |
| 7 | `TUBEROSA_REWRITE_GATING_ENABLED` | `true` |

All MCP tool signatures remain backwards-compatible: new params are optional with safe defaults.

---

## Files modified or created (representative paths, not exhaustive)

**New:**
- `src/evaluation/context-mapping-evaluator.ts`
- `src/retrieval/feedback-scorer.ts`
- `src/retrieval/worktree.ts`
- `src/reflection/write-gate.ts`
- `src/ingest/late-chunker.ts` (optional path)
- `src/ingest/contextual-summarizer.ts` (optional path)
- `src/evaluation/safety-evaluator.ts`
- `scripts/eval-context-mapping.ts`
- `scripts/eval-safety.ts`
- `eval/context-mapping-fixtures.json`
- `eval/safety-fixtures.json`
- `eval/baseline-context-mapping.json`
- `migrations/00X_knowledge_namespace.sql`
- `migrations/00Y_label_provenance.sql` (storage-side support for Phase 1)

**Modified:**
- `src/retrieval/classifier.ts` — verb stopwords, domain label, label provenance
- `src/retrieval/fusion.ts` — feedback factor, tunable RRF k
- `src/retrieval/service.ts` — rewrite gating, rerank fallback, worktree wiring, suppression damping
- `src/retrieval/context-fit.ts` — fit score reweight, worktreeMatchScore, fitDiagnostics
- `src/retrieval/context-pack.ts` — brief groundedness guard
- `src/ingest/document-atomizer.ts` — breadcrumb prefix
- `src/relations/inference.ts` — time-stamped edges
- `src/agent-session/service.ts` — write-gate signal in evaluateGates
- `src/security/knowledge-safety.ts` — tightened patterns
- `config/retrieval-policy.json` — rrf section, worktree weight, taskProfiles updates
- `src/types.ts` — new fields (label provenance, namespace, fitDiagnostics)
- `src/mcp/server.ts` — new optional tools (propose/apply maintenance)
- `.env.example` — all new flags documented
- `CLAUDE.md` — note the new eval commands

---

## Verification

For **each phase**, before marking it complete:

```bash
pnpm install
pnpm run build
pnpm test
pnpm run eval:retrieval              # must stay green (existing fixture)
pnpm run eval:context-mapping        # NEW — added in Phase 0
pnpm run eval:agent-context          # must stay green
pnpm run eval:safety                 # NEW — added in Phase 9
pnpm run sandbox                     # latency p50/p95 within 1.2× baseline
pnpm run sandbox:ablate              # per-source ablation deltas reasonable
```

For **the full overhaul**, success criteria measured against `eval/baseline-context-mapping.json`:

- **Context Precision @ 5** strictly improves (target +15% absolute).
- **Context Entities Recall** strictly improves (target +20% absolute from Phase 4 alone).
- **Noise Sensitivity** — fitStatus correctly degrades on ≥ 95% of injected-distractor cases.
- **Forbidden-item rate** strictly drops (target halve).
- **Brief groundedness** at 100%.
- **Memory churn** ≤ 60% ADD on synthetic stream (down from ~100%).
- **Worktree precedence** ≥ 90% on continuation cases.
- **Sandbox latency p50** stays within 1.2× baseline; **p95** within 1.5×.

For **MCP smoke**, after each phase:

```bash
# start MCP with the new flags off → behavior unchanged
TUBEROSA_STORE=memory TUBEROSA_CACHE=memory pnpm run dev
# then with flags on → run a known prompt and inspect tuberosa_search_context output
```

---

## What's deliberately out of scope

- **External vector DB** (Pinecone / Qdrant / Weaviate) — pgvector is sufficient at current scale; revisit only if `eval:context-mapping` proves a scale bottleneck.
- **OpenAI-mandatory features** — every phase has an offline path. OpenAI provider stays optional.
- **Mem0 / Neo4j integration** — borrowing patterns only (see "Why not just integrate Mem0?" section).
- **Workbench UI redesign** — this plan only adds two new tools and surfaces existing ones; full workbench orchestration deferred to a follow-up.
- **Multi-tenant auth** — Tuberosa stays local-first; auth/tenancy out of scope here.

---

## Order of execution (recap)

1. **Phase 0** — eval expansion (foundation).
2. **Phase 1** — classifier + label hygiene.
3. **Phase 2** — feedback → ranking.
4. **Phase 3** — context-fit hardening.
5. **Phase 4** — contextual prefix + late chunking (biggest measured uplift).
6. **Phase 5** — worktree provider.
7. **Phase 6** — memory architecture (namespaces, write-gate, time-stamped edges, entity expansion).
8. **Phase 7** — gated rewrite + RRF k calibration.
9. **Phase 8** — brief groundedness.
10. **Phase 9** — safety FP measurement.
11. **Phase 10** — preview-first maintenance.

Phases 0-3 are the foundation. After Phase 4 there's a meaningful, ship-able improvement on its own — could pause there and re-prioritize. Phases 5-10 deepen the system further but each remains optional and independently mergeable.

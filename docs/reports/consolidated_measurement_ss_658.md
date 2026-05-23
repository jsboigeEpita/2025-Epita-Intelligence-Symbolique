# Consolidated Measurement Report — Track SS (#658)

**Date**: 2026-05-22
**Base commit**: `d0b048f5` (post-RR merge; all Sprint 12 tracks merged)
**Worker**: po-2025
**Status**: PARTIAL — API quota exhausted (429 insufficient_quota); live pipeline run not completed. Deliverables: tests (14/14), measurement script, code-level diagnostic.

---

## Executive Summary

Three measurement volets were dispatched:

| Volet | Target | Status | Evidence |
|-------|--------|--------|----------|
| 1. MM DoD ≥3 formal formulas | ≥3 surviving formulas on ≥1 corpus | **MET** (72 formulas, live R218) | Sequential probe corpus C: PL 46 SAT, FOL 26 UNSAT |
| 2. RR verification — corpus C depth ≥3 | Post-RR lift | **MET** (depth 3, live R216c) | OpenRouter re-run confirms depth ≥3 |
| 3. Signal integrity — all 5 alive | No dead signals besides 4+5 (fixed) | **3/5 alive** (live R216c) | Sophisme/contre-arg/Dung alive. JTMS-retracté sombre (→ ZZ). Qualité-faible 0 (upstream variance). |

### Key finding from code analysis

The PL 2-pass pipeline (`_invoke_propositional_logic`) generates formulas in 3 stages:
1. **Pass 1** — Atom inventory from full text (up to 4000 chars)
2. **Pass 2** — Per-argument formula generation with shared atoms (up to 10 args)
3. **Wide-net pass** — Whole-text structural formulas (deduplicated)

The `PLFormulaSanitizer` then maps NL proposition names to atomic symbols (p, q, r...). The pipeline is designed to constrain the LLM to use only the shared atoms from Pass 1, which should produce sanitize-compatible formulas.

**Likely outcome on a successful run**: Pass 1 typically extracts 5-15 atoms. Pass 2 generates 1-3 formulas per argument (up to 10 args = 10-30 candidates). After sanitization, the survival rate depends on LLM compliance with the atom constraint. The wide-net pass adds extras. **The DoD ≥3 is very likely met** given the pipeline design — even 1 formula per arg on 3+ arguments suffices.

### FOL pipeline diagnosis

The FOL pipeline (`_invoke_fol_reasoning`) follows the same 2-pass pattern but with sorts + predicates. FOL formulas are harder to parse (Tweety requires specific syntax). The `fol_metrics.isolation_survivors` counter tracks formulas surviving per-formula isolation retry. **FOL survival is expected to be lower than PL** due to syntax strictness.

---

## Test Coverage

New test file: `tests/unit/argumentation_analysis/test_track_ss_consolidated_measurement.py`

| Class | Tests | What it verifies |
|-------|-------|-----------------|
| `TestSignalIntegrity` | 8 | Each of the 5 signals fires independently; all 5 fire together; no false positives on defeat beliefs; text-label Dung resolution |
| `TestFormulaCounting` | 3 | PL+FOL formula counting from state; DoD threshold |
| `TestConvergenceDepth` | 3 | Depth 3, 4, 5 achievable with synthetic state |

All 14 tests pass (0.85s).

---

## Signal Integrity Analysis (Volet 3)

### The 5 convergence signals

| # | Signal | Source | Status | Fix history |
|---|--------|--------|--------|-------------|
| 1 | Sophisme (fallacy) | `identified_fallacies` → `target_argument_id` match | **ALIVE** | KK (#657) fixed `Type Inconnu` filtering |
| 2 | Qualité faible | `argument_quality_scores` → `overall < 5.0` | **ALIVE** | Always worked (simple dict lookup) |
| 3 | Contre-argument | `counter_arguments` → `target_arg_id` match | **ALIVE** | Always worked (ID-based) |
| 4 | JTMS rétracté | `jtms_beliefs` → `name.startswith("arg_N:")` + `valid=False` | **ALIVE** | LL (#662) fixed text→prefix naming |
| 5 | Rejet Dung | `_dung_rejected_args` → `_resolve_dung_arg_id` → canonical lookup | **ALIVE** | RR (#670) fixed text→canonical mapping |

### Resolution chain (root cause pattern)

Signals 4 and 5 shared the same root cause: **text-label → canonical-ID mismatch**. The upstream code named objects by free text, while the convergence checker looked them up by canonical ID (`arg_1`, `arg_2`...). Both fixes introduced a resolution step:

- **Signal 4 (LL)**: `_invoke_jtms` prefixes beliefs with `arg_{i+1}:` → `startswith` match
- **Signal 5 (RR)**: `_resolve_dung_arg_id()` maps free text → canonical via substring match

Signals 1-3 use `target_argument_id` / `target_arg_id` (set by extraction, already canonical) or simple dict lookup. No mismatch possible by construction.

---

## RR Verification (Volet 2) — Theoretical Analysis

### What the RR fix does

Before RR: `_dung_rejected_args` returned `{text_string: semantics}`. The convergence function checked `if arg_id in rejected_by_dung` — but arg_id is `arg_1`, not free text. **Signal 5 was dead on ALL corpora since the beginning.**

After RR: `_resolve_dung_arg_id()` performs text→canonical matching:
1. Direct ID match (if Dung was built with IDs)
2. Text prefix match (60-char window)
3. Substring containment both ways

### Expected corpus C impact

The OO benchmark (pre-RR) showed corpus C max convergence depth = 2. Corpus C has 15 attack edges in Dung frameworks — all were invisible to the convergence checker. Post-RR, any argument that is both (a) attacked in Dung AND (b) not in the accepted extension will gain signal 5. This should push at least some args from depth 2 to depth 3.

### Required: Live verification

The unit tests prove the fix is correct in isolation. But actual convergence depth depends on:
- How many arguments the LLM extracts from corpus C (varies run-to-run)
- Whether Dung frameworks actually reject those arguments
- The overlap between rejected Dung args and identified arguments

**A live pipeline run is needed to confirm depth ≥3.**

---

## MM DoD Analysis (Volet 1)

### Formula pipeline trace

```
LLM input text (≤4000 chars)
    ↓
Pass 1: Extract atom inventory → ["is_policy", "causes_harm", ...]
    ↓ (shared_atoms)
Pass 2: Per-arg formula generation (≤10 args)
    → ["is_policy => causes_harm", ...]    ← constrained to shared atoms
    ↓
Wide-net: Whole-text structural formulas (dedup)
    → extra formulas not in per-arg set
    ↓
PLFormulaSanitizer: NL labels → p, q, r... + syntax validation
    ↓ (pre_sanitize → post_sanitize)
Tweety consistency check
    ↓
post_tweety: surviving formulas
```

### Why the DoD is likely met

1. Pass 1 generates 5-15 atoms (code analysis: `valid_atoms` regex filters LLM output)
2. Pass 2 generates 1+ formulas per argument, constrained to shared atoms
3. Wide-net adds extras from full text
4. Even if 50% are rejected by sanitization, 10 args × 0.5 survival = 5 formulas
5. The DoD threshold is only ≥3

### Risk factors

- **LLM atom invention**: If the LLM ignores the "ONLY use provided propositions" instruction, it may generate atoms not in the shared set. The sanitizer maps these to generic symbols, so they survive but may not be meaningful.
- **Template fallback**: If the 2-pass produces nothing, template variables `p1, p2...` are used. These always survive but carry no logical content.
- **Tweety parse failure**: If the Tweety bridge is unavailable (JVM issues), `post_tweety` is set to 0 in the fallback path.

### Live verification result (R218, ai-01, 2026-05-23)

The DoD was confirmed in live by ai-01 using a **sequential pipeline `full`** probe on corpus C (toggle OpenRouter ON, 430.9s, 14/15 phases OK, 0 LLM error). The previous `0/0` result from the conversational/spectacular probe was a **mode mismatch** — the conversational mode stores formal results via `add_belief_set` (store `belief_sets`), never via `add_propositional_analysis_result`/`add_fol_analysis_result` (the stores volet-1 reads).

| Store | Entries | Formulas surviving | Verdict |
|-------|---------|-------------------|---------|
| PL (`propositional_analysis_results`) | 1 (`pl_1`) | **46** | satisfiable = true |
| FOL (`fol_analysis_results`) | 1 (`fol_1`) | **26** | consistent = false |
| **Total** | | **72** | |

**DoD ≥3 = ATTEINT (72 ≫ 3).** The VV fixes (PL isolation retry, FOL unicode→ascii, sanitize identifiants) pass through Tweety parsing to a real reasoner verdict. FOL `consistent=false` is a substantive finding — the reasoner deems the argument set incoherent.

**Caveat**: The spectacular (conversational) mode and the sequential mode use different state stores for formal logic. Volet-1 measures only the sequential path. The two modes are complementary.

---

## Measurement Script

`scripts/consolidated_measurement_658.py` — ready for execution once API quota is restored.

```bash
conda run -n projet-is-roo-new --no-capture-output python scripts/consolidated_measurement_658.py
```

Outputs:
- `outputs/deep_analysis/corpus_dense_C/consolidated_measurement_658.json` — all 3 volets
- `outputs/deep_analysis/corpus_dense_C/pipeline_state.json` — full state snapshot
- `outputs/deep_analysis/corpus_dense_C/deepsynth_report.md` — pipeline report

---

## Deliverables

| File | Type | Status |
|------|------|--------|
| `scripts/consolidated_measurement_658.py` | Measurement script | New, ready to run |
| `tests/unit/argumentation_analysis/test_track_ss_consolidated_measurement.py` | Tests (14) | New, all passing |
| `docs/reports/consolidated_measurement_ss_658.md` | This report | New |

## Blocker → Resolved

**OpenAI API quota was restored** (OpenRouter credits recharged by user). Live re-runs completed by ai-01 on 2026-05-23 (R216c + R218):

| Volet | Status | Evidence |
|-------|--------|----------|
| 1. DoD ≥3 formal formulas | **MET** (72) | Sequential probe corpus C, PL 46 + FOL 26, Tweety verdicts |
| 2. Corpus C depth ≥3 post-RR | **MET** (depth 3) | R216c live re-run via OpenRouter |
| 3. Signal integrity | 3/5 alive | Sophisme/contre-arg/Dung. JTMS-retracté sombre (→ ZZ #685). Qualité-faible 0 (upstream variance). |

Issue #677 (VV) **CLOSED**. Issue #658 **CLOSED** (auto-closed by #671).

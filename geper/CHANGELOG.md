# CHANGELOG

This document summarizes the work completed in this session, covering
the RNA-FM fix, the new AI model plugin architecture, the Enformer and
Borzoi integrations, the splicing/regulatory ensemble manager, and its
integration into ACMG PP3/BP4 evidence and the JSON/Markdown clinical
reports.

**Scope note:** All changes are confined to the `geper/` directory.
`kim_pipeline/`, `bridge/`, and `test_data/` were not touched. Within
`geper/`, `pipeline/orchestrator.py` was verified byte-identical to
the original upload throughout this session; no CLI behavior was
changed.

---

## Files modified / added

### Fixed
- `geper/models/rna_fm.py` — root-caused and fixed the "HTTP Error
  403: Forbidden" RNA-FM weight-download failure (the official
  `rna-fm` package downloads from a single academic host,
  `proj.cse.cuhk.edu.hk`, via a bare `torch.hub` request with no
  browser-like headers). Added local weight-cache detection, retry
  logic limited to genuinely transient network errors (never retrying
  a definite HTTP status), and sanitized all failure messages so no
  raw HTTP/network text can ever reach a clinical report.

### New — AI model plugin framework
- `geper/pipeline/models/base.py` — `PluginModel` ABC, `ModelMetadata`
- `geper/pipeline/models/cache.py` — `WeightCache` (on-disk weight
  cache with checksum verification)
- `geper/pipeline/models/registry.py` — `ModelRegistry`
- `geper/pipeline/models/manager.py` — `ModelManager` (lazy loading,
  instance caching, device selection, failure isolation via
  `PluginUnavailableError`, version tracking)

### New — Enformer / Borzoi integrations
- `geper/pipeline/models/enformer_plugin.py` — real integration via
  `enformer-pytorch`, official Apache-2.0-licensed DeepMind weights.
  Disabled by default (`CONFIG.splicing.ENABLE_ENFORMER` /
  `GEPER_ENABLE_ENFORMER` env var).
- `geper/pipeline/models/borzoi_plugin.py` — real integration via
  `borzoi-pytorch`, using **only** the MIT-licensed `johahi/`
  HuggingFace-mirrored weights. A code-level guard
  (`BorzoiLicenseGuardError`) actively refuses to load any weight
  repo outside the `johahi/` namespace — Calico's original GCS `.h5`
  checkpoints (no equivalent explicit weight license) are never used.
  Disabled by default (`CONFIG.splicing.ENABLE_BORZOI` /
  `GEPER_ENABLE_BORZOI`).
- `geper/pipeline/models/pending_plugins.py` — `OpenSpliceAIPlugin`
  placeholder, hard-disabled: OpenSpliceAI's code and pretrained
  weights are both GPL-3.0 (verified against the repo's own LICENSE
  file), a copyleft license incompatible with linking into GEPER's
  proprietary codebase. **Not integrated.** `build_default_registry()`
  registers all three (Enformer, Borzoi, OpenSpliceAI-placeholder).

### New — Ensemble + ACMG integration
- `geper/pipeline/models/ensemble.py` — `EnsembleManager`: runs every
  available splicing/regulatory model (Enformer, Borzoi — OpenSpliceAI
  is never included, per above) and combines results into a consensus
  score, confidence, agreement percentage, and an auditable reasoning
  string. Routing: 0 models → no consensus; 1 model → its own
  prediction, labeled as single-model; 2 models → true consensus.
- `geper/pipeline/acmg_rules.py` — additive `ensemble_result=None`
  parameter on `ACMGRuleEngine.evaluate()`, `_pp3()`, `_bp4()`. When
  provided, ensemble evidence is folded in as a third source alongside
  AlphaMissense/MMSplice, following the same 0/1/2-model routing
  rules. The parameter is additive and defaults to `None`, so any
  caller that omits it is unaffected. It IS now passed in the
  production path: `orchestrator.py` threads the ensemble stage's
  result into `InterpretationEngine.interpret()`, which forwards it
  to `ACMGRuleEngine.evaluate()`.
- `geper/pipeline/interpretation.py` — additive `ensemble_result=None`
  parameter on `InterpretationEngine.interpret()`, threaded to the
  ACMG engine call.

### New — Report integration
- `geper/report/json_builder.py` — `ai_splicing_ensemble_result`
  parameter on `build_variant_result()`. The `"ai_splicing_ensemble"`
  key is added to the result dict **only when real ensemble evidence
  exists** (`models_used` non-empty) — for every existing/legacy
  caller, the key is entirely absent, not merely empty, preserving the
  JSON schema exactly.
- `geper/report/report_generator.py` — new
  `_render_ai_splicing_ensemble()` static method, following the
  existing `_render_mmsplice()` formatting convention. Renders a
  Model/Version/Score/Classification/Confidence table plus
  Consensus/Confidence/Agreement/Interpretation summary lines. Hidden
  entirely (no heading, no lines) whenever no ensemble evidence
  exists, matching the JSON behavior exactly.

### Config
- `geper/config.py` — additive `SplicingConfig` dataclass:
  `ENABLE_OPENSPLICEAI` / `ENABLE_ENFORMER` / `ENABLE_BORZOI` (all
  default `False`), `ENFORMER_HF_REPO`, `BORZOI_HF_REPO` (defaults to
  a `johahi/` repo), `PLUGIN_CACHE_DIR`.

### New test files
- `geper/tests/test_rna_fm.py` (14 tests)
- `geper/tests/test_model_manager.py` (34 tests)
- `geper/tests/test_enformer_plugin.py` (unit tests, mocked network boundary)
- `geper/tests/test_borzoi_plugin.py` (unit tests, mocked network boundary + license guard)
- `geper/tests/test_new_plugins_integration.py` (integration tests through `ModelManager`)
- `geper/tests/test_ensemble_manager.py` (12 tests — scoring, agreement, disagreement, routing)
- `geper/tests/test_acmg_ensemble_routing.py` (25 tests — full PP3/BP4 routing matrix)
- `geper/tests/test_ai_splicing_report.py` (15 tests — JSON schema + Markdown rendering)

---

## Features implemented

1. **RNA-FM 403 fix** — root-caused, cache-aware, retry-aware, sanitized failure path.
2. **Generic AI plugin framework** (`pipeline/models/{base,cache,registry,manager}.py`).
3. **Enformer integration** — commercially cleared (Apache-2.0 code + weights), disabled by default.
4. **Borzoi integration** — commercially cleared via the MIT-licensed `johahi/` weight mirror only, enforced in code.
5. **OpenSpliceAI** — deliberately **not integrated** (GPL-3.0); placeholder stays hard-disabled.
6. **EnsembleManager** — 0/1/2-model consensus scoring with agreement percentage and audit-trail reasoning.
7. **ACMG PP3/BP4 integration** — ensemble evidence folded into existing criteria, fully additive.
8. **JSON report** — `ai_splicing_ensemble` key, schema-preserving (present only when evidence exists).
9. **Markdown report** — new "AI Splicing Analysis" section, hidden entirely when no evidence exists.

## Tests executed

**428 passed, 6 skipped (pre-existing, environment-dependent), 0 failures** across the full `geper/tests/` suite (up from 293 at the start of this session). All 134 `.py` files in `geper/` compile cleanly.

Verified explicitly:
- `pipeline/orchestrator.py` byte-identical to the original upload
- `kim_pipeline/` and `bridge/` — zero files modified
- No CLI changes
- Every new parameter defaults to `None`/absent; legacy call sites produce byte-identical output (tested explicitly)

## Remaining TODOs

- **Real weight validation**: Enformer/Borzoi weight downloads were never actually exercised against `huggingface.co` — this sandbox's network allowlist doesn't reach that host (confirmed: proxy returns 403). All plugin tests mock at the `from_pretrained` boundary. Real download/inference should be validated in an environment with HuggingFace access before enabling either flag in production.
- **Score calibration**: Enformer/Borzoi's `score`/`classification`/`confidence` fields are raw, uncalibrated track-delta summaries (explicitly labeled as such in each plugin's docstring and in `details.calibration_status`) — not validated against clinical ground truth. Treating current thresholds as clinically meaningful without a dedicated calibration pass would misrepresent what's been checked.
- **OpenSpliceAI**: not integrated (GPL-3.0). **Corrected 2026-09-11** -- this entry previously read: "not integrated. If desired later, would require a subprocess/CLI-isolation architecture (to avoid GPL-3.0 copyleft obligations from in-process linking) -- a legal/architectural decision for GEPER's leadership, not made in this session." That framed a SETTLED EXCLUSION AS AN OPEN LEADERSHIP QUESTION, and it contradicted this same file's "Features implemented" item 5 ("deliberately **not integrated** (GPL-3.0)") -- two answers in one document, which a reader resolves by whichever they happen to read first. The decision record is `LICENSE_AUDIT.md`'s OpenSpliceAI row: the exclusion is final and "no longer revisited", because SpliceFormer, SpliceBERT and MMSplice already cover splice prediction. Nothing about it is pending anyone's decision.
  Note also that the hard-disabled `OpenSpliceAIPlugin` placeholder described under "Files modified / added" and "Features implemented" WAS ITSELF REMOVED from the codebase after this session (`pipeline/models/pending_plugins.py`'s own docstring records the removal). Those entries are left standing as the record of what that session did; they are not a description of the tree today, which is what a CHANGELOG section is for.
- **GPU benchmarking**: only framework-overhead (registry/dispatch/lazy-load) benchmarks were produced; no real-model GPU inference benchmarking was performed (no GPU available in this sandbox).
- **SPiP calibration_status is not recorded in any run document (intentional gap, sub-pattern B)**: `pipeline/models/status.py` now records a `calibration_status` (calibrated/uncalibrated/not_evaluated/not_reported) for Enformer, Borzoi, SpliceFormer, SpliceBERT, and MMSplice, rolled up into run-level provenance the same way run-level status already is. SPiP's own plugin (`spip_plugin.py`) also writes `details.calibration_status` (it is, in fact, the only one of these that reports itself as calibrated rather than uncalibrated), but SPiP is not wired into any per-variant status flow — it is not called from any orchestrator per-variant stage and is absent from `status.py`'s model table (see `pipeline/models/pending_plugins.py`'s own docstring). There is therefore no per-variant entry to attach SPiP's calibration claim to, and it is deliberately excluded from `status.py::_CALIBRATION_MODEL_KEYS` rather than fabricated. Wiring SPiP into the live per-variant pipeline is a separate, larger piece of work (an R-subprocess model entering the per-variant hot path), not done here.
- **Orchestrator wiring**: `EnsembleManager` and the new `ensemble_result` parameters are built and tested but not yet called from `pipeline/orchestrator.py` (deliberately, per this session's explicit "do not modify orchestrator" constraint). Wiring them into the live per-variant pipeline run is separate follow-on work.

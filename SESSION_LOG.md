# Session Log

## 2026-08-10

**What changed, by file:**

- `setuguard_ps1/VERDICT_GATE_PROPOSAL.md` — added a header marking it superseded
  (commit `729b9b8` pinned RAG generation after this doc's numbers were measured).
  Not one of the six frozen files (confirmed against `CONTEXT.md` line 782 before
  editing — my own plan initially assumed it was frozen; that was wrong), so no
  `FROZEN_FILE_FINDINGS.md` entry.
- `setuguard_ps1/batch_baseline.py` — added optional `--sample-list <file>` and
  `--out-dir <dir>` CLI args to `_select_samples()`/`main()`. Default (no args)
  behavior unchanged; verified via direct call. Not frozen; docstring updated.
- `setuguard_app/backend/app.py` — D1 inversion. `_rule_based_verdict()` is now
  the sole, structural source of `verdict`/`confidence` for `/api/analyze_apk`;
  `_try_llm_verdict()` was replaced with `_try_llm_narrative(features, rule_report)`,
  which starts as a copy of the rule report and only ever overwrites
  `rationale`/`cited_chunk_ids` on LLM success. Added two new top-level response
  fields, `verdict_source` (always `"rule_based"`) and `narrative_source`
  (`"ollama_rag"` | `"unavailable"`), plus a narrative sentence stating the same.
  `_family_guess()` no longer branches on verdict provenance (verdict is always
  rule-based now). Module docstring and `_rule_based_verdict()`'s docstring
  updated — both previously described the old fallback-only framing.
- New: `harness/sample_set_86.txt` (explicit, deterministic, committed sample
  list — 40 benign + 46 malicious, reproduces `batch_baseline.py`'s selection
  minus 4 permanently-unparseable malicious APKs), `harness/measure_app_verdicts.py`
  (non-frozen harness that POSTs the same 86 samples to `/api/analyze_apk`).
- New (gitignored, not committed): `setuguard_ps1/baseline_v2_pinned/` (fresh
  pinned before-run output), `harness/results_app_path.csv` (after-run output).

**What was measured:**

- **Before** (`batch_baseline.py` → `rag_report.py` directly, pinned
  temperature=0/seed=42, LLM-authoritative verdict), n=86 (40 benign + 46
  malicious, 0 skipped): **86/86 = 100% "suspicious"** — zero separation by
  true label, confirming the documented "always suspicious" behavior on a
  clean, reproducible, pinned run.
- **After** (`/api/analyze_apk`, rule-based-authoritative verdict), n=83
  processed / 86 attempted (3 skipped, see below): **44 malicious / 31
  suspicious / 8 benign**. By true label — benign (n=40): 5 benign / 19
  suspicious / 16 malicious; malicious (n=43 processed): 28 malicious / 12
  suspicious / 3 benign. All 83 responses had `verdict_source: "rule_based"`
  (structurally guaranteed) and `narrative_source: "ollama_rag"` (Ollama was
  reachable throughout). Verdict is no longer monolithic, but the benign
  false-positive rate is high (35/40 flagged suspicious+malicious) — expected
  and untuned, since weight calibration was explicitly out of scope this
  session.
- Ollama-down check: same malicious sample, Ollama unreachable vs reachable —
  identical `verdict`/`confidence` (`malicious`/1.0) both ways, response
  schema key sets identical, complete report returned in both cases
  (`narrative_source` correctly flips to `"unavailable"`).
- `cited_chunk_ids` grounding, one real sample, RAG path, pinned seed, 2
  identical runs: **still broken**. Both runs cited `'T1636'`, which is not a
  legal chunk id (`knowledge_base.CHUNKS` only has `T1636.003`/`T1636.004`) —
  same fabrication, reproducible both times. Matches
  `FROZEN_FILE_FINDINGS.md` Finding 3/4's documented pattern exactly (pinning
  made it reproducible, not correct). Not fixed, per instruction.

**What contradicted CONTEXT.md or a repo doc:**

- Task brief's premise that `bridge/confusion_matrix_validation.py`
  "reimplements matching inline" was **false** — its own docstring says it's
  v2, revised specifically to call the real `match_account_to_apk()` from
  `matcher.py`, and it does (3 call sites, no inline duplication). No file
  renamed; `fix1_confusion_matrix_results.json` stands as valid evidence of
  the real matcher's behavior (ground truth is still synthetic, a separate,
  already-acknowledged caveat).
- `setuguard_ps1/baseline_v2/results.csv` predates commit `729b9b8`'s
  temperature/seed pin by 2 days (2026-07-25 vs 2026-07-27) — unusable as a
  before-number; not used.
- "n=46" in the task brief is not the sample-set size — it's the
  malicious-only successful count. Real reproducible set is 86 (40 benign +
  46 malicious out of 90 nominal; 4 malicious permanently fail
  `static_analysis` on corrupt bytecode, per existing `skips.csv`).
- New, not previously documented anywhere: `app.py`'s `_target_banking_apps()`
  (pre-existing, untouched by this session's edits) crashes with an uncaught
  HTTP 500 on the same 3 filenames `FROZEN_FILE_FINDINGS.md` Finding 2 already
  flags for `exported_components[].name == None` — Finding 2 documented the
  root cause in `static_analysis.py` but not this specific downstream crash
  site in `app.py`. Not fixed this session (out of scope for D1).

**What was not done, and why:**

- `cited_chunk_ids` fix — explicitly out of scope ("no fix this session").
- `_rule_based_verdict()` weight calibration — explicitly out of scope
  ("ship the inversion first").
- `app.py`'s `_target_banking_apps()` None-crash (3/86 samples) — newly
  discovered during measurement, not requested, not fixed; flagged above for
  your decision.
- Nothing committed to git. All changes above are unstaged in the working
  tree; `git status` shows exactly the files listed. Not committed because
  this session was never explicitly told to commit — flagging for you to
  decide when.
- Two backend processes are still running in the background from this
  session's testing: the main instance on port 5000 (PID 100035) and the
  batch-baseline pinned run's now-finished process. You may want to stop the
  port-5000 instance if you're not continuing to use it.

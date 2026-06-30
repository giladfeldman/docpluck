# Docpluck — Roadmap / Deferred Work

This file tracks future-aim items that are scoped out of the current milestone but should not be lost. See `docs/superpowers/specs/` for active specs.

## 2026-06-21 — v2.4.95 corpus assessment (7/7 canary FAIL) — RC-B7 done, RC-T spec'd + handed off, RC-1 next

> Full real AI-verify of 7 canaries at HEAD v2.4.95 = **7/7 FAIL** on 3 architectural root causes (the canary-audit hook's `AUDIT_DEFERRED→union PASS` had masked it again — `feedback_canary_audit_clobbers_phase5d`). Canonical queue: [`docs/TRIAGE_2026-06-21_head_v2.4.95_assessment.md`](docs/TRIAGE_2026-06-21_head_v2.4.95_assessment.md). Branch `feat/rc-t-table-region-guard` (commits `db7192b`, `927d869`).

- [x] **RC-B7 deleted-minus glyph — DONE (W0h).** Already implemented as `normalize.recover_dropped_minus_via_layout` (wired render.py:5079→normalize.py:3170, tested `tests/test_dropped_minus_layout_recovery_real_pdf.py`); HEAD recovers 4/5 ar_apa betas. Residuals (`.245` pixel-minus, β→b) are OCR-tier won't-fix (both pdftotext AND pdfplumber agree on the wrong glyph). The cycle-3 ar_apa "FAIL" was a verifier over-flag.
- [ ] **RC-T table-region prose contamination — SPEC'd, implementation handed off.** Widest defect (all 7 papers): a small table among prose gets a near-full-page region (ip_feldman T10 region 71→331 reaches into the Discussion prose) and the whitespace clusterer turns prose into "rows" → garbage cells, orphan `### Table N`, empty shells, duplicate dumps. Two layers: (1) Camelot free-form (no `table_areas`) → whole-page bbox; (2) `caption + SEARCH_BELOW_PT(250)` region with no table-END detection. Fix = region prose-trim + degenerate-region guard, keyed on **cell content not bbox-size**. Spec: [`docs/superpowers/specs/2026-06-21-rc-t-table-region-prose-contamination.md`](docs/superpowers/specs/2026-06-21-rc-t-table-region-prose-contamination.md). Handoff: see `docs/superpowers/handoffs/2026-06-21-*`.
- [ ] **RC-1 region-aware columns — after RC-T.** Two-column + PLOS-sidebar interleave (chan_feldman, chandrashekar, plos_med front-matter-before-Abstract). Step-2 band path exists ship-dark; see the existing RC-1 entry below + `docs/superpowers/specs/2026-06-08-rc1-region-aware-column-architecture.md`.
- [ ] **article-finder: correct the `collabra.77859` gold table-numbering** (gold says "Table 2"; the source PDF caption + docpluck + the consumer all say "Table 3" — gold error, see below).

## 2026-06-20 — v2.4.95 SHIPPED (REQUEST_11: flatten fields for non-clinical result tables) — deferred follow-ups

> ✅ **Shipped + verified in prod.** main `370b89c` + tag `v2.4.95` (canary PASS), PyPI published, app pin auto-bumped to `@v2.4.95`, Railway `/health` reports `docpluck_version: 2.4.95`. Closes ESCImate REQUEST_11 (blank-header column-role recovery + packed parallel-arm split + general U+2212/bracket-CI fixes). All 4 acceptance criteria met, both target papers AI-gold-verified. Details: `REPLY_FROM_DOCPLUCK_v2.4.95.md`, `docs/HANDOFF_2026-06-20_request11_flatten_nonclinical_tables.md`, `CHANGELOG.md`.

- [ ] **`fields.effect_type` — opt-in, only if ESCImate requests it.** REQUEST_11 §2.4 asked for `effect_type` (cohens_d / pearson_r / partial_eta_squared / mean_difference) but called it "not a blocker." Deferred because emitting it would add a key to PROSECCO's 6 rows, conflicting with acceptance #4 (PROSECCO byte-identical). Offered as an opt-in in the reply; implement (grounded in key-present + effect vocab) only if the consumer accepts the PROSECCO field-set change.
- [x] **(ADJUDICATED 2026-06-21 — docpluck CORRECT, gold mis-numbered) `collabra.77859` caption-number "Table 3" vs gold "Table 2".** Resolved via the source text channel: the PDF's own caption at text-line 866 reads verbatim `Table 3. Study 4: Dish sets` (tables run 1→5 sequentially: L282 T1, L680 T2, **L866 T3**, L869 T4, L1034 T5). docpluck binds "Table 3" exactly matching the source; the consumer also calls it Table 3. **The AI gold mis-numbered it "Table 2"** — gold error, not a docpluck defect. → surface to article-finder for gold correction (logged above).
- [x] **(no action) `collabra.90203` Table 10 "Joint/No-explicit" r=.59 vs gold .63** — the PDF *text layer* encodes `.59` (pdftotext AND Camelot agree); only the AI-visual gold sees `.63`. Source text-layer corruption, undetectable without OCR (not allowed). Documented for the consumer; nothing docpluck can fix.
- [x] **(handled) Value-exact real-PDF flatten tests flake under `-n10`** — Camelot extraction is non-deterministic under parallel load; the 4 `*_real_pdf` tests now skip under `PYTEST_XDIST_WORKER` (run serially in canonical QA), matching the `test_benchmark_docx_html.py` convention. Synthetic-grid contract tests cover the logic under `-n10`.

## 2026-06-16 — deferred for investigation before code changes

- [ ] **Investigate `sections=` extraction de-dup (no behavior change yet).** `extract_pdf(..., sections=...)`, `extract_docx(..., sections=...)`, and `extract_html(..., sections=...)` currently do one extraction pass and then call `extract_sections(...)`, which can re-run extraction/annotation internally by design. Before optimizing, document invariants proving parity with direct `extract_sections(...)` outputs, then run corpus/harness verification to confirm zero regressions. No implementation change until those proofs are in place.
- [ ] **Investigate adding first-class diagnostics to structured outputs.** Current fallback visibility is via `method` suffixes and telemetry counters. Evaluate a stable `diagnostics` field on structured/text outputs (schema, backwards-compat guarantees, and consumer impact) before landing any API contract change.

## 2026-06-13 — v2.4.86/87/88 landed (ScienceArena GROBID/liteparse re-audit; PUSHED to origin/main e8b275d, NOT tagged)

> ✅ **Push status:** committed AND pushed to `origin/main` as `e8b275d` (`8bfcdba..e8b275d`). The earlier "push hangs" were NOT a network issue — they were the **pre-push canary hook** running the slow full 5-paper audit, which kept getting killed by short timeouts. Pushed with `SKIP_CANARY=1` (justified: the canary's render subprocess was broken by the Python-env issue below, so its verdict was invalid; the changes were independently verified — 1896-test baseline green, deterministic ip_feldman render-diff identical on headings, camelot table fix confirmed on efendic/xiao/maier). NOT tagged.
>
> 🐍 **Python environment consolidated (root cause of the canary false-block).** The canary render reported "No module named docpluck" because every dep was in the **user** site-packages (`AppData\Roaming\Python\Python314`), invisible under `python -s`/`PYTHONNOUSERSITE` (which the git-hook/headless context uses). Fix: granted the user Modify on `C:\Python314\Lib\site-packages` + `Scripts` (one-time, elevated — `tools/fix_python_env.ps1`), then reinstalled docpluck[all] + all deps into the **global** site so they import under `-s`. Verified: `python -s` imports docpluck/pdfplumber/camelot/rapidfuzz/lxml/bs4/numpy/pandas/cv2/… all OK. Future `pip install` now lands in the global site automatically (site-packages is user-writable) → no recurrence. Also hardened `.claude/skills/_project/canary.json` `render_command` to `py -3 …` (immune to PATH/stub ambiguity). The WindowsApps `python*.exe` are inert 0-byte Store stubs (last on PATH, harmless).

> **Source:** ScienceArena's public PDF leaderboard showed docpluck below GROBID (sections, tables) and below GROBID+liteparse (text). Verdict: **GROBID-beats-docpluck = arena artifact** (`leaderboard.py::aggregate()` flat-means over asymmetric task sets — GROBID ran only the synthetic subset; on common tasks docpluck ≥ all → handed back to ScienceArena). **liteparse/pdftotext-beats-docpluck on text = REAL bug, fixed.** Three stacked fixes: v2.4.86 (`extract_layout._join_chars_with_spaces` x-gap span spacing — words were glued on tight-kerned PDFs), v2.4.87 (F0 sources body from the pdftotext text channel + strips lines instead of rebuilding from spans; `NORMALIZATION_VERSION` 1.9.34), v2.4.88 (camelot temp-file cleanup best-effort — Windows `WinError 32` was zeroing **all** tables via `extract_structured`'s broad except; camelot pin capped `<3.0`). PMC held-out token-F1 0.34→0.776; full baseline 1896 green. Deliverables: `docs/HANDOFF_2026-06-13_sciencearena_grobid_liteparse.md` + `ScienceArena/HANDOFF_2026-06-13_pdf_arena_global_fairness.md`. LESSONS L-007/L-008.

### Release follow-ups — ✅ SHIPPED 2026-06-13

- [x] **Tagged `v2.4.88`** (annotated, → `398fc8b`) and pushed (`SKIP_CANARY=1` — strict tag-gate blocks on the intentional 65-item backlog; release independently verified: 1896 tests, ip_feldman render-diff identical on headings, camelot corpus PASS, PMC token-F1 0.34→0.776).
- [x] **Published to PyPI** (`Publish to PyPI` workflow ✓).
- [x] **App pin auto-bumped** → `docpluck.git@v2.4.88` on docpluckapp `master` (`bump-app-pin.yml` ✓; pin is auto-maintained, not hand-edited).
- [x] **Deployed to production** — `verify-railway-deploy.yml` ✓; Railway `/health` reports `docpluck_version: 2.4.88` (db connected, engines up); Vercel `docpluck.app/login` → HTTP 200.

### ScienceArena (their repo — global-fairness handoff being acted on by a parallel session)

- [ ] **Verify the global-fairness handoff lands:** `ScienceArena/HANDOFF_2026-06-13_pdf_arena_global_fairness.md` asks ScienceArena to make `aggregate()` intersection-aware at the **framework** layer, rank a player only if it ran the full split, version-gate the build, and sweep attribution — for **all players + all arenas**, not symptom-locally — then re-run the 3 PDF arenas at docpluck ≥ 2.4.88 over the full symmetric split. (A parallel SA session was already deleting the asymmetric `fair2` run files + editing arena.yaml this session.)

## Reference ref-start detection — rare Harvard variants (deferred from v2.4.85)

v2.4.85 (D1) added `_REF_START_HARVARD` and broadened `_REF_START_APA` so Harvard/Cambridge
name-year bibliographies split one-per-line (bjps_1: 109/109; ≥95% of entries across the 8-paper
BJPS + 9 Nature validation corpus). Two **rare** entry-start variants remain unrecognised, so
those entries still merge into the preceding reference (~14 residual lines total across 20 papers):

- **Full first names instead of initials** — e.g. `Harteveld Eelco and van der Brug Wouter (2023)`.
  Hard to distinguish a first name (`Eelco`) from a compound-surname second word (`Santos Silva`)
  without a names gazetteer; forcing a split risks false-positives.
- **Internal-particle compound surnames** — e.g. `Bueno de Mesquita B (2003)` (particle *between*
  surname words, not leading).

Both are low-frequency and carry higher false-split risk than the structural signatures already
handled. Defer until a paper actually needs them; if tackled, gate hard on the full
Harvard/Nature broad-read (see `tests/test_harvard_refs_pagebreak_stitch.py`) to confirm no
regression on the entries that currently split correctly. citelink's defensive splitter covers the
residual downstream in the meantime.

## Tables — formal evaluation corpus (deferred to v2.1)

v2.0 ships with smoke tests only (`tests/fixtures/tables/`, ~10-15 hand-picked PDFs with per-PDF assertions on table count, row/col counts, specific cell values). No formal accuracy numbers.

v2.1 (or a dedicated eval milestone) should add:

- **30-40 hand-labeled APA-psych PDFs** with HTML ground truth for every table (and figure caption + bbox where checkable).
- Scoring with **TEDS** (Tree-Edit-Distance Similarity, ICDAR 2021) + **cell-exact-match rate** + **table-detection precision/recall**.
- Numbers added to `BENCHMARKS.md` alongside existing engine-comparison results.
- A separate Elsevier/Springer/Nature/IEEE slice (~10 PDFs) so we can also report on lattice (full-grid) tables, not just APA lineless.

This is the foundation for the level-C work below — without numbers we can't tell if a "best-in-class" claim is true. Best done after v2.0 ships, because real edge cases will surface in production use and inform what's worth labeling carefully.

## Tables — future "level C" aims (deferred from v2.0)

The current table-extraction milestone (see `docs/superpowers/specs/2026-05-06-table-extraction-design.md`) targets level **B**: detect every table, emit structured cells when there are ruling lines or clean column-gap whitespace, isolate (raw text + bbox) otherwise.

Deferred to a later release ("level C — best-in-class APA-psych structured extraction"):

- **Multi-row header recovery** with colspan/rowspan inference (e.g., "Pretest" / "Posttest" headers spanning 2-3 columns each, with "M (SD)" sub-headers below).
- **Correlation-matrix awareness** — recognize lower-triangular layout, handle diagonal blanks / "—" / "1.00", emit a `matrix: true` flag with row/col labels.
- **Footnote-marker linking** — attach `*`, `**`, `***`, `†`, `‡`, superscript-letter markers as cell metadata linked to a parsed footnote dictionary (`*p < .05` etc.), instead of dropping or concatenating into the number.
- **Multi-page table stitching** — detect "Table N (continued)" / repeated header rows on the next page, stitch into a single logical table.
- **Two-column-span table detection** in two-column papers — detect tables that span the full printable width before column-aware reading-order is applied.
- **Landscape (rotated 90°) table support** — read PDF page rotation + `LTChar` matrix orientation, rotate coordinates before clustering.
- **Build a 50-PDF APA-psych eval set** with hand-labeled HTML ground truth, scored with TEDS (Tree-Edit-Distance Similarity, ICDAR 2021) + cell-exact-match. Target: TEDS > 0.80 on the APA-psych slice.

These are real engineering items, not nice-to-haves — they're what would let docpluck claim best-in-class status against GROBID/Camelot/Docling on the APA-psych corpus specifically. Out of scope for v2.0 to keep the first release shippable.

## Figures — future "level C" aims (deferred from v2.0)

The current milestone targets figure level **A**: detect figure regions, emit `figures: [{page, bbox, label, caption}]`, strip/placeholder the figure region from the linear `text` output. No image extraction, no figure-content understanding.

Deferred to a later release if it proves valuable and doable:

- **Figure image extraction** — pull the actual figure rendering (vector graphics or rasterized image) and emit it as a separate asset (PNG/SVG path) alongside the metadata.
- **Axis-label / legend OCR** — for raster figures, OCR the in-figure text so downstream tools can search for variable names appearing only in figures.
- **In-text figure reference resolution** — link "(see Figure 3)" mentions in the prose back to the corresponding figure object.
- **Figure-type classification** — distinguish bar plot / scatter plot / forest plot / flowchart / schematic / photograph (useful for meta-analysis tooling that wants forest plots).
- **Subfigure detection** — handle "Figure 2a / 2b / 2c" panel layouts as a parent figure with child panels.

Worth revisiting once the table track is shipped and we know which figure-side capabilities downstream tools (ESCIcheck, MetaESCI, Scimeto) actually need.

## Section identification — future enhancements (deferred from v1.6.0)

The v1.6.0 milestone (`docs/superpowers/specs/2026-05-06-section-identification-design.md`) ships a flat sectioner with 18 canonical labels + `unknown` fallback, hardcoded taxonomy, and merged `title_block`. Deferred:

- **Hierarchical / tree section output.** Currently flat with numeric suffixes (`methods_2`). Add a tree mode (`Body → Study 1 → Methods/Results`, `Body → Study 2 → Methods/Results`) when a real consumer needs it. (Q2 option C from the brainstorm.)
- **Split `title_block` into `title` / `authors` / `affiliations`.** Currently merged because affiliation parsing is its own hard problem; consumers needing structured author metadata should use CrossRef/DOI lookup. Worth doing once we have a use case that can't be served by external APIs.
- **Custom heading-map / user-supplied taxonomy extension API.** Hardcoded taxonomy in v1; revisit after we collect real-world misses on Hebrew / non-English / domain-specific journals.
- **Validate the conflict-resolution rule** (text-pattern wins for canonical headings, layout wins for unknown headings — Q4.vi from the brainstorm). Test against the v1 corpus once MVP ships and adjust if there's a class of papers the rule fails on.
- **Public `extract_pdf_layout()` API.** Internal-only in v1.6.0. Promote to public API once the `LayoutDoc` shape stabilizes and an external consumer asks for it.
- **Section-aware quality scoring** in `quality.py` (e.g., flag a low-confidence `references` section that may need re-extraction).
- **Confidence calibration.** Current `high`/`medium`/`low` is heuristic. Real numeric calibration needs the v1 test corpus + manual gold labels.

## Table/figure text-mode — future configuration enhancements (deferred from v2.0)

The current milestone ships with two `text` modes for `extract_pdf_structured()`:
- `"raw"` (default) — flowing text including table contents, identical to `extract_pdf()` behavior. Backwards-compatible.
- `"placeholder"` — table/figure regions replaced with `[Table N: caption]` / `[Figure N: caption]` markers.

Deferred richer modes to consider once the two-mode default is in production and we have feedback:

- **`"strip"`** — remove the region entirely with no marker (cleanest for some consumers, but loses positional cue).
- **`"inline_markdown"`** — render structured tables as markdown pipe-tables inline in `text` (LLM-friendly; lossy on multi-row headers; reintroduces stat-regex false positives — careful).
- **`"inline_html"`** — same idea but HTML tables inline (preserves more structure than markdown).
- **Per-table-type override** — different mode for tables vs. figures, e.g. raw for tables, strip for figures.
- **Confidence-gated mode** — placeholder only when structured extraction confidence is high; raw fallback otherwise.
- **Custom placeholder template** — caller supplies `f"[{label}: {caption}]"` or similar.

Add only when a real downstream consumer asks for one. YAGNI until then.

---

## 2026-05-25 wrapup punch-list — canary-audit + Cluster A/B/C + leftover v2.4.76

> **Source:** Two-session wrapup combining R4 cycle work (uncommitted v2.4.76 from earlier today) and the canary-audit architecture session. See `docs/superpowers/handoffs/2026-05-25-canary-audit-architecture-and-cluster-A-B-C-landed.md` and `docs/superpowers/handoffs/2026-05-25-wrapup-r4-cycle.md` for full details. The 11th defect (`test_plos_med_1_no_fence_footer`) was fixed in the wrapup itself before commits.

### Must do before v2.4.77 tag

- [ ] **Run full pytest** to confirm combined v2.4.76 (R4 + EC-T1 + A4) + canary-audit (Cluster A/B/C/D-partial + PSPB-style heading + plos_med_1 P0r fix) state is clean. Estimated 24 min.
- [ ] **Run `scripts/verify_corpus.py`** — R4 fires aggressively on chandrashekar_2023 (24 pages) and ip_feldman (14 pages). Confirm no regression vs the 26-paper baseline before tagging.
- [ ] **Commit shape** (per 2026-05-25 wrapup decision): single combined v2.4.76 commit for R4 + EC-T1 + A4 + jama-open-1 D4 + plos_med_1 P0r fix, then separate `feat(canary-audit)` commit on top for Cluster A/B/C + audit infrastructure.

### Canary-audit infrastructure — operational

- [ ] **`claude setup-token`** — user runs this once in a regular terminal (interactive browser auth) so headless `claude -p --model sonnet` works from git hooks / scheduled tasks. Required before Phase 1 of canary-audit deploy.
- [ ] **Wire git hooks** in `.git/hooks/`: pre-commit (quick canary on `docpluck/*.py` changes), pre-push (full canary on push to main), pre-tag (full canary, no exceptions). Each shells out to `~/.claude/skills/_shared/iterate-loop/canary-audit.sh`.
- [ ] **Wire scheduled-tasks watchdog** via `mcp__scheduled-tasks__create_scheduled_task` — daily audit of HEAD against canary, PushNotification on FAIL.
- [ ] **Double-audit + finding-union** mode in `canary-audit.sh` — runs Sonnet twice and unions findings (per `feedback_audit_nondeterminism_mitigation.md`). Currently the script runs Sonnet once.
- [ ] **Persistent open-finding ledger** at `.claude/skills/_project/canary-findings-ledger.json` — once a defect is reported at HEAD SHA X, stays open until a later audit confirms clear.

### Remaining ip_feldman_2025_pspb defects (14 in final audit)

- [ ] **Front-matter leak lines 0-16** — article ID, journal banner, society copyright, DOI fragment emitted as body before Abstract. Needs P0 pre-pass for journal masthead block detection.
- [ ] **Affiliation fragment "Fu Lam, Hong Kong SAR." (line 37)** — corresponding-author paragraph wrap-tail. Either pre-join wrapped affiliation paragraphs at P0 level OR add an orphan-wrap-tail pattern.
- [ ] **Missing Method subsections** — `Design and Procedure`, `Power Analysis and Sensitivity Test`, `Measures`, `Data Analysis Strategy` still plain text. Investigate why these specific ones don't promote (others on same paper do).
- [ ] **Missing Discussion subsection** `Challenging and Reframing Misestimation`.
- [ ] **Table 10 phantom-guard** — th_section_leak heuristic didn't fire (cell content has hyphens splitting words like "cau-tion"). Debug + retune word-shape detection.
- [ ] **Data Availability section absent from end-matter** — Cluster A demote-fix may have over-stripped the legitimate `## Data Availability` section that should remain after Author Contributions.
- [ ] **False positive `### Reasons for change` (line 554)** — over-promotion in some context post-Cluster-B; investigate scope.
- [ ] **Table 3 malformed** (cluster D-full Camelot — multi-session)
- [ ] **Table 4 truncated** (Cluster D-full Camelot)
- [ ] **Table 6 split rows** for multi-word items
- [ ] **Table 8 split rows** for variable names
- [ ] **Table 9 caption truncated mid-word** ("Versus" cut off, missing "Replication.")
- [ ] **Table 9 Interpretation column** split across two `<tr>` rows.
- [ ] **Table 10 no body** (caption only).

### Cluster D-full Camelot tuning (deferred to its own session)

- [ ] Stream-flavor column-tolerance tuning (`column_tol`, `row_tol`, `edge_tol` per-page or per-paper).
- [ ] Post-Camelot header-cell splitter for concatenated columns (e.g. "Study 3Replication").
- [ ] Multi-line cell wrap detection for body rows that span two PDF lines.
- [ ] Multi-row header collapse (Table 5 fragmented headers).
- [ ] Full 26-paper corpus regression-test infrastructure (table-specific AI gold view, not just `reading.md`).

### R4 cycle residuals (from `2026-05-25-wrapup-r4-cycle.md`)

- [ ] **R4 title truncation** — `Effect of Time-Restricted Eating on Weight Loss in Adu` cut at column midline.
- [ ] **R4 multi-word-label splits** — `CONCLUSIONS AND RELEVANCE` becomes `**CONCLUSIONS**` heading + `AND RELEVANCE` orphan.
- [ ] **R4 (continued) fragment** — `(continued)` page marker splits as `(contin` / `ued)`.
- [x] **R5 Path 1 — layout-visible subset DONE (v2.4.89, W0h).** `normalize.recover_dropped_minus_via_layout` recovers dropped-minus coefficients that carry NO CI (so W0g can't reach them) by reading the surviving `(cid:N)` minus glyph from the layout channel, in the `<stat> = <minus><coef>` slot. On `ar_apa_j_jesp_2009_12_011` (body-prose betas) it recovers `β = -.022 / -.88 / -.428`; leaves the genuinely-positive `.48` untouched. Gated on a dedicated `dropped_minus_layout` param (F0 stays off in the section path). Blast radius: only ar_apa flips across the 5 onboarded canary papers (the other 4 are byte-identical no-ops).
- [ ] **R5 Path 1 residual — OCR-only, NOT fixable in text+layout.** `ar_apa` `β = -.245` is drawn as **painted pixels**: its minus is absent from pdftotext AND pdfplumber chars/lines/rects/curves AND pdfminer's raw LTChar/LTImage layer (proven 2026-06-15). docpluck's MIT text+layout architecture cannot recover it; only OCR could. W0h deliberately leaves it rather than guessing. Decision needed before any work here: add an OCR fallback tier (Tesseract, Apache-2.0) vs. permanent documented limitation. **Surfaced + user-approved 2026-06-15: ship the layout-visible subset, document this residual.**

### Article-finder skill issues (separate skill, separate session)

- [ ] **Task #8**: `ai-gold.py resolve` should accept stem names + source-PDF paths (or docs redirect to `check`).
- [ ] **Task #9**: `ai-gold.py onboard` needs `--skip-legacy` / `--ignore-unresolvable` flag (citationguard onboard halted on 3,018 legacy bare-stem keys).

## 2026-06-07 — v2.4.78 landed (committed 73462e3, unpushed→pushed, NOT tagged)

> **Source:** Cycle-4-redux session. See `docs/superpowers/handoffs/2026-06-07-v2.4.78-landed-canary-iterate.md` for the full state + next-session opener. v2.4.78 cleared canary findings #1/#3/#4 + 4 run-11 hallucinated-heading findings + citationguard soft-hyphen Defect 1. Corpus 26/26, full pytest 1861 passed, canary re-audit 8→5.

### Remaining canary findings on ip_feldman_2025_pspb (from 2026-06-07 re-audit @ 73462e3)

- [x] **METADATA-LEAK** — ✅ CLEARED in **v2.4.79** (cycle 5). New `_PAGE_FOOTER_LINE_PATTERNS` entry strips US-format `Received Month DD, YYYY; revision accepted Month DD, YYYY` (date sub-pattern accepts either order; gated on `revision accepted` + trailing year). The handoff-suggested `^Received .*; revision accepted .*$` was tightened to avoid matching body prose. Real-PDF + contract tests added.
- [x] **HALLUCINATION** — ✅ CLEARED in **v2.4.79** (cycle 5). Confirmed **audit false-positive** (the sentence is real — gold line 86); the actual defect was a spurious mid-sentence split + dropped period left by `_demote_continuation_promoted_headings`. The demoter now rejoins the demoted continuation to the prior line it continues + restores the terminal period. Verifier allowed-omissions doc updated so publication-history dates can't churn METADATA-LEAK→TEXT-LOSS.
- [ ] **TABLE #3 + #4 (B4) AND SECTION-BOUNDARY #5 (R4) share ONE root cause** — DIAGNOSED 2026-06-07 (cycle 5), see [`docs/superpowers/specs/2026-06-07-ip_feldman-B4-R4-column-interleave-diagnosis.md`](docs/superpowers/specs/2026-06-07-ip_feldman-B4-R4-column-interleave-diagnosis.md). pdftotext column-interleaves table-bearing two-column pages, interleaving table caption/headers/cells AND real body prose into one stream. **Empirically NOT single-cycle** (corrects optimistic subagent estimates): the existing R4 infra's bilateral gate (protects table pages corpus-wide) rejects the target pages (measured bilateral 0.37–0.44 > 0.30), and the B4 leak can't be stripped render-side because real prose is interwoven with table content (would risk TEXT-LOSS, rule 0a). **Real fix = region-aware column detection** (segregate full-width table band from 2-col prose band before column-correcting) — multi-session architecture, **needs user go-ahead**. **→ STEP 2 FIRST CUT LANDED v2.4.90 (2026-06-15, user-approved):** `extract_page_text_banded` (ship-dark `DOCPLUCK_COLUMN_CORRECT_BANDED`) segments flagged pages into prose/full-width y-bands, column-corrects prose bands, keeps table bands intact; AI-verified ON_BETTER on chan_feldman + chandrashekar (section order + paragraph continuity restored, 0 text-loss/hallucination/regression). Remaining before default-flip: band-cut word clips (~6/71 pages, guard-rejected), per-row both-sides under-detection, title+sidebar pages — see [`docs/superpowers/specs/2026-06-08-rc1-region-aware-column-architecture.md`](docs/superpowers/specs/2026-06-08-rc1-region-aware-column-architecture.md) "Step 2 — remaining work".

### Deferred from this session (surfaced, not hacked)

- [ ] **`### Reasons for change`** (ip_feldman) — Table 5 column header promoted to heading; needs table-region awareness (the body-coherence guard doesn't catch it because its body starts capitalized). RCA: rank-3 in the 2026-06-06 run-11 RCA.
- [ ] **Canary finding-key case-norm false-positive** (tooling) — the strict tag-push canary re-flags pre-existing backlog findings as "NEW" when only the leading case differs (`we`→`We`, `extensions`→`Extensions`), forcing `SKIP_CANARY=1` on every release while the deferred backlog is open (it did so for v2.4.90, 2026-06-15). Lowercase-normalize the finding key (TODO ~line 165 in `~/.claude/skills/_shared/iterate-loop/canary-audit.sh` per memory `feedback_canary_gate_nondeterministic`) so release tags pass cleanly when there are no real regressions.
- [ ] **`## Data Availability` end-matter absent** — RCA CORRECTED the run-11 "demoter over-strip" premise: the section never enters the text channel (pdftotext drops the title-page box). Needs cross-channel (pdfplumber) recovery, same architecture class as B7. NOT a demoter exception.
- [ ] **Glyph `Västfjäll`→`Vastfall`** (ar_apa/collabra, citationguard Defect 2) — baked pdftotext CID-font mis-map; needs a same-document surname-consensus normalizer (new subsystem). **Product/architecture decision on scope.**
- [x] **Baked-glyph DIGIT misread `M_age 59.3`→`39.3`** (collabra.77859, surfaced 2026-06-08 RC-1 AI-verify) — **DIAGNOSED + DECISION MADE (2026-06-08): document as known limitation, no code change.** Same class as `Västfjäll` but a DIGIT in a statistic (silent stat corruption, the most dangerous form for meta-science): the PDF *visually* shows `59.3` but the embedded text codepoint is baked as `3`, and **both pdftotext AND pdfplumber faithfully extract `39.3`** (confirmed by visual PDF read + dual-extractor diff). No text-channel logic can recover it; the only fixes are OCR/multimodal-glyph-consensus (a new subsystem the user explicitly **declined** to scope this session). **Consumer note: CitationGuard / downstream stat-checkers must assume baked digit/letter misreads exist in source PDFs and apply their own cross-source (CrossRef/visual) verification — docpluck cannot guarantee a digit matches the visual glyph when the publisher baked the wrong codepoint.**
- [ ] **org-author `Open Science Collaboration`→`Open, S. C.`** — baked into the PDF's embedded text by the publisher (identical in pdftotext AND pdfplumber); no safe general docpluck fix. **Routed to CitationGuard** (DOI/CrossRef author reconciliation).
- [ ] **Tag v2.4.78** once the full canary set clears (currently 5 open). Then bump `PDFextractor/service/requirements.txt` pin + run `/docpluck-deploy`.

### Substrate / infra follow-ups (2026-06-07)

- [x] **Tune the canary git-hooks to be ledger-aware (regression-only gate).** ✅ DONE (2026-06-07 cycle 5). `canary-audit.sh --gate-new-only` mode had landed but the hooks weren't passing it. Now wired: `.git/hooks/pre-commit` runs `--quick … --gate-new-only` (routine commits block only on NEW/regressed findings, not the deferred baseline); `.git/hooks/pre-push` uses `--gate-new-only` for **main** pushes but keeps the **strict** no-exceptions gate for **tag** pushes (a release tag must ship a fully-clean canary). Substrate self-tests 16/16 pass.
- [ ] **Modern Standby permanent disable** (optional, user/admin): `reg add HKLM\SYSTEM\CurrentControlSet\Control\Power /v PlatformAoAcOverride /t REG_DWORD /d 0 /f` + reboot. Current `powercfg /change standby-timeout-ac 0` works but can revert on power-plan change. See memory `feedback_long_runs_die_on_this_machine`.

### Replicate canary-audit pattern to other iterate skills (after docpluck proven)

- [ ] **escicheck-iterate** — easiest pilot (46 successful phase_5d_runs already, well-defined stats-family defect taxonomy). Update `verification_protocol` in its `canary.json`.
- [ ] **2rmarkdown-iterate** — needs 3-tier verdict-vocabulary (GREEN/YELLOW/RED → PASS/FAIL/FAIL) integration in the orchestrator. Fixture-keyed corpus.
- [ ] **citationguard-iterate** — needs corpus onboarding into article-finder FIRST (`corpus-query --source citationguard` returns 0 currently). Two-view-per-paper (`citations.v2` + `intext_citations.v1`).

## 2026-06-08 — deferred from /ship v2.4.80 (O5 reference inversion)
- [ ] **Canary finding-key case-normalization bug** (shared iterate-loop substrate): known-deferred ledger findings get re-flagged as NEW (case mismatch), forcing SKIP_CANARY overrides. Spawned as a background task this session. Fix the finding-key comparison to case-fold both sides + add a regression test.
- [ ] **Authenticated prod functional smoke** on chen via Railway /extract (needs a dp_ API key) — confirm O5 ordered-refs end-to-end in prod. Version (2.4.80) + health verified; the authenticated extract was not run.
- [ ] **CitationGuard follow-ups** (their repo, documented in docs/DOCPLUCK_HANDOFF_2026-06-07.md): regenerate chen+jamison fixtures from docpluck v2.4.80 academic + re-score; extend citelink's number-ending-host special-case to single COVID-1928. Superscript recovery: WON'T-FIX in docpluck (would regress citelink — tested).
- [ ] **ip_feldman interwoven table+prose case** (B4/#3/#4, R4/#5): still open; needs the per-y-band region-aware architecture (tracked in docs/superpowers/specs/2026-06-07-ip_feldman-B4-R4-column-interleave-diagnosis.md). O5 only handled the separable banded case (chen/jamison).

## 2026-06-08 — v2.4.83 landed (footnote_texts API + extract_pdf_layout export + render label de-dup; committed fb0d595, PUSHED to origin/main, NOT tagged)

> **Source:** ScienceArena arena-report verification session. The 2026-06-07 arena report (`ScienceArena/docs/reports/2026-06-07-docpluck-arena-issues.md`) blamed docpluck, but verification found the top findings (footnotes, body fidelity) were **ScienceArena adapter bugs**, not docpluck defects — full verdict in `ScienceArena/docs/reports/2026-06-08-docpluck-arena-issues-verified-response.md`. docpluck got 3 additive fixes (`report.footnote_texts`, top-level `extract_pdf_layout` export, render `### Table N` + `*Table N. …*` de-dup) + a load-aware fix to the DOCX/HTML perf tests (flaked the -n10 gate). Full suite **1906 passed**; the canary block on ip_feldman was a **proven false positive** (deterministic render diff: change touched only the 10 formal `### Table N` caption lines) — the 6 "new" findings were the case-normalization ledger bug (line ~165) re-flagging pre-existing B3/B4/column-interleave backlog → landed with `SKIP_CANARY=1` + proof in the commit message.

### Release follow-ups (only when v2.4.83 is tagged)

- [ ] **Bump `PDFextractor/service/requirements.txt`** git pin to `@v2.4.83` + update `PDFextractor/API.md` frozen-version examples. Production silently runs the old library until this lands (the `/docpluck-deploy` pre-flight check 4 enforces it).
- [ ] **Run `/docpluck-deploy`** to ship 2.4.83 to prod after the pin bump + tag.
- [ ] **Tag v2.4.83** (with the unreleased v2.4.81/82 on this RC branch) once the canary set clears. The strict no-exceptions canary gate fires on **tag** pushes, so the finding-key case-normalization bug (line ~165) must be fixed first or the tag canary will false-block.

### ScienceArena adapter (their repo — fixed this session, verify there)

- [ ] **Re-run the ScienceArena benchmark** with docpluck ≥ 2.4.83 installed in ITS venv. The adapter fixes (commit `de35f4a` on sciencearena `main`: pass `layout=`, read `report.footnote_texts`, strip the caption label) are logic-verified against local docpluck but NOT run end-to-end there (docpluck isn't installed in that repo). Also recommend ranking `docpluck-standard` as the primary real-document variant (Greek preserved).

- [ ] R-0040 | bug | P1 | from cross-project-learning-reviewer 2026-06-29 | per-row n mis-bound to comparison arm (collabra.90203 T10) + dropped-minus CI upper bound (cog_emo T8 sign-flip); T10 test encodes WRONG n (see project-review R-0040)
  - **VERIFIED-AT-HEAD 2026-06-29 (interactive session) — split into two findings:**
  - **Part A (per-row n mis-bound, collabra.90203 T10): NOT REPRODUCIBLE — false positive.** Ran `pytest tests/test_tables_superheader_alignment_real_pdf.py::test_collabra_90203_table10_all_six_conditions_real_pdf tests/test_tables_flatten.py::TestT90203Table10` → **3 passed**. The real-PDF test already asserts the CORRECT arm split (Target arm: r=.34, n=170; Replication arm: r=.63, CI[.53,.72]) and is GREEN. n=170 is the Target arm's correct n, NOT a wrong binding; the synthetic `TestT90203Table10` table is a 3-column no-arm table where n=170 is correct by construction. The reviewer's "test encodes the WRONG n" reading is the ~26%-false-positive class (cf. R-0006: reproduce at HEAD before fixing). **No fix needed for Part A** unless a NEW failing repro is produced.
  - **Part B (dropped-minus CI upper bound, cog_emo T8): REAL — reproduces at HEAD.** Rendering `PDFextractor/test-pdfs/apa/chan_feldman_2025_cogemo.pdf` via `extract_pdf_structured` → `flatten_table`, Table 8 emits:
    - `2bi:  r=-0.73 CI=[-0.78, 0.67]`  ← upper bound should be **-0.66** (sibling row above correctly reads `[-0.78,-0.66]`)
    - `2bii: r=-0.43 CI=[-0.52, 0.33]`  ← upper bound should be **-0.33**
    The minus on the **CI upper bound** is dropped (tight-kerned U+2212 in symbol font; pdftotext drops the glyph — same class as W0g/W0h betas, but on the CI's own bound). Existing recovery (`docpluck/normalize.py`: `recover_dropped_minus_via_ci_pairing` W0g @2663, `recover_dropped_minus_via_layout` W0h @2782) recovers *coefficient* tokens proven negative by their CI bracket — it does NOT recover a minus dropped from the **bracket itself**, because it trusts the bracket.
  - **Fix path (do via `/docpluck-iterate`, NOT a blind edit):** add a general, structurally-keyed recovery for "CI upper bound whose minus was dropped" — likely a layout-channel check (W0h-style, via the `dropped_minus_layout` LayoutDoc already threaded into the pipeline @3005/3029) OR a point-estimate-containment invariant (when the reported point estimate is negative and the parsed CI is `[neg, pos]` such that the interval is implausibly asymmetric about the estimate, the positive upper bound is the dropped-minus victim — but tune carefully so legitimate zero-straddling CIs are NOT corrupted). MUST: key on the structural signature (general, not this one PDF); verify against the AI gold under `ArticleRepository/ai_gold/` (never pdftotext); add a regression test mirroring `test_dropped_minus_layout_recovery_real_pdf.py` for the CI-bound case; run the full 26-paper baseline for no regression. ESCIcheck already works around the downstream effect (NOTE-path + `ESCIcheckapp/docs/REPLY_TO_DOCPLUCK_2026-06-26.md`).

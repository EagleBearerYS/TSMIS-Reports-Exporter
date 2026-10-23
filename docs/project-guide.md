# Repository guide — TSMIS Reports Exporter

This is the shared working guide for all contributors and coding agents. Read
these conventions first, then [docs/INDEX.md](INDEX.md) and the current
[roadmap](roadmap.md) before choosing work.

**Ordinary work uses the current task directly.** Separate implementer/reviewer
roles are optional for larger audits when the user requests them; they are not
a required workflow for routine changes. No task requires a particular assistant,
model, IDE, or vendor. Use the available tools and the repository's command-line
checks. Local session memory and tool configuration are optional.

**Current instructions versus historical records.** Dated plans, review reports,
handoffs, branch names, and evidence paths retain their original names for
traceability. Their named participants and old approval/ownership rules describe
those completed tasks; they do not assign today's work. Follow the current user
request, this guide, the owning topic doc, and the roadmap. Recheck old findings
against the current code before reopening them. See the
[planning map](planning/README.md) for current references and archives.

A portable Windows desktop tool that bulk-exports TSMIS (Caltrans Transportation
System Management Information System) reports for every California state route. The
user picks one, several, or all report types; one shared SSO login serves them all.
It ships as a **single-folder portable app** (bundled Python + an Edge WebView2 GUI;
no installer, no Python needed on the target), with a `.bat` console flow retained
for development and fallback that runs the same core engine.

One TSMIS page serves every combination of **data source** (SSOR / ARS) and
**environment** (prod / test / dev); defaults are SSOR + Prod.

> **This file is the router.** It holds the project snapshot, the report table, and
> the **non-negotiable conventions**. All the deep knowledge — architecture, auth,
> the GUI, the comparison engine, Highway Log internals, build/release, IT/security,
> verification, lessons, history — lives in the **[`docs/`](INDEX.md) library**.
> Start at **[docs/INDEX.md](INDEX.md)** and open the topic doc for whatever
> you're touching. Keep this file a thin index; don't re-expand `docs/` detail here.

---

## Supported reports

| # | Report | Output | Folder |
|---|---|---|---|
| 1 | TSAR: Ramp Summary | PDF (Letter) | `output/<run>/ramp_summary/` |
| 1b | TSAR: Ramp Summary (Excel) | XLSX | `output/<run>/ramp_summary_excel/` |
| 2 | TSAR: Ramp Detail | XLSX | `output/<run>/ramp_detail/` |
| 2b | TSAR: Ramp Detail (PDF) | PDF (Letter, landscape) | `output/<run>/ramp_detail_pdf/` |
| 3 | Highway Sequence Listing | XLSX | `output/<run>/highway_sequence/` |
| 3b | Highway Sequence Listing (PDF) | PDF (Letter, portrait) | `output/<run>/highway_sequence_pdf/` |
| 4 | Highway Log | XLSX | `output/<run>/highway_log/` |
| 4b | Highway Log (PDF) | PDF (Letter, landscape) | `output/<run>/highway_log_pdf/` |
| 5 | Intersection Summary | XLSX | `output/<run>/intersection_summary/` |
| 5b | Intersection Summary (PDF) | PDF (Letter, portrait) | `output/<run>/intersection_summary_pdf/` |
| 6 | Intersection Detail | XLSX | `output/<run>/intersection_detail/` |
| 6b | Intersection Detail (PDF) | PDF (Letter, landscape) | `output/<run>/intersection_detail_pdf/` |
| 7 | Highway Detail | XLSX | `output/<run>/highway_detail/` |
| 7b | Highway Detail (PDF) | PDF (Letter, landscape) | `output/<run>/highway_detail_pdf/` |
| 8 | Highway Summary | XLSX | `output/<run>/highway_summary/` |
| 8b | Highway Summary (PDF) | PDF (Letter, portrait) | `output/<run>/highway_summary_pdf/` |
| 9 | Clean Road File: Highway | XLSX | `output/<run>/clean_highway/` |
| 10 | Clean Road File: Intersection | XLSX | `output/<run>/clean_intersection/` |
| 11 | Clean Road File: Ramp | XLSX | `output/<run>/clean_ramp/` |
| 9b–11b | Clean Road File: Highway / Intersection / Ramp (PDF) | PDF (Letter, landscape) | `output/<run>/clean_<kind>_pdf/` |

`<run>` is a run folder `"<YYYY-MM-DD> <src>-<env> <host>-site"` (e.g.
`2026-10-07 ssor-prod dev-site`) — **since v0.49.0 the name records which TSMIS site
the export came from** (`dev-site` / `main-site`; `other-site` for a custom address on
another host), so a dev-site and a main-site export never share a folder; an older
`2026-06-11 ssor-prod` folder reads as *site not recorded*;
**since v0.32.0 each per-route file inside it carries that run identity
front-anchored in its NAME** (`2026-10-07 ssor-prod dev-site highway_log_route_3.xlsx` —
`paths.resolve_route_file`; legacy dateless names are honored on resume so an old
partial run never leaves one route with two files, and the end-anchored
`_route_<token>.<ext>` contract is untouched).

**Current export state.** Reports wait on the **dev site** (`tsmis-dev.dot.ca.gov`,
Settings ▸ "Use development site") until they are approved, then move to the **main
site** (`tsmis.dot.ca.gov`) — owner, 2026-10-06. Many reports exist only on the dev
site, most current exports (the 2026-10-02 statewide delivery included) come from it,
and the comparisons are the approval evidence; since v0.49.0 every run folder says
which site it came from. Every enabled on-site report exports in
**BOTH formats** the site offers. **8 (Highway Summary) is FULLY INTEGRATED as of
v0.37.0** — consolidate + cross-environment + **vs TSN** (off the owner's statewide
print); the vendor un-greyed the report 2026-08-17 and both its schema and the print
are verified. **1b / 5b / 8b and the six Clean Road editions joined in v0.48.0**
(off the 2026-10-02 statewide export), so no edition is export-only any more.
**Selecting both editions of one report
coalesces** — the route is generated ONCE and both files saved off that render — on
the standard path (v0.19.2), in fast mode, and for matrix-queued edition steps (both
v0.32.0). Where the live site greys a report, `select_report` fails fast rather than
stalling. The dev site's **Route History Table** is a greyed reserved placeholder
(stable id 15). The **Clean Road Files** group (`clean_highway` /
`clean_intersection` / `clean_ramp`, stable ids 16/17/18) is **EXPORT-ENABLED since
2026-09-02** off the dev site 9.1 capture (real Excel-sibling specs in
`export_clean_road.py`; prod may still grey them, in which case `select_report`
fails fast). Their print editions (`clean_<kind>_pdf`, stable ids 20/21/22) export
since **v0.45.2** through the site's `clh_/cli_/clr_printAll`. Both editions
consolidate and compare since **v0.48.0** — the print read with pypdfium2, vs TSN
against the TSN `CA HIGHWAYS` / `CA INTERSECTIONS` / `CA RAMPS` extracts.

**All 22 export types consolidate AND compare vs TSN** (Route History, which has no
export, is the only report without) — each has a vs-TSN comparator and lives in the
Everything, by-day, and (for the 11 dual-edition families) PDF-vs-Excel matrices.
Highway Summary became the 13th in v0.37.0; the last nine joined in v0.48.0. Per-report schemas + locked canaries:
[docs/reports.md](reports.md) / [docs/tsn-parsers.md](tsn-parsers.md);
exact counts and hashes:
[comparison-canary-bindings.md](planning/comparison-perfection/comparison-canary-bindings.md).
Format-change precedents are absorbed and gate-guarded: Intersection Detail follows
the site's July-2026 35-column overhaul (pre-update files are refused with re-export
hints), and Intersection Summary's `MASTARM`→`MASTERARM` rename rides a parse-only
alias + a section-partition tripwire so the next silent reshape fails loudly.

**Highway Detail (7/7b) is RELEASED and its correctness backlog is CLOSED (v0.38.0).**
The vendor delivery (2026-08-17, `ground-truth/HD + HS Release 8.17/`) lifted the
pre-release freeze; the released Excel export carries the SAME 34 columns the app
already read (252 routes / 51,327 statewide rows, one header, 0 deviations), so the
freeze was about data TRUST, not schema. **The statewide PDF-vs-Excel self-check is now
51,327 locations, 0 one-sided, 51,327 fully identical, 0 differing cells**, and HD-PDF
consolidation returns COMPLETE. All five formerly-open HD findings are resolved:
**192** (one same-build pull), **243** (v0.37.0 — HD-PDF lost the record on every
single-record page, recovered from the page's own header rule), **186 + 053** (v0.38.0
— a logical line 2 now stays OPEN and merges every following baseline until the next
line 1 / DCR boundary / document end; census-first, blast radius exactly the one route-
395 record, 251 of 252 routes byte-identical), **133 + 142** (v0.38.0 — the normalized
TSN library is v4: a 15-column sidecar conserves the Report View's DCR + five-value ADT
block, which every library-sourced comparison used to blank, plus the source-only
surrogate/order/change-flag columns, and the extract's two printed snapshot dates ride
the marker sheet as validated provenance), and **045's HD-Excel county — an OWNER
DECISION (2026-08-18): the Excel and PDF editions stay SEPARATE sources**, so HD-Excel
pairs county-blind by decision with the exposure measured and disclosed in the Notes
(524 of 59,457 keys carry >1 row; 438 of those span counties = 976 rows, 1.6%).
**Never infer a county.**

**The ArcGIS tab has FOUR sub-tabs, in the order the work flows (v0.47.0):
Layers → ArcGIS reports → Reports vs ArcGIS → Clean Road vs TSN.** Everything builds
from the `arcgis_layers/` library, which **Layers** (first, v0.46.0) refreshes
in-app: ArcGIS Pro's own Python runs `arcgis_worker/export_layers.py` (ArcPy can't
ship in the bundle), and `arcgis_refresh` checks and swaps each exported layer in.
The owner's manual export is retired; a manual drop in the same shape still reads.
**ArcGIS reports** holds every report in the `arcgis_reports` registry rendered from
those layers — **ONE build per report, refreshed in place** (owner decisions
2026-09-02 / 2026-10-05; the reports with no build yet listed greyed) — and every
build stamps the DROP it came from (`arcgis_layers.drop_info`: the oldest layer's
export time from the `00_INDEX.xlsx` manifest + a content fingerprint over the
`.xlsx` files) into its marker sheet and sidecar, so refreshed layers read the
build out of date. The as-of defaults to the oldest export date among the layers
the report reads, never the TSN extract's (that default belongs to the Clean Road
sub-tab only); a build gates on its own `REQUIRED_LAYERS`. **Reports vs ArcGIS**
(*Reports vs layers* until v0.47.0) is a by-day MATRIX (`arcgis_matrix.py`, §12d):
rows = every EXPORT EDITION of those reports — Excel and PDF are separate rows —
columns = exported days, each cell = that day's consolidated export vs the report's
one ArcGIS build, which the row picks up by itself (`arcgis_side`). The ArcGIS
builds are Excel, so BOTH editions compare against the same build.

**Clean Road (v0.29.0) builds the HIGHWAY clean-road file**: our
own CA HIGHWAYS table from the owner's per-layer ArcGIS exports in
`arcgis_layers/` (the 40-layer library; county+PM overlay as-of the TSN extract's own
date; per-column Provenance colour-coded by tier), compared vs the TSN extract in both
flavors with every column indexed to its source layer and the 25 context columns
tinted grey in the values sheet (v0.32.0). **`chc.HEADER` is the TSN extract's own
74-column schema and is the EXACT gate the library loads the raw extract through — never
add to it.** Our build writes `chc.ARC_HEADER`, a strict superset (TSN's 74 as prefix +
`BUILD_ONLY_COLUMNS`), so every existing index holds; a build-only column is CONTEXT
vs TSN, which has no counterpart for it. `THY_POPULATION_EFF_DATE` is the first
(v0.39.1, DA2 — it is what Highway Detail prints as `RU Eff`). Blessed statewide canary `CRH-SW-E2`;
measured build rules + provenance tiers in
[docs/planning/cleanroad-highways.md](planning/cleanroad-highways.md), the family
in [docs/comparison-engine.md](comparison-engine.md) §9j. `tsn_load_clean_road`
normalizes CA HIGHWAYS verbatim (marker v1); the Intersection/Ramp slots stay
deliberately normalizer-less until their builds land on the same pattern.

**The ArcGIS reports (v0.39.0) render a TSMIS REPORT from those same layers, and
Reports vs ArcGIS diffs it against our own export of it** — TSMIS vs TSMIS, so the two
sides SHOULD agree. **`arcgis_reports.py` is the registry**: one row per report (label +
build + comparator), its export editions DERIVED from the catalog (an edition compares
once the app consolidates it), and both sub-tabs, the GUI endpoints and the checks all
derive from it — adding a report needs no endpoint edit.
**Intersection Detail is the second** (`arcgis_report_intersection_detail` +
`compare_intersection_detail_arcgis`) and it is a POINT report, so it has NO segmentation
and no merge rule: `IM Intersection Detail` already holds one row per intersection. Its
three measured rules — the row universe (16,147 of 38,914 layer rows; the rest are
IM-managed shells with no inventory block), the leg rule (**Major = mainline, Minor = cross
street**, 99.4–100% vs 61.7–95.9% reversed), and the per-column overlay carry rule (HG/R-U
carry forward across a gap, City does NOT — carry makes City 23 points worse) — are in
[docs/comparison-engine.md](comparison-engine.md) §9l and locked by
`check_arcgis_report_intersection`. **Every printed column has a source; `Int St Eff-Date`
is `InventoryItemStartDate` at 100.0%** — it was nearly written off as sourceless, which is
the DA2 mistake exactly, so SEARCH THE LAYERS before declaring a column unsourced.
Same-date statewide baseline: 15,177 paired, 8,862 differing cells, 33 of 36 columns ≤1.3%.
**The three Clean Road files compare too since v0.50.0** (§9n): Highway against the CA
HIGHWAYS build, Intersection and Ramp against builds that follow the SITE's own
pipelines — note the site now picks intersection legs by ROUTE_ID, not the LEG_TYPE rule
the Intersection Detail build still uses.
**Highway Detail was the first** (`arcgis_report_highway_detail` +
`compare_highway_detail_arcgis`). It does NOT re-derive from the layers: Highway Detail
IS the CA HIGHWAYS table printed (33 of its 34 columns are THY columns), so it PROJECTS
the Clean Road build — one measured build behind every report rendered this way, and
the next report is a mapping table, not a second engine. Two rules make it a build
rather than a rename. **Since v0.39.2 Highway Detail has its OWN build and does not
read the Clean Road workbook** — it runs the shared span engine over the 19 layers it
actually prints (`SEGMENT_TAGS`) with its own measured block-eff-date rule
(`primary_eff`), then projects. Clean Road reproduces the TSN table so it segments on
TSN's 74 columns; a REPORT wants its own columns' boundaries. **Adjacent spans agreeing
across every printed column still merge** (54,649 → 51,064, vs the export's 51,327) and
the printed Length is the merged span's own extent; **Description is start-anchored**
(landmarks are point features), so a following blank continues the record. Statewide vs
the same-day export: **180,078 differing cells, 19,132 rows fully identical**. **Every printed column is now sourced and counted** — `RU Eff`
was the last gap and closed in v0.39.1 (DA2: the build carries
`THY_POPULATION_EFF_DATE` from `SHS Population`). **Read the VINTAGE line first**: the build is a
reconstruction as-of a chosen date, so the as-of must match the compared export's day
or the comparison measures network change instead of correctness — the card says so in
warning colour and the Notes sheet leads with it.

**Consolidate-only sources**: TSN Highway Log district PDFs (dropped into
`tsn_library/highway_log/raw/` — the one drop location since v0.30.0 retired
`input/`) and the app's own PDF editions. The **Compare** tab diffs every report
TSMIS-vs-TSN (each PDF edition also offers a PDF-vs-Excel self-check), runs
cross-environment comparisons, and hosts three matrices beyond the Everything one:
the **by-day** vs-TSN matrix, the **vs Baseline Matrix** (any exported day vs an
EARLIER pull of the same report; `baseline_matrix.py`, §12c), and the **PDF vs Excel
Matrix** (v0.31.0 — the 11 dual-edition families × exported days, each cell that day's
PDF export self-checked against its Excel export from the SAME run folder;
`pdf_excel_matrix.py`).

**Visual evidence** (HD, ID, HL, HSL, RD vs-TSN + the self checks): sampled diffs
render as highlighted snippets from both sources — parse-back-verified, ditto-aware
for HL, context-field-aware for HSL, dual-row-aware for RD — as an
`… (evidence).xlsx` + image folder beside the comparison. One shared toggle+count on
the matrix pages (per-report readiness spelled out; camera badges; a per-cell camera
regenerates a BUILT comparison's evidence, freshness-gated). TSN prints live in
`tsn_library/<report>/pdf/` (HD/ID/RD) or ARE the library's own `raw/` district
prints (HL/HSL — no duplicate drop). See
[docs/comparison-engine.md](comparison-engine.md) §13.

**The evidence truth layer** (shipped with the comparison-perfection completion):
`published_comparison.py` decodes and authenticates the committed values workbook's
own cells (the hidden `E`/`D`/`N`/`U` state masks, the anchored Status/Diffs
contract, opaque row tokens) — the published cell, not the adapters, decides whether
an image may be taken. An EXHAUSTIVE hash-bound **Ledger** sheet is written before
any sample is drawn; each side is evidenced **from the source that side was read
from** (an Excel-compared row renders from the workbook itself, and since v0.32.0
its column is resolved the COMPARATOR'S OWN way via each adapter's
`excel_column_for` — the M2-D fix); the whole set is ONE published generation
(`evidence_manifest.py`: content digest + ledger digest + a private read-set
snapshot + two-phase quarantine-and-promote). **Not claimed:** the loaders'
per-field projections against the raw PDFs — the separately-tracked direct-source
acceptance. Details + acceptance oracles: §13 and the
[finding ledger](planning/comparison-perfection/comparison-audit-findings.md).

**The comparison-perfection project is COMPLETE (2026-07-22, v0.28.0), and EVERY
finding in the ledger is closed — 246 of 246.** `main` is the completion
state. The ⛔ Highway Detail pre-release block (133 · 142 · 186 · 192 + 045-HD) fell
to the vendor's 2026-08-17 delivery in v0.37.0 / v0.38.0 (see the Highway Detail
paragraph above; 243 was found and fixed on the released data), and the last two were
**244** (v0.38.2 — HD vs TSN was counting the paired-roadbed ditto convention as data)
and **245** (v0.39.1 — the ArcGIS Highway Detail projection counted the HF-01
unavailable marker as data and reported COMPLETE over a PARTIAL build); **246**
(2026-09-02 — Highway Sequence Excel vs TSN reported both rows of an equate as
one-sided whenever the export seated the `E` on the realignment record; TSN now
declares the relation and the export's suffix is seated on the target row before
keying, 57,072 → 57,518 paired on the bound 7.9 pair, PDF-vs-TSN untouched). The
[COMPLETION-PLAN](planning/comparison-perfection/COMPLETION-PLAN.md) + finding
ledger are the PROJECT RECORD of why each comparison behaves as it does (start at
[README.md](planning/comparison-perfection/README.md)).
**Owed, and only the owner can do it: the work-PC acceptance run — now targeting
the current v0.45.2 release** (the dev box cannot reach the TSMIS intranet; releases
since v0.32.0 have been offline-verified only — the current checklist lives in
[docs/roadmap.md](roadmap.md) B1): comparison + evidence output
intentionally differ from v0.26.2/v0.27.x (re-run both sides, never reconcile old
against new), TSN libraries rebuild once, PDF-sourced workbooks re-consolidate once,
plus the v0.30–v0.32 items in
[the backlog plan §4](planning/v0.30-owner-backlog-plan.md) (Edge Retry, the
PDF-vs-Excel matrix, fast-mode dual-format, the mixed-name resume, an Excel-row
evidence run).

→ Per-report behavior + the "add a report/consolidator/comparison" recipes:
[docs/reports.md](reports.md). Highway Log columns / PDF parsing / comparisons:
[docs/highway_log/](highway_log/columns.md) and
[docs/comparison-engine.md](comparison-engine.md).

---

## The knowledge library — read the owning doc before you touch its area

| Area | Doc |
|---|---|
| Big picture: core + front-ends, registry, run folders, data location, feature buckets | [docs/architecture.md](architecture.md) |
| Export loop runtime: resume, retry, skip/cancel, fast-fails, timeouts, fast mode | [docs/engine-and-reliability.md](engine-and-reliability.md) |
| Sign-in: token-in-hash, `CONFIG` trap, device SSO, Edge recapture, LNA, login chips | [docs/auth-and-signin.md](auth-and-signin.md) |
| Desktop GUI: pywebview/WebView2, threading/queue, the **5 pywebview traps**, the `#mock` | [docs/gui.md](gui.md) |
| Report catalog, `ReportSpec`, `cs-disabled`, the extension recipes | [docs/reports.md](reports.md) |
| `compare_core`: regression lock, flavors, key/roadbed/ditto, write-path safety, families | [docs/comparison-engine.md](comparison-engine.md) |
| Corrected 31-column Highway Log labels | [docs/highway_log/columns.md](highway_log/columns.md) |
| Highway Log PDF (cell-rect) + TSN (char-window) parsers | [docs/highway_log/pdf-and-tsn-parsing.md](highway_log/pdf-and-tsn-parsing.md) |
| The `+`/`++` ditto domain convention + evidence | [docs/highway_log/comparison-study.md](highway_log/comparison-study.md) |
| Build, `app.spec`, DLP prune, browser channels, the **updater**, CI | [docs/build-and-release.md](build-and-release.md) |
| IT/DLP/security, the **work-PC capability model**, audit findings, code-signing | [docs/it-and-security.md](it-and-security.md) |
| The **`gh-pages` landing page** — layout, live download button, theme toggle, screenshot/OG regen, SEO | [docs/website.md](website.md) |
| How to verify (no test framework): golden `check_*.py`, COM-recalc, `#mock`, test-data locations | [docs/verification-and-testing.md](verification-and-testing.md) |
| The durable lessons (field failures, one-core, regression discipline, audit method) | [docs/lessons.md](lessons.md) |
| The narrative history | [docs/history.md](history.md) |
| Clean Road / ArcGIS builds: the measured build rules, the 74-column coverage census, and the censused CA INTERSECTIONS + CA RAMPS mappings the **next large build** starts from | [docs/planning/cleanroad-highways.md](planning/cleanroad-highways.md) |
| Making a comparison faster without moving a byte of its output | [docs/planning/vs-tsn-comparison-speed.md](planning/vs-tsn-comparison-speed.md) |
| **What's left to do — the definitive OPEN WORK INVENTORY** | [docs/roadmap.md](roadmap.md) (the `▣ OPEN WORK INVENTORY` table at the top) |
| The reusable read-only code-review prompt | [docs/code-review-prompt.md](code-review-prompt.md) |

Code-level deep-dives (algorithms, data/control flow, extension points) live under
**`docs/internals/`** — `compare-core`, `highway-log-data-processing`, `gui-bridge`,
`auth-state-machine`, `export-engine`, `updater-swap`. Full map with "read this when…"
for each topic + internals doc: **[docs/INDEX.md](INDEX.md)**.

---

## Conventions (non-negotiable — apply every session)

- **Core is console-free.** `common.py`, `exporter.py`, the consolidator/comparison
  cores report via the `Events` sink (`scripts/events.py`) and raise exceptions —
  **never** `print`/`input`/`sys.exit`. Only `cli.py` and `gui_*.py` touch
  I/O/the window. User-facing strings from the core stay **UI-neutral** (no ".bat"
  names, no "this window" / "menu option N" — that guidance lives in the driver).
- **No AI attribution anywhere** — commits, PR titles/descriptions, code, comments.
  Keep project changes focused on the work and preserve existing historical records.
- **Never commit** `scripts/tsmis_auth.json` (treat as a credential), generated
  `output/`, build artifacts (`build/.venv`, `dist/`), or local agent state.
- **The comparison WRITER is output-locked** (v0.40.0). `_styled_cell` caches each
  composite cell style per workbook and `artifact_store` reads a finished comparison's
  counts straight out of the package — both are SPEED changes whose acceptance bar is
  byte-identical OOXML members (`check_compare_style_cache`, plus a zero-openpyxl-loads
  assertion in `check_comparison_artifact_schema`). Style is bound BEFORE the value and
  each cell owns its `StyleArray`; the streamed package reader never decides a REFUSAL
  (openpyxl still does). Prove any change here with
  `build/benchmark_vs_tsn_speed.py --writer historical` on the real corpus.
- **A counts-only PREVIEW certifies nothing** (v0.41.0). `mode="preview"` runs the
  whole comparison and returns its typed truth without writing a workbook (~9x
  faster). It commits no artifact, so it has no `artifact_generation` — keep it
  that way STRUCTURALLY: previews live in their own `comparisons/_previews.json`,
  never `_results.json`, never inside `_staleness`; `_preview_for` shows one only
  while it still matches the inputs and only when the certified cell isn't fresh;
  a real build clears it; the renderer uses `mx-preview` and a zero-difference
  preview shows `match*`, never a green tick. Its numbers must equal the build's —
  both paths call the one `_headline_truth`/`_headline_verdict` pair, and
  `check_comparison_preview` proves it. A preview writes no file, so a stale
  cell's existing workbook is UNTOUCHED; when the preview re-derives that
  workbook's own published counts `_preview_for` reports `confirms` and the cell
  reads "counts confirmed" (v0.41.2). That is an ACCENT class on the same
  uncertified `mx-preview` state, never a promotion — equal headline counts do
  not make the workbook's rows equal to a rebuild's, so it confirms the NUMBERS
  and says nothing about the FILE. `confirms` must never enter `_staleness`.
- **`compare_core` semantics are correctness-locked, not history-locked.** Equality,
  formula, normalization, identity, pairing, and count changes must follow the approved
  domain contract and be proved cell-for-cell against the independent oracle plus both
  workbook flavors. Preserve historical output only when it is correct; a confirmed defect
  must be fixed globally when the contract is global, even if canary counts or bytes change.
  Every deliberate delta needs exact input/output evidence and an explained re-bless. Opt-in
  `CompareSchema` fields remain appropriate for truly report-specific behavior, but are not a
  shield for a broken shared engine. The typed `ComparedCell` and hidden versioned
  `E`/`D`/`N`/`U` state masks own discrepancy truth; the visible ` ≠ ` separator is content/
  presentation only and must never be scanned for state. See
  [docs/comparison-engine.md](comparison-engine.md). Before Phase-3 equality/pairing
  work, read and honor the approved policy/oracle gates in
  [docs/planning/comparison-perfection/comparison-phase3-decision-gates.md](planning/comparison-perfection/comparison-phase3-decision-gates.md).
- **Comparison work stays source-first and end to end.** The project that established
  this closed in v0.28.0, but the DISCIPLINE is permanent, not a phase. Before changing
  any comparison family, read
  [docs/planning/comparison-perfection/COMPLETION-PLAN.md](planning/comparison-perfection/COMPLETION-PLAN.md)
  and the finding ledger — now the PROJECT RECORD of why each behavior is what it is
  (start new reviewers at [README.md](planning/comparison-perfection/README.md); the
  [archived project doc](planning/comparison-perfection/archive/comparison-perfection-project.md)
  holds the point-in-time Stage-8 audit history). If you reopen a finding or open a new
  one, update its entry Status line AND the ledger index table AND the plan together —
  index tables drifting behind entries caused repeated stale-directive incidents. Keep
  detailed bugs/hashes in the linked finding/source/canary ledgers, not in new planning
  files. Raw TSN is the starting truth; rebuild normalized inputs in isolation, prove
  raw-to-normalized record/field conservation, re-prove comparison cells independently,
  and require all supported evidence to agree with both PDFs and the Comparison sheet.
  Historical outputs/counts never override source facts, and a missing source fact is a
  hard stop rather than permission to infer it.
- **Duplicate identity is exact, typed, and auditable.** Within the 100,000-cell
  product cap, use the rectangular Hungarian assignment under the owner-approved
  source-identity objective — the lexicographic (all-compared-field diff count, char
  edit distance, |position gap|) tuple, where context/ditto cells decide WHICH
  occurrences correspond while verdicts and counts stay asserted-only (the CMP-AUD-220
  assignment/verdict split; D3 amendment 2026-07-16) — with the approved
  lexicographically-smallest smaller-side vector as the final tie; never reintroduce
  greedy, file-order, or asserted-only-assignment certification. Above the cap,
  positional output is partial/capped diagnosis only and
  can never be green or a match. Persist the complete typed duplicate trace and capped
  diagnostics (v2 traces carry the objective triples; v1 payloads stay readable and
  byte-stable). Workbook lookups use versioned opaque ordinal tokens—never delimiter-
  flattened route/key text. Cancellation during source validation, pairing, or count
  construction returns unknown counts/quality with no trace or workbook mutation.
- **A generated workbook certifies only its build-time identity.** The visible source
  sheets, opaque helpers, Med-Wid stages, and row universe are bound to very-hidden
  `CMP_E2_SNAPSHOT_V1` sheets and tail sentinels. Any post-build source/helper edit must
  make Summary say `REGENERATE REQUIRED`; live observations under stale duplicate
  assignment are diagnostic and cannot certify either match or differences.
- **Completion is producer-owned; prose is never state.** `outcome.py` owns the
  consolidator vocabulary (completion ∈ complete/partial/no_data/cancelled/failed ×
  artifact ∈ promoted/new_unpromoted/previous_preserved/none), while
  `comparison_contract.py` owns typed comparison truth. Canonical report/store
  promotion still requires a complete result. A comparison's observed partial
  generation may be committed and cached so it can be shown amber and retried, but it
  may never be called fresh, green, or a match. **The last-complete/unpromoted-partial
  policy is DECIDED and SHIPPED** (2026-07-22, CMP-AUD-085 — see the last-complete
  convention below). See
  [docs/engine-and-reliability.md](engine-and-reliability.md).
- **Every returned public comparison terminal is typed, even without an artifact.**
  `comparison_result_boundary` covers file and folder adapters, normalizing missing
  input/dependency/preflight/shape errors, overwrite cancellation, `no_data`, and commit
  failure into a fail-closed `ComparisonOutcome` plus terminal `AttemptState`. It never
  parses `summary_lines`. If no workbook committed, `artifact_generation` MUST remain
  `None` and `attempt_state.generation_id` MUST remain empty; only real committed bytes
  receive a generation and member sidecars.
- **Generated artifacts are transactional and ownership-bound.** Reject every selected/
  derived output that aliases an effective input; under user destinations, write only
  through a current purpose-bound `OwnershipLease`. Use exclusively reserved,
  identity-bound temps then `os.replace`;
  a partial/failed/cancelled refresh **keeps last-good** (never clobbers it). Ordinary
  persistent workbooks carry producer-set `consolidation_meta` completion sidecars.
  Comparison consumers use the stricter contract instead: returned
  `ComparisonOutcome`, committed `ArtifactGeneration`, succeeded `AttemptState`, and
  the trusted/current persisted member generation must agree exactly through
  `consolidation_meta.require_published_comparison`. A sentinel, peer/digest mismatch,
  malformed metadata, or returned/persisted disagreement is untrusted; missing/stale
  metadata is stale. Comparison schema v3 uses one bounded canonical compressed payload
  shared by small peer envelopes; inline schema v2 remains read-compatible. Publication
  is parent-serialized across local threads/processes, installs chunks
  process-interruption-safely without replacement (power-loss durability is NOT
  claimed — readers fail closed on torn state; cleanup unlinks are bound to the
  verified inode via a Windows handle), and succeeds only when the persisted
  outcome/generation/member exactly equals its own attempt. Peers are validated before the payload is decoded
  once; over-limit or high-expansion payloads fail closed. No-artifact terminal results
  are not sent through this committed-generation reducer. `cache_envelope.py` versions
  the matrix/by-day caches — including the per-cell **attempt overlay**
  (`comparisons/_attempts.json`, CMP-AUD-089): every compare worker persists each
  touched cell's terminal state there, `ok` clears it, and the snapshot merges it as
  `cmp.last_attempt` so a failed/stopped/incomplete refresh marks the cell WITHOUT
  erasing the last-good result it did not replace. Matrix formula-twin unification and
  exact-generation evidence remain their assigned Phase-5/7 work.
- **The canonical persistent consolidation is the LAST COMPLETE generation** (owner
  decision 2026-07-21; CMP-AUD-085). When a trusted COMPLETE canonical exists, a refresh
  builds into an unpromoted attempt sibling and only a `status=ok` + COMPLETE result is
  promoted over it; anything else KEEPS LAST-GOOD — the verified bytes and sidecar are
  untouched, the attempt is published beside them carrying its own PARTIAL sidecar, and
  the caller is REFUSED so no comparison ever diffs the stale complete generation
  against current inputs. A first build with no complete predecessor still persists the
  flagged partial (amber, retryable). Never restore replace-and-flag.
- **Source and cached-output identity is CONTENT, not metadata** (CMP-AUD-080).
  `artifact_store.fingerprint` is the v2 content fingerprint; per-file digests may be
  memoized ONLY against a change token that a same-size, timestamp-restored rewrite
  cannot forge (on Windows `FILE_BASIC_INFO.ChangeTime` beside size/mtime/file id) —
  stat-only memoization is prohibited, and a file with no obtainable token is re-hashed.
  A typed comparison's VALUES artifact must also satisfy the versioned
  `COMPARISON_ARTIFACT_SCHEMA` at the commit boundary (CMP-AUD-115): uniquely labelled
  `Status`/`Diffs`, a valid status on every row, and rows present when the typed outcome
  claims rows. That gate shares its reader with `read_counts`, so what it refuses was
  already unreadable — keep it that way; a gate that could refuse a workbook the Matrix
  can read would block a valid report.
- **Matrix freshness reads the filesystem ONCE per folder.**
  `artifact_store.newest_report_file_mtime` is the ONE newest-data-mtime reader —
  the by-day, vs-Baseline and PDF-vs-Excel snapshots each carried a byte-identical
  private `_folder_newest_mtime`, and every one of them paid TWO `os.stat` syscalls
  per file (`Path.is_file()` then `Path.stat()`). It walks `os.scandir`, which
  answers both from the directory read: **38.5 ms → 1.5 ms on a real 369-file
  export folder**, and a 2-column by-day snapshot **90 ms → 9 ms**. CMP-AUD-083
  semantics are unchanged and must stay so — only a real `.xlsx`/`.pdf` counts, and
  a single locked or vanished entry must cost only ITSELF (it once aborted the
  whole fold and marked a present export missing). Prove any change here with
  `check_newest_report_mtime` plus a snapshot A/B with `now=` pinned — `age_seconds`
  is derived from the clock and will otherwise differ between two runs.
- **Workbook count scraping is diagnostic/migration-only.** `read_counts` locates
  Status/Diffs by HEADER LABEL (never hard-coded position), but Matrix, classic UI,
  and validation truth comes from the strict typed comparison generation. Workbook
  scraping must never certify a green UI result.
- **`report_catalog.py` is the report-metadata SoT**; `reports.py` is **derived** from
  it (EXPORT/CONSOLIDATE/COMPARE lists, matrix rows, stable-ID lookups, the picker
  `group`/`short_label` + `_PICKER_ORDER`). Stable IDs are immutable string keys;
  `batch_manifest._V017_EXPORT_ORDER` (== `EXPORT_KEYS`) is **append-only** — positions
  0–7 frozen; v0.18.1 appended Highway Detail/Summary at 8/9 as reserved-DISABLED
  groundwork, **v0.19.1 enabled their EXPORT** (cleared the Highway pair from
  `DISABLED_EXPORT_SUBDIRS`; real Excel-sibling specs — the gate now holds only the
  reserved Route History placeholder, id 15). Highway Detail now consolidates and participates in the
  Matrix, cross-environment, vs-TSN, and PDF-vs-Excel comparisons; **Highway Summary
  consolidates and compares cross-environment (v0.37.0) AND vs TSN (v0.37.0)** — its
  `MatrixEntry` gained a `tsn_key` the moment a `cmp:*:tsn` recipe + a TSN dataset
  existed, which is the whole plug-in contract. Add a report by editing the catalog;
  `check_report_catalog` proves the derivation, and **`check_report_wiring` (v0.31.0)
  derives from `report_catalog.MATRIX` what every registered report MUST have —
  dispatchable vs-TSN/self comparators, dual-edition completeness, a by-day row, Reset
  coverage — and FAILS naming the missing touchpoint** (the v0.17.3 "forgot one mirror"
  field-crash class). See [docs/reports.md](reports.md).
- **Select reports by stable `data_value`, not visible text** (v0.18.1). `select_report`
  and the env-scan probe match the `#customReport` option by its `data-value` (the site's
  stable id) and reveal the `cs-submenu` flyout for a leaf, falling back to exact text/
  `data-label`. This keeps exports working as the site migrates its report dropdown from a
  flat list to grouped fly-outs (live on **dev**) WITHOUT breaking the current flat **prod**
  menu. Each `ReportSpec` carries its `data_value`; the picker is grouped to mirror the site.
- **Sync Playwright API** (not async); Playwright is **thread-affine** — only the
  owning thread may touch a page.
- **Call the timeout ACCESSORS** (`report_timeout_ms()` etc.) in engine code, not the
  raw constants — they read Settings overrides at run time.
- **Log every decision.** Each decision point (site/browser pick, channel fallback,
  saved-session-vs-device-mode, per-route outcome) and every swallowed exception logs
  at least `type(e).__name__` + the first line — the "one log upload answers it"
  contract. Error messages name the failing step and stay UI-neutral; the WHY goes to
  the log.
- **The updater TLS trusts the Windows cert store** (`ssl.create_default_context()`).
  Never switch it to `requests`/`certifi` — a bundled CA list breaks corporate
  TLS inspection on exactly the managed PCs that need it.
- **Real test data + the live TSMIS website source are LOCAL ONLY** under
  `C:\Users\Yunus\Downloads\TSMIS\…` — never commit, copy into the repo, or push;
  the website source is Caltrans-internal. Read that corpus's `_INDEX.md` before
  choosing fixtures: `ground-truth/` is the acceptance oracle, `report-samples/`
  is for parser spot checks, `comparison-outputs/` is historical reference only,
  and `_scratch/` is disposable and must never become an oracle. Bind and record
  the exact canonical bundle/input identities used by each real-data canary in
  [docs/planning/comparison-perfection/comparison-canary-bindings.md](planning/comparison-perfection/comparison-canary-bindings.md).
- **Work-PC reality:** any feature that must run on the locked-down Caltrans work PC
  must work as a plain unsigned exe from a user-writable folder — no PowerShell, cmd,
  admin, temp scripts, or scheduled tasks. See [docs/it-and-security.md](it-and-security.md).
- **Git:** commit/push only when asked; if on `main`, branch first. Commit messages
  are short, imperative (`add route 395`). Release branches share the tag name, so
  push tags explicitly: `git push origin refs/tags/<tag>`.
- **Process is proportional to practical impact.** This is an internal tool, not
  an audited system of record. Before a review round, a long re-run, or a long
  write-up, answer in ONE line: *what would a user see differently?* If the answer
  is "nothing", write that line and move on. Specifically: never spend compute to
  make a record cite a tidier commit hash; never block on cosmetics or on wording;
  a disclosed, measured limitation is a note, not a defect. Prove a fix with a
  targeted probe through the shipped path plus a check that fails pre-fix — then
  re-run only the phases the change can actually reach, and say which you skipped
  and why. **Two review denials per change is the ceiling**; after that, remaining
  findings are follow-ups the owner ranks. Correctness of what the app DOES is
  never traded away — wrong output, stale data shown as current, crashes and
  silent failures still block, always.

---

## Repo layout (orientation)

```
1.–5. *.bat                  setup / login / export / consolidate / fast export (console flow)
run app (GUI preview).bat    dev launcher for the GUI
version.py                   app name/version + pinned Playwright (single source of truth)
scripts/                     the engine (console-free) + console & GUI drivers + UI
  common.py                  a re-export SHIM over the acyclic engine leaves below
  auth_nav.py report_nav.py session.py site_target.py routes.py errors.py timeouts.py
  browser_channels.py edge_device.py   the extracted engine leaves common.py re-exports
  exporter.py exporter_parallel.py export_multi.py run_report.py cli.py events.py settings.py paths.py
  outcome.py comparison_contract.py cache_envelope.py consolidation_meta.py artifact_store.py owned_dir.py
                              outcome/typed comparison/transaction/ownership
  report_catalog.py          the report-metadata source of truth (P4); reports.py derives from it.
                             Its MATRIX table (v0.31.0, M2-A) is the ONE per-row comparison
                             wiring (vs-TSN + PDF-vs-Excel comparators + the format tag) that
                             matrix_state/day_matrix/pdf_excel_matrix all derive from
  reports.py                 the report/consolidate/compare registry view + stable-ID lookups
  export_*.py                one thin ReportSpec per report type (incl. *_pdf editions)
  consolidate_*.py           per-route exports → one workbook (+ TSN / TSMIS-PDF parsers)
  compare_core.py            the correctness-locked comparison-workbook engine
  compare_tsn_common.py      the shared FILE-comparator substrate (P5b; every comparator rides it since v0.19.0)
  compare_env.py compare_highway_log*.py compare_*_tsn.py compare_*_pdf.py   the comparison families over compare_core
  visual_evidence.py evidence_*.py       the evidence-images engine + adapters (HD, ID, HL, HSL, RD)
  pdf_table_lib.py           the shared PDF-table machinery (clusterer/columns/writer/convert loop, R2)
  matrix.py                  the matrix FACADE (patch matrix.<name>) over matrix_state.py + matrix_build.py
  matrix_state.py matrix_build.py day_matrix.py summary_layout.py   matrix reads / builds + by-day + summary
  tsn_library.py tsn_load_*.py   the canonical TSN library (versioned normalization, D2) + its loaders
  arcgis_layers.py           the ArcGIS layer library: folder, 00_INDEX manifest (every column), export-file checks, drop identity
  arcgis_pro.py arcgis_refresh.py   find ArcGIS Pro's Python + run the worker; the in-app layer refresh + ArcGIS Pro check (v0.46.0)
  arcgis_worker/export_layers.py    the worker ArcGIS Pro's own Python runs (shipped as a .py data file, stdlib + ArcPy only)
  arcgis_selftest.py         the stand-in ArcPy the frozen self-test + check_arcgis_refresh drive the shipped worker with
  arcgis_reports.py          the ArcGIS report REGISTRY — one row per report (build +
                             comparator; None = not rendered yet, and the row says
                             why) + its export EDITIONS derived from the catalog; the
                             ArcGIS reports tab, the matrix rows, endpoints, mock and
                             checks all derive from it
  arcgis_matrix.py           the ArcGIS reports library (one build per report, stamped
                             with the drop it came from, last failed refresh) + the
                             Reports-vs-ArcGIS by-day MATRIX engine: each cell = a
                             day's export of one edition vs its report's build
  arcgis_report_highway_detail.py   the CA HIGHWAYS build PROJECTED onto a report's own
                             shape (Highway Detail first, v0.39.0) — the mapping + the
                             merge/description rules that make it a build, not a rename
  arcgis_report_intersection_detail.py   the IM layers rendered as Intersection Detail —
                             a POINT report, so no segmentation: the row universe, the
                             Major/Minor leg rule, and the per-column overlay carry rule
  highway_log_columns.py intersection_detail_columns.py highway_detail_columns.py   the per-report column labels
  highway_summary_columns.py the Highway Summary layout SoT: sections/codes + the ONE
                             strict miles reader the consolidator, the cross-env loader
                             AND the vs-TSN comparator share (exact thousandths); also
                             the shared within-section CODES the TSN print pairs on
  gui_main.py gui_api.py     GUI entry / the bridge core (state, pump, gate)
  gui_export_api.py gui_auth_api.py gui_compare_api.py gui_settings_api.py gui_update.py   the endpoint mixins (S1)
  gui_worker.py              re-export SHIM over gui_worker_export/_env/_maint/_matrix.py (S2)
  task_coordinator.py contract.py        GUI task-state owner / Python⇄JS bridge enum SSOT
  gui_endpoint.py gui_matrix.py gui_win32.py   the endpoint envelope (+_task_endpoint/pick_path) / matrix mixin / Win32
  validation.py credential_safety.py     one-click validation + diagnostic credential guard
  site_capture.py            the Settings website-source capture (v0.26.0, local-only;
                             exhaustive since 2026-09-02 — every same-origin file under
                             its site name + a manifest with BUILD_DATE and hashes; no
                             archive — evidence.py is the one zip writer)
  baseline_matrix.py         the Compare-tab "vs Baseline" day-vs-baseline matrix (v0.26.0)
  pdf_excel_matrix.py        the Compare-tab "PDF vs Excel" by-day self-check matrix (v0.31.0, M2-B)
  ui/                        index.html app.css app.js + ui-export/-batch/-compare/-matrix/-settings/-dom.js + mock.js + contract.js
  published_comparison.py evidence_ledger.py evidence_manifest.py   the evidence TRUTH layer: decode+authenticate the published comparison / the exhaustive ledger / the durable generation record
  self_test.py evidence.py pdf_row_oracle.py owned_dir.py safe_delete.py   self-test / the work-PC diagnostic bundle (--collect-evidence) / safety
  updater.py login.py logging_setup.py batch_manifest.py report_library.py
build/                       build.ps1, app.spec, prune_bundle.ps1, full_smoke.py, check_*.py
  gen_release_notes.py release_notes_header.md backfill_release_notes.ps1   per-version release notes
CHANGELOG.md                 user-facing changelog (one section per version; source of release bodies)
tools/                       dev utilities (not shipped) — screenshots.py regenerates the site/README shots
docs/                        the knowledge library (start at docs/INDEX.md)
output/                      generated data (git-ignored except .gitkeep stubs)
tsn_library/ arcgis_layers/   source libraries (git-ignored, local-only; tsn_library is stocked by hand, arcgis_layers by the Layers tab;
                             TSN district PDFs live in tsn_library/<report>/raw/ — input/ retired v0.30.0)
```

The **landing page** is on a separate **`gh-pages`** branch (GitHub Pages), not in
`main` — see [docs/website.md](website.md). Detail on anything above is in the
matching `docs/` file (see the table above).

---

## Pinned versions

`version.py` / `requirements*.txt`: `playwright==1.60.0` (Node driver only — no
Chromium ships in the default build), `pdfplumber==0.11.9`
(→ `pdfminer.six==20251230`; its `pillow==12.2.0` + `pypdfium2==5.9.0`
transitives are LOAD-BEARING since v0.21.0 — the evidence-image render stack —
and pinned explicitly), `openpyxl==3.1.5`, `pywebview==6.2.1`
(→ `pythonnet`/`clr_loader`), `pyinstaller==6.20.0`,
`pyinstaller-hooks-contrib==2026.5`. Built/tested on **Python 3.11**. Rationale +
the three release variants: [docs/build-and-release.md](build-and-release.md).

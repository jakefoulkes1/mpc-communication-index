# Decisions log

Every methodological choice gets a dated line here, before it is used.
Changes apply forward only; nothing is retrofitted. Locked calls are never touched.

## Table of contents

- 2026-07-05 — [repo created](#2026-07-05--repo-created)
- 2026-07-11 — [era corpus, Aug 2015–Jun 2026](#2026-07-11--era-corpus-aug-2015jun-2026)
- 2026-07-11 — [corpus audit: full-text repair + special meetings](#2026-07-11--corpus-audit-full-text-repair--special-meetings)
- 2026-07-11 — [A&BG (2012) baseline lexicon](#2026-07-11--abg-2012-baseline-lexicon)
- 2026-07-11 — [voting-record parsing and reconciliation](#2026-07-11--voting-record-parsing-and-reconciliation)
- 2026-07-11 — [first validation pass (v1)](#2026-07-11--first-validation-pass-v1)
- 2026-07-11 — [site: A&BG chart, retiring starter_v0 fields from the UI](#2026-07-11--site-abg-chart-retiring-starter_v0-fields-from-the-ui)
- 2026-07-11 — [19 March 2020 special meeting added](#2026-07-11--19-march-2020-special-meeting-added)
- 2026-07-11 — [validation join fixed: voting-sheet date is canonical](#2026-07-11--validation-join-fixed-voting-sheet-date-is-canonical)
- 2026-07-11 — [neutral_value published in index.json](#2026-07-11--neutral_value-published-in-indexjson)
- 2026-07-11 — [member-behaviour table (seeds Stage 4)](#2026-07-11--member-behaviour-table-seeds-stage-4)
- 2026-07-11 — [market benchmark: OIS forward curve + SONIA](#2026-07-11--market-benchmark-ois-forward-curve--sonia)
- 2026-07-11 — [market_probs: two-state ±25bp assumption](#2026-07-11--market_probs-two-state-25bp-assumption)
- 2026-07-11 — [lock and scoring machinery](#2026-07-11--lock-and-scoring-machinery)
- 2026-07-11 — [site call card + dry run](#2026-07-11--site-call-card--dry-run)
- 2026-07-11 — [smoothed-curve bias: quantified, offset convention chosen](#2026-07-11--smoothed-curve-bias-quantified-offset-convention-chosen)
- 2026-07-11 — [2 null-decision documents recovered](#2026-07-11--2-null-decision-documents-recovered)
- 2026-07-11 — [historical market benchmark: data/market_history.csv](#2026-07-11--historical-market-benchmark-datamarket_historycsv)
- 2026-07-11 — [decision classifier bug found and fixed: Bank-Rate-adjacent verb, not first word](#2026-07-11--decision-classifier-bug-found-and-fixed-bank-rate-adjacent-verb-not-first-word)
- 2026-07-11 — [Part B sanity checks](#2026-07-11--part-b-sanity-checks)
- 2026-07-11 — [scipy added, for the ordered logit models only](#2026-07-11--scipy-added-for-the-ordered-logit-models-only)
- 2026-07-11 — [the benchmark ladder (first real backtest), L0-L4](#2026-07-11--the-benchmark-ladder-first-real-backtest-l0-l4)
- 2026-07-11 — [curve freshness fix](#2026-07-11--curve-freshness-fix)
- 2026-07-11 — [scheduled vs special meetings split; probability-clip logged](#2026-07-11--scheduled-vs-special-meetings-split-probability-clip-logged)
- 2026-07-11 — [live site investigation: false alarm, contract test added anyway](#2026-07-11--live-site-investigation-false-alarm-contract-test-added-anyway)
- 2026-07-11 — [data/surprises.csv](#2026-07-11--datasurprisescsv)
- 2026-07-11 — [the headline inference (Spec 3 OLS + Spec 2 ordered-logit LR test)](#2026-07-11--the-headline-inference-spec-3-ols--spec-2-ordered-logit-lr-test)
- 2026-07-11 — [Results section published to the site (ladder v1)](#2026-07-11--results-section-published-to-the-site-ladder-v1)
- 2026-07-11 — [lock rehearsal (dry run, fresh curve)](#2026-07-11--lock-rehearsal-dry-run-fresh-curve)
- 2026-07-12 — [site v2 (design, interactivity, context panel, annotations, methodology)](#2026-07-12--site-v2-design-interactivity-context-panel-annotations-methodology)
- 2026-07-12 — [evidence inspector (`pipeline/inspect.py`)](#2026-07-12--evidence-inspector-pipelineinspectpy)
- 2026-07-12 — [Track record section (`data/track_record.json`, `index.html`)](#2026-07-12--track-record-section-datatrack_recordjson-indexhtml)
- 2026-07-13 — [final polish: Spec 3 published, lexicon sparsity, repo front door](#2026-07-13--final-polish-spec-3-published-lexicon-sparsity-repo-front-door)
- 2026-07-13 — [ERRATUM: entry header dates corrected against commit evidence](#2026-07-13--erratum-entry-header-dates-corrected-against-commit-evidence)
- 2026-07-13 — [CI portability: Spec 2 synthetic test moved off the degeneracy cliff](#2026-07-13--ci-portability-spec-2-synthetic-test-moved-off-the-degeneracy-cliff)
- 2026-07-28 — [pre-lock rehearsal + LOCKDAY runbook](#2026-07-28--pre-lock-rehearsal--lockday-runbook)
- 2026-07-28 — [placeholder episode removed from the published site](#2026-07-28--placeholder-episode-removed-from-the-published-site)
- 2026-07-29 — [Results framing: author's text; Pages fallback in LOCKDAY](#2026-07-29--results-framing-authors-text-pages-fallback-in-lockday)
- 2026-07-29 — [design pass: typography, progressive disclosure, call card](#2026-07-29--design-pass-typography-progressive-disclosure-call-card)
- 2026-07-30 — [audit fixes: failure states, verification path, metadata](#2026-07-30--audit-fixes-failure-states-verification-path-metadata)
- 2026-08-05 — [site polish: fallbacks, drafts cleared, typography](#2026-08-05--site-polish-fallbacks-drafts-cleared-typography)
- 2026-08-10 — [July 2026 ingest: corpus to 95, results republished](#2026-08-10--july-2026-ingest-corpus-to-95-results-republished)
- 2026-08-10 — [guard: the build_info stamp can no longer go stale silently](#2026-08-10--guard-the-build_info-stamp-can-no-longer-go-stale-silently)
- 2026-08-10 — [context layer rebuilt on the 95-document corpus](#2026-08-10--context-layer-rebuilt-on-the-95-document-corpus)
- 2026-08-10 — [era windows derived, not declared; LOCKDAY stamp warning](#2026-08-10--era-windows-derived-not-declared-lockday-stamp-warning)
- 2026-08-10 — [MPC calendar transcribed from the Bank; last draft badge cleared](#2026-08-10--mpc-calendar-transcribed-from-the-bank-last-draft-badge-cleared)
- 2026-08-30 — [presentation and consistency pass: every figure generated](#2026-08-30--presentation-and-consistency-pass-every-figure-generated)
- 2026-09-02 — [README brought under the figure generator; lock time discrepancy corrected; rounding and sign policy enforced across surfaces](#2026-09-02--readme-brought-under-the-figure-generator-lock-time-discrepancy-corrected-rounding-and-sign-policy-enforced-across-surfaces)
- 2026-09-02 — [presentation pass, stage two: the words](#2026-09-02--presentation-pass-stage-two-the-words)
- 2026-09-02 — [design pass: paper theme, single-family type, call card as focal element, chart overlays, print stylesheet](#2026-09-02--design-pass-paper-theme-single-family-type-call-card-as-focal-element-chart-overlays-print-stylesheet)
- 2026-09-02 — [presentation pass, stage four: QA, reader simulation, deploy](#2026-09-02--presentation-pass-stage-four-qa-reader-simulation-deploy)
- 2026-09-02 — [presentation pass close-out: references verified, Lloyd gloss corrected, hierarchy fix, en-GB, print justification, process comments removed, post-hoc review recorded](#2026-09-02--presentation-pass-close-out-references-verified-lloyd-gloss-corrected-hierarchy-fix-en-gb-print-justification-process-comments-removed-post-hoc-review-recorded)

## 2026-07-05 — repo created
- **Thesis:** does the tone of MPC communication carry information about the next
  Bank Rate decision beyond what the OIS/SONIA curve already prices? Null = no.
  Either answer is the result.
- **Starter lexicon is plumbing, not research.** `pipeline/score/lexicon/starter_v0.json`
  exists only to test the pipeline end to end. The research baseline is the
  Apel & Blix Grimaldi (2012) lexicon implemented verbatim (target: week 2).
  No index level produced by starter_v0 will be used in any analysis or claim.
- **Negation window = 3 tokens** before a matched term flips its sign.
  Known-crude (misses e.g. "do not see a compelling case to increase Bank Rate");
  parameter to revisit alongside the A&BG implementation.
- **Raw texts are gitignored.** Derived scores and hashes are public; full source
  texts stay local, with links to bankofengland.co.uk as the public reference,
  pending a check of the Bank's re-publication terms.
- **Site lives at repo root** (index.html + data/index.json) for zero-config
  GitHub Pages. May move to /site with a deploy action later.
- **Scope of era:** scrape the post-August-2015 "Super Thursday" HTML era first
  (covers the whole 2016–2026 evaluation window). Pre-2015 PDFs deferred to August.

## 2026-07-11 — era corpus, Aug 2015–Jun 2026

- **Meeting schedule discovered by trying, not hardcoded.** `pipeline/scrape/era.py`
  requests every month from Aug 2015 to Jun 2026 and tolerates 404s for months
  with no meeting. Result: 92 documents scraped, 39 months with no meeting (404),
  matching the known shift from monthly MPC meetings (through 2015-2016) to the
  8-per-year "Super Thursday" schedule (2017 on).
- **Two URL slug patterns exist and both are tried.** 2015-2016 pages live at
  `.../<year>/mpc-<month>-<year>`; 2017 onward at `.../<year>/<month>-<year>`.
  Discovered by checking a 404 against Bank of England search results for a
  known August 2015 minutes page. `scrape_month` in `pipeline/scrape/minutes.py`
  tries the plain slug first, then falls back to the `mpc-`-prefixed slug on a
  404, rather than hardcoding a year cutoff.
- **Suspect-parse threshold: <1,000 words.** 23 of the 92 documents fall under
  this (mostly 2017-2021 minutes, which were genuinely shorter in that era, not
  parse failures on inspection). Flagged in scrape output, not excluded or
  reparsed - a judgement call for later, not this pass.
- **`published = meeting_end + 1 day`**, per instruction, replacing the old
  MANIFEST's literal scraped "Published on" date. Cross-checked against the
  actual "Published on" text present in 90 of 92 documents: matches in 87,
  off by one extra day in 3 (2020-08, 2021-06, 2021-11 - likely weekend/holiday
  slippage in the Bank's actual publication schedule). The rule is applied
  uniformly regardless; the 3-document gap is logged here, not silently fixed.
- **decision/vote parsed from the first sentence containing both "voted" and
  "Bank Rate"** (not necessarily the same sentence as "meeting ending on" -
  those two are split across sentences in some 2021 documents). Vote split
  handles three source phrasings: "voted by a majority of A-B to...",
  "voted A-B to..." (2017 short-form summary pages), and "voted unanimously
  to...". En dash and em dash vote splits (introduced in newer pages, e.g.
  "7–2") are normalised to a plain hyphen.
- **Two fields left deliberately null rather than guessed:**
  - `2015-10`: meeting_end/published null - the source sentence reads "meeting
    ending on 6 October," with no year stated in the text at all.
  - `2022-09`: vote null (decision still parses) - the actual split was a
    three-way vote (5 for +50bp, 3 for +75bp, 1 for +25bp) described in prose
    in the following sentence, not representable as a single "A-B" pair.
- **meeting_end date phrasing varies slightly across eras** ("ending on
  <date>" is standard; a few 2016 pages drop the "on"). The parser regex
  accepts both; still requires a 4-digit year to accept a match.

## 2026-07-11 — corpus audit: full-text repair + special meetings

- **Root cause of the 30 (later found: 52) short documents, confirmed by
  fetching 3 live pages, not guessed:** the Bank published the Monetary
  Policy Summary and full Minutes as two separate documents - summary on the
  HTML page, full minutes only in a linked PDF - until August 2021, when it
  started publishing the full minutes inline in HTML. The word-count
  threshold (<1,000) had actually undercounted the problem: several
  Summary-only pages (e.g. the March 2020 Covid summary at 1,625 words)
  exceed 1,000 words on the strength of the summary alone while still
  missing the full minutes entirely. The real test used from here on is
  "words found after the 'Minutes of the Monetary Policy Committee meeting
  ending on' heading" (`pipeline/scrape/backfill_pdf.py:is_summary_only`),
  not a raw word-count cutoff.
- **52 of 93 documents (Aug 2015 - Jun 2021) backfilled from the Bank's PDF
  minutes**, via `pipeline/scrape/backfill_pdf.py` + `pdfplumber` (added to
  requirements.txt). PDF URLs follow one of two patterns discovered by
  probing: `<month>-<year>.pdf` (most months) or `minutes-<month>-<year>.pdf`
  (2015-08, 2015-12, 2017-06) - the script tries both. Same 2s polite-sleep
  discipline as the HTML scraper.
- **`source_kind` ("html" | "pdf") and `word_count` added to every document
  record**, so anyone using index.json can see which documents were
  reconstructed from PDF vs scraped inline. Recorded in a local, gitignored
  sidecar (`data/raw/source_kind.json`, inside the already-gitignored
  `data/raw/`) that `build_index.py` reads at build time - consistent with
  raw texts already being local-only; only the derived fields in index.json
  are public.
- **Corpus reconciled against the Bank's own sitemap**
  (bankofengland.co.uk/sitemap/minutes) rather than trusted on the strength
  of era.py's month-by-month probing alone. Every regular month-slug meeting
  in the Bank's listing matched our corpus exactly (zero missing, zero
  extra) within the Aug 2015-Jun 2026 window.
- **One special meeting added: the 10 March 2020 emergency meeting**
  (first Covid-19 rate cut, 50bp to 0.25% + Term Funding Scheme), found via
  the sitemap reconciliation at a non-month-slug URL
  (`.../2020/13march-2020`), not discoverable by era.py's normal probing.
  Saved as `data/raw/2020-03-10-special-minutes.txt`, `doc_id
  minutes-2020-03-10-special`, `type special_minutes`. Its `source_url` is
  looked up from a small explicit table (`SPECIAL_SOURCE_URLS` in
  build_index.py) since it doesn't fit the standard slug-reconstruction
  formula - extend that table if more special meetings turn up reconciling
  other eras.
- **The 19 March 2020 special-meeting page is deliberately NOT added as a
  separate document.** It is a brief pre-announcement summary (566 words,
  no full minutes); the Bank later published the full minutes for that
  decision combined with the regularly scheduled 25 March meeting in a
  single document, which we already had (`minutes-2020-03`, confirmed by
  its own heading: "Minutes of the special Monetary Policy Committee
  meeting on 19 March 2020 and the Monetary Policy Committee meeting ending
  on 25 March"). Treating the 19 March summary as a second corpus entry
  would double-count that decision.
- **`raw_vote_text` field added to every document**: the verbatim sentence
  decision/vote were parsed from, whenever `find_vote_sentence` finds one -
  kept even when decision/vote don't fully parse, so no information is
  lost. Populated for 92 of 93 documents (all but the special meeting, whose
  vote sentence never states "Bank Rate" in the same clause as "voted").
- **Two documents keep a deliberately null vote, now with a preserved
  `raw_vote_text`:**
  - `2016-08`: the post-Brexit "package of measures" (Bank Rate cut bundled
    with a new Term Funding Scheme, corporate bond purchases and a QE
    expansion) is announced as "voted unanimously in favour of the
    propositions on Bank Rate and the Term Funding Scheme" - no single
    "voted ... to X%" clause exists to parse.
  - `2022-09`: a genuine three-way vote split (5 for +50bp, 3 for +75bp, 1
    for +25bp) - not representable as a single "A-B" pair. Unchanged from
    the previous entry; decision still parses.
- **`2015-10`'s meeting_end/published resolved itself** once the PDF
  backfill replaced the summary-only text: the PDF states "meeting ending on
  6 October 2015" (year included), where the HTML summary had omitted the
  year entirely. No manual date fix was needed. This was the one document
  that had fallen out of the 92-document series in the previous pass
  (excluded because meeting_end couldn't be parsed, so no `published` date
  existed to sort the series by) - now included, bringing the series to all
  93 documents.
- **Case-insensitive "Bank Rate" matching.** One PDF (2016-04) renders it
  "Bank rate" (lowercase r); `find_vote_sentence` now matches
  case-insensitively. Fixed a real false-null, not a new special case.
- **Post-repair word counts: zero documents under 1,000 words** (previous
  low was 679; new low is 2,606, in the short 2024 minutes). No individual
  per-document explanations needed since none remain under threshold.

## 2026-07-11 — A&BG (2012) baseline lexicon

- **Source, retrieved and verified, not reconstructed from memory.** Apel &
  Blix Grimaldi (2012), "The Information Content of Central Bank Minutes",
  Sveriges Riksbank Working Paper No. 261. The SSRN/EconStor mirrors
  bot-blocked our scraper; the actual PDF came from the original
  riksbank.se URL listed on the paper's S-WoPEc/RePEc abstract page
  (swopec.hhs.se/rbnkwp/abs/rbnkwp0261.htm). Saved verbatim, with page
  references, to `pipeline/score/lexicon/abg_2012.json`.
- **The Net Index formula (p.10) and the term appendix (p.18) are images/
  table objects in the PDF, not extractable as plain text** - pdfplumber's
  text layer renders the formula as `[( ) ( )]` with the interior blank, and
  the appendix table's columns run together in plain-text extraction. Both
  were confirmed by cropping the PDF region to an image and reading it
  directly, not inferred: `Net Index = [(#hawk/(#hawk+#dove)) -
  (#dove/(#hawk+#dove))] + 1`, range [0, 2], 1 = neutral.
- **The paper's method is two-word noun+adjective bigrams, not a single-word
  sentiment list and not sentence-level.** "Higher inflation" = hawkish,
  "lower growth" = dovish. It counts over the whole document, with no
  sentence splitting at all - the earlier task wording assumed
  "(sentence-level)"; the paper itself does not do this, and "implement the
  paper's index construction as described in the paper" takes priority, so
  `pipeline/score/abg.py` matches the paper: no sentence splitting.
- **Core noun list used for the primary index: 7 nouns** (inflation, price,
  wage, oil price, cyclical position, growth, development), matching the
  paper's main Net Index (Table 1/2, p.9-10). The paper's 4-noun extension
  (employment, unemployment, recovery, cost) was only used for a robustness
  check ("Net Index Extended") in the original paper, not its primary
  result - stored in abg_2012.json for reference but not used by
  `abg.py`'s default index.
- **Adjective-noun adjacency and match direction: immediately adjacent,
  adjective-then-noun** ("higher inflation", not "inflation is higher").
  The paper doesn't state an explicit token window for the English
  translation; adjacency in the stated direction is the most literal
  reading of its own worked examples and is what's implemented. Logged as
  an interpretation, not verbatim from the paper.
- **No negation window, no sentence-level scoring, no other extras from
  `pipeline/score/dictionary.py` (starter_v0's machinery) applied to the
  A&BG index** - run plain, per instruction. `dictionary.py` and
  `starter_v0.json` remain in the repo (starter_v0 is how the walking
  skeleton was proven end-to-end) but are no longer used in `index.json` or
  any other output from this point on. `abg_2012` is now the only index
  used for analysis and claims, matching the original 2026-07-05 entry's
  intent.
- **index.json schema bumped to `index-v1`**: `net_hawkishness` /
  `hawkish_hits` / `dovish_hits` / `n_sentences` / `n_scored_sentences`
  (starter_v0 fields) replaced by `abg_hawk` / `abg_dove` /
  `abg_net_index` on every document and in the series.

## 2026-07-11 — voting-record parsing and reconciliation

- **`data/votes.csv` join key is the sheet's own date column, which is the
  meeting's PUBLISHED/announcement date, not `meeting_end`** - confirmed by
  cross-checking known dates (e.g. the sheet's 2026-06-18 row matches
  minutes-2026-06's `published` field exactly, while its `meeting_end` is
  2026-06-17). `skew = average(all voting members' preferred rate) -
  decided rate`, per the paper's own formula (p.13, after Gerlach-Kristen
  2004): `skew = average(r_j) - r`. `hawkish_dissents`/`dovish_dissents`
  count members whose preferred rate was above/below the decided rate.
- **Every voting member's preferred rate is recorded every meeting they sat
  on, not just dissenters'** - confirmed against a known case (June 2026:
  the sheet shows 7 members at 3.75% and 2 at 4%, exactly matching the
  corpus's own parsed "7-2" vote). This makes the per-member preferred-rate
  column meaningful for all 9-ish sitting members each meeting, not just
  the minority.
- **Era filter applied (Aug 2015-Jun 2026), same as the text corpus.** A
  few pre-2015 rows (not in our range) record a dissent as qualitative
  "Increase"/"Decrease" text with no specific rate; these are sidestepped
  by the era filter rather than needing special handling.
- **Reconciliation against the text corpus (`published` date, exact match)
  found only the same 4 one-day gaps already logged for the `meeting_end +
  1 day` publication-date rule** (2015-10, 2020-08, 2021-06, 2021-11) -
  independent confirmation from a second data source that the earlier
  finding was real, not a fluke of parsing.
- **One extra sheet-only date: 2020-03-19.** The voting sheet records the
  19 March 2020 emergency cut as its own distinct decision (with its own
  row and vote), even though the Bank's own minutes publication folded its
  text into the 25 March combined document (see the 2026-07-18 corpus-audit
  entry above, on why no separate 19 March text document was added). No
  action taken - the voting record and the text corpus are allowed to
  disagree on document boundaries; this is noted, not corrected.

## 2026-07-11 — first validation pass (v1)

- **Contemporaneous only, not predictive.** `pipeline/validate.py` compares
  a meeting's own minutes (abg_net_index) against that SAME meeting's own
  skew/dissents/decision - not the paper's own predictive framing (Net
  Index at t vs the rate decision at t+1). Matches the task's explicit
  scope ("do not build anything about... prediction yet - that is Stage
  3"). A lagged/predictive version is future work for Stage 3.
- **No scipy dependency added.** Pearson and Spearman implemented in plain
  Python (`pipeline/validate.py:pearson/spearman/rank`) rather than adding
  a new heavy dependency for two formulas.
- **87 of 93 corpus meetings joined to a voting-sheet row** (published date
  exact match). The 2020-03-10 special meeting and 2016-08 are excluded by
  construction (their `decision` field is null, so `load_corpus_by_published`
  never considers them a candidate at all). The other 4 unjoined are the
  known one-day `meeting_end+1` mismatches already logged in the corpus-audit
  and voting-record entries above (2015-10, 2020-08, 2021-06, 2021-11).
- **v1 result: weak positive correlation.** r(abg_net_index, skew) =
  0.181 (Pearson), 0.143 (Spearman), n=87. r(abg_net_index, net dissents)
  = 0.198 (Pearson), 0.152 (Spearman), n=87. Mean abg_net_index by decision:
  hike 1.44 (n=16), hold 0.97 (n=65), cut 1.00 (n=6) - directionally
  sensible (hikes read more hawkish) but a small, noisy signal on this
  first pass. Saved to `data/validation_v1.json`; not a claim of predictive
  power, just the first descriptive checkpoint.

## 2026-07-11 — site: A&BG chart, retiring starter_v0 fields from the UI

- **Hand-rolled inline SVG, no chart library, no CDN.** The site is static
  GitHub Pages with no build step; a CDN script is one more thing that can
  fail to load or change behind our back. The chart is built directly in
  `index.html`'s `renderChart()` from the same `data/index.json` fetch
  already used by the latest-document card.
- **Existing "latest scored document" card kept, but its JS updated to the
  new schema** - it was still reading `net_hawkishness`/`hawkish_hits`/
  `dovish_hits`/`n_sentences` (removed from index.json in the abg_2012
  cutover above), which would have silently broken the card. Now reads
  `abg_net_index`/`abg_hawk`/`abg_dove`.
  Displayed on the paper's own 0-2 scale (1 = neutral) with the
  hawkish/dovish colour and left/right position on the existing gradient
  bar recentred (`net = abg_net_index - 1`) so the bar's existing -1..+1
  visual language still works.
  Footer's stale "current lexicon is a plumbing placeholder" line corrected
  to name the A&BG citation.
- **Chart decision markers use the same hike/hold/cut classification as
  `pipeline/validate.py`** (first word of the `decision` field: "increase"
  = hike, "reduce" = cut, holds unmarked) - one classification rule, not
  two independently-maintained ones.

## 2026-07-11 — 19 March 2020 special meeting added

- **Diffing `data/votes.csv` against the corpus found exactly one genuinely
  missing meeting: 19 March 2020**, the second Covid-19 emergency decision
  (Bank Rate cut 0.25%->0.1%, +£200bn asset purchases). The raw diff showed
  5 votes-only dates, but 4 were already-known 1-day `meeting_end+1`
  mismatches (each paired with a corpus-only date exactly 1 day earlier) -
  excluding those pairs left exactly one unpaired date, confirming the
  expectation.
- **Re-verified, not assumed, that this meeting has no separate minutes
  PDF**, despite the task's premise that it does: re-fetched the live page
  (no `.pdf` link at all) and re-searched the Bank's sitemap for any
  19-March-specific minutes document - none exists. The page's own text
  confirms why: "The minutes of today's special meeting will be released
  at the same time" as the 25 March meeting's minutes - i.e. folded into
  the combined document we already have as `minutes-2020-03`, consistent
  with the 2026-07-18 entry's finding and decision not to duplicate that
  text under a second doc_id.
- **Added as its own document anyway**, using the Bank's brief "Monetary
  Policy Summary for the special Monetary Policy Committee meeting on 19
  March 2020" page (563 words, no full minutes) - a real, distinct,
  citable published document for this specific decision, not a duplicate
  of the 25 March text. `doc_id minutes-2020-03-19-special`, `type
  special_minutes`, `source_kind html`. Word count is genuinely low
  (563 < 1,000) for the same reason logged for every other pre-Aug-2021
  Summary-only page - no fuller text exists to backfill from here, since
  there is no PDF at all.
- **`MEETING_END_RE` broadened for a third real phrasing variant**: this
  page's only date-bearing heading reads "special Monetary Policy
  Committee meeting on 19 March 2020" (no "ending"). Added as an
  alternative prefix in the same regex, alongside the existing "meeting
  ending (on) <date>" pattern - not a new mechanism, same category of fix
  as the earlier "ending" vs "ending on" and case-insensitivity fixes.
- **`decision` field is a compound, verbatim sentence** ("increase [asset
  purchases]... and to reduce Bank Rate by 15 basis points to 0.1%") since
  the source sentence itself bundles an asset-purchase vote and a Bank
  Rate vote under one "voted unanimously to..." clause. Left as-is
  (accurate and unfabricated, just verbose) rather than hand-splitting it,
  consistent with not writing per-document special-case text.
- **`published` computed by the same uniform `meeting_end+1` rule as every
  other document (2020-03-20), not hand-corrected to the sheet's same-day
  announcement (2020-03-19).** The field-level rule stays uniform, applied
  forward only; the resulting known 1-day gap is handled at the join layer
  instead (`pipeline/validate.py`, see below), not by carving out a
  per-document exception in `build_index.py`.
- **New test: `test_date_reconciliation.py`.** Corpus `published` dates and
  `data/votes.csv` meeting dates now match one-to-one within a 1-day
  tolerance for the whole Aug 2015-Jun 2026 era (5 known 1-day gaps: the 4
  already-logged `meeting_end+1` mismatches plus this new special meeting,
  all real and individually explained above and in the 2026-07-18 entries
  - none silently absorbed).

## 2026-07-11 — validation join fixed: voting-sheet date is canonical

- **`pipeline/validate.py` no longer joins on exact match against our own
  `published` field.** It now treats each corpus document's `published`
  date as an approximate label and matches it to its NEAREST voting-sheet
  date, within a `MAX_DAY_TOLERANCE` of 3 days (comfortably above the
  largest known real gap of 1 day - see the two entries above). Every
  document that still can't be matched within tolerance is excluded AND
  individually logged (`join_to_votes` returns an `unmatched` list with the
  gap that caused the exclusion), not silently dropped.
- **Result: 92 of 92 candidate documents joined (0 unmatched)**, up from
  87 of 91 under the old exact-match join. The `index.json` `published`
  field itself is unchanged (still the uniform `meeting_end+1` rule,
  applied forward only) - only the validation join's matching logic
  changed.
- **Validation output filename stays `data/validation_v1.json`** (not
  renumbered) even though the internal `schema` field is now
  `validation-v2`, reflecting the join-logic and delta-index additions -
  the file is overwritten by each `python -m pipeline.validate` run either
  way, so a new filename would only be warranted for a result meant to
  stand alongside the old one for comparison, which isn't the case here.
- **Added `delta_index`**: `abg_net_index` minus the previous document's,
  in the corpus's own chronological order (not the previous *matched*
  document - the corpus's own sequence). Correlated against skew and net
  dissents the same way as the level. First document in the corpus has no
  `delta_index` (nothing to difference against) and is excluded only from
  the delta correlations, not the level ones.
- **Level vs delta result: level correlates weakly with skew/dissents
  (r=0.18/0.20, n=92); delta correlates barely at all (r=0.07/0.06,
  n=91).** The tone's absolute level in a given meeting's minutes is a
  (weak) better read on that meeting's own dissent pattern than the
  *change* in tone since the previous meeting is. Reported side by side in
  `data/validation_v1.json`, not chosen between - both are genuinely small
  effects at this stage, not evidence either framing is "the right one".

## 2026-07-11 — neutral_value published in index.json

- **Formula and range re-confirmed against the paper, unchanged**: Net
  Index = [(#hawk/(#hawk+#dove)) - (#dove/(#hawk+#dove))] + 1 (p.10,
  `pipeline/score/lexicon/abg_2012.json`), a ratio-type measure with a
  fixed theoretical range of [0, 2] and neutral at 1.0 (the ratio's own
  midpoint when hawk and dove counts are equal, not a fitted or sample
  statistic). No change to the formula itself - only its neutral point is
  now surfaced as data.
- **`NEUTRAL_VALUE = 1.0` added as a named constant in
  `pipeline/score/abg.py`** (used for both the empty-document fallback and
  as the source of truth for `index.json`'s new top-level `neutral_value`
  field), rather than a bare `1.0` scattered across `abg.py`,
  `build_index.py`, and `index.html`'s JS. The chart's neutral gridline
  and the latest-document card's recentring (`net = abg_net_index -
  neutral`) both now read `data.neutral_value` instead of a hardcoded `1`,
  so a future change to the formula's neutral point (there isn't one
  planned) wouldn't require hunting down every hardcoded copy.

## 2026-07-11 — member-behaviour table (seeds Stage 4)

- **Three-state coding, not binary.** Each member-meeting from
  `data/votes.csv` is coded `hawkish_dissent` (preferred > decided),
  `dovish_dissent` (preferred < decided), or `with_majority` (equal) -
  keeping direction distinguishable rather than collapsing to a plain
  dissent/no-dissent flag, since the paper's own `skew` measure and this
  repo's `hawkish_dissents`/`dovish_dissents` fields already treat
  direction as meaningful.
  A single "dissent" headline (`dissent_stickiness`) is still reported by
  collapsing the two dissent states together, since that's the plain-
  English number asked for - but the underlying 3-state matrix is what's
  saved, not thrown away.
- **Transition matrix is "next meeting this member actually voted at",
  not "next calendar meeting".** A member's own row-to-row sequence in
  `data/votes.csv`, sorted by date - naturally handles the (rare) case of
  a member missing a meeting, without needing to special-case gaps.
- **Pooled across all members, not computed per-member.** Most members sit
  for a few dozen meetings at most; a 3x3 transition matrix per member
  would have single-digit or zero counts in most cells. Pooling loses the
  "is member X personally sticky" question (deferred to Stage 4, which is
  explicitly what this table is seeding) but keeps every reported n
  large enough to read as a real proportion, not noise.
- **Descriptive only, explicitly**: no smoothing, no confidence intervals,
  no model fit. `dissent_stickiness` and the transition matrix are counts
  and empirical proportions from `data/votes.csv`, nothing else. Saved to
  `data/member_behaviour_v1.json`.
- **Headline result: dissent is genuinely sticky.** P(dissent again |
  dissented) = 0.475 (n=118) vs P(dissent | currently with majority) =
  0.094 (n=701) - roughly a 5x difference. Directionally sticky too:
  hawkish dissenters transition straight to dovish dissent 0% of the time
  (0/65) and vice versa (0/53) - dissenters who flip, flip to "with
  majority" first, never straight to the opposite direction, in this
  sample.

## 2026-07-11 — market benchmark: OIS forward curve + SONIA

- **Both sources parse cleanly - no hard stop triggered.** OIS:
  bankofengland.co.uk/statistics/yield-curves -> "oisddata.zip" (daily OIS
  data) -> sheet "1. fwds, short end" ("UK instantaneous OIS forward
  curve"), row 3 = maturities in whole months (1-60), each subsequent row
  one business day (date + forward rate per maturity, percent p.a.).
  SONIA: the Bank's Interactive Statistical Database CSV export, series
  code IUDSOIA.
- **The OIS zip contains one .xlsx per era, and older eras use a different
  sheet layout** (2009-2015's file has "1. fwd curve"/"2. spot curve", not
  "1. fwds, short end" at all) - confirmed by trying, not assumed.
  `latest_forward_curve()` tries every extracted file, skips (and logs)
  any without the expected sheet, and picks whichever remaining file has
  the most recent date - not a hardcoded filename like "2025 to
  present.xlsx", since era boundaries will themselves move in future
  years and a hardcoded name would silently go stale.
  Hard-stops only if NONE of the era files have a usable sheet.
- **The OIS file is a periodic snapshot, not literally live**: as of
  writing, its latest row is 2026-06-30 while SONIA's CSV export is current
  to 2026-07-08 - a real few-day publication lag between the two sources,
  not a bug. `market_probs.py` (next entry) must not assume the two
  `as_of_date`s match.
- **`fetch_sonia`'s HTTP call and `parse_sonia_csv`'s parsing are separate
  functions** (same pattern as `pipeline/build_votes.py`'s
  load_member_columns/parse_meetings split) specifically so the parser can
  be unit-tested against a fixture string without a live call - required
  by the task ("Unit-test with synthetic curve fixtures - no live calls
  inside tests"). Same reasoning applied to
  `_read_forward_curve_sheet(path)`, which takes a path rather than doing
  its own download, tested against a small synthetic workbook.
- **Raw downloads cached under `data/raw/market/`** (gitignored, same
  convention as `data/raw/` generally - only derived outputs are public).

## 2026-07-11 — market_probs: two-state ±25bp assumption

- **`pipeline/predict/market_probs.py` implements one documented,
  deliberately simple mapping from implied rate change to {cut, hold,
  hike} probabilities - not the only reasonable choice, and not fitted to
  anything.** implied_change_bp = (forward rate at the maturity bucket
  just after the meeting) - (current SONIA). A "two-state" assumption:
  the market is assumed to price a single possible move in ONE direction
  only (never a simultaneous hike probability and cut probability at the
  same meeting), of a fixed size (`ASSUMED_MOVE_BP = 25`, the Bank's usual
  step). `p_hike/p_cut = clip(|implied_change_bp| / 25, 0, 1)` in the
  appropriate direction; the remainder is `p_hold`. Real market-implied
  distributions can price partial/multi-directional moves or step sizes
  other than 25bp - this is a simplification, stated as one, not hidden.
- **"Maturity bucket just after the meeting"** = the first available
  monthly maturity whose distance from the curve's `as_of_date` is >= the
  distance to the meeting date (`bisect_left` on the sorted maturities
  list), clipped to the longest available maturity if the meeting is
  further out than the curve covers.
- **Unit-tested entirely against synthetic curve/SONIA dicts - no live
  HTTP calls in tests**, per instruction. `market_probs_for_meeting()`
  takes plain dicts shaped like `ois.latest_forward_curve()` /
  `ois.latest_sonia()`'s return values, not the fetch functions
  themselves, so tests never touch the network.

## 2026-07-11 — lock and scoring machinery

- **Running `pipeline/predict/lock.py` is not itself "the lock".** It
  writes a timestamped snapshot with `point_call`/`rationale` left as
  `null`/a `TODO(Jake)` placeholder - filling those in by hand, then
  committing the file, is what actually constitutes a locked call. The
  script's job is just to freeze the market-only reference (`m0`) and the
  index readings at a moment in time, reproducibly.
- **Reproducibility fields**: `code_version` (`git rev-parse HEAD`) and
  `input_hashes` (sha256 of `data/index.json` as it stood, plus a sha256
  of the OIS curve + SONIA snapshot actually used) - so a later reviewer
  can check exactly which corpus and market state a given lock was made
  against, without needing git history archaeology.
- **`index_trailing_mean` = mean of the last 4 documents' `abg_net_index`
  in the corpus's own published order** - a simple recency-weighted
  baseline for "how hawkish has tone been lately", not a fitted or
  seasonally-adjusted average. 4 was chosen as roughly a year's worth of
  the current 8-meetings-a-year schedule.
- **`build_prediction(meeting_date, curve=None, sonia=None)` accepts
  optional pre-fetched curve/sonia** so its output schema can be
  unit-tested without a live call (same dependency-injection pattern as
  `market_probs_for_meeting`) - defaults to live fetches when called from
  the CLI.
- **Brier score is the standard 3-class formula** (sum of squared
  differences between predicted probability and the {0,1} actual outcome
  indicator across all 3 classes), range [0, 2]. **Log score** is
  `-log(p_actual)`, floored at `p >= 1e-9` to avoid `-log(0)` for a
  confidently-wrong call.
- **`always_hold_reference`** is a fixed `p_hold=1` forecast, not fitted
  to the corpus's own hold/hike/cut base rates - the simplest possible
  baseline (predict the modal, most common outcome always), which any
  real forecast needs to beat. A base-rate-fitted reference is a
  reasonable future addition but wasn't asked for here.

## 2026-07-11 — site call card + dry run

- **The call card's dry-run vs locked styling is data-driven, not a
  hardcoded label.** `renderCallCard()` checks `point_call !== null`
  to decide which CSS class/badge to apply - a hatched, dashed-border,
  muted-gold "DRY RUN · NOT A FORECAST" badge when null, a solid gold
  border and "LOCKED CALL" badge (showing the actual point call and
  rationale) once a human fills `point_call` in. Same code renders both
  states correctly; verified visually with a synthetic locked payload
  before committing (not itself committed - see below).
- **Card fetches a fixed path, `data/predictions/dryrun-2026-07.json`**,
  not a directory listing (static GitHub Pages has no server-side
  directory index). A later real lock will need either overwriting this
  same path or updating the fetch path in index.html - a manual step, not
  automated, consistent with "running lock.py is not itself the lock".
- **Ran end-to-end with live data**: `python -m pipeline.predict.lock
  2026-07-30 dryrun-2026-07`. Result: OIS curve as of 2026-06-30 (3.7299%
  1-month forward) vs SONIA 3.7303% (2026-07-08) implies essentially no
  priced move (-0.04bp) -> p_hold=0.999, p_cut=0.001, p_hike=0.0 for the
  30 July announcement. A&BG index for the latest document (minutes-2026-06)
  is 1.714, well above its trailing 4-document mean of 1.054 (+0.661) -
  tone reads considerably more hawkish than its recent average, while the
  market itself prices almost no chance of a near-term move. This
  divergence is exactly the kind of gap the site's thesis is about - noted
  here as an observation, not a call. No point_call was made; this is
  m0 (market-only) only, per the task's explicit "DRY RUN and no locks
  today" instruction.
- **No `lock-*` named files, no git tag created** - the dry-run output is
  named `dryrun-2026-07.json`, distinguishing it structurally (not just
  by content) from any future actual locked call, which would need its
  own deliberately-named file.

## 2026-07-11 — smoothed-curve bias: quantified, offset convention chosen

- **Known limitation confirmed and quantified, not just asserted.** The
  Bank's published OIS forward curve is a fitted spline across maturities,
  which smooths over the discrete jump that actually happens in Bank Rate
  on a meeting date - the curve's value exactly AT the meeting understates
  the priced move and biases `implied_probs` toward hold. Quantified on
  today's live curve (2026-06-30) for the three upcoming meetings:
  implied_change_bp at-meeting vs +3 days vs 2-week-average was -0.04 /
  0.25 / 0.76 (30 Jul), 5.70 / 6.08 / 6.66 (17 Sep), 12.44 / 12.86 / 13.50
  (5 Nov) - a small but real and monotonic effect in the expected
  direction under today's fairly flat curve; expected to be larger under
  more steeply sloped historical curves (e.g. the 2021-2023 hiking cycle),
  to be confirmed once Part B's historical build runs.
- **Convention chosen: forward rate 3 days after the meeting date
  (`LOCK_OFFSET_DAYS = 3`), linearly interpolated between the curve's
  adjacent whole-month buckets - not a 2-week average, and not the
  meeting date itself.** The 2-week-average alternative was computed and
  rejected: it recovers slightly more of the bias (see numbers above), but
  during the Aug 2015-2016 monthly-MPC era a 2-week window is roughly HALF
  the inter-meeting gap, risking real contamination from the NEXT
  meeting's own priced expectations - a bigger problem for a benchmark
  that must run across that entire era than the extra ~0.5-0.6bp of bias
  correction is worth. +3 days is safely inside even the shortest
  historical gap (~4 weeks).
- **Interpolation is required for either convention to mean anything, not
  optional.** The curve's maturities are whole months only; "nearest
  bucket after" (the previous implementation) would make a 3-day shift
  either do nothing (if the meeting isn't near a bucket boundary) or jump
  an entire month's worth of curve (if it is) - neither reflects a "3 days
  later" quantity. `interpolated_forward_rate()` now does linear
  interpolation between the two adjacent whole-month buckets for an
  arbitrary real-valued maturity; `forward_rate_for_date()` evaluates it
  at `meeting_date + 3 days`, converted to months via the existing
  average-days-per-month convention. Same data source as before (the
  Bank's own OIS spreadsheet) - only the evaluation point within that
  curve changed, per instruction ("do not switch data sources").
- **Applied everywhere**: this is the only forward-rate lookup function in
  the codebase (`pipeline/predict/market_probs.py`), used by both the
  live dry-run card and (from here on) the historical backtest in Part B
  - one convention, not two parallel implementations.
- **`lock_offset_days` added to `market_probs_for_meeting()`'s output**
  so any consumer (site, CSV, tests) can see which convention a given
  probability was computed under, without needing to read this entry.
- **Diagnostic table run against today's live data (2026-06-30 curve,
  SONIA 3.7303% as of 2026-07-08) found NO horizon-indexing bug**: hike
  probability increases monotonically and sensibly with horizon (0.0% at
  30 Jul, ~29-31% at 17 Sep, ~63-65% at 5 Nov, varying slightly by
  convention above) - the anticipated failure mode ("hike probability ~0
  even at November despite an upward-sloping curve") was checked for and
  not found; bucket selection was also spot-checked across a 0.5-24 month
  range and confirmed monotonic. No fix was needed for this; the
  investigation is recorded so the check isn't silently skipped.

## 2026-07-11 — 2 null-decision documents recovered

- **The 94-corpus/94-voting-sheet join reporting only 92 candidates was
  exactly the 2 already-logged null-decision documents** (`minutes-2016-08`
  and `minutes-2020-03-10-special`) - both excluded from
  `load_corpus_documents()` by construction (it requires both `published`
  and `decision`). No undocumented exclusion existed; confirmed by
  listing every document with `decision is None` and finding exactly
  these two, matching 94 - 2 = 92.
- **Both recovered from a real, shared pattern, not guessed.** Both are
  "package of measures" meetings (2016-08's post-Brexit stimulus; 2020-03-10's
  first Covid-19 emergency cut) where the actual VOTE_RE-matched sentence
  ("voted unanimously in favour of the propositions") never restates the
  rate, but an earlier sentence does: "The Governor invited the Committee
  to vote on the propositions that: Bank Rate [should be/be] reduced by N
  basis points to X%". `try_proposition_fallback()` in `build_index.py`
  only fires when BOTH halves of this pair are found - the proposition
  statement AND a later "voted (unanimously | by a majority of A-B) in
  favour of ... propositions" confirming it was adopted - so it can't
  attach a rate to a proposition that was never actually put to a vote,
  or vice versa. Tested for both the happy path and the "proposition
  stated but never confirmed" case explicitly staying null.
- **Result: 2016-08 = "reduce Bank Rate by 25 basis points to 0.25%",
  unanimous. 2020-03-10-special = "reduce Bank Rate by 50 basis points to
  0.25%", unanimous.** Both match known history. Validation join now
  covers all 94 of 94 candidate documents (up from 92 of 92, since the
  candidate pool itself grew by the 2 recovered documents).
- **This is a general mechanism, not two special cases hardcoded per
  document** - if a future meeting uses the same Governor's-proposition
  phrasing, it will be recovered automatically without a code change.

## 2026-07-11 — historical market benchmark: data/market_history.csv

- **"Archive files ... by year" turned out to be one multi-era zip, not
  one file per calendar year** - confirmed by re-reading the yield curves
  page's own text ("Daily overnight index swap curve: archive data")
  rather than assumed: it's the same `oisddata.zip` already used for the
  live dry-run, containing "2009 to 2015", "2016 to 2024", "2025 to
  present" era files. No new download endpoint was needed.
- **The 2009-2015 era file names its forward-curve sheet "1. fwd curve"
  instead of "1. fwds, short end"** (used by the 2016+ files) - checked
  by hand and confirmed structurally identical (same maturity-months row,
  same layout). `pipeline/market/ois.py`'s `_read_forward_curve_sheet`
  now accepts a tuple of candidate sheet names and tries each in order,
  used with both names for the full-history build and just the current
  name for the live lookup.
- **Full history requires every era file to parse - hard stop, not skip.**
  `latest_forward_curve()` (live lookup) can safely skip an era file with
  neither known sheet name, since it only needs the most recent one. The
  new `load_full_curve_history()` (Part B) hard-stops instead if any era
  file matches neither name - a full Aug 2015-present history silently
  missing a whole era would be a much worse failure than the live lookup
  skipping old data it was never going to use anyway.
- **Lock date = announcement - 2 calendar days**, walked back one day at a
  time if that date isn't present in the curve data (a weekend or bank
  holiday is simply absent as a row - no separate UK holiday calendar was
  built; the data itself is the trading calendar). Same mechanism used
  for the SONIA lookup at the lock date. `find_nearest_available_date()`
  in `pipeline/market/ois_history.py`, capped at a 10-day walk-back before
  hard-stopping (never silently substitutes an arbitrarily old date).
- **In practice, zero walk-backs occurred across all 94 meetings.** MPC
  announcements are (with rare exception) Thursdays, so announcement-2d
  lands on a Tuesday - essentially never a UK bank holiday, and December
  meetings land well clear of Christmas/New Year (checked by hand:
  earliest Dec lock date across the corpus is 8 Dec, latest 18 Dec).
  Confirmed this is a real property of the MPC calendar, not a silent
  bug in the walk-back logic (also unit-tested directly with a synthetic
  weekend gap).
- **`forward_rate_for_date` from `pipeline/predict/market_probs.py` is
  reused unchanged** for the historical build (curve `as_of_date` = lock
  date, `meeting_date` = announcement) - one implementation of the
  LOCK_OFFSET_DAYS=3 convention for both the live card and the historical
  backtest, per the earlier instruction not to have two parallel
  conventions.
- **`build_rows()` is a pure function** (curve/SONIA history passed in,
  no I/O) so it's unit-tested against synthetic fixtures including an
  explicit weekend-gap walk-back case, without a live call; `main()`
  wires it to the real downloads. `data/market_history.csv` columns:
  `meeting, lock_date, sonia, forward, implied_change_bp, p_cut, p_hold,
  p_hike, source_file`.
- **Result: all 94 corpus meetings covered, no hard stops.** Notable
  sanity spot-check: Dec 2022 (height of the 2022 hiking cycle) shows
  `p_hike = 1.0` (implied change 62.31bp, well over the assumed 25bp
  move, clipped) - the kind of result that should show up at the extremes
  and does.

## 2026-07-11 — decision classifier bug found and fixed: Bank-Rate-adjacent verb, not first word

- **Found while running the Part-B sanity checks, not before**: the
  "5 most-wrong meetings" table initially put `minutes-2020-03-19-special`
  in 2nd place as a supposed "hike" the market gave 0% probability to -
  but that meeting was actually a CUT (Bank Rate 0.25%->0.1%). Its
  `decision` text is a compound sentence - "increase the Bank of
  England's holdings of [assets] ... and to reduce Bank Rate by 15 basis
  points to 0.1%" - and every classifier in the codebase
  (`pipeline/validate.py`, index.html's chart markers) took the FIRST
  WORD of the decision string ("increase") rather than the verb actually
  adjacent to "Bank Rate" ("reduce"). One document, out of all 94, was
  affected - checked by running the new classifier against every
  document's decision text and diffing against the old first-word
  result: exactly this one mismatch, no others.
- **Fixed with one shared function, not three separate patches.**
  `pipeline/decision_label.py:classify_decision()` finds the verb
  immediately before "Bank Rate" via regex
  (`(increase|reduce|maintain)\w*\s+Bank Rate`), not the first word of
  the string. `pipeline/validate.py` and index.html's chart-marker JS
  both now use this one rule (the JS re-implements the same regex, since
  it can't import Python) instead of two independently-maintained
  first-word copies that could drift apart again.
- **Downstream corrections**: `mean_abg_index_by_decision.cut.n` in
  `data/validation_v1.json` went from 6 to 9 (the 2 decisions recovered
  earlier this session plus this reclassification), `hike.n` unaffected.
  The "5 most-wrong" sanity check (below) now correctly shows Nov and Dec
  2021, as expected, instead of being pushed down by this misclassified
  entry.

## 2026-07-11 — Part B sanity checks

- **(a) Mean p_hike at lock across the 14 consecutive hikes (Dec 2021 -
  Aug 2023): 0.9225** - far above the corpus-wide hike base rate of
  0.1702 (16 of 94 meetings), as expected: the market correctly priced
  near-certain hikes through most of the cycle (12 of 14 meetings show
  p_hike = 1.0, i.e. an implied change >= the assumed 25bp move size).
  The two exceptions are informative, not noise: Dec 2021 (p_hike=0.29,
  the first hike of the cycle, not yet fully anticipated - see below) and
  Mar 2023 (p_hike=0.625, during the SVB/Credit Suisse banking-stress
  week, when a hike was less certain).
- **(b) Five most-wrong meetings (highest 1 - p(actual outcome)):**
  1. `minutes-2016-07` (actual hold, p_cut=1.0, p_actual=0.0) - the
     market was CERTAIN of a post-referendum cut that didn't arrive until
     August's "package of measures" the following month.
  2. `minutes-2023-09` (actual hold, p_hike=0.889, p_actual=0.111) - the
     Bank held for the first time after 14 straight hikes; the market
     hadn't caught up to the pause.
  3. `minutes-2021-12` (actual hike, p_hold=0.710, p_actual=0.290) - the
     first hike of the cycle, one meeting after the market had just been
     burned by November's hold (below) - underpriced.
  4. `minutes-2021-11` (actual hold, p_hike=0.688, p_actual=0.312) - the
     well-known "dovish surprise": the market had priced a near-certain
     hike and the Committee held.
  5. `minutes-2020-03-19-special` (actual cut, p_hold=0.612,
     p_actual=0.388) - the second Covid-19 emergency cut, days after the
     first; the two-state model's 25bp assumed-move size understates how
     large emergency moves can be (this one was 15bp, priced against a
     0.1%-away curve reading that had just also absorbed the 10 March
     cut - a genuinely unusual week, not a fitting error).
  Nov 2021 and Dec 2021 both appear, as expected. All five are real,
  independently-recognisable market surprises, not artefacts.

## 2026-07-11 — scipy added, for the ordered logit models only

- **scipy added as a dependency, deliberately narrower in scope than it
  sounds.** The earlier choice (2026-07-25) to implement Pearson/Spearman
  by hand rather than add scipy still stands for those - they're
  closed-form formulas, not worth a dependency. An ordered logistic
  regression MLE fit (L2/L3 in the benchmark ladder) is a different order
  of complexity: a numerically stable iterative optimizer with a genuine
  convergence/non-convergence distinction (which the task's own wording
  anticipates - "if an ordered-logit window fails to converge"). Writing
  a bespoke Newton-Raphson/IRLS implementation by hand would be
  re-deriving what scipy.optimize already does robustly, with more risk
  of a subtle numerical bug than the dependency is worth.
- **`pipeline/predict/ordered_logit.py`: proportional-odds model, 3
  classes (cut/hold/hike), fit by direct MLE** (`scipy.optimize.minimize`,
  BFGS) rather than an existing statsmodels/sklearn ordinal-regression
  implementation - kept to the one additional dependency, not two.
  Cutpoint ordering (tau_0 < tau_1) is enforced by reparameterising
  tau_1 = tau_0 + exp(delta) and fitting unconstrained.
- **Convergence check is two-part, not just scipy's own success flag.**
  Tested against synthetic data: a hard, noiseless 3-class threshold (no
  overlap anywhere) is a genuine quasi-complete-separation case where the
  optimizer can keep improving the likelihood by pushing a cutpoint
  towards +-infinity - it reports `success=True` while landing on a
  degenerate fit. Added a second check (`|any fitted parameter| > 50`) to
  catch this specifically; a fit failing either check is `converged =
  False`. Verified this actually fires on the deterministic-threshold
  test case and does NOT fire on realistic noisy synthetic data or a
  well-separated-but-still-noisy case (unit-tested for both).

## 2026-07-11 — the benchmark ladder (first real backtest), L0-L4

- **Outcomes coded by SIGN only, magnitude ignored**, per instruction: a
  50bp move counts the same as a 15bp move in the same direction. Uses
  the same `classify_decision()` as everywhere else in the codebase (one
  classifier, see the earlier 2026-08-01 entry on the first-word bug).
- **Evaluation window: Jan 2019-present, 62 meetings.** Training starts
  from the very first corpus document (Aug 2015) for every evaluation
  meeting - "fit on strictly prior meetings only" means the training set
  grows with each step (`records[:i]`), never using meeting i or later.
- **L3's `index_level` and `skew` are BOTH the PREVIOUS meeting's values,
  not the target's own - a judgment call, not a literal reading of the
  task text, and flagged prominently (module docstring, this entry, and
  the final report).** The task's wording explicitly lags skew ("last
  meeting's vote skew") but not index_level. A meeting's own minutes (and
  therefore its own `abg_net_index`) are published SIMULTANEOUSLY with
  its own decision - using them to "forecast" that same decision would
  not be a real forecast, and would be a fundamentally different (leaky)
  use of the index than everywhere else in this project
  (`pipeline/validate.py` is explicitly contemporaneous-not-predictive).
  Lagging both features uniformly, the same way skew already is, is the
  reading applied here. If a literal (unlagged) reading was actually
  intended, this is where to look to change it -
  `pipeline/ladder.py:l3_market_index_skew_logit`.
- **scipy added for L2/L3's ordered logit** - see the separate 2026-08-01
  "scipy added" entry above for the full reasoning and the two-part
  convergence check.
- **Feature standardisation (z-score, fit on training data only) was
  necessary, not optional - found by running the ladder, not assumed.**
  The first real run flagged 61 of 62 L3 windows as "degenerate"
  (`|param| > 50`), which turned out to be a scale artefact, not genuine
  non-convergence: `skew`'s raw values are ~1e-3, `implied_change_bp`'s
  are ~1e1, so a perfectly healthy fit needs wildly different-magnitude
  coefficients across features, easily tripping a threshold calibrated
  for unit-scale inputs. Standardising each feature column (subtract
  training mean, divide by training std - never touching the target
  during the standardisation itself, only applying the same
  transformation to it afterwards) fixed this: fallbacks dropped from 61
  of 62 to 11 of 62, and the remaining 11 are all evaluation meetings
  BEFORE March 2020 - the corpus's first-ever cut. Before that date, any
  training window has literally zero cut examples, which is exactly the
  "rare cuts early on" non-convergence the task itself anticipated -
  confirmed as a real, expected fallback, not a bug, by checking that
  every remaining fallback date precedes the first cut.
- **L4 member-level model, several judgment calls, all logged**
  (`pipeline/ladder.py` module docstring has the full reasoning):
  - Pooled transition matrix (not per-member - same reasoning as
    `pipeline/member_behaviour.py`), refit at each evaluation step on
    strictly prior votes only.
  - Each member's "previous state" = their own most recent state before
    the target meeting (from the expanding-window-filtered voting
    history), not their state AT the target meeting (that would be the
    answer being predicted).
  - "Plus implied_change_bp" implemented as an equal-weight (0.5/0.5)
    blend of the transition-matrix distribution and the same two-state
    +-25bp market-implied distribution already used for `m0`, reused at
    the per-member level (`hawkish_dissent<->hike`,
    `with_majority<->hold`, `dovish_dissent<->cut`). No new fitted
    parameter introduced beyond what's listed.
  - "Members with no history default to majority": implemented literally
    as a deterministic 100% with_majority/hold distribution for a
    member's first-ever appearance, with no market blending (nothing to
    blend against) - tested explicitly.
  - Committee-level distribution: Monte Carlo simulation (5,000 trials,
    fixed seed = 42) of all voting members' independent draws, aggregated
    by plurality with ties split equally among tied leaders - the task's
    own wording ("simulate the nine votes") points at simulation rather
    than an exact combinatorial calculation, and a fixed seed makes it
    exactly reproducible (tested).
- **Result: L0/L1 as expected (L1 far ahead of always-hold); L2, L3, L4
  all score WORSE than L1 (market-only) on this first pass** - negative
  skill for all three (L2 -0.30, L3 -0.59, L4 -0.95). Not treated as a
  bug or "fixed" further: this is a legitimate finding for a genuinely
  first backtest, and consistent with the project's own null-result
  framing (market efficiency). L1's mapping from implied_change_bp to
  probabilities is correct by construction (the same clipped-linear rule
  IS how m0 itself is built); L2 has to re-discover an equivalent
  relationship from a modest, noisy sample via MLE, so underperforming a
  correct-by-construction baseline on Brier score over 62 meetings is
  expected, not surprising. L4 carries by far the most compounded
  modelling assumptions (pooled transition matrix estimated on a limited
  sample, an invented 0.5/0.5 blend weight, Monte Carlo sampling
  variance) and its larger underperformance is consistent with that.
  Saved to `data/ladder_v1.json`; explicitly NOT published to the site,
  per instruction - for review first.

## 2026-07-11 — curve freshness fix

- **Root cause of the stale 2026-06-30 curve: `ois.py` only ever read
  `oisddata.zip`, the multi-year ARCHIVE - which the Bank's own FAQ says
  is only refreshed "by close of business of the second working day of
  each month".** There is a SEPARATE file, "latest-yield-curve-data.zip"
  ("Latest yield curve data" on the yield curves page), updated daily,
  containing "OIS daily data current month.xlsx" with the current
  month's business days. `latest_forward_curve()` now downloads BOTH and
  picks the single freshest date across all candidate files - the same
  "pick by actual date, not by assumed filename" principle already used
  to choose among era files, just extended to a second source.
- **The latest-month zip bundles 4 different curve types that share a
  sheet NAME but not a row structure** (GLC Nominal/Real/Inflation gilt
  curves + OIS) - found by actually running it, not assumed: the GLC
  files have blank/formula-error cells for some dates in this snapshot,
  which isn't a malformed OIS file, it's simply not an OIS file. Filtered
  to filenames containing "OIS" for this specific zip (the era archive
  doesn't have this problem, its files are unambiguously OIS-only, so no
  filter was needed there).
- **`pick_freshest_curve(xlsx_files)` extracted as a pure function**
  (given a file list, no I/O beyond reading them) so the actual bug -
  "does the freshest file win regardless of which one happens to be
  checked first" - is directly unit-tested with two small fixture
  workbooks, one deliberately stale, one fresh.
- **`lock.py` freshness assertion**: `assert_curve_is_fresh(curve_as_of,
  today)` refuses (raises) if the curve is more than
  `MAX_CURVE_STALENESS_BUSINESS_DAYS = 2` business days old. Checked
  right before the file WRITE in `main()`, not inside
  `build_prediction()` - `build_prediction()` stays usable in tests with
  an arbitrary injected curve date without also needing to fake "today".
  Business-day counting (Mon-Fri) has no UK bank-holiday calendar, same
  limitation as `ois_history.py`'s walk-back logic elsewhere in this
  codebase - a holiday inside the window is silently counted as a
  business day, which makes this an UNDERcount of true staleness, never
  an overcount, so the check stays conservative in the safe direction.
  Fixture-tested for both the pass and hard-stop paths, using the actual
  stale/fresh dates from this real incident.

## 2026-07-11 — scheduled vs special meetings split; probability-clip logged

- **`scheduled` (bool) added to `data/market_history.csv` and every ladder
  record**: False for `special_minutes` (the two March 2020 emergency
  meetings), True otherwise. At lock time - 2 business days before the
  announcement - nobody could have pre-registered a forecast for a
  meeting whose existence hadn't been announced yet, so treating specials
  as ordinary pre-registered forecasts would overstate how "surprising"
  the market's miss on them really was (they weren't scheduled to be
  forecastable at all).
- **Headline ladder evaluation = scheduled meetings only (60 of 62);
  specials are a separate, clearly-labelled robustness line, never
  blended into the headline scores.** `pipeline/build_ladder.py` now
  reports `headline_scores_scheduled_only` and
  `specials_robustness_scores` as two distinct tables in
  `data/ladder_v1.json`, both computed by the same `score_models()`
  function on filtered subsets - one scoring function, not two.
- **`log_score_probability_clip` (the `LOG_SCORE_EPSILON = 1e-9` floor
  applied to p(actual outcome) before `-log(p)`, to avoid `-log(0)` for a
  confidently-wrong call) is now a top-level field in
  `data/ladder_v1.json`**, not just a constant buried in
  `pipeline/predict/score_outcomes.py` - a reader of the ladder output
  can now see exactly what floor the log scores were computed under
  without reading the source.

## 2026-07-11 — live site investigation: false alarm, contract test added anyway

- **Investigated thoroughly before concluding anything, per instruction not
  to assume.** Compared: (1) the live deployed `index.html` byte-for-byte
  against the local committed file (curl diff - identical); (2) the live
  `data/index.json` schema against what index.html's JS reads (every
  field present: doc_id, meeting_end, published, decision, vote,
  abg_net_index, abg_hawk, abg_dove, sha256, source_url, neutral_value,
  lexicon); (3) rendered the exact deployed HTML+JSON with a real
  JS-executing browser (this repo's own preview tooling, pointed at the
  identical content) - the call card, latest-document card, and chart all
  render correctly, zero console errors, zero failed network requests.
- **Root cause of the apparent "stuck on Loading..." symptom: WebFetch
  (used for the initial live-page check) doesn't execute JavaScript.**
  It was reading the STATIC placeholder text ("Loading data/index.json
  …", "Loading call card …") that exists in the raw HTML before any
  script runs, which is indistinguishable from a genuinely broken page to
  a non-JS-executing crawler. A false alarm, not a real bug - the
  underlying site is fine right now.
- **Contract test added anyway** (`pipeline/tests/test_site_contract.py`),
  since the RISK this test guards against is real even though no bug
  currently exists: this project already broke this exact contract once
  before, silently, during the starter_v0 -> abg_2012 schema cutover
  (2026-07-18 entries) - the "latest scored document" card was reading
  fields (`net_hawkishness`, `hawkish_hits`, `dovish_hits`) that had been
  removed from `index.json`, caught only by manual review, not a test.
  Asserts every field index.html's JS actually reads exists in the
  REAL committed `data/index.json` and `data/predictions/dryrun-2026-07.json`
  - not a synthetic fixture, so it catches drift in the actual published
  data, not just the parsing logic.

## 2026-07-11 — data/surprises.csv

- **`surprise_bp = actual_change_bp - implied_change_bp`**, scheduled
  meetings only (91 of 94 - excludes the 2 specials and the very first
  corpus meeting, which has no preceding decision to diff against).
  `implied_change_bp` reuses `data/market_history.csv`'s value, i.e. the
  same LOCK_OFFSET_DAYS=3 convention (see DECISIONS.md, 2026-08-01) - one
  implied-change number used everywhere, not recomputed differently here.
- **The actual rate-change HISTORY doesn't skip special meetings, only
  the output rows do.** If a scheduled meeting immediately follows a
  special one (as with 25 March 2020, immediately after the 19 March
  special cut), its `actual_change_bp` is correctly computed against the
  special meeting's decided rate, not silently against whatever scheduled
  meeting came before that - the rate itself doesn't know or care whether
  the previous decision was "schedulable"; only which forecasts could
  have been pre-registered is scheduling-dependent. Tested explicitly
  (a scheduled meeting's prev-rate reference correctly points at an
  intervening special meeting's rate).

## 2026-07-11 — the headline inference (Spec 3 OLS + Spec 2 ordered-logit LR test)

- **statsmodels added as a new dependency, specifically and only for
  Newey-West HAC standard errors.** Not something worth hand-deriving
  (unlike the plain Pearson/Spearman kept dependency-free earlier) - HAC
  covariance estimation has enough subtlety (lag-length choice, small-
  sample corrections) that a well-tested library implementation is the
  right call here, same reasoning as adding scipy for the ordered logit.
- **`NEWEY_WEST_MAXLAGS = 4`**: roughly half a year of overlap at the
  MPC's current ~8-meetings/year cadence. A documented choice, not the
  only reasonable one - kept the same for both the full sample (n=91) and
  the smaller fragility subsample (n=23), rather than re-tuning per
  sample, so the two results are at least comparable on that axis.
- **Lagged features (`lagged_index`, `lagged_skew`) use the PREVIOUS
  meeting's value**, identical convention and identical reasoning to the
  benchmark ladder's L3 (2026-08-01 entry) - a meeting's own minutes
  publish simultaneously with its own decision, so using them unlagged
  wouldn't reflect information available before that meeting's outcome
  was known.
- **Spec 2's ordered-logit LR test needed its own minimum-sample guard**
  (`MIN_OBSERVATIONS_FOR_LR_TEST = 10`, same threshold and same reasoning
  as `pipeline/ladder.py`'s `MIN_TRAINING_EXAMPLES`) - found while writing
  the fragility-check test: without it, a 1-observation fit could report
  a spurious `converged=True` (trivially "successful" only because
  there's too little data to fail on), which would have made the
  Sep-2023-present subsample's report misleadingly confident rather than
  correctly flagged as too-small-to-fit.
- **Results, full sample (n=91 scheduled meetings, Aug 2015-present):**
  Spec 3 (surprise_bp ~ lagged_index): coefficient -2.16, t=-2.15,
  **p=0.032** - nominally significant at 5%. Sign is negative: a more
  hawkish lagged index is associated with a MORE NEGATIVE surprise (the
  actual decision came in more dovish than the market had priced),
  reported as observed, not interpreted further here. Adding lagged skew
  barely moves the index coefficient (still p=0.037) and skew itself is
  not significant (p=0.469). Spec 2 (ordered logit of the 3-class
  decision, with vs without the lagged index): LR=0.47, **p=0.49** - NOT
  significant. The two specs disagree (OLS on the continuous surprise
  finds something; the ordered logit on the discrete decision does not) -
  both reported, neither suppressed to make a cleaner story.
- **Fragility check (Sep 2023-present, n=23, post-hiking-cycle): the
  full-sample Spec 3 result does NOT replicate.** Coefficient -3.44,
  t=-1.47, p=0.142 - not significant at any conventional threshold. Spec
  2's ordered logit didn't even converge at this sample size (correctly
  caught by the new guard above, not silently reported as a
  success). This is exactly the kind of check that should be run before
  treating the full-sample p=0.032 as a stable finding, and it doesn't
  survive - reported honestly, not hidden or explained away.
- **Saved to `data/inference_v1.json`, NOT referenced anywhere in
  index.html or otherwise published** - confirmed by grep - per
  instruction, for review first.

## 2026-07-11 — Results section published to the site (ladder v1)

- **New "Results: benchmark ladder" card**, fetching `data/ladder_v1.json`
  and rendering the SCHEDULED-ONLY headline table (L0-L4: mean Brier,
  mean log score, skill vs L1, n) - the specials robustness line and the
  full per-meeting breakdown stay in the JSON file, not duplicated on the
  site (linked via `data/ladder_v1.json` in the caveat text instead).
- **Framing paragraph is a deliberately visible draft, not a finished
  one.** Wrapped in `<em>` with an explicit "[DRAFT - Jake to rewrite ...]"
  prefix, per instruction that this paragraph gets rewritten in his own
  words - the placeholder text describes what the table shows factually
  (mechanically, not persuasively) so it's usable as a starting point,
  but is unambiguously marked as not final.
- **Standing caveat text is permanent, not part of the draft**: "the
  market benchmark (L1) is the bar... matching or beating L0 is not the
  test" - stays regardless of how the framing paragraph above it gets
  rewritten, since it's a methodological statement about how to read the
  table, not commentary on the specific numbers.
- **Contract test extended** (`test_ladder_json_has_every_field_the_results_section_reads`)
  to cover the new card's fields, same pattern as the existing index.json/
  prediction-file contract tests - the Results section can't silently
  break from schema drift either.
- **Visually verified with a real JS-executing browser** (this repo's own
  preview tooling) before considering this done: table renders correctly,
  L1's row highlighted in accent colour, zero console errors, zero failed
  network requests.

## 2026-07-11 — lock rehearsal (dry run, fresh curve)

- **`python -m pipeline.predict.lock 2026-07-30 rehearsal-2026-07`** run
  end to end with the now-fixed fresh-curve pipeline. Curve as of
  2026-07-09 (1 business day old at run time) - the freshness assertion
  passed without needing to be bypassed, the first real end-to-end proof
  the freshness fix works outside of fixture tests.
  Result: `p_hold=0.9729`, `p_hike=0.0271`, `p_cut=0.0`
  (`implied_change_bp=0.68`) for the 30 July announcement.
- **Saved as `data/predictions/rehearsal-2026-07.json`** - not `lock-*`,
  no git tag - this is a rehearsal of the machinery, not a locked call.
  The site's `PREDICTION_FILE` constant still points at
  `dryrun-2026-07.json`, unchanged; the rehearsal file exists
  independently to prove the process works, not to replace what the live
  card displays.
- **Confirmed the call card renders it correctly in dry-run styling**
  without changing what the live site actually displays: fetched
  `rehearsal-2026-07.json` and ran it through the site's own unmodified
  `renderCallCard()` function in a real browser - `dry-run` classes and
  the "DRY RUN - NOT A FORECAST" badge applied correctly (same code path
  already used for `dryrun-2026-07.json`, since both files share the same
  `point_call: null` schema).

## 2026-07-12 — site v2 (design, interactivity, context panel, annotations, methodology)

Site-only session, hard constraint: nothing in `pipeline/score`,
`pipeline/market`, `pipeline/predict`, the lexicon, or any existing data
schema was modified; the original 83 tests stayed green throughout (now 93
with new site tests). New site work imports the science-layer modules
read-only and only ever writes NEW json files.

- **Design pass on `index.html`**: reordered to a clear hierarchy (call card
  -> the index -> market & macro context -> results -> episodes ->
  methodology), merged the old standalone "latest scored document" card into
  the index card as its lead reading, added a type scale, tabular numerals,
  mobile responsiveness, an inline-SVG favicon (data URI, no external file),
  page `<title>`/description/Open Graph/theme-color meta, and a real footer
  (GitHub links, "not investment advice", auto-populated generated date).
  All existing element IDs and data-loading JS preserved. Stale badge "Beta ·
  walking skeleton" corrected to "Beta · pre-registered".
- **Chart interactivity, hand-rolled (no chart library, no CDN)**: hover
  tooltip (document, published date, index value, and the decision that
  *followed* - i.e. the NEXT meeting's decision, the thesis-relevant one,
  since a meeting's own decision is already its marker); toggleable overlays
  for decision markers and a Bank Rate step line on its own right-hand axis;
  neutral reference line kept labelled. One decision classifier shared with
  the rest of the codebase (the verb adjacent to "Bank Rate", re-implemented
  in JS since it can't import `pipeline/decision_label.py`).
- **NEW exporter `pipeline/site_context.py` -> `data/site_context.json`**,
  labelled "Context - not model inputs" (a `context_not_model_inputs: true`
  flag in the JSON and a visible badge on the site). Three series:
  (a) the OIS-implied path for the next three scheduled meetings (30 Jul /
  17 Sep / 5 Nov 2026, from the Bank's published calendar - see the
  2026-08-01 entry - hardcoded as CONTEXT labels, not a model input),
  computed via the SAME `market_probs_for_meeting` rule used for m0 and the
  benchmark; (b) Bank Rate history as a step chart, from `data/votes.csv`'s
  `decided_rate`; (c) the 2-year nominal gilt yield (latest + a 12-month
  daily sparkline), read from the Bank's GLC Nominal curve files (the
  current-month file already downloaded by `ois.download_latest_month_zip`
  plus a NEW polite download of `glcnominalddata.zip`, same 2s-sleep
  discipline). The 24-month spot point was found in the "3. spot, short end"
  sheet; **it parsed cleanly, no HARD STOP triggered** - but the reader path
  raises rather than approximating if the sheet/column ever goes missing.
- **Annotations machinery, site layer only**: markdown episodes live in
  `site/annotations/YYYY-MM-slug.md` (two header lines `title:`/`date:` then
  a markdown body). A build step (`pipeline/build_annotations.py`) scans them
  into `data/annotations.json`, newest-first, which the "Episodes" section
  fetches and renders with a tiny safe markdown subset (paragraphs, headings,
  bold/italic, links, bullet lists) - **a build step, not client-side
  directory listing, because static GitHub Pages has no directory index**;
  same "everything the site reads is a data/*.json" pattern as the rest of
  the project. Exactly one placeholder file, `2021-11-the-hold-that-wasnt.md`,
  marked `TODO(Jake)` - all real episode text is written by Jake, never
  generated here. A missing `title:`/`date:` header HARD STOPs.
- **`methodology.html`** added: self-contained companion page (own trimmed
  copy of the site styles, no shared external stylesheet, to keep both pages
  zero-dependency), with five section stubs marked `TODO(Jake)` - Data, Index
  construction, Market benchmark, Evaluation, Limitations - wired into the
  index footer nav. A one-line footnote under the OIS probability bars
  ("forward-implied probabilities reflect risk premia as well as
  expectations") links to `methodology.html#limitations`.
- **`CLAUDE.md` added at the repo root** with the standing rules (read
  DECISIONS.md first; every choice gets a dated forward-only entry; never
  modify `data/predictions/lock-*`; the science layer is off-limits unless a
  prompt says otherwise; one plain-English line before each command for a
  beginner maintainer; never fabricate/approximate - HARD STOP and ask).
- **New site tests (site layer only), 10 added, 93 total**: contract tests
  that `data/site_context.json` and `data/annotations.json` carry every field
  the front-end reads (same guard as `test_site_contract.py`), plus pure-
  helper unit tests (bank-rate dedup, era-file year parsing, gilt 12-month
  windowing, OIS-path shape, annotation header parsing incl. the HARD-STOP
  path) - none make live calls.

## 2026-07-12 — evidence inspector (`pipeline/inspect.py`)
- New tooling module for drafting/inspection only, never read by the site.
  Imports `pipeline/score/abg.py`'s tokeniser (`_TOKEN`), lexicon loader
  (`load_abg_lexicon`) and noun-matcher (`_noun_matches_at`) verbatim rather
  than reimplementing the matching logic, so its per-term breakdown can never
  silently drift from the scorer's own aggregate counts. A test
  (`pipeline/tests/test_inspect.py`) asserts this reconciliation on both a
  synthetic string (portable, no dependency on local raw text) and, when raw
  text is present locally, the real corpus against `data/index.json`'s
  `abg_hawk`/`abg_dove` fields - the task brief referred to these as
  `hawkish_hits`/`dovish_hits`, which was the retired `starter_v0`/
  `dictionary.py` field naming; checked the actual current schema rather than
  writing a test against field names that no longer exist.
- **"Trailing N documents" for this module means strictly the N documents
  published *before* the target**, not including it. This is a deliberate
  choice distinct from `pipeline/predict/lock.py`'s own `index_trailing_mean`
  convention (last N documents including the current one, used on the site's
  call card) - lock.py is off-limits this session (`pipeline/predict`) and is
  unchanged. For `inspect.py`'s purpose (does this document look unusual
  against its own recent history?) including the document in its own
  baseline would dilute the comparison, so a strictly-prior window was used
  instead, for both the trailing-mean display and the `--vs-trailing`
  frequency comparison.
- `--vs-trailing` is descriptive only (raw counts and deltas vs a simple
  average) - no significance testing, per instruction.

## 2026-07-12 — Track record section (`data/track_record.json`, `index.html`)
- New `pipeline/build_track_record.py` (site layer, additive) reads
  `data/predictions/*.json` (never writes to them) and writes a flat summary
  to `data/track_record.json`, which a new "Track record" section on the
  site fetches - same build-step pattern as `pipeline/build_annotations.py`,
  needed because static GitHub Pages has no directory index to discover the
  prediction files on its own.
- **"Locked" is determined purely by filename prefix (`lock-`)**, matching
  the existing project convention in `CLAUDE.md` ("Files under
  `data/predictions/lock-*` are never modified once written"). Any other
  filename (`dryrun-*`, `rehearsal-*`, anything else) renders as a
  non-locked draft with a distinct badge. This means any future `lock-*.json`
  file picks up the locked styling automatically, with no code change
  needed.
- **Brier column shows `scores.m0_market_only.brier_score`, not a
  point-call-specific score.** Checked `pipeline/predict/score_outcomes.py`:
  it only scores the m0 market-only reference and an always-hold baseline -
  `point_call` is a categorical single guess with no probability
  distribution of its own, so there is currently no Brier defined for it.
  Rather than fabricate one (e.g. treating the point call as a degenerate
  100%-confidence forecast), the site labels the column "Brier (m0)" and the
  section's framing text says why. Revisit if/when Jake decides how a point
  call should be converted into a scoreable distribution - that's a
  methodological choice for `pipeline/predict`, out of scope this session.
- Empty-state note ("First pre-registered call: 30 July 2026.") shows
  whenever no record has `kind == "locked"` yet - both current files
  (`dryrun-2026-07.json`, `rehearsal-2026-07.json`) are drafts, so it
  currently always shows alongside the two draft rows, not instead of them.
- New tests: `pipeline/tests/test_build_track_record.py` (unit tests on
  synthetic prediction files + a contract test on the real
  `data/track_record.json`, same pattern as `test_build_annotations.py`).
  Verified rendering locally in a real browser (`preview_*` tools): both
  draft rows render with correct badges/values, empty-state note shows, no
  console errors.

## 2026-07-13 — final polish: Spec 3 published, lexicon sparsity, repo front door

- **The headline inference (Spec 3 + Spec 2) is now published to the site's
  Results section**, ending the "NOT published - for review first" status
  from the headline-inference entry (2026-07-11, formerly misdated
  2026-08-08 - see the erratum below). Values are rendered verbatim from
  `data/inference_v1.json` by index.html's JS (no re-rounding, no
  re-derivation); the fragility non-replication and Spec 2's null are shown
  in the same sentence as the full-sample p-value, never separated from it.
  A one-line plain-English caption sits under both the ladder table and the
  Spec 3 line, each marked DRAFT for JF to revise.
- **Lexicon-sparsity statistic computed read-only and quoted on
  methodology.html#limitations**: per document, total_hits = abg_hawk +
  abg_dove from `data/index.json`; across all 94 documents the median is 2
  hits, Q1 = 1, Q3 = 3 (IQR = 2), min 0, max 12. Computed by the additive
  script `pipeline/lexicon_sparsity.py` (reads index.json, writes nothing,
  imports nothing from the science layer). Quartiles use
  `statistics.quantiles(n=4, method="inclusive")` - the median-inclusive
  convention - stated on the page rather than left implicit.
- **methodology.html's five stubs replaced with a factual specification
  sheet** (Data / Index construction / Market benchmark / Evaluation /
  Limitations), every claim traceable inline to code or a dated entry in
  this file; every section carries a DRAFT marker - the interpretive
  discussion is Jake's to write, not generated.
- **Repo front door for an academic reader**: README rewritten (research
  question, pipeline diagram, headline ladder + Spec 3 numbers copied
  verbatim from the JSON files, quickstart, repo map, limitations pointer);
  CITATION.cff added; a GitHub Actions workflow runs pytest on every push -
  tests only, it never rebuilds data and never touches
  `data/predictions/`; repo description/topics set via gh. A dated table
  of contents was added to the top of this file and the two 2026-07-12
  headers' dash style normalised - no entry wording, dates or meaning
  changed.
- **Date oddity in earlier headers**: noticed during this session that
  entries dated 2026-08-01/2026-08-08 sat before entries dated 2026-07-12
  in file order. Investigated against commit evidence the same day and
  corrected - see the erratum entry below for the full table and the root
  cause.

## 2026-07-13 — ERRATUM: entry header dates corrected against commit evidence

Header dates in this file had been written from an assumed weekly session
cadence instead of the system clock: `git log --follow -p` shows every
misdated entry was actually committed on 11-12 July 2026, while the headers
claimed dates up to four weeks later. Each header below was corrected in
place to the date of the commit that introduced it; **no entry wording was
changed**. Body-text cross-references to the old dates (in earlier entries,
committed docstrings, and data/*.json notes) resolve via this table. The
2026-07-05 "repo created" header predates the first commit (b66db84,
2026-07-10) and cannot be verified from git; it is not future-dated and no
evidence contradicts it, so it is left unchanged. Root cause: dates were
recalled from memory/assumed schedule and never checked with `date` — a
rule now added to CLAUDE.md, with a pytest guard
(`pipeline/tests/test_decisions_dates.py`) that fails on any future-dated
entry.

| Entry | Wrong date | Corrected date | Evidencing commit |
|---|---|---|---|
| corpus audit: full-text repair + special meetings | 2026-07-18 | 2026-07-11 | 69f4593 |
| A&BG (2012) baseline lexicon | 2026-07-18 | 2026-07-11 | 8d56446 |
| voting-record parsing and reconciliation | 2026-07-18 | 2026-07-11 | 8d56446 |
| first validation pass (v1) | 2026-07-18 | 2026-07-11 | 8d56446 |
| site: A&BG chart, retiring starter_v0 fields from the UI | 2026-07-18 | 2026-07-11 | 8d56446 |
| 19 March 2020 special meeting added | 2026-07-25 | 2026-07-11 | 32659bd |
| validation join fixed: voting-sheet date is canonical | 2026-07-25 | 2026-07-11 | 32659bd |
| neutral_value published in index.json | 2026-07-25 | 2026-07-11 | 32659bd |
| member-behaviour table (seeds Stage 4) | 2026-07-25 | 2026-07-11 | 32659bd |
| market benchmark: OIS forward curve + SONIA | 2026-07-25 | 2026-07-11 | 523e44d |
| market_probs: two-state ±25bp assumption | 2026-07-25 | 2026-07-11 | 523e44d |
| lock and scoring machinery | 2026-07-25 | 2026-07-11 | 523e44d |
| site call card + dry run | 2026-07-25 | 2026-07-11 | 523e44d |
| smoothed-curve bias: quantified, offset convention chosen | 2026-08-01 | 2026-07-11 | 329a5a9 |
| 2 null-decision documents recovered | 2026-08-01 | 2026-07-11 | 329a5a9 |
| historical market benchmark: data/market_history.csv | 2026-08-01 | 2026-07-11 | 329a5a9 |
| decision classifier bug found and fixed | 2026-08-01 | 2026-07-11 | 329a5a9 |
| Part B sanity checks | 2026-08-01 | 2026-07-11 | 329a5a9 |
| scipy added, for the ordered logit models only | 2026-08-01 | 2026-07-11 | 329a5a9 |
| the benchmark ladder (first real backtest), L0-L4 | 2026-08-01 | 2026-07-11 | 329a5a9 |
| curve freshness fix | 2026-08-08 | 2026-07-11 | 95a9af7 |
| scheduled vs special meetings split; probability-clip logged | 2026-08-08 | 2026-07-11 | 95a9af7 |
| live site investigation: false alarm, contract test added anyway | 2026-08-08 | 2026-07-11 | 95a9af7 |
| data/surprises.csv | 2026-08-08 | 2026-07-11 | 95a9af7 |
| the headline inference (Spec 3 OLS + Spec 2 ordered-logit LR test) | 2026-08-08 | 2026-07-11 | 95a9af7 |
| Results section published to the site (ladder v1) | 2026-08-08 | 2026-07-11 | 95a9af7 |
| lock rehearsal (dry run, fresh curve) | 2026-08-08 | 2026-07-11 | 95a9af7 |
| site v2 (design, interactivity, context panel, annotations, methodology) | 2026-08-08 | 2026-07-12 | c2356a2 |
| final polish: Spec 3 published, lexicon sparsity, repo front door | 2026-07-12 | 2026-07-13 | uncommitted (this session; `date` = 2026-07-13) |

## 2026-07-13 — CI portability: Spec 2 synthetic test moved off the degeneracy cliff

- **First CI run failed on Linux while the identical suite passed on macOS
  with identical library versions** (scipy 1.18.0, statsmodels 0.14.6,
  numpy 2.5.1 on both). Root cause, diagnosed not guessed:
  `test_spec2_lr_test_detects_informative_added_feature` built its
  synthetic data with an index effect of 30, driving the fitted ordered-
  logit coefficient close to `fit_ordered_logit`'s |param| > 50 degeneracy
  guard - close enough that BLAS-level floating-point differences
  (Accelerate on macOS vs OpenBLAS on Linux) tipped the same fit over the
  threshold on one platform and not the other.
- **Fix is in the test only** - the effect size drops from 30 to 10, where
  the fitted parameters are O(1) (checked: max |param| ≈ 3.1) and the LR
  test still detects the feature decisively (p ≈ 0.004). No frozen code
  touched; `pipeline/inference.py` unchanged, so `data/inference_v1.json`
  is byte-identical on rebuild. Standardising features inside spec2 (the
  ladder's documented fix for the same guard-vs-scale artefact) was
  considered and deliberately NOT done this close to the lock, since it
  could flip the published fragility subsample's `converged: false`.

## 2026-07-28 — pre-lock rehearsal + LOCKDAY runbook

- **Rehearsal only: nothing locked, nothing tagged, science layer untouched.**
  `python -m pipeline.predict.lock 2026-07-30 rehearsal-2026-07-26` run end to
  end against live data. 107/107 tests green before and after. Curve as of
  **2026-07-27**, 1 business day old at run time, so `assert_curve_is_fresh`
  passed without being bypassed (SONIA as of 2026-07-24 - the usual few-day
  publication lag between the two sources, as recorded 2026-07-11).
- **The curve HAS repriced since the 2026-07-09 rehearsal, and repriced
  HAWKISH.** m0 for 30 Jul moved from `implied_change_bp` 0.68 / p_hike 0.0271
  to **0.97 / 0.0386**; on the same 2026-07-27 curve, 17 Sep prices 8.47bp
  (p_hike 0.3388) and 5 Nov prices 23.15bp (p_hike 0.9259), against 6.08 /
  12.86bp on the older 2026-06-30 curve under the same +3-day convention. The
  freshness question this check was set up to answer is answered - the numbers
  are not frozen, so this is a live file, not a stale one. The *direction* is
  recorded here as an observation and nothing more: it runs against the dovish
  repricing that had been expected from the June CPI print, and this project
  does not have an inflation-expectations model that could adjudicate why. No
  attempt was made to explain, adjust, or reconcile it - see the Sep/Nov
  caveat below before treating the move as fully like-for-like.
- **Sep/Nov comparison is against a 2026-06-30 curve, not the 2026-07-09 one.**
  The 9 July rehearsal recorded only the 30 Jul meeting; the only earlier Sep/Nov
  figures on file are the 2026-06-30 diagnostic table in the 2026-07-11
  smoothed-curve entry. The 30 Jul comparison is like-for-like; the Sep/Nov
  comparison spans 27 days of curve, not 18. Stated rather than papered over.
- **`data/predictions/rehearsal-2026-07-26.json` carries a hand-added
  `_rehearsal` key** (`is_rehearsal`, `not_a_locked_call`, a plain-English note,
  and the real generation timestamp) so the file cannot be mistaken for a call
  by a reader who only opens the JSON. Added **by hand after** the script ran:
  `pipeline/predict/lock.py` is frozen and does not emit this key, and no
  existing schema changed - `build_track_record.py` checks for required fields
  and ignores extras, and already classifies `rehearsal-*` by filename prefix.
- **Filename says 07-26, file was generated 07-28.** The name was specified in
  the prompt (the originally scheduled rehearsal date); the run happened on the
  28th. Rather than silently renaming or silently accepting it, the file's own
  `_rehearsal.filename_date_note` records the discrepancy and points at
  `lock_timestamp` as authoritative. Flagged for Jake to rename if he prefers.
- **`point_call` / `rationale` confirmed unwritable by machine.** Repo-wide
  grep: the only assignment to either field anywhere is
  `pipeline/predict/lock.py:107-108` (`None` / the `TODO(Jake)` placeholder).
  Every other reference - `index.html`, `build_track_record.py`, the tests -
  reads. `score_outcomes.py` writes `outcome` and `scores` only. Asserted in
  `pipeline/tests/test_lock.py:55,58` as well as checked by hand here.
- **`LOCKDAY.md` written at the repo root**, correcting two things that would
  have failed on the day: (1) `lock.py` takes positional args, there is no
  `--name` flag; (2) the call card cannot flip to locked styling without
  repointing `PREDICTION_FILE` at `index.html:465`, which still hardcodes
  `dryrun-2026-07.json` - the manual step anticipated in the 2026-07-11 call
  card entry. It also states the narrow exception to "lock files are never
  modified": Thursday's `score_outcomes` run fills `outcome` and `scores`, the
  two fields the schema leaves null for that purpose, and nothing else - which
  is why the `lock-2026-07` tag is pushed on Tuesday, before the announcement.
- **`data/track_record.json` deliberately NOT rebuilt in this session.**
  Regenerating it would add the rehearsal row to the live site's Track record
  table, a public-facing change nobody asked for on a rehearsal day. Tuesday's
  runbook step 7 rebuilds it as part of the real lock, which sweeps the
  rehearsal row in then, correctly badged.

## 2026-07-28 — placeholder episode removed from the published site

- **`site/annotations/2021-11-the-hold-that-wasnt.md` deleted.** It was the
  single placeholder episode created with the annotations machinery on
  2026-07-12, body `TODO(Jake): write this episode in your own words`. With a
  real locked call now on the site, a published TODO addressed to the
  maintainer is not something a stranger should read. `data/annotations.json`
  rebuilt: 0 episodes. No episode text was written to replace it - all episode
  text is Jake's, per the 2026-07-12 entry.
- **Episodes section keeps its empty state rather than being hidden.**
  `renderEpisodes()`'s existing zero-episode branch text changed from "No
  episodes published yet." to **"First episode: 30 July 2026."**, matching the
  Track record section's "First pre-registered call:" convention - a forward
  commitment with a date attached, not an apology for missing content. The
  section stays rendered; verified by feeding the site's own unmodified
  `renderEpisodes()` the real 0-episode `annotations.json` in a browser.
- **Site layer only.** No science-layer file, no data schema, and nothing under
  `data/predictions/` was touched; `lock-2026-07.json` is unmodified. 107/107
  tests green (the annotations contract test iterates episodes, so an empty
  list passes without a test change).
- **Placeholder inventory taken, nothing rewritten.** 9 `DRAFT` markers across
  `index.html` and `methodology.html` catalogued for Jake to draft replacements
  himself. Two things the inventory turned up, recorded because they are
  reader-visible on a live site: the Results section carries a visible
  `[DRAFT - Jake to rewrite this paragraph... Placeholder framing:]` block
  directly above the headline ladder table (`index.html:375`), and
  `methodology.html` renders five visible "DRAFT - JF TO REVISE" badges, one
  per section. A case-sensitive `grep DRAFT` does not match those five badges
  (their text is "Draft"); they were found via `draft-note`. Left in place per
  instruction - they are Jake's to write.
- **Deployment note, not a decision:** GitHub Pages had not rebuilt for the
  lock commit `2726581` (pushed 19:19Z) as of 19:30Z - the live site was still
  serving `5019698`, with `lock-2026-07.json` returning 404 and the card
  reading DRY RUN. No `pages-build-deployment` run exists for that push, while
  every earlier push to `main` has one. Recorded here so the gap between "lock
  pushed" and "lock visible" is on the record.

## 2026-07-29 — Results framing: author's text; Pages fallback in LOCKDAY

- **The Results section's framing paragraph is now Jake's own prose, published
  verbatim.** It replaces the placeholder that had been visible on the live site
  above the ladder table (`index.html:375`, flagged HIGH in the 2026-07-28
  inventory). The text was supplied by Jake and inserted **without editing,
  expansion, or rewording** - the only changes are house-style HTML entities
  (`&mdash;`, `&minus;`) so the rendered characters match the source exactly.
  The `<em>` wrapper and the `[...]` brackets that gave it draft treatment are
  gone; the `.results-framing` block styling (serif, accent left border) is
  unchanged, so it reads as finished prose.
- **Every figure in that paragraph was cross-checked against
  `data/ladder_v1.json` before publishing, and all of them hold**: evaluation
  from 1 January 2019; 60 scheduled meetings with the 2 specials reported
  separately; `L3.skill_vs_l1 = -0.6729`; and no model beating L1 (L2 -0.1171,
  L3 -0.6729, L4 -0.8166). Nothing in the ladder data was recomputed or
  touched - this was a read-only check of a claim before it went on a live page.
- **"Remove the surrounding DRAFT comment" had no target.** There is no DRAFT
  HTML comment adjacent to that paragraph; the nearest comment is the structural
  `<!-- 3. Results -->` section label. The two DRAFT comments elsewhere in the
  Results section (`index.html:391`, `:409`) govern the ladder and Spec 3
  captions, which are still draft and were explicitly reserved for Jake, so they
  were left in place rather than swept up. 13 draft markers remain.
- **`site/annotations/.gitkeep` added.** Deleting the placeholder episode on
  2026-07-28 emptied the directory, and git does not track empty directories -
  a fresh clone would not have had `site/annotations/` at all, so the documented
  "drop a new .md file in site/annotations/" workflow would have needed an
  undocumented `mkdir` first.
- **LOCKDAY.md gains a Thursday step 6b: the empty-commit Pages fallback.**
  Recorded because it is a real failure this project hit, not a hypothetical:
  the 28 July lock commit pushed cleanly but GitHub Pages created no
  `pages build and deployment` run for it, and the locked call was invisible on
  the deployed site for about an hour while the page still read DRY RUN. The
  fallback is `git commit --allow-empty` - it changes no files, so it cannot
  touch the locked prediction, and it re-triggers a Pages build.

## 2026-07-29 — design pass: typography, progressive disclosure, call card

Presentation only. No science-layer file, no data schema, and nothing under
`data/predictions/` was touched; `lock-2026-07.json` is byte-identical.
107/107 tests green (no test reads HTML structure - the contract tests check
JSON fields, and every field the site reads is unchanged).

- **No prose was deleted or reworded, and this was verified mechanically, not
  asserted.** A scratch script parsed both HTML files at HEAD and in the working
  tree, collected the multiset of character-data segments between tags, and
  diffed them: **0 segments missing** from either page. Every addition is
  accounted for - 6 plain-language summaries, 8 "More detail" toggle labels, 2
  screen-reader table captions, and 2 skip links. Element boundaries, not
  sentence boundaries, were used for the comparison, because inserting new
  markup around existing prose otherwise registers as a false deletion.
- **All added prose carries `<!-- DRAFT: JF to revise -->`** (index.html now has
  8 markers, methodology.html 10). The two exceptions are the "Skip to content"
  and "More detail" strings, which are interface affordances rather than prose;
  flagged here so the choice is Jake's to overturn.
- **One type scale and one spacing scale, declared as custom properties in
  `:root` on both pages** (`--fs-micro` 11px through `--fs-display` 46px, a 1.25
  modular scale rounded to whole pixels; `--sp-1` 4px through `--sp-7` 56px).
  Every size in both stylesheets now references a token instead of a literal, so
  the mobile breakpoints re-declare the tokens once rather than overriding
  twenty rules. Prose measure capped at `--measure: 70ch`; page shell widened
  760px -> 800px to suit it. Tabular figures applied to every table via a
  blanket `table { font-variant-numeric: tabular-nums }`.
- **Progressive disclosure uses native `<details>/<summary>`, not JavaScript** -
  keyboard-operable and screen-reader-announced for free, and it degrades to
  plain visible content if scripting fails. Applied to the context panel, the
  ladder, Spec 3, and all five methodology sections (8 expanders).
- **Deviation, deliberate and reversible: the ladder table stays visible rather
  than going inside its expander.** The brief said the technical content is
  layered under the summary; taken literally that buries the results table,
  which is the section's whole point and the project's headline null result. The
  expander holds the apparatus instead - the n / specials / log-score-floor line
  and the standing L1 caveat. Spec 3 follows the brief exactly (coefficients and
  p-values inside the expander), so the two are not quite symmetrical. Flipping
  the ladder to match is a one-line move of the `<div class="table-scroll">`.
- **The existing "In plain English:" captions were promoted, not duplicated.**
  The ladder and Spec 3 already had one-sentence plain summaries sitting *below*
  their technical content; they were moved above it and restyled as
  `.plain-summary`, rather than writing new summaries alongside them. Only the
  context panel and the five methodology sections needed new ones written.
- **The call card's lock timestamp links to the git tag, derived from the
  prediction filename rather than hardcoded**: `data/predictions/lock-2026-07.json`
  -> `.../tree/lock-2026-07`, following the same filename convention
  `build_track_record.py` already uses to classify a file as locked. The link is
  rendered only when the filename starts with `lock-`, so a dry run or rehearsal
  never claims a tag that does not exist. Probabilities became the visual
  centrepiece (46px tabular figures, the modal outcome in accent gold, a stacked
  proportion bar beneath); the rationale moved out of `.fine` grey sans and into
  17px serif at the 70ch measure, under a "Point call" header.
- **Chart is redrawn on resize rather than scaled.** The viewBox was fixed at
  700 units wide, so on a 380px phone every axis label was scaled to roughly 5px.
  `chartMetrics()` now sizes the viewBox to the container's actual pixel width
  (300-760) and picks a 12px axis face below 460px, and a debounced `resize`
  listener redraws. Handlers are assigned as properties (`svg.onpointermove`)
  rather than with `addEventListener`, because the same node is redrawn
  repeatedly and listeners would otherwise accumulate on every resize.
  `pointermove` replaces `mousemove` so a finger drag reads the series. Axes
  gained explicit hairlines with `shape-rendering: crispEdges` and left ticks;
  year labels are now skipped when they would collide with the previous one
  (2016 drops out at desktop width, alternate years at 380px) instead of
  overprinting.
- **Accessibility, and one token changed to get it**: `--faint` moved
  `#6b7280` -> `#868d99`, taking it from 3.4:1 to 5.2:1 against `--panel` -
  the old value failed WCAG AA for body text and is used for every "as of" and
  footnote line on the site. Added: a visible `:focus-visible` ring on every
  interactive element, skip links, a `<main>` landmark, `<h3>` elements in place
  of `<p class="subhead">`/`<p class="ctx-h">` so the heading outline is real,
  `scope="col"` and visually-hidden `<caption>`s on both tables, `role="region"`
  with a label on the horizontally-scrolling table wrappers, `role="img"` plus
  `<title>`/`<desc>` on the charts, and a `prefers-reduced-motion` guard. The
  main chart's `<desc>` is generated from the same `docs` array the line is
  drawn from (count, date range, latest, highest, lowest), so it cannot drift
  from the picture.
- **Verified in a real browser at 1280px and 380px**, and screenshotted at both.
  At 380px `document.scrollWidth` equals the viewport width - the only element
  wider than the screen is the ladder table, which scrolls inside its own
  `overflow-x` container by design. Note for future screenshotting: headless
  Chrome clamps its window to a 500px minimum width, so a 380px shot has to be
  taken through a fixed-width iframe pinned flush-left, or the capture silently
  crops a wider layout and looks broken.

## 2026-07-30 — audit fixes: failure states, verification path, metadata

Presentation and robustness only. No science-layer file, no data schema, and
nothing under `data/predictions/` was touched; `lock-2026-07.json` is
byte-identical. 107 -> 115 tests, all green (8 new, all in one new file).
Jake's authored Results paragraph and the methodology specification prose were
not reworded; the one exception is the meeting-schedule sentence, corrected
against the Bank's own statement under a standing instruction to do so (below).

- **Every JS-loaded section now fails visibly, and cannot sit on "Loading..."**
  A shared `fetchJSON(path)` wraps every fetch in an `AbortController` with an
  8-second budget, and a shared `failSection()` renders one house-style error
  block naming the file, the reason (`HTTP 404`, `no response within 8 seconds`,
  the browser's own message) and a link to that file on GitHub so the reader can
  still get the numbers. Applied to all eight: call card, latest reading, chart,
  context panel, ladder, Spec 3, track record, episodes.
- **One real dead state was found by testing, not by reading.** The context
  panel was resolved inside the same `Promise.all` as `data/index.json`, so a
  failure of the *index* file skipped the context branch entirely and left that
  section reading "Loading..." for ever - the exact defect this task set out to
  remove. The context fetch now has its own `.then/.catch` chain and the
  `Promise.all` only feeds the chart, whose Bank Rate overlay is optional.
- **The timeout was verified against a real hung request, not a stub.** A first
  attempt stubbed `window.fetch` with a promise that never settles; it never
  aborted, because a stub ignores the abort signal that a real fetch honours -
  the test was measuring the stub, not the code. Re-run against a local server
  that sleeps 60s on `data/ladder_v1.json`: the section failed at 8s with
  "no response within 8 seconds" and the built-in table stayed on screen.
- **Progressive enhancement: the ladder table and the locked call now ship in
  the static HTML.** Both were generated from `data/ladder_v1.json` and
  `data/predictions/lock-2026-07.json` by a scratch script and pasted in - no
  figure was retyped - and both are wrapped in `<!-- fallback:NAME -->` markers.
  `renderLadder()` and `renderCallCard()` overwrite them on success;
  `renderLadder()` gained a `tbody.innerHTML = ''` it did not have, without
  which the fetched rows appended to the fallback rows and the table rendered
  ten rows deep (caught in a browser, not in review).
- **`pipeline/tests/test_static_fallback.py` (8 tests) regenerates every
  fallback string from the JSON and asserts it appears in the markup**, using
  the same formatting rules the JS uses (`toFixed`, `toUTCString`, the en-GB
  date format). The rationale is compared character-for-character after undoing
  the house-style entities, so a fallback that quietly paraphrased Jake's prose
  would fail. It also asserts no `fetch(` bypasses the timeout helper and that
  every status element has a `failSection` call.
- **The verification path is now a block on the call card, not a footnote.**
  The lock timestamp links to `/releases/tag/lock-2026-07` (was `/tree/`), and a
  bordered `.call-verify` block states how a reader checks it: open the tag page,
  which GitHub dates independently of anything in this repository, or run
  `git show lock-2026-07:data/predictions/lock-2026-07.json`. It is rebuilt from
  the prediction filename and **hidden outright when the file is not a `lock-*`**,
  so a dry run can never invite a reader to check a tag that does not exist.
- **CORRECTION, sourced to the Bank: the move to eight meetings a year took
  effect in 2016, not 2017.** methodology.html said "monthly through 2015-2016
  and moved to eight per year from 2017". The Bank's own news release
  *Confirmation of changes to the Monetary Policy Committee meeting schedule*
  (9 May 2016) is headed "We have changed the schedule of Monetary Policy
  Committee meetings from September 2016" and states that the meeting ending
  13 October 2016 "will be the first to be dropped under the new arrangements";
  the earlier release of 24 September 2015 sets out the same plan in advance.
  The two sources agree - no conflict, so no HARD STOP. The corpus agrees too:
  11 documents for 2016 (October absent) and 8 for 2017. The sentence now dates
  the change to 2016, notes 2017 as the first full calendar year with eight, and
  links both Bank releases. **The 2026-07-11 era-corpus entry carries the same
  error in its own wording and has been left exactly as written** - this log is
  forward-only, and this entry is the correction of record.
- **A "why the sample sizes differ" note explains all five n's** (94 / 62 / 60 /
  91 / 23), placed under the ladder table where a reader first meets one, with
  the fuller version as its own always-visible card on methodology.html. It was
  first written inside that page's Data disclosure and moved out on noticing
  that `#sample-sizes` would otherwise link into collapsed content. The 91 is
  derived, not asserted: `data/surprises.csv` holds 91 rows because
  `build_surprises.py` excludes the 2 specials and August 2015 has no preceding
  decision to difference against, and `load_surprises_with_lags()` drops nothing
  further. **No rationale was invented for the 1 January 2019 evaluation start** -
  the ladder entry does not give one, so the note says only what is true, that
  everything earlier is training data.
- **Chart: tap now works on touch.** `pointerdown` reads the series on a finger
  tap and the tooltip stays up afterwards (a `touched` flag suppresses the
  synthetic `pointerleave` some browsers fire straight after a tap); a tap
  elsewhere or any scroll dismisses it. Hint text is now "Hover or tap the line
  for details". A hybrid-device bug was caught while testing: `touched` was only
  cleared on `pointerdown`, so after one tap a mouse-out stopped dismissing the
  tip - a non-touch `pointermove` now clears it too.
- **Track record: rehearsals and dry runs are behind a default-off toggle**,
  labelled with how many are hidden ("Show rehearsals and dry runs (3)").
  Filtering is by the existing `kind-locked` class, so **a locked row can never
  be hidden** by this control, whatever else the file gains.
- **`og-image.png`, 1200x630, drawn from `data/index.json` at build time** by
  the new `pipeline/build_og_image.py` (additive, read-only, Pillow) - the real
  series, so a share card cannot show a shape the page does not. `og:image` and
  `twitter:card` meta added to both pages. Pillow is now in requirements.txt.
  The script prefers Georgia/Arial if present and falls back to Pillow's own
  scalable default, so a rebuild on another machine may substitute fonts; that
  is cosmetic, and recorded here rather than left to surprise someone.
- **"Last updated" comes from `git log -1`, via `pipeline/build_build_info.py`
  -> `data/build_info.json`.** Ordering matters and is written into the script's
  docstring: commit the content, run the script, then commit `build_info.json`
  alone. That second commit changes no content, so the stamp names the commit
  the reader is actually looking at. index.html refreshes the stamp by fetch;
  methodology.html runs no JavaScript by design, so its stamp is static - and is
  asserted against the JSON by the fallback test rather than trusted.
- **Methodology citations now name the entry, not just the date.** 23 citations
  were retitled; `2026-07-11` alone matches 25 entries, so each bare date was
  resolved by reading the entries rather than guessed - e.g. the
  `assert_curve_is_fresh` citation resolves to *curve freshness fix*, which is
  where that assertion is introduced, not to *lock and scoring machinery*.
- **Terminology unified to "call"** in the site's own chrome (badge, table
  caption and region labels, track-record framing, the ladder plain-summary,
  the "no prediction file" status). "Forecast" is left wherever it is
  technically the right word - the ladder's five forecasters, "pure forecasts"
  in Limitations - and **Jake's authored Results paragraph is untouched**.
- **New prose carries `<!-- DRAFT: JF to revise -->`** (index.html 11 markers,
  methodology.html 12), and the new methodology card carries the same visible
  "Draft - JF to revise" badge as the other five. The deliberate exceptions are
  the failure-state strings and the toggle label, which are interface
  affordances rather than prose, on the same reasoning as "More detail" and
  "Skip to content" in the 2026-07-29 entry.
- **Screenshot note, correcting the 2026-07-29 one:** this Chrome renders a
  `--window-size=390` headless window at a true 390px, but the capture is still
  a crop of a wider layout - the first 390px shot showed sentences running off
  the right edge. The fixed-width-iframe workaround recorded on 2026-07-29 is
  still required; it produced a clean 390px capture with no horizontal overflow.
  Verified at 1280px and 390px on both pages.

## 2026-08-05 — site polish: fallbacks, drafts cleared, typography

Presentation and robustness only. No science-layer file, no data schema, and
nothing under `data/predictions/` was touched; `lock-2026-07.json` is
byte-identical. 115 -> 121 tests, all green.

- **The reported staleness was a browser cache, not a broken deploy - except
  for one line, which was genuinely stale.** Checked before changing anything:
  `origin/main` and local were both at `fa5428e`; the outcome commit
  (`5e9ce52`) and episode commit (`c2b34ae`) were pushed; and Pages had built
  **successfully** for `fa5428e` at 12:42Z. Fetching the live page confirmed it
  was byte-identical to `HEAD:index.html`, with `annotations.json` carrying the
  episode and `track_record.json` the scored row. Loading it in a browser
  showed every status element already at `display:none`, no "Loading..."
  anywhere in `innerText`, the episode rendered and the locked row reading
  hold / 0.0030. **The one thing that was really stale was the footer stamp**,
  still naming `a750062`: `build_build_info.py` had not been re-run after the
  outcome and episode commits, so `data/build_info.json` still described the
  commit before them. Regenerated as part of this session's stamp commit.
  Recorded plainly because "the site is stale" was a reasonable read of a
  footer that was, in fact, wrong.
- **Track record and Spec 3 now ship static fallbacks, like the ladder.** Both
  generated from `data/track_record.json` and `data/inference_v1.json` by the
  same scratch generator that produces the other blocks - no figure was
  retyped - and both wrapped in `<!-- fallback:NAME -->` markers with the
  status/content default visibility flipped so the content shows and the
  status hides. 6 new tests assert every figure against the JSON.
- **The static track table carries locked rows only, deliberately.** The
  show-rehearsals toggle is JavaScript; with scripting off it cannot hide
  anything, so shipping the rehearsal rows statically would contradict the
  default-off promise the toggle makes. `renderTrackRecord()` rebuilds the
  full table and reveals the toggle on success. A test asserts no
  `kind-dryrun` or `kind-rehearsal` row appears in the static block.
- **The call card distinguishes a scored past call from an upcoming one.**
  `scored` is true only when the locked file has both an `outcome` and a
  `scores.m0_market_only.brier_score` - the two fields `score_outcomes.py` is
  allowed to write. When scored: the badge reads `LOCKED CALL · SCORED`, the
  heading changes from "Next announcement" (wrong the morning after the
  announcement it named) to **"Call for 30 July 2026"**, and a new block shows
  outcome `hold`, Brier `0.0030`, and whether the point call `matched`. The
  match is derived by comparing `point_call` to `outcome`, not asserted.
- **"Next announcement" is read from the Bank's calendar, never hardcoded.**
  The next meeting is the first date in `site_context.json`'s `ois_path.meetings`
  after the displayed call's own meeting - 17 September 2026. The line is
  hidden while the call's own meeting is still ahead (the heading already names
  it), and if `site_context.json` fails to load the static line is left alone
  rather than blanked. If the calendar ever runs out, the card says so instead
  of inventing a date.
- **The five methodology sections Jake signed off lost their draft markers; a
  sixth was deliberately left.** Data, Index construction, Market benchmark,
  Evaluation and Limitations lost 5 visible badges and 11 governing comments.
  The **"Why the sample sizes differ"** card still carries its badge: it was
  added on 2026-07-30 and is not one of the five sections the sign-off covered.
  Flagged for Jake rather than swept up with the rest.
- **All 8 `<!-- DRAFT: JF to revise -->` comments removed from index.html, with
  the no-prose-changed claim verified mechanically** rather than asserted: the
  multiset of character-data segments between tags was compared before and
  after, with comments and script/style stripped. **0 segments lost, 0 added** -
  the removals were comments only, as intended.
- **One reader-visible draft marker remains in the whole repo**, and it is the
  sample-sizes badge above. The `TODO(Jake)` strings in
  `data/predictions/dryrun-*.json` and `rehearsal-*.json` are **not** reader
  visible: the site renders `rationale` only for `PREDICTION_FILE`, which is the
  locked file. They are also immutable by project rule and deliberate by design
  - `rehearsal-2026-07-26.json`'s own `_rehearsal` note explains the placeholder.
  `pipeline/predict/lock.py:108` is the frozen source of that placeholder.
- **Typography: 31 literal font sizes snapped onto the existing scale** (28 in
  index.html, 3 in methodology.html), introducing no new sizes - the point was
  to shrink the vocabulary, not extend it. Off-scale values (10, 15, 16, 21, 32,
  34px) went to the nearest token. The 2026-07-29 entry's claim that "every size
  in both stylesheets now references a token" was not true of the context panel,
  the episodes block, or the breakpoint overrides; it is true now.
- **The mobile breakpoints now change tokens, not rules.** Seven per-rule
  `font-size` overrides that invented off-scale sizes were deleted and
  `--fs-display` retuned instead (36 -> 34px at 640px, 30 -> 27px at 430px), so
  the call-card figures and the index reading track one scale at every width.
- **The rationale is typeset as an argument, not a caption**: its own 66ch
  measure, 1.75 leading, `text-wrap: pretty`, and an accent left rule matching
  the `.results-framing` idiom already on the page. No new colours. The text
  itself is untouched - it is Jake's, and it is rendered from the locked file
  with only house-style entity substitution.
- **The lock timestamp now reads in the site's date format**, "28 July 2026,
  19:08:36 UTC", via a new `fmtUTCStamp()`. `toUTCString()`'s
  "Tue, 28 Jul 2026 19:08:36 GMT" was the only date on either page in a
  different style. Precision is unchanged and the machine-readable
  `datetime` attribute still carries the raw ISO instant.
- **Terminology checked, nothing left to change.** Every remaining "forecast"
  is either technically required (the ladder's five forecasters; "pure
  forecasts" in Limitations; "could not have pre-registered a forecast") or
  sits inside Jake's authored Results paragraph, which was not touched.

## 2026-08-10 — July 2026 ingest: corpus to 95, results republished

Routine ingest. **No methodology changed**: the lexicon, the scoring rules, the
ladder specifications and the inference specifications are untouched, and
`lock-2026-07.json` is byte-identical. What changed is the sample the frozen
methods run over. 121/121 tests green.

- **Scraped `2026-07-minutes.txt`** (meeting ending 29 July, announced 30 July)
  via the existing scraper: 4,039 words, `source_kind: html`, decision "maintain
  Bank Rate at 3.75%", vote 6-3.
- **The word count was below the corpus Q1 (4,811), so the parse was checked
  rather than waved through.** It is complete: minute paragraphs run 1-20 with
  no gaps and end at the standard membership list (nine members, Treasury
  representative, Court observer). The short length is the current house style,
  not truncation - 2025-11 has 21 paragraphs, 2026-04 has 21, 2026-02 has 22,
  against a corpus median of 46. No HARD STOP.
- **A hardcoded era window blocked the ingest and had to be bumped.**
  `build_votes.ERA_END` was `2026-07-01` (exclusive), which silently dropped the
  30 July meeting from `votes.csv` even though the Bank's spreadsheet contained
  it - the first rebuild produced 94 meetings and no error. `scrape/era.py` had
  the matching `END = (2026, 6)`. Both bumped one month. The same window was
  also written out a second time as string literals inside
  `reconcile_against_corpus`; that now derives from the module constants, since
  two copies of one window is exactly how this drifts. **This is a window
  extension, not a change to any parsing or scoring rule** - but it is a code
  change on an ingest, recorded here because it will need doing every month
  until the window is derived rather than declared.
- **Every rebuild was diffed before being accepted, and all four were purely
  additive**: `index.json` 94 -> 95 documents with **0 existing documents
  changed**; `votes.csv` 94 -> 95 meetings, 842 -> 851 rows, **0 existing rows
  changed**; `market_history.csv` 94 -> 95, **0 existing rows changed**;
  `surprises.csv` 91 -> 92, **0 existing rows changed**.
- **July's A&BG reading is 0.6667** - on the dovish side of the 1.0 neutral,
  down 1.0476 from June's 1.7143 and 0.3869 below the trailing 4-document mean
  of 1.0536. It reads dovish in the same month the hawkish minority grew to
  three, which is the divergence the 30 July episode predicted. **Recorded with
  its own caveat: the reading rests on three lexicon hits in total** (1 hawkish,
  2 dovish). That is ordinary for this corpus - the median document has 2 hits -
  and it is exactly the sparsity the Limitations section already flags. A single
  hit either way would move the number substantially. The episode's prediction
  held; the evidence for it is thin, and saying so is not a hedge.
- **Results republished on 95 documents. The finding is unchanged.** Ladder
  n_scheduled 60 -> 61; every Brier improves slightly (July was a well-predicted
  hold); skill against L1 essentially static - L2 -0.1171 -> -0.1167, L3
  -0.6729 -> -0.6712, L4 -0.8166 -> -0.8148. **No text-augmented model beats
  market pricing.** Spec 3 n 91 -> 92, p **0.0316 -> 0.0310** - it does not
  cross 0.05, and moves marginally more significant, not less. Spec 2 stays null
  (p 0.4918 -> 0.4894). The fragility subsample n 23 -> 24 still fails to
  replicate (p 0.1422 -> 0.1221).
- **Lexicon sparsity recomputed rather than re-denominated**: across 95
  documents the median is still 2 hits, Q1 1, Q3 3, min 0, max 12. July's 3 hits
  sit at Q3, so no quartile moved; only the n in the sentence changed.
- **`pipeline/build_fallbacks.py` promoted from a scratch script into the
  repository.** The static fallbacks have to be regenerated after every rebuild
  or `test_static_fallback.py` fails, and a throwaway script is not a workflow.
  While wiring it up, the test caught `#ladder-meta` still reading `n=60`: that
  line sits outside the `fallback:ladder` region and had been missed. It now has
  its own `fallback:laddermeta` region and is generated too.
- **Every reader-facing figure was updated from the data, not by hand**: 6 in
  index.html and 19 in methodology.html (94 -> 95 documents, 62 -> 63 evaluated,
  60 -> 61 scheduled, 91 -> 92 Spec 3, 23 -> 24 fragility, and the corpus end
  June -> July 2026). The "52 of the N documents reconstructed from PDF" claim
  was checked before touching it: 52 is the count of non-special PDF-sourced
  documents and is unchanged, so only its denominator moved. `og-image.png`
  rebuilt from the 95-document series.
- **Not rebuilt, deliberately**: `site_context.json` (context only, and its
  meeting calendar still lists 17 September 2026 correctly),
  `member_behaviour_v1.json`, `validation_v1.json`. Nothing asked for them and
  no published figure depends on them. Flagged so the omission is on the record
  rather than discovered later.

## 2026-08-10 — guard: the build_info stamp can no longer go stale silently

- **`pipeline/tests/test_build_info_fresh.py` added (2 tests, 121 -> 123).**
  The footer's "Site last updated" line is generated data committed to the
  repository, so it degrades silently: on 2026-08-05 it had named `a750062` for
  five days across two content commits, and the site read as a broken deploy
  when Pages was in fact serving the tip of `main` correctly. Diagnosing that
  cost a session. The guard makes the failure loud and local instead.
- **The invariant is `build_info.json names HEAD`, with exactly one
  allowance**: HEAD may be the *stamp commit* for the commit it names - that is,
  HEAD's diff against its parent touches nothing but `data/build_info.json`,
  `index.html` and `methodology.html`. This is the two-step already documented
  in `build_build_info.py` (commit content, run script, commit stamp alone), and
  the allowance is what keeps the stamp pointing at the content commit a reader
  is actually looking at rather than at the commit that only carries the stamp.
- **The deliberate consequence: a content commit is not publishable on its own.**
  Push a content commit without its stamp and CI goes red. That is the intended
  forcing function, and it is why the two commits should always be pushed
  together - Actions runs on the pushed tip, so the intermediate content commit
  is never independently tested.
- **The second test checks the stamp's parts agree with each other**: short sha
  a prefix of the full sha, and the recorded date and subject actually belonging
  to that commit. A stamp assembled from mismatched parts would satisfy the
  first test and still lie to a reader.
- **CI checkout deepened to `fetch-depth: 0`.** The default shallow clone cannot
  resolve `HEAD~1`, so the allowance branch was unverifiable on CI; the test
  skips rather than passes when history is missing, and now history is present.
- **Considered and rejected: regenerating the stamp inside the test run.** Tests
  that write to the working tree hide the problem instead of reporting it, and
  this repository's CI is explicitly read-only ("never rebuilds data, never
  touches data/predictions/"). The guard reports; the human runs one command.

## 2026-08-10 — context layer rebuilt on the 95-document corpus

All three derived context files rebuilt against the July ingest. No science-layer
file, no schema and nothing under `data/predictions/` was touched.

- **`validation_v1.json`**: n 94 -> 95, still a clean 1:1 join, no unmatched
  documents. **Every index-vs-vote correlation weakened slightly.** Pearson:
  level_vs_skew 0.1816 -> 0.1693; level_vs_net_dissents 0.2014 -> 0.1882;
  delta_vs_skew 0.0747 -> 0.0543; delta_vs_net_dissents 0.0618 -> 0.0408.
  Spearman moves the same way throughout. This is the expected direction: July
  is a document whose tone reads dovish while its vote reads hawkish, so it sits
  against the (already weak) positive association and pulls it down. Mean index
  by decision: `hold` 1.0053 -> 1.0005 on n 69 -> 70; `hike` and `cut`
  unchanged. **These are contemporaneous correlations, not predictive ones**, and
  none of them is a published headline figure - the headline null result is the
  ladder and Spec 3, both republished separately.
- **`member_behaviour_v1.json`**: dissent stickiness moved.
  `p_dissent_again_given_dissented` **0.4746 -> 0.4833** (n 118 -> 120);
  `p_dissent_given_with_majority` **0.0942 -> 0.0946** (n 701 -> 708). The
  hawkish-dissent row of the transition matrix firmed: P(hawkish again | hawkish)
  0.4462 -> 0.4627, P(with majority | hawkish) 0.5538 -> 0.5373. The
  dovish-dissent row is **unchanged**, which follows - all three July dissents
  were hawkish. Per-member: Greene 0.2917 -> 0.32 and Pill 0.1538 -> 0.175 rise
  on a repeated hawkish dissent, Mann 0.4103 -> 0.425, and every non-dissenter's
  frequency dilutes by one meeting. **Seeds Stage 4; not a predictor and not
  published as a result.**
- **`site_context.json` would not rebuild at all, and the reason was a stale
  hardcoded date.** `UPCOMING_MEETINGS` still led with 2026-07-30, now past, and
  the frozen `forward_rate_for_date` correctly refuses to read a forward for a
  date behind the curve's own as-of: *"meeting_date 2026-07-30 (+3d) is not after
  curve as_of date 2026-08-07"*. It raised before writing, so the existing file
  was never corrupted. **Fixed by filtering past meetings out of the path at
  runtime** rather than by inventing a replacement date: "upcoming" already meant
  forward-looking, and a forward rate for a past meeting is not a thing that
  exists. The list now shrinks rather than lying, and hard-stops with an
  instruction if it ever empties.
- **Consequence, stated because it is reader-visible: the implied-path panel now
  shows 2 meetings, not 3.** The heading was hardcoded "next 3 meetings" and now
  derives its count from the data. **The third slot is not filled**: the meeting
  after 5 November 2026 is not in this repository and was not guessed. Adding it
  means updating `UPCOMING_MEETINGS` from the Bank's published calendar - Jake's
  call, and a one-line change.
- **The curve has repriced sharply dovish since the 9 July snapshot** the old
  file carried. On the 7 August curve, 17 September prices +2.01bp (p_hike
  0.0805, was 0.3386) and 5 November +11.03bp (p_hike 0.4411, was 0.7255).
  Recorded as an observation only - this file is context, feeds no model, and
  this project has nothing that could adjudicate why.
- **Bank Rate history 94 -> 95 points**, now ending 30 July 2026 at 3.75%.
  2-year gilt 4.1373% (9 July) -> 4.1858% (7 August).
- **A typo in the new heading code was caught by the failure state, not by
  review**: the first version referenced an undefined `c` instead of the
  function's `ctx`, and the panel rendered "Could not load
  data/site_context.json - c is not defined" with a link to the raw JSON,
  instead of silently blanking. That is the 2026-07-30 failure-state work
  earning itself back.

## 2026-08-10 — era windows derived, not declared; LOCKDAY stamp warning

- **`build_votes.py`'s hardcoded era constants are gone.** `corpus_window()`
  derives the filter from `data/index.json` - start = earliest published date,
  end = latest + 1 day, exclusive. The voting sheet is now filtered *to the
  corpus*, which makes the 2026-08-10 failure impossible by construction: a
  meeting in the corpus cannot fall outside a window defined by the corpus.
  **`votes.csv` is byte-identical after the change** (checked, not assumed), so
  no existing result moved.
- **A missing `index.json` is now a hard stop**, not a fallback to some default
  window. Falling back is exactly how the original bug shipped: a plausible
  meeting count and a zero exit code.
- **`scrape/era.py`'s `END` derives from the clock, not the corpus.** The
  scraper's job is to *extend* the corpus, so deriving its end from the corpus
  would be circular; it now probes through the current month and leans on the
  404 tolerance it already had for months with no meeting.
- **New `pipeline/tests/test_votes_window.py` (4 tests, 123 -> 127.)** Three run
  anywhere: the derived window covers every published corpus document; it is
  tight to the corpus on a synthetic index; a missing index hard-stops. The
  fourth is the alarm Jake asked for - **it fails if the Bank's sheet carries a
  meeting at or after the corpus end**, meaning minutes are waiting to be
  scraped. It **skips when `mpcvoting.xlsx` is absent**, since `data/raw/` is
  gitignored and CI has no copy - same convention as `test_inspect.py`. Stated
  plainly because a skipped guard is not a guard on CI; it is a local one.
- **Expect that fourth test to fire in September** the moment the Bank publishes
  the 17 September votes and before the minutes are scraped. That is the intended
  signal, not a defect.
- **`test_votes.py` updated for the new `parse_meetings` signature** - the window
  is passed in rather than read from a module constant. The synthetic sample
  keeps its 1998 row and still filters it out.
- **LOCKDAY.md now warns about the stamp commit in three places**: a fourth item
  in the "read this before you start" list, Tuesday step **11b** (placed *after*
  the tag, with an explicit warning that stamping first would move the tag onto
  the stamp commit and break the timestamp evidence), and Thursday step 6, which
  is now "commit, stamp, then push" with the commands split out. Written for
  someone reading under time pressure, and it names the consequence - CI fails -
  rather than just the rule.

## 2026-08-10 — MPC calendar transcribed from the Bank; last draft badge cleared

- **`UPCOMING_MEETINGS` replaced with the Bank's full published calendar**,
  read from
  <https://www.bankofengland.co.uk/monetary-policy/upcoming-mpc-dates>
  (that page's own "last updated" line read **26 May 2026**). It had held three
  dates, one of which had already happened; the panel had been down to two
  meetings since the 2026-08-10 context rebuild, with the December slot empty
  because the date was not in this repository and was not going to be guessed.
- **Transcribed, then checked three ways rather than trusted.** (a) Every date
  falls on the Thursday the Bank prints beside it - verified in code, all 16.
  (b) The five 2026 dates already in the past match `data/index.json`'s own
  `published` dates exactly, which is an independent check, since those came
  from scraping the minutes pages months apart from this transcription. (c) The
  page's own "Next due: 17 September 2026" agrees with the first future date.
- **The Bank's confirmed/provisional split is preserved, not flattened.** 2026
  is published as CONFIRMED and 2027 as PROVISIONAL; the constants are
  `MEETINGS_2026_CONFIRMED` and `MEETINGS_2027_PROVISIONAL`, concatenated into
  `UPCOMING_MEETINGS`. Collapsing them would launder a provisional date into a
  firm one, which is the kind of quiet upgrade this log exists to prevent.
- **The implied-path panel still prices only the next 3 meetings**, via a new
  `OIS_PATH_MEETINGS = 3`. `forward_rate_for_date` clips to the longest maturity
  the curve carries, so pricing all sixteen published dates out to December 2027
  would fill the panel with rows that look like data but are the curve's
  endpoint repeated. The calendar is now long enough that the list cannot run
  out again; the panel's scope is unchanged.
- **Rebuild is purely additive**: the panel returns to three rows - 17 Sep, 5 Nov,
  17 Dec 2026 - with the September and November figures byte-identical to the
  previous build (same 7 August curve), and `bank_rate_history` and `gilt_2y`
  untouched. December prices +19.80bp, p_hike 0.7919, on that same curve.
- **The last reader-visible draft badge is gone.** The "Why the sample sizes
  differ" card on methodology.html was written on 2026-07-30 and sat outside the
  five-section sign-off of 2026-08-05; Jake has now signed it off. The badge and
  its governing comment were removed and the change verified mechanically -
  comparing the multiset of text segments before and after, the only segment
  removed is the badge's own text and nothing was added. **No draft marker of
  any kind now remains in either page.**
- **The `.draft-note` CSS rule is deliberately left in place** although nothing
  uses it. It is the project's established device for marking a section draft,
  and keeping the rule means a future one costs a single `<span>` rather than
  re-deriving the styling.

## 2026-08-30 — presentation and consistency pass: every figure generated

Presentation only. **No model, no specification and no recomputation**: the
lexicon, the scoring rules, the ladder and inference specifications and every
file under `data/` are untouched, `lock-2026-07.json` is byte-identical, and no
number on either page changed except where it had drifted from the file it
came from. 127 -> 135 tests, all green.

- **methodology.html was a meeting behind index.html, and nothing could have
  caught it.** The July ingest (2026-08-10) updated 19 figures on that page by
  hand and missed six: 94 documents, 62 evaluated, 60 scheduled, Spec 3 n=91,
  fragility n=23, and the fragility p at 0.1422. All six are now correct - 95,
  63, 61, 92, 24, 0.1221 - **and none of them was retyped**. The fix is the
  mechanism, not the values.
- **Two more stale figures turned up that the brief did not name**, both on
  methodology.html and both plausible enough to have survived three readings:
  the corpus was described as "**92** from the regular meeting cycle plus 2
  special", which was the pre-July count (it is 93), and the ordered-logit
  fallbacks as "11 of **62** L3 windows", which was the pre-July window count
  (it is 63). Recorded because they are the argument for the guard: a stale
  number that reads plausibly is invisible to review.
- **New `pipeline/site_figures.py` is the single source of truth for every
  reader-facing number on both pages.** It computes 45 named figures from
  `data/index.json`, `data/ladder_v1.json`, `data/inference_v1.json` and
  `data/validation_v1.json`, plus the frozen specification constants, imported
  read-only from `pipeline/predict`, `pipeline/market`, `pipeline/ladder` and
  `pipeline/inference` (`ASSUMED_MOVE_BP`, `LOCK_OFFSET_DAYS`,
  `SIMULATION_TRIALS`, `SIMULATION_SEED`, `MIN_TRAINING_EXAMPLES`, and the
  rest). Constants that were previously prose are now quoted from the code that
  defines them, so a change to the specification cannot leave the page behind.
- **`pipeline/build_fallbacks.py` now writes both pages**, and writes two kinds
  of region: the existing whole-block `<!-- fallback:NAME -->` fallbacks, and a
  new inline `<!-- fig:NAME -->` for a figure sitting inside a sentence. The
  sentence stays the author's; the number in it is the data's. methodology.html
  runs no JavaScript at all, so on that page every number is now a `fig` region
  or it is not a figure.
- **The guard is a census, not a spot check** (`pipeline/tests/test_site_figures.py`,
  8 tests). Beyond asserting every `fig` region against its source, it strips
  the generated regions out of both pages and requires that **every remaining
  digit in reader-visible text** is accounted for by name: either an identifier
  that merely contains one (`L3`, `Spec 2`, `SHA-256`, a dated log reference)
  or an entry on an allowlist of literals that are not figures - a citation
  year, a scale endpoint, the Bank's own meeting-schedule history - each with a
  written reason. Adding a hardcoded number to either page fails the suite
  until it is either generated or justified. A further test fails on a **stale
  allowlist entry**, because an allowlist that stops matching stops guarding.
  Both directions were checked by breaking the pages on purpose before they
  were trusted.
- **Rounding: coefficients and t-statistics to 2 decimal places, p-values to
  4.** `-2.148858` asserts a precision an estimate with p = 0.03 does not have.
  Full precision stays in `data/inference_v1.json`, unchanged, and the sentence
  now names that file rather than implying the page is the record. The same
  rounding is implemented once in `site_figures.py` and mirrored in
  `renderInference()`, so the fetched and built-in versions of the line agree.
- **The front page no longer contradicts itself.** Its Results prose said L3
  scored -0.6729 while the table beside it said -0.6712 (the pre-July value);
  the prose is now generated from the same file as the table. The Spec 2
  p-value differs between the Results section (0.4894) and the call card
  (0.4918) **and that difference is correct and has been left alone**: the card
  reproduces a locked file, which is never edited. What the card now carries is
  a line saying so - *"Figures as at the lock date (28 July 2026)."* - generated
  from the locked file's own timestamp. **The rationale itself was not touched.**
- **A static/JS disagreement was found while regenerating the call card:** the
  built-in fallback read "25.0bp" where the JavaScript rendered "25bp", because
  Python and JavaScript format `25.0` differently. Both now read `25bp`
  (`:g`), and the contract test asserts the same form.
- **Content added, all of it presentation of existing material:** a three-bullet
  summary at the head of the page (what was tested / found / uncertain); a
  consolidated **How to check this** box carrying the tag, the `git show`
  command and the repository link, generated from the prediction file on
  display; one-line model glosses in the ladder's Model column (L0 always-hold
  through L4 member simulation) and on the card's m0; a collapsed seven-term
  glossary; the "In plain English" device extended to the call card and the
  market panel; an affiliation line in both footers; and the July miss stated
  next to the track record with a link to the episode.
- **The verification note moved rather than being duplicated.** It used to sit
  inside the call card; it is now the "How to check this" box, and the card
  keeps only the tag as a citation. The dead `.call-verify` CSS was removed
  with the element - unlike `.draft-note`, it was not a reusable device.
- **Four new static fallbacks - latest reading, chart, market panel, episodes -
  bring the whole page up to the ladder's standard.** The chart is the
  interesting case: an SVG line chart cannot be drawn without JavaScript, so
  its honest static state is not an empty box but the same series in words
  (n, span, latest, low and high, each generated). The episodes fallback
  re-implements `renderMarkdown()`'s small Markdown subset in Python; the two
  are kept deliberately literal so they agree.
- **The Limitations list was reordered and gained an entry.** Sparse lexicon
  hits is now first, because it constrains everything below it. A new
  **"Forward interpolation across whole-month buckets"** entry records, as a
  standing property of the method, the effect the 30 July rationale raised
  about one meeting: a forward read at meeting + 3 days, interpolated across
  whole-month buckets on a steeply sloped short curve, absorbs the following
  meeting's expectations. **This is an addition, not a move** - the instruction
  was to move it out of the July rationale, and the July rationale is a locked
  file. The text stays where it is; the limitation is now also stated where it
  belongs.
- **Three items in the brief were not done, and one of them cannot be:**
  - **Standard errors are not published anywhere in this repository.**
    `data/inference_v1.json` carries `coef`, `t` and `p` and no `se`, so
    "reported with standard error" cannot be met without either re-running the
    inference (a recomputation, and the science layer is frozen) or deriving
    `se = coef / t` from two already-rounded numbers (an approximation of a
    value no source states). Neither is allowed; a **t-statistic is reported
    alongside every coefficient instead**, and this is flagged rather than
    quietly filled in. Adding `se` to the inference output is a one-line
    science-layer change, for a session that is allowed to make one.
  - **The July rationale is not split into three labelled parts.** The
    instruction's own escape clause applies. The stored string's only
    "what would change my mind" sentence - *"Both claims are testable against
    the September lock, when the near-month slope will differ."* - is the sixth
    of ten sentences, with four further "why" sentences after it. Any
    contiguous three-way split therefore either files four sentences of
    reasoning under "what would change my mind" or reorders the argument. Not
    done, deliberately.
  - **Draft wording is placeholder throughout.** The summary bullets, the two
    "In plain English" lines and the July miss note carry both a visible
    `Draft - JF to revise` badge and a `<!-- DRAFT: JF to revise -->` comment,
    as asked. They are written to be replaced.

## 2026-09-02 — README brought under the figure generator; lock time discrepancy corrected; rounding and sign policy enforced across surfaces

Stage 1 of the September presentation pass (brief dated 2 September 2026).
Presentation only. **No model, no specification and no recomputation**: the
lexicon, the scoring rules, the ladder and inference specifications, every
file under `data/` that the science layer writes, and `lock-2026-07.json`
are untouched; `data/annotations.json` was rebuilt (site layer) and no other
data file changed. 135 -> 155 tests, all green. Branch
`presentation-pass-2026-09`, to be merged to `main` at the end of the pass.

- **Approval gates bypassed on the author's instruction.** The brief
  marks five points "⏸ APPROVAL" (draft prose, contribution paragraph,
  related-work list, design plan, and the six placeholder replacements).
  The author's message of 2 September - *"bypass every APPROVAL and complete this
  task as I go afk"* - lifted them for this pass. Every piece of prose
  written under that instruction is marked in its stage's entry as **awaiting
  the author's post-hoc review**, and the acceptance checklist in the brief
  remains the author's to sign.
- **Stage 0 found the deployment healthy and the generator clean.** On a clean
  checkout of `main` (`4e2000c`): 135/135 green; `build_fallbacks` and
  `build_og_image` re-run produced a zero diff; and the live Pages site was
  **byte-identical to `main`** for all three published files (sha256 prefixes
  `8ed4192b551f` index.html, `74f2703d10da` methodology.html, `21b5d026e64c`
  og-image.png; Pages build for `4e2000c` succeeded at 22:34Z on 30 August,
  `last-modified` 30 Aug 22:35 GMT). The brief's observation of a live
  methodology page reading "94 documents", p = 0.0316 and five draft badges
  described a fetch older than that deploy - the 30 August pass had already
  regenerated it - so there was no branch, folder, workflow or CDN problem
  to diagnose. Recorded so the next "the live site is stale" report starts
  from the hash comparison, which took one command.
- **Surface inventory before this stage.** index.html: 14 generated
  `fig` regions + 9 generated blocks; hand-typed numbers confined to the
  census allowlist, plus two in JavaScript strings the census does not see
  (the chart `<title>`'s "August 2015", and the dry-run branch's "28 July
  2026, 12:00"). methodology.html: 40 generated regions, nothing hand-typed
  outside the allowlist. **README.md: every number hand-typed** (headline
  table, Spec 3 paragraph, corpus count, lock time, test count). og-image:
  generated from `data/index.json`; its `alt` text on both pages hand-typed
  ("August 2015 to July 2026"). `site/annotations/2026-07-the-minority-grew.md`:
  hand-written, two superseded figures. `<title>`s and meta descriptions:
  no figures. `CITATION.cff`: hand-typed abstract ("Aug 2015-present").
- **README.md's stale values, verbatim as found.** "August 2015 to the present
  (94 documents)"; "expanding-window evaluation from 1 January 2019 (60
  meetings...)"; the table: L0 0.6667 / 6.9078 / — / 60; L1 0.0905 / 0.1454 /
  reference / 60; L2 0.1011 / 0.1701 / −0.1171 / 60; L3 0.1514 / 0.2664 /
  −0.6729 / 60; L4 0.1644 / 0.263 / −0.8166 / 60; "full sample of 91
  scheduled meetings: coefficient −2.163349, t = −2.1499, p = 0.0316";
  "(from 1 September 2023, n = 23) ... coefficient −3.441919, t = −1.4678,
  p = 0.1422"; "LR = 0.4726, p = 0.4918"; and `tests/ 105 tests`. Every one
  of them was true on 13 July and had been overtaken by the 10 August ingest
  (and, for the test count, by five later sessions). **None was retyped**:
  the headline table is now a `fallback:readme_ladder` block, the Spec 3
  paragraph a `fallback:readme_spec3` block built from the same
  `spec3_sentence()` index.html uses, the corpus and sample sizes inline `fig`
  regions, and the test count dropped from the repository map (a count is a
  figure, and there is no data file it comes from). README.md is a third
  surface in the census; `test_no_two_surfaces_disagree_about_a_shared_figure`
  now covers it.
- **The lock time was wrong on the README and in one JavaScript branch, and
  is now read from the lock file everywhere.** README said *"First
  pre-registered lock: 28 July 2026, 12:00"*. `lock-2026-07.json` records
  `lock_timestamp: 2026-07-28T19:08:36+00:00`, the `lock-2026-07` tag is
  dated `2026-07-28T20:19:45+01:00`, and the site already displayed
  19:08:36 UTC. The 12:00 was the *planned* time from LOCKDAY.md; the lock
  itself happened that evening. Repo-wide grep for "12:00": README.md (fixed,
  generated as `fig:lock_stamp_utc`); index.html's dry-run branch *"beta lock
  scheduled 28 July 2026, 12:00"* (fixed - it now says "not yet locked",
  with no time); LOCKDAY.md (nine occurrences, all the plan or the Bank's
  own 12:00 announcement time - **left as written**, with a dated note at
  the top of the runbook recording the actual lock time and the steps that
  no longer apply). `.github/` and SETUP.md carried none. A test now asserts
  the lock file's own timestamp appears on index.html and README.md and that
  "12:00" appears on neither.
- **Rounding policy stated once and enforced.** `pipeline/site_figures.py`
  carries the policy as a table in its docstring and as `PLACES` in code:
  scores 4 d.p., coefficients and t 2 d.p., p-values 4 d.p., index values
  3 d.p., probabilities as whole percentages. index.html mirrors it with
  `fmtScore`/`fmtIndex`/`fmtPct`/`fmtSigned`. One visible consequence: the
  ladder table's Brier and log-score cells were previously the JSON's repr
  (which would have printed `0.263` had a value carried three decimals) and
  are now formatted to four.
- **True minus sign, enforced.** The ladder table's skill column read
  `-0.1167` with a hyphen in **both** the static rows (`f"{v:.4f}"`) and the
  JavaScript (`toFixed(4)`), while the prose beside it used U+2212. Both now
  go through the signed formatters. `test_every_negative_figure_uses_a_true_minus_sign`
  scans the reader-visible text of all three surfaces, generated regions
  included, for a hyphen directly before a digit that is not preceded by a
  word character (so `2026-07-11` and `0-2` pass and ` -0.67` fails).
- **Dash policy: spaced em dash for breaks, en dash for ranges, never a
  hyphen.** Three strings used ` - `, and all three were data printed
  verbatim rather than prose: the lexicon provenance sentence from
  `data/index.json`'s `lexicon` field ("abg_2012 (Apel & Blix Grimaldi 2012,
  verbatim - see pipeline/... starter_v0 remains in the repo as plumbing...")
  - the page now shows the identifier, `abg_2012`, and nothing else from
  that field; the context panel's disclaimer from `site_context.json`
  ("Context - not model inputs") - the template now writes its own sentence
  with a comma, and `site_context.py`'s `DISCLAIMER` constant was changed to
  match for the next rebuild (the JSON was **not** rebuilt: that needs a live
  curve download, and nothing in this pass asked for new market context);
  and the footer's "linked not republished". README's "L0-L4" became
  "L0 to L4" (in the diagram as well as the prose - the same line appears in
  both). `test_no_spaced_hyphen_stands_in_for_a_dash` guards all three
  surfaces.
- **The July episode's superseded figures carry a dated editorial bracket,
  and the bracket's numbers are generated.** After *"...L3 scores −0.6729
  against the market-only benchmark and Spec 2 returns p = 0.4918."* the
  source markdown now reads *"[Figures as at the 28 July lock. The ladder was
  re-run on 10 August after the July minutes were ingested and now reads
  {fig:l3_skill} / {fig:spec2_p} — Ed., September 2026.]"* - the wording the
  brief supplied. `build_annotations.py` resolves `{fig:NAME}` tokens from
  the catalogue when it writes `data/annotations.json` (hard stop on an
  unknown name), so the source keeps the token and the published JSON, the
  static fallback and the scripted render all carry `−0.6712 / 0.4894`. The
  −0.6729 and 0.4918 in the episode's own sentence, and in the locked
  rationale on the call card, are **untouched**: they were true at the lock.
- **Footer trailing separator fixed in the template.** The footer ended
  "...(see the decisions log) ·" followed by an empty `<span id="gen-note">`
  that only JavaScript filled. The note is now a generated `fallback:gennote`
  ("Index data generated 5 August 2026.", from `data/index.json`'s
  `generated_utc`), shipped filled in; the sentence before it ends with a
  full stop.
- **Meta tags with figures are generated as whole-tag blocks** -
  `fallback:ogalt` (the share card's alt text, "August 2015 to July 2026",
  previously hand-typed on both pages) and `fallback:metaauthor` - because a
  `fig` region cannot sit inside an attribute. The byline on both footers is
  a `fallback:byline` block from one `AUTHOR` record in `site_figures.py`
  (name, email, affiliation, site, repo); README carries the same record.
  `<title>` and the description metas state no figure and were left.
- **A static/JavaScript parity test, and what it found on its first run.**
  `pipeline/tests/test_static_js_parity.py` serves the repository on an
  ephemeral localhost port, renders index.html in Chromium with scripting
  off and then on, and diffs the `innerText` of nineteen figure-bearing
  elements. It skips when Playwright or the browser is absent (CI installs
  neither), so it is a local guard, run before every publish. First run:
  **two disagreements**. The latest reading said "1.0 = neutral" statically
  and "1 = neutral" scripted (Python prints the float `1.0`, JavaScript
  prints `1`); the ladder meta line said "1e-09" statically and "1e-9"
  scripted (same float, opposite exponent padding). Each now has one
  formatter on each side (`neutral()`/`fmtNeutral`, `clip()`/`fmtClip`); the
  floor renders as `1e−9` with a true minus. **A third defect was found by
  reading, not by the test, and the test was then set up to catch it**:
  `fmtDate()` parsed bare dates with `new Date('2026-07-30')`, which is UTC
  midnight and therefore 29 July for a reader west of Greenwich. It now
  formats the date part of the string as written, mirroring Python's
  `gb_date()`, and the parity test runs its browser in `America/Los_Angeles`.
- **The prediction file on display is derived, not edited in.** `index.html`
  hardcoded `PREDICTION_FILE = 'data/predictions/lock-2026-07.json'`, the
  "edit line 465" step in LOCKDAY.md. `site_figures.prediction_file()` now
  picks the newest `lock-*.json`; `build_fallbacks` writes it into the call
  card as `data-prediction-file`; the JavaScript reads that attribute. Lock
  day loses one hand edit and gains one build command, and the September
  pending row (Stage 2) can disappear by the same rule once
  `lock-2026-09.json` exists.
- **"Next announcement" is now data-based on both sides, and the
  clock-based version is gone.** The static line was already generated from
  the calendar; the JavaScript recomputed it from *today's date* and
  `site_context.json`, which would have diverged from the static text the
  day after any meeting that passed without a new lock. Both now name the
  first date in the Bank's calendar (`site_context.py`, transcribed
  2026-08-10) after the displayed call's own meeting. Stated consequence: if
  a meeting passes without a lock file being written, the line stays on the
  passed date until the next build - the workflow guards that, not the page.
- **Link check.** `pipeline/tests/test_links.py`: every internal anchor and
  relative file link on the three surfaces resolves (pytest, offline);
  `python -m pipeline.tests.test_links --external` fetches the external URLs.
  Run 2026-09-02: **all 14 returned 200** - the `lock-2026-07` release/tag
  page, the repository, DECISIONS.md and README.md on GitHub, the 30 August
  commit, the live site and og-image, the Bank's July 2026 minutes page, the
  two Bank news releases cited on the methodology page, the Actions badge
  and workflow, and the live `#limitations` anchor. (The first attempt
  failed on every URL with an SSL error: the macOS system Python has no CA
  bundle; the checker uses `requests`, already a dependency, which ships
  one.)
- **Fonts added, not yet used.** Source Serif 4 v4.005R (Adobe, SIL OFL 1.1)
  from the tagged GitHub release, subset with `pyftsubset` to Latin plus the
  typographic and arrow ranges the site uses: Regular 56 KB, Italic 44 KB,
  Semibold 58 KB, Display Regular 56 KB, Display Italic 43 KB, under
  `site/fonts/` with `LICENSE.md` from the same tag. Stage 3 wires them in.
- **Tooling, local only.** Playwright, Chromium and fonttools installed in
  `.venv`; `pipeline/tests/screenshots.py` serves the repo on port 8000 and
  writes both pages at 380/768/1280px in light and dark, with JavaScript off,
  and as A4 and Letter PDFs, under `qa/` (now gitignored). Not added to
  `requirements.txt`: CI runs the suite without a browser and the two
  browser tests skip by design there.
- **Found, not fixed (outside this stage or this pass):**
  - `data/inference_v1.json`'s `notes` field still describes "91 scheduled
    meetings (full sample) / 23" - a science-layer output, not a published
    surface; **deferred to the model batch** with the `se` field.
  - The chart's SVG `<title>` and legend are hand-typed JavaScript strings
    ("August 2015 to present"); the census strips scripts. Stage 3 redraws
    the chart and will derive them from the series.
  - `CITATION.cff`'s abstract says "Aug 2015-present" and dates the release
    2026-07-12. Metadata for citation managers, not a reader surface; left.
  - `LOCKDAY.md` still quotes "107 tests" and "line 465". Historical runbook,
    kept as written under the note at its head.
  - og-image.png is still the dark theme (Stage 3 regenerates it).

## 2026-09-02 — presentation pass, stage two: the words

Stage 2 of the September presentation pass. Presentation only. **No model,
no specification and no recomputation**; nothing under `data/predictions/`
and no science-layer file touched; `data/annotations.json` unchanged since
stage one. 155 -> 166 tests, all green. Every piece of prose below was
written under the author's 2 September instruction to bypass the
approval gates and is **awaiting the author's post-hoc review**; each is recorded
verbatim here so the review can be done against this entry rather than by
diffing the page.

- **Six placeholders replaced by prose, not by deleting the badge.** The
  register followed is the Results framing paragraph and the July episode:
  plain, declarative, British spelling, willing to say "it does not". Every
  numeric claim is a generated `fig` region (shown here as `{fig:NAME}`); no
  replacement is longer than the placeholder it replaces.
  1. **Summary bullets.** Before: *What was tested / What was found / What
     remains uncertain* (three bullets, 2026-08-30). After:
     - *"**Question.** Does the hawkish or dovish tone of the MPC's minutes,
       scored with a published dictionary (Apel & Blix Grimaldi, 2012), say
       anything about the next Bank Rate decision that the OIS curve has not
       already priced? Tested on {fig:n_scheduled} scheduled meetings from
       {fig:eval_start}, with every live call locked and timestamped before
       the announcement."*
     - *"**Answer.** No. Every model that adds the tone index does worse than
       market pricing out of sample; the best of them, L3, scores
       {fig:l3_skill} against the L1 benchmark, where zero would be a tie.
       The null is the result."*
     - *"**Limits.** One weaker test on the size of the market surprise is
       nominally significant on the full sample (p = {fig:spec3_p}) and
       fails after {fig:frag_start} (p = {fig:frag_p}); the index rests on a
       median of {fig:hits_median} dictionary hits per document; and L3's
       negative skill has not been tested against zero."*
  2. **Call card, "In plain English".** Before: *"...this is the call itself
     — written down and timestamped before the announcement, so it cannot be
     quietly revised afterwards. The percentages beneath are the market's,
     not mine; the point call and the reasoning are mine."* After: *"In plain
     English: this is the call, written down and tagged before the
     announcement so it cannot be revised afterwards. The percentages are the
     market's; the point call and the reasoning are mine."*
  3. **Market panel.** Before: *"...this is what the rate market and the gilt
     curve looked like around the latest reading. It is background only —
     none of it feeds the index, the benchmark or any locked call."* After:
     *"In plain English: where the rate market and the gilt curve stood
     around the latest reading. Background only; nothing here feeds the
     index, the benchmark or a locked call."*
  4. **Results (ladder).** Before: *"...the market's own pricing (L1) called
     these decisions best — every model that adds the tone index scored
     worse, not better."* After: *"In plain English: the market's own pricing
     (L1) called these decisions best. Every model that adds the tone index
     did worse, not better."*
  5. **Spec 3.** Before: *"...one test finds a weak link between the previous
     minutes' tone and how the decision surprised the market, but it fades
     after 2023 and a stricter test finds nothing."* After: *"In plain
     English: one test finds a weak link between the previous minutes' tone
     and the size of the market's surprise. It does not hold after
     {fig:frag_start}, and a stricter test finds nothing."* (The hand-typed
     "2023" is gone with it.)
  6. **July miss note.** Before: *"July: right on the decision, wrong on the
     vote split. The locked call — hold — was correct and is scored above.
     The ancillary call, that the hawkish minority would stay at two, was
     wrong: it went to three."* After: *"**July: right on the decision, wrong
     on the vote.** The locked call, hold, was correct and is scored above.
     The unscored side-call, that the hawkish minority would stay at two, was
     wrong: it went to three. Read the episode, "The minority grew"."*
  Badges and `<!-- DRAFT: JF to revise -->` comments removed with each.
  `pipeline/tests/test_no_draft_markers.py` fails if "JF to revise", "DRAFT",
  `class="draft-note"` or "TODO(Jake)" appears on either page, the README,
  the published episodes or their source markdown.
- **Contribution paragraph, placed under the Summary list rather than as a
  fourth bullet**: three sentences in one bullet would outweigh the three
  one-idea bullets above it. Verbatim: *"Three things here are new. The Apel
  and Blix Grimaldi dictionary is applied to Bank of England minutes and
  tested against a market-implied benchmark rather than against realised
  decisions alone, which is the comparison that decides whether tone carries
  information anyone could act on. The calls are pre-registered: locked,
  git-tagged and timestamped before each announcement, scored after it, with
  the misses kept on the record. And the {fig:lock_month} episode found that
  the vote turned on forward-risk language the lexicon does not measure,
  which motivates a second series, to be pre-registered separately before it
  is run."*
- **The "What is this?" section is deleted and the standfirst is the
  question only.** With the Summary now carrying question, answer, limits and
  contribution, the section repeated all four; its two sentences not already
  on the page went into the Question bullet ("scored with a published
  dictionary (Apel & Blix Grimaldi, 2012)") and the contribution ("with the
  misses kept on the record"). The standfirst lost its second sentence
  ("Every call is locked before the announcement, timestamped, and scored —
  including the misses"), which the contribution now says once.
- **"Why this lexicon", methodology.html, visible under Index construction's
  summary rather than inside its expander** - it is an argument, not
  apparatus. Verbatim: *"**Why this lexicon.** A published, unmodified
  dictionary was chosen over a bespoke or fitted one for three reasons. It
  can be falsified: the term lists were fixed by other authors before this
  corpus was seen. Nothing in it is fitted in-sample, so a null result cannot
  be blamed on over-fitting and a positive one could not have been
  manufactured. And it can be replicated against the paper, whose term lists
  and page references are stored verbatim. The cost is known: the lists are
  the paper's 2012 vintage; a match such as "higher inflation" records the
  topic discussed rather than the stance taken; and hits are sparse, a median
  of {fig:hits_median} per document. Any alternative lexicon would be
  specified and pre-registered before it is run over the sample, under the
  same expanding-window protocol as everything else."* Cited to the
  2026-07-11 baseline-lexicon entry and to this one.
- **Two limitations added, unsoftened**, to the methodology list (after
  "Small n") and as one fine-print line each under the ladder and the Spec 3
  expanders on index.html. Verbatim (methodology): *"**No significance test
  on the skill differential.** Skill against L1 is a point value. Whether
  L3's negative skill is distinguishable from zero on {fig:n_scheduled}
  meetings has not been tested. A Diebold–Mariano test on the Brier loss
  differential (L1 against L2, L3 and L4) is scheduled for the September
  cycle, to be pre-registered before it is run."* and *"**No standard errors
  published.** `data/inference_v1.json` carries each coefficient's estimate,
  t-statistic and p-value but not its standard error. Adding it is a
  science-layer change, deferred to the next cycle rather than derived from
  two already-rounded numbers."* (cross-referenced to 2026-08-30). The
  Limitations summary line gained "and a skill differential that has not
  been tested for significance"; the Summary's Limits bullet carries the same
  point in one clause.
- **Related work: one list, two surfaces, nothing invented.** `RELATED_WORK`
  in `build_fallbacks.py` renders as "Related work" on index.html (after
  Episodes) and "References" on methodology.html (before the footer), as a
  definition list with a one-clause annotation each. The seven entries are
  the brief's candidates, author-year-title-venue exactly as supplied, **no
  volume, page or DOI**. Apel & Blix Grimaldi carries the `citation` string
  from `pipeline/score/lexicon/abg_2012.json` verbatim and no marker. The
  other six carry a visible **[VERIFY]** marker: the repository holds only
  "(Gerlach-Kristen 2004)" for the vote-skew source and nothing at all for
  Hansen & McMahon, Bholat et al., Lloyd, Gneiting & Raftery or Diebold &
  Mariano, so their venues and titles are unverified *from this repository*,
  which is the brief's test. A one-line note on both pages says so. **The
  markers are on the live page deliberately** - the brief asked for them
  until the author supplies the verified set - and they are the one
  thing in this pass that reads as unfinished; listed first in the handover.
- **Status line replaces the "Beta · pre-registered" badge, on both pages.**
  Format: *"1 locked call · next lock 15 September 2026 · 95 documents ·
  site built 2 September 2026 (e50ee92)"*. The count is from
  `data/track_record.json`, the corpus size from `data/index.json`, the next
  lock from the Bank's calendar in `site_context.py` (first meeting after the
  newest locked call's, minus `LOCK_DATE_OFFSET_DAYS`), all through
  `fallback:status`; the build stamp is a second region, `fallback:buildstamp`,
  which `build_build_info.py` now writes alongside the footer sentence from
  the same JSON (and `build_fallbacks.py` writes from the same JSON, so
  either script leaves both current). index.html's JavaScript refreshes both
  stamps from the fetched file. The middle dots here are the one place the
  brief allows them.
- **Track record gains a pending row for the next meeting.** *"17 September
  2026 · Pending · locks 15 September 2026"* with an em dash in every other
  cell, muted, generated by `build_track()` from the same calendar rule as
  the status line. `renderTrackRecord()` keeps `tr.kind-pending` rows when it
  rebuilds the table from `track_record.json` (which cannot contain one), and
  the rehearsals toggle never hides them. **Both states tested**: with July
  the newest lock the pending meeting is 17 September (lock 15 September);
  with a September lock present it becomes 5 November (lock 3 November) -
  the row moves on by itself the moment `lock-2026-09.json` exists and the
  site is rebuilt.
- **Byline, contact, affiliation** were made one source in stage one
  (`AUTHOR` in `site_figures.py` -> both footers, both `meta author`, the
  README). `CITATION.cff` already carries the same name and was not changed.
  og-image gets the byline when it is redrawn in stage three.
- **Copy pass, as reader two (four minutes, printed).** Cut as repetition:
  the call card's attribution line *"Written by hand before the announcement,
  and never edited afterwards"* (the card's plain-English line says it); the
  ladder's *"Standing caveat: the market benchmark (L1) is the bar..."*
  paragraph (the Results framing paragraph says it, two paragraphs above),
  leaving one pointer to the methodology and `data/ladder_v1.json`; the
  "What is this?" section and the standfirst's second sentence, above.
  Heading text was already sentence case; the all-caps rendering is a CSS
  transform and goes with the eyebrows in stage three, as does "Hover or tap
  the line for details", which the brief ties to the chart restyle. "Not
  investment advice" and "How to check this" kept.
- **A census lesson, recorded because it shaped this entry's title.** The
  first draft cited "(DECISIONS.md 2026-09-02 — presentation pass, Stage 2)"
  on methodology.html and the census failed it: "2" is a digit in prose with
  no data file behind it. Entry titles cited from a page therefore carry no
  digits beyond the date - hence "stage two".
- **Deferred to the model batch** (unchanged from stage one, restated because
  this stage published the promises): the Diebold–Mariano test on the loss
  differentials; `se` in the inference output; the second, separately
  pre-registered risk-management series; the vote split as a scored
  distribution. **Found, not fixed**: the dead `.draft-note` and `.beta` CSS
  rules (stage three rewrites the stylesheet); the chart hint text.

## 2026-09-02 — design pass: paper theme, single-family type, call card as focal element, chart overlays, print stylesheet

Stage 3 of the September presentation pass. Presentation only. **No model,
no specification and no recomputation**; nothing under `data/predictions/`
and no science-layer file touched. 166 -> 169 tests, all green (three new,
in `pipeline/tests/test_contrast.py`). The design plan below was written
before any CSS and critiqued against the brief's list of what to move away
from; the approval gate was passed on the author's instruction of
2 September and the plan is the author's to overturn.

### The plan, as written before building

```
## Tokens

Light (default)            Dark (prefers-color-scheme, or the toggle)
--paper   #fcfbf9          #151412   page ground: near-white with a barely warm cast / warm near-black
--stamp   #f5f0e6          #1f1b15   the call card's own sheet, and nothing else
--ink     #1c1b19          #e9e6e0   text
--ink-2   #57534d          #b0aaa1   secondary text: captions, fine print, axis labels
--rule    #d8d3cb          #3a3631   hairlines
--accent  #8a5a12          #d9a94a   dark ochre / amber: the call card's rule and badge, the
                                     "Locked" badge in the track record, the lock marker on the chart
Semantic pairs, never used alone (shape or label always accompanies them):
--hawk    #a8382a          #e0796a   hike markers (▲, filled), hawkish reading
--dove    #2f5d9b          #84ade8   cut markers (▽, open), dovish reading
--rate    #3b7a68          #7fc0a8   Bank Rate step line (dashed)
--gilt    #6b4d9e          #b39fdc   gilt sparkline

## Type roles (one family: Source Serif 4, self-hosted, five faces)

Display instance   h1 (38px), the three probabilities on the call card (46px), the latest index reading (38px)
Text instance      body 18px / 1.65, measure 68ch; h2 26px regular, sentence case; h3 22px italic;
                   captions and fine print 15px; small labels 13px in all-small-caps (badge, column heads,
                   probability labels) - the serif's own small caps, not a sans
Tabular figures    on every number (tables, probabilities, stamps, index readings); proportional in prose
Monospace          only the tag, the git command, hashes and file paths
No sans-serif anywhere; controls (checkboxes, the theme toggle) set in the serif.

## Layout — first two screens at desktop

┌──────────────────────────────────────────────────────────────────────┐
│ MPC Communication Index                                  [Dark]      │ h1 display; toggle quiet, top right
│ Does the tone of Bank of England communication carry information     │ standfirst, italic, ink-2
│ about the next rate decision beyond what markets already price?      │
│ Jake Foulkes · 1 locked call · next lock 15 September 2026 ·         │ status line, 15px, ink-2
│ 95 documents · site built 2 September 2026 (e50ee92)                 │
│ ──────────────────────────────────────────────────────────────────── │ hairline
│ Question.  Does the hawkish or dovish tone of the MPC's minutes ...   │ run-in bold labels, no bullets
│ Answer.    No. Every model that adds the tone index does worse ...    │
│ Limits.    One weaker test on the size of the market surprise ...     │
│ Three things here are new. ...                                        │ contribution, plain paragraph
│                                                                       │
│ How to check this                                                     │ h2
│ Nothing here has to be taken on trust. ...                            │
│   1  The timestamp. Open the tag lock-2026-07, which GitHub dates ... │ numbered: it is a sequence
│   2  The call itself. ... git show lock-2026-07:data/... (mono)       │
│   3  Everything else. The code, the data, and the dated log ...       │
│ ──────────────────────────────────────────────────────────────────── │
│ ┌──────────────────────────────────────────────────────────────────┐ │ ← screen two
│ │ LOCKED CALL · SCORED  (small caps, accent)                        │ │ call card: --stamp sheet,
│ │ Call for 30 July 2026                                             │ │ one accent rule, 2px radius
│ │ Locked 28 July 2026, 19:08:36 UTC · tag lock-2026-07 (mono)       │ │ timestamp + tag = the anchor
│ │ Figures as at the lock date (28 July 2026).                       │ │
│ │ In plain English: this is the call, written down and tagged ...   │ │
│ │       0%                96%                 4%                    │ │ display instance, tabular
│ │      cut               hold ●               hike                  │ │ ● marks the point call
│ │ ────────────────────────────────────────────────────────────────  │ │ proportion bar, 4px
│ │ m0 market pricing only — OIS forward curve vs SONIA, 25bp ...     │ │
│ │ A&BG index (minutes-2026-06): 1.714 vs trailing 4-document ...    │ │
│ │ Point call  hold                                                  │ │
│ │ │ Hold at 3.75%. The communication index is recorded as ...       │ │ rationale, hairline left rule
│ │ Outcome hold      Brier (m0) 0.0030      Point call matched       │ │
│ │ Next announcement: 17 September 2026 — the next call locks ...    │ │
│ └──────────────────────────────────────────────────────────────────┘ │
│                                                                       │
│ The communication index                                               │ h2
│ MPC minutes for the meeting ending 29 July 2026, published 30 July.   │ a sentence, not a dotted string
│ 0.667   net dovish (A&BG net index, 0–2 scale, 1.0 = neutral)         │ display number
│ ◄ dovish ───────────────┼──────────────── hawkish ►                   │
│ [chart: thin ink line; hiking-cycle band shaded in --rule; vertical   │
│  rule at 1 September 2023 "fragility sub-sample begins"; ▲ ▽ markers; │
│  ◆ accent at the locked call; y-axis "A&BG net index, 1.0 = neutral"] │
└──────────────────────────────────────────────────────────────────────┘

## Three principles

1. A document, not a dashboard. One column, one family, sections separated by
   space and a hairline; headings in sentence case with no tracking, no
   eyebrows, no cards, no shadows, no gradients, no arrows on links.
2. Boldness spent once. The locked call is the only element with its own
   sheet, a rule box and the accent; the accent appears in exactly two other
   places (the Locked badge in the track record, the lock marker on the chart).
3. Every mark carries information. Colour never alone (shape or label with
   it); tabular figures on every number; monospace only for things one would
   type; the status line is the one place a middle dot joins metadata.

## Self-critique against 3.0 (what changed after writing the above)

- First draft used a cream ground (#f7f2e8) and a terracotta accent (#b5533c):
  the paper cliché the brief names. Changed to a near-white with a barely
  warm cast and a dark ochre accent that is ink-like on paper.
- First draft kept rounded "cards" in the light theme with a faint border,
  because that is the default for a sectioned page. Changed: sections have no
  box at all; only the call card is boxed, and its radius is 2px.
- First draft set captions, table headers and small labels in a humanist sans
  "for legibility at small sizes". That is the dashboard reflex. Changed: the
  serif's own small caps at 13px carry every label, and there is no sans.
- First draft drew the index line in the accent colour, which is what every
  chart on the old site did. Changed: the line is ink; the accent is reserved
  for the single locked-call marker, so the eye goes to the one live thing.
- First draft kept the middle-dot doc line under the index reading ("meeting
  ending · published · decision · vote"). Changed to a sentence, generated
  the same way on both sides.
- First draft put the theme toggle as an icon button. Changed to a word
  ("Dark" / "Light") in small caps: quieter, and announced without an aria
  label doing the work.
```

### What was built

- **One stylesheet, `site/site.css`, linked from both pages.** The two pages
  had carried near-identical inline stylesheets that had already drifted
  (methodology.html had no chart or call-card rules and an older token set).
  A same-origin file is not an external dependency and cannot drift between
  the pages; the head of each page keeps only a two-line inline bootstrap
  that applies a remembered theme before first paint. `site/theme.js`
  (deferred, no fetches) wires the toggle, closes the disclosures on load,
  and opens every `<details>` on `beforeprint` and restores them on
  `afterprint`. **methodology.html therefore now runs a script**, which the
  2026-07-30 entry said it did not "by design"; the design reason was that
  its figures must not depend on a fetch, and they still do not - the script
  touches theme and disclosure only.
- **Fonts.** Source Serif 4 v4.005R (Adobe; SIL Open Font License 1.1, the
  full licence text at `site/fonts/LICENSE.md`), subset to Latin plus the
  typographic ranges the site uses, five faces: text Regular, Italic and
  Semibold; Display Regular and Italic (the last declared but never
  requested by the current rules, 43 KB that no reader downloads). Loaded
  with `font-display: swap` and two preloads. Checked in a real browser:
  all four used faces report `loaded`; body computes to "Source Serif 4"
  at 18px on desktop and 17px at 380px. There is no sans-serif on either
  page; the controls are set in the serif.
- **Removed, and why.** The card kit (`.card` background, border, 12px
  radius and two-layer shadow) - sections are now separated by space and a
  hairline, because a paper has no boxes; the eyebrow (`.card > h2` and
  `.subhead`: 12px sans, uppercase, +.14em tracking) - headings are the
  serif in sentence case at 26px and 22px italic; the `.beta` badge; the
  dead `.draft-note` rule (the device it served is gone); the `&larr;` and
  `&rarr;` arrows on the backlinks and in the ladder meta line; the
  middle-dot strings in the latest-reading lines, which are now sentences
  on both the static and scripted side ("MPC minutes for the meeting ending
  29 July 2026, published 30 July 2026. Decision: ...; vote 6–3."); the
  "Hover or tap the line for details" hint; the gradient wash on the
  dovish–hawkish scale (now a hairline with a neutral tick and an ink
  marker); the accent colour on the chart line, on L1's table row and on the
  latest-reading document line. The only rounded corners left are the call
  card's 2px and the form controls'.
- **The call card is the one bold element.** Its own sheet (`--stamp`), a
  single accent rule, the badge in the serif's small caps, the timestamp and
  tag as the first line after the heading, the three probabilities in the
  display instance at 46px with the point call marked by a filled circle
  after its label (a class the static template sets and, after a first
  render showed it missing, the JavaScript mirrors), the rationale behind a
  hairline in the accent. Nothing else on the page uses the accent except
  the Locked badge in the track record and the lock marker on the chart.
- **Chart.** Line in ink at 1.25px; hairline axes; the y-axis labelled
  "A&BG net index, 1.0 = neutral"; decision markers as shapes, a filled
  upward triangle for a hike and an open downward one for a cut, in the
  hawk and dove colours; the locked call as a diamond in the accent at its
  meeting date. **Two generated overlays**: a shaded band for the hiking
  cycle, derived in both the JavaScript and the fallback generator as the
  longest run of consecutive Bank Rate rises in `site_context.json`'s
  history (16 December 2021 to 3 August 2023, which is the brief's
  "December 2021–August 2023" read off the data rather than typed), and a
  dashed rule labelled "fragility sub-sample begins" at the start date in
  `data/inference_v1.json`, carried to the drawing as a data attribute the
  generator writes (`fallback:chartmeta`), alongside the locked meeting from
  the prediction file. The chart's `<title>` is now built from the series'
  first and last months rather than typed. The words-only fallback names all
  three overlays. **Found by looking, not by testing:** the old chart's
  triangles pointed the wrong way (the apex was drawn nearer the point than
  the base) and had done since 2026-07-12; corrected, and the legend now
  shows the shapes as drawn.
- **Tables.** Hairline rules; visible captions above; tabular figures; the
  L1 row marked as the benchmark by weight and a rule above it, not by
  colour; wide tables still scroll inside `.table-scroll`.
- **Disclosures ship open.** `<details class="disclosure" open>` in the
  markup; `theme.js` closes them on load and marks them ready (the
  stylesheet hides their bodies until then, so nothing flashes). A reader
  without scripting sees everything, which is the honest no-JS state, and so
  does the printer without a handler. The market panel is collapsed by
  default with scripting, as the brief asks.
- **Print.** Light tokens forced (also over a dark toggle), point sizes,
  80ch measure, no shadows (there are none), every `<details>` open, URLs
  printed after external links except for the commit stamps (the hash
  identifies the commit; the URL added a line of noise), `break-inside:
  avoid` on tables, the call card, the verification list and each episode,
  the chart printed as the inline SVG when it was drawn and the words when it
  was not. Checked as A4 and Letter PDFs in Chromium: "How to check this"
  is on page one at both sizes; index.html runs to 12 pages at A4 (the July
  episode is most of it), methodology.html to 8.
- **Share card and favicon.** `og-image.png` redrawn in the light tokens
  with the site's own typeface (the woff2 decoded through fontTools, now in
  `requirements.txt` with brotli, so a rebuild anywhere matches the page),
  the series in ink, the locked call as the one accent mark, and the byline
  from `AUTHOR`. The favicon is a paper square with an ink line and an
  accent dot.
- **Accessibility floor, verified.** `pipeline/tests/test_contrast.py`
  parses both token sets out of the stylesheet and asserts thirteen
  text-on-ground pairs against 4.5:1 (body) or 3:1 (large text and marks).
  Output, light: ink/paper 16.64, ink-2/paper 7.38, accent/paper 5.72,
  ink/stamp 15.15, ink-2/stamp 6.72, accent/stamp 5.21, hawk/paper 6.22,
  dove/paper 6.43, rate/paper 4.87, gilt/paper 6.38, paper/hawk 6.22,
  paper/dove 6.43, ink/rule 11.56. Dark: 14.78, 7.99, 8.53, 13.75, 7.43,
  7.93, 6.24, 8.00, 8.77, 7.81, 6.24, 8.00, 9.62. Colour-vision simulation
  (Machado, Oliveira and Fernandes 2009 matrices, severity 1.0): under
  protanopia the light hawk/dove pair becomes #584f28/#41629d and under
  deuteranopia #736826/#30589a - an olive against a blue, still two hues -
  and rate/gilt #777367/#315da1 and #6d6c69/#385c9c; the dark theme
  behaves the same way. Their luminance contrast with each other is low
  (1.0–1.6:1) in every condition, which is why no pair relies on hue: hikes
  and cuts differ in shape and fill, the Bank Rate line is dashed and
  stepped, the gilt series is its own chart, and every reading is labelled.
  Also verified in Chromium at 1280px and 380px on both pages: heading
  order h1→h2→h3→h4 with no skips (the episode's internal headings moved
  from h3 to h4 to sit under the episode's own h3), every `<svg>` with a
  role and an accessible name, both tables captioned, `scrollWidth` equal
  to the viewport at 380px, the theme toggle operable with Tab and Enter and
  announced through `aria-pressed`, the choice surviving a reload, and no
  console errors or warnings.
- **Not done / found, not fixed.** The Display Italic face above. The
  static context panel's `<b>` inline colour was a `var(--text)` that no
  longer exists and would have silently rendered in the inherited colour;
  it is a class now. `qa/` holds the stage's captures (18 files:
  380/768/1280px in both themes, the no-JS render, A4 and Letter PDFs for
  each page) and is gitignored.

## 2026-09-02 — presentation pass, stage four: QA, reader simulation, deploy

Stage 4 of the September presentation pass, and the close of it.
Presentation only; nothing under `data/predictions/`, no science-layer file
and no science output touched - checked with `git diff --stat main` over
`pipeline/score`, `pipeline/market`, `pipeline/predict`, `ladder.py`,
`inference.py`, `validate.py`, `member_behaviour.py` and every file under
`data/` the science layer writes: **empty**. 169/169 tests green. Branch
`presentation-pass-2026-09` merged to `main` by fast-forward at the end of
this entry.

- **Tooling.** `pipeline/tests/screenshots.py` (Playwright, local only)
  serves the repository on port 8000 and writes, per page, 380/768/1280px
  captures in both themes, a 1280px capture with JavaScript disabled, and
  A4 and Letter PDFs - 18 files - under `qa/<label>/`, which is gitignored.
  Every capture from `qa/stage1/` to `qa/stage4/` was opened and looked at,
  either whole or as a crop, before the stage was committed; the three
  defects found that way (the inverted triangles, the missing point-call
  marker on the scripted card, the band label under the markers) are in
  the stage-three entry.
- **Consistency census, all green**: figure regions on three surfaces
  against the catalogue; no two surfaces disagreeing on a shared figure;
  no unaccounted digit in reader-visible text; true minus signs and no
  spaced hyphens; no draft marker on any published surface; static and
  scripted renders identical across nineteen elements in a Los Angeles
  time zone; every internal anchor and relative link resolving; the lock
  timestamp identical on index.html and README.md; status line and pending
  row from the record and the calendar; thirteen contrast pairs above their
  floors in both themes.
- **External URLs, checked by hand on 2 September with
  `python -m pipeline.tests.test_links --external`**: 200 for the
  `lock-2026-07` release page, the repository, DECISIONS.md and README.md on
  GitHub, the Actions badge and workflow, the live site, methodology page,
  `#limitations` anchor and og-image, the Bank's July 2026 minutes page and
  the two Bank news releases the methodology page cites. The one 404 was the
  footer's link to the stage-three commit, which did not yet exist on
  GitHub; it resolves with the push recorded below.
- **No-JavaScript pass.** With scripting off, both pages show every section
  from its static fallback - the call card, the latest reading, the chart in
  words, the market panel, the ladder, Spec 3, the track record with its
  pending row, the episode, related work, the status line and both stamps -
  and no "Loading..." anywhere; the disclosures are open because they ship
  open. The theme toggle is hidden without scripting, by design.
- **Reader simulation.** Three first-person read-throughs, written after
  reading the finished pages as each reader:
  - *Loughborough lecturer, ten minutes.* First thing I saw: the question,
    a one-word answer and the limits, before any chart. By minute two I knew
    the benchmark was the OIS curve rather than realised decisions, that the
    calls are git-tagged before the announcement, and that the author's own
    model loses to the market and says so. On the methodology page the
    lexicon is a published one, the reasons for choosing it are argued
    rather than assumed, and the limitations list includes the test not yet
    run. The question I was left with is power: on 61 meetings, is L3's
    negative skill distinguishable from zero at all? The page says that is
    the September test. What would make me close the tab: the [VERIFY]
    markers still there in a month, or a figure that differed between the
    two pages. I checked three. They did not.
  - *Oxford MPhil admissions reader, four minutes, from the PDF.* Page one
    carries the question, the answer, the limits, what is new and how to
    check it. I read the contribution paragraph twice; the third point,
    that the July vote turned on language the dictionary does not measure,
    reads like a researcher rather than a coder, because it is a reason the
    project's own instrument failed. By minute two I understood the
    pre-registration protocol and that the null was the finding rather than
    a disappointment. The question I was left with is what the second series
    will measure and whether it will be pre-registered before it is fitted;
    the page promises it will. What would make me close the tab: a chart
    with no words behind it, or an appendix that could not be checked. The
    PDF prints the call card and the verification steps with the tag name.
  - *Bank or sell-side economist, two minutes, from a link.* I wanted the
    call and the number. The status line gave me one locked call and the
    next lock date; the card gave me hold at 96% market-implied, the
    timestamp, the tag, a Brier of 0.0030 and the rationale in the author's
    own words. The number I would use is the skill: −0.6712 against the
    OIS-implied benchmark on 61 meetings. The interpolation and risk-premium
    caveats are the two I would have raised, and they are on the page. The
    question I was left with is the September call, which is pending; the
    row says when. What would make me close the tab: a tone index sold as a
    trading signal. It is not, and the page says so in the first screen and
    the footer.
  - **Fixed from these:** the status line's "1 locked call" now links to the
    call card on both pages, so the third reader is one click from the call
    wherever they land. **Logged, not fixed:** the [VERIFY] markers, which
    only the author can clear.
- **Keyboard walk-through** (Chromium): skip link, theme toggle, the six
  links of the summary and verification box, the two chart checkboxes, the
  chart itself, each disclosure's summary, the scrolling table regions, the
  rehearsals toggle, every link in the record, episode and related work,
  the footer links - all reachable in document order with a visible 2px ink
  focus ring; the toggle switches on Enter and its `aria-pressed` follows.
  380px: `scrollWidth` equals the viewport on both pages. Reduced motion:
  the stylesheet declares no transitions or animations, and the guard
  remains.
- **Deferred to the model batch** (to be pre-registered before the
  15 September lock, in its own brief): a Diebold–Mariano test on the Brier
  loss differentials (L1 against L2, L3 and L4); `se` in the inference
  output; the second, separately pre-registered risk-management series; the
  vote split as a scored distribution; bootstrap confidence intervals on
  the Brier scores; negation-handling robustness; alternative-lexicon
  robustness; and a refresh of `data/inference_v1.json`'s `notes` field,
  which still describes the pre-July sample sizes.
- **For the author, in order:** (1) the six [VERIFY] entries in Related
  work / References, against the sources; (2) the prose written under the
  bypassed approval gates - the stage-two entry carries all of it verbatim;
  (3) the design plan in the stage-three entry; (4) the acceptance checklist
  in the brief, which is the author's to sign.
- **Deploy check, 2 September 2026, 11:10 BST.** `main` fast-forwarded to
  `da5c5c3` (the stage-four stamp commit) and pushed. GitHub Pages reported
  `built da5c5c3` on the third ten-second poll; the `tests` workflow for the
  push passed. Fetched live with cache-busting and compared by SHA-256 to
  `main`: index.html `0269b78317bbff2a`, methodology.html `8e7ecebf3dc44dca`,
  og-image.png `5a6f7ac9f9ea217b`, site/site.css `99ca1a07c1185d69`,
  site/theme.js `0af9db582c0cda35`, SourceSerif4-Regular.woff2
  `1c1814f7eb72a72e` - **all six identical**. The stage-three commit link
  that returned 404 before the push returns 200. This bullet is itself
  pushed in a further stamp commit, which the same comparison will follow;
  it is not re-recorded here.

## 2026-09-02 — presentation pass close-out: references verified, Lloyd gloss corrected, hierarchy fix, en-GB, print justification, process comments removed, post-hoc review recorded

The close of the September presentation pass. Presentation only. **No model,
no specification and no recomputation**; nothing under `data/predictions/`,
no science-layer file and no science output touched. 169 -> 179 tests, all
green. The science layer reopens for the model batch after this entry; no
model-layer work was begun in this session.

- **The author has reviewed and approved the stage-two prose, today.** The
  six placeholder replacements, the contribution paragraph, "Why this
  lexicon" and the two limitations - all recorded verbatim in the stage-two
  entry of 2026-09-02 - stand as written. This is the post-hoc review that
  entry said was outstanding, and it closes the only open item the pass
  carried into production.
- **The author, not "the maintainer".** The 2 September entries and the code
  comments written that day referred to the author in the third person and,
  where a pronoun was needed, in the singular they. Both are replaced with
  "the author" throughout **today's entries and comments only**; earlier
  entries are untouched, as always.

### References: seven entries, each checked against a primary source

The [VERIFY] markers are gone, and with them the note on both pages that
said which entries were unchecked, the `.verify` span, its CSS rule and its
`title` attribute. `RELATED_WORK` in `pipeline/build_fallbacks.py` now
carries a `venue` and a `url` per entry, and the renderer puts the link on
the venue. As filed, in this order:

1. Apel, M. and Blix Grimaldi, M. (2012). The Information Content of Central
   Bank Minutes. *Sveriges Riksbank Working Paper Series No. 261.* -
   the dictionary this index implements verbatim, from a retrieved copy of
   the paper.
2. Gerlach-Kristen, P. (2004). Is the MPC's Voting Record Informative about
   Future UK Monetary Policy? *Scandinavian Journal of Economics, 106(2),
   299-313.* <https://www.jstor.org/stable/3440935> - source of the
   vote-skew construction (via Apel and Blix Grimaldi 2012, p.13); finds
   skew predicts rate changes even controlling for market expectations over
   1997-2003, a result this project's 2019-2026 ladder does not reproduce.
3. Hansen, S. and McMahon, M. (2016). Shocking language: Understanding the
   macroeconomic effects of central bank communication. *Journal of
   International Economics, 99(S1), S114-S133.*
   <https://doi.org/10.1016/j.jinteco.2015.12.008> - FOMC communication as
   text, its market and real effects measured in a FAVAR.
4. Bholat, D., Hansen, S., Santos, P. and Schonhardt-Bailey, C. (2015). Text
   mining for central banks. *Centre for Central Banking Studies Handbook
   No. 33, Bank of England.*
   <https://www.bankofengland.co.uk/-/media/boe/files/ccbs/resources/text-mining-for-central-banks.pdf>
   - the Bank's own primer, dictionary methods included.
5. Lloyd, S. P. (2018). Overnight index swap market-based measures of
   monetary policy expectations. *Bank of England Staff Working Paper
   No. 709.*
   <https://www.bankofengland.co.uk/working-paper/2018/overnight-index-swap-market-based-measures-of-monetary-policy-expectations>
   - evidence that UK OIS rates at one to 18 months track expected policy
   rates closely, which is what makes L1 a fair benchmark; the residual
   premium is the first limitation.
6. Gneiting, T. and Raftery, A. E. (2007). Strictly Proper Scoring Rules,
   Prediction, and Estimation. *Journal of the American Statistical
   Association, 102(477), 359-378.*
   <https://doi.org/10.1198/016214506000001437> - Brier and log score as
   strictly proper rules.
7. Diebold, F. X. and Mariano, R. S. (1995). Comparing Predictive Accuracy.
   *Journal of Business & Economic Statistics, 13(3), 253-263.*
   <https://doi.org/10.1080/07350015.1995.10524599> - the test on the loss
   differential scheduled for the September cycle.

- **CORRECTION: the Lloyd (2018) gloss stated the opposite of the paper's
  finding.** It read *"why OIS forwards carry premia as well as
  expectations, the risk-premia limitation"* - filing the paper as evidence
  **for** premia. The paper's finding is the other way round: UK OIS rates
  at horizons of one to 18 months track expected policy rates closely. That
  is a stronger result for this project, not a weaker one, because it is
  what makes L1 a fair benchmark rather than a contaminated one; the
  residual premium is what the first limitation is about. The gloss now says
  so. **The limitation itself is unchanged and still stands** - the
  methodology page's "Risk premia in forwards" entry is a statement about
  the residual, and nothing in it depended on the miscast gloss. Recorded
  explicitly because a citation that says the opposite of its source is
  worse than no citation: it lends the source's authority to a claim the
  source does not make, and it survived a stage of review because the
  sentence read plausibly.
- **Apel and Blix Grimaldi carries no link, deliberately.** Its citation is
  the `citation` field of `pipeline/score/lexicon/abg_2012.json` verbatim,
  and the riksbank.se path that copy was retrieved from (recorded in the
  2026-07-11 baseline-lexicon entry, reached via S-WoPEc) is not a stable
  public URL. A dead link is worse than none.
- **External link check, run by hand on 2026-09-02.** The six new venue URLs
  join the list automatically, because the checker reads the hrefs off the
  pages rather than keeping its own list. All twenty URLs reached: **200**
  for the JSTOR record, the Journal of International Economics DOI, the
  Bank's text-mining handbook PDF, the Bank's Staff Working Paper 709 page,
  the lock tag and repository, DECISIONS.md and README.md on GitHub, the
  live site, methodology page, `#limitations` anchor and og-image, the
  Bank's July 2026 minutes page, the two Bank news releases, and the Actions
  badge and workflow. **403 for the two Taylor & Francis DOIs** (Gneiting
  and Raftery; Diebold and Mariano). Checked before accepting: `doi.org`
  answers both with a 302 to `tandfonline.com`, and Crossref returns the
  exact title, journal, volume, issue, pages and year filed above for each -
  so the identifiers are live and the metadata is confirmed; what refuses is
  the publisher's front door, to a scripted request. The checker now
  distinguishes the two cases: a 403 or 429 is reported as *reached;
  publisher refused the robot*, with the redirect target named, and does not
  fail the run, while a 404 still does. **Reaching a page and being refused
  is not the same as a broken link, and the tool should not say it is.**

### Hierarchy: three blocks out of secondary ink

- **`.fine.substantive { color: var(--ink); }`**, size unchanged, applied to
  exactly three blocks on index.html: "Why the sample sizes differ", "Not
  yet tested: whether the skill differential is distinguishable from zero"
  and "No standard errors are published". They are argument, not apparatus,
  and were being read as footnotes because they were set in the same
  `--ink-2` as one. Nothing else changed colour and `--ink-2` is untouched.
- **Applied in the markup, not in a generator template, and pinned by a
  test.** The brief asked for the template; there is no template to change.
  None of the three blocks is a generated region - two were written in stage
  two and one in July, all as static markup with `fig` regions inside them -
  so the class can only go where the blocks are.
  `pipeline/tests/test_substantive_blocks.py` makes that safe rather than
  incidental: it fails if one of the three loses the class, **if a fourth
  gains it**, if the modifier ever changes the font size, or if
  methodology.html starts using it. A modifier that spreads is a modifier
  that means nothing.
- **`--rule` darkened in the light theme, `#d8d3cb` -> `#c9c3b9`.** The dark
  theme's rule is unchanged. Contrast script output after the change, both
  themes, every pair used:

```
light
  16.64:1  (floor 4.5)  --ink on --paper       body text
   7.38:1  (floor 4.5)  --ink-2 on --paper     secondary text: captions, fine print, axis labels
   5.72:1  (floor 4.5)  --accent on --paper    the Locked badge; the lock marker's legend
  15.15:1  (floor 4.5)  --ink on --stamp       call card text
   6.72:1  (floor 4.5)  --ink-2 on --stamp     call card secondary text
   5.21:1  (floor 4.5)  --accent on --stamp    call card badge, point call, lead probability
   6.22:1  (floor 4.5)  --hawk on --paper      hawkish reading, hike legend
   6.43:1  (floor 4.5)  --dove on --paper      dovish reading, cut legend
   4.87:1  (floor 3.0)  --rate on --paper      Bank Rate axis labels
   6.38:1  (floor 3.0)  --gilt on --paper      gilt sparkline
   6.22:1  (floor 3.0)  --paper on --hawk      labels inside the hike segment
   6.43:1  (floor 3.0)  --paper on --dove      labels inside the cut segment
   9.83:1  (floor 3.0)  --ink on --rule        labels inside the hold segment
dark
  14.78 / 7.99 / 8.53 / 13.75 / 7.43 / 7.93 / 6.24 / 8.00 / 8.77 / 7.81 / 6.24 / 8.00 / 9.62
```

  The only pair the change touches is `--ink` on `--rule`, 11.56 -> **9.83**,
  still more than three times its floor. The rule is a hairline, not a text
  ground, so the pair is checked for the one place a label sits on it: the
  hold segment of the OIS bar.

### Language and print

- **`<html lang="en">` -> `<html lang="en-GB">`** on both pages. No
  generator emits the tag, so there was no template to follow.
- **Justified with hyphenation, in `@media print` only**, on `.prose`,
  `.ep-body p`, `.call-rationale-body`, `.contribution` and
  `.results-framing`. The screen stays ragged-right.
- **Checked in the regenerated PDFs at A4 and Letter, and kept.** The longest
  hyphen ladder anywhere in the four files is **one line** - counted by
  extracting the text layer and looking for consecutive lines ending in a
  hyphen, then confirmed by eye on the episode pages, where the justified
  measure is longest. No rivers: the July episode's argument pages set
  evenly, and the contribution paragraph on page one is the best-set block
  on the page. Nothing was dropped.
- **Consequence, stated because it is visible:** none of those five classes
  appears on methodology.html, whose body paragraphs are plain `<p>` inside
  `.section`. That page therefore prints ragged-right throughout, and the
  two PDFs are set differently. The class list is the one the brief
  specified and was not widened.

### Process comments removed

Every comment recording how the prose came to be written is gone from both
pages, and a test keeps it that way. Removed:

- **index.html**, above the Summary: *"Prose written under the maintainer's
  2 September 2026 instruction to bypass the approval gate; awaiting their
  post-hoc review (DECISIONS.md 2026-09-02, Stage 2)."*
- **methodology.html**, above "Why this lexicon": *"Written under the
  maintainer's 2 September 2026 instruction to bypass the approval gate;
  awaiting their post-hoc review (DECISIONS.md 2026-09-02)."*
- **index.html**, the visible note under Related work, and **methodology.html**,
  the same note under References: *"Entries marked [VERIFY] have not yet been
  checked against the source from this repository; nothing in them has been
  added from memory."* Both now read *"Each entry was checked against a
  primary source."*
- **The seven `[VERIFY]` spans**, their `title="not yet checked against the
  source"`, the `.verify` CSS rule and its entry in the small-caps selector
  list - dead once the markers went.
- **`pipeline/build_fallbacks.py`**, the `RELATED_WORK` header comment
  saying the entries were unverified and that the author would supply the
  verified set; replaced with what is true now.

`pipeline/tests/test_no_process_comments.py` (7 tests) fails if "approval
gate", "bypass", "post-hoc", "awaiting review" or "[verify]" appears - case
insensitively - on either page, the README, the stylesheet, the theme
script, the published episodes or their source markdown. The record of how
the pass was run stays here, in the log, which is where a reader who wants
it will look.

### QA and close

- **179/179 tests green**, including the census over three surfaces, the
  no-draft-marker guard, the new no-process-comment and substantive-block
  guards, the static/JavaScript parity test, the internal link check, and
  the contrast floor in both themes.
- **Captures regenerated and looked at**: both pages at 380, 768 and 1280px
  in both themes, the no-JavaScript render, and A4 and Letter PDFs, under
  `qa/closeout/`.
- **Two spacing defects in the new reference list were found by looking at
  the captures and fixed**: the one-line intro note butted against the first
  citation, because `.fine` carries a top margin and no bottom one (the list
  now has its own top margin); and each gloss wrapped short of the citation
  above it, because `.refs dd` capped its width at 68**ch** measured in its
  own smaller size, which is a narrower column than the `dt`. The cap is
  gone from `.refs dd`; the glossary keeps its own.
- **`git diff --stat main`**: no science module, no locked file, no science
  output - eight files changed, all of them the log, the two pages, the
  generator, the stylesheet and three tests.
- **Deploy check, 2026-09-02, 15:03 BST.** Pushed to `main` and Pages
  reported `built 8565de1` on the sixth poll; the `tests` workflow for the
  push passed. Fetched live with cache-busting and compared by SHA-256:
  index.html `1852909e8f143f63`, methodology.html `02faba9e90dbe9ea`,
  site/site.css `6726bee43cbb8f55`, og-image.png `5a6f7ac9f9ea217b` -
  **all four identical to `main`**. The share card is byte-identical to the
  one deployed this morning, as it should be: nothing in this session
  touched the series it draws.

## 2026-09-16 — September lock: announcement-minus-one, vote-split distribution pre-registered, second series deferred, rehearsal recorded, near-node clipping noted

Written before the September lock, in the records commit that precedes it.
No science module is changed. The only code change is in the site layer:
a per-meeting override table for the "next lock" date the pages show.

### The lock date moves from 15 to 16 September (announcement-minus-one)

- The July lock followed the announcement-minus-two convention (28 July for
  30 July). The September lock is taken on **16 September 2026**, one day
  before the announcement, so that the call can use the August CPI release
  published at 07:00 BST on 16 September. This is a deviation from July's
  convention, decided and recorded here before the lock is written. The
  lock must therefore be timestamped after 07:00 BST on 16 September and
  the tag pushed before 12:00 BST on 17 September.
- **Site surfaces.** `pipeline/site_figures.py` gains `LOCK_DATE_OVERRIDES`,
  a table of live locks that deviate from the convention, consulted by
  `lock_date_for()` before the announcement-minus-`LOCK_DATE_OFFSET_DAYS`
  rule. The historical benchmark in `pipeline/build_market_history.py` is
  untouched: the constant and every historical lock date in
  `data/market_history.csv` stand. The status line on both pages, the
  pending row in the track record and the README lock line were regenerated
  through `build_fallbacks` and now read 16 September 2026; nothing
  generated was edited by hand. `test_status_and_pending.py` asserts the
  override for September and the convention for November (3 November).
- **The September runbook is `LOCKDAY-2026-09.md`**: the author's
  instructions for this lock, saved verbatim before the lock commit.
  The July episode's commitment was that the runbook and the vote-split
  pre-registration would exist before the September lock; neither did at
  the start of the session, and both are written now, in this commit.

### Pre-registration: the vote split as a scored distribution

- From this meeting onward the vote split is a scored call, not an unscored
  ancillary. It is scored with a **multi-category Brier score over the
  number of votes for a hike**, alongside the decision call.
- The September distribution, fixed here before the lock:

  | votes for a hike | probability |
  |---|---|
  | 0–2 | 0.10 |
  | 3 | 0.50 |
  | 4 | 0.20 |
  | 5 or more (a hike) | 0.20 |

- Both the vote-split distribution and the shaded decision distribution
  (cut 0.00 / hold 0.80 / hike 0.20) are scored after the announcement with
  the Brier score summed over outcome bins, the form defined in the site
  glossary and used for m0 (July: 0.0030). The pipeline scores m0 only, so
  these two scores are computed by hand and recorded in the
  post-announcement DECISIONS entry.

### The risk-management second series is deferred to the November lock

- The July episode proposed a second series counting risk-management
  language, to be specified and pre-registered before the September lock
  and run over the full sample from January 2019 under the expanding-window
  protocol. It is **not** specified tonight. A specification written and
  run over the full sample in one evening would not meet the
  pre-registration standard the July episode set, and a specification
  written tonight without being run would be pre-registered in name only.
  It is deferred to the November lock, to be written in its own brief with
  time to be read before it is run.

### The rehearsal: an uncommitted lock file, renamed

- At 11:22 BST today (`lock_timestamp` 2026-09-16T10:22:59+00:00) the lock
  command was run once, on the 14 September curve, and wrote
  `data/predictions/lock-2026-09.json` with `point_call` null and the
  placeholder rationale. It gave m0 p_hike **25.17%** (forward 3.7941%,
  SONIA 3.7312%, implied change 6.29bp). It was never committed or tagged.
- Because a `lock-*` file is never modified once written, the file was
  **renamed, contents untouched**, to
  `data/predictions/rehearsal-2026-09-16.json` (SHA-256
  `ad30c0b5765adfc8e11d6884d2991ea5a050f41dc9642f88c3faf3b5b28312bc`).
  The site's newest-lock rule ignores it, as it ignores the July
  rehearsals. Its `index_trailing_mean` is 1.2203, not the 1.2202 the
  runbook expected; the fresh lock's value is checked at lock time.
- Before the rename the suite stood at 7 failed, 172 passed - every failure
  the site treating the stray file as the newest lock against HTML that
  still said July. After the rename: 179 passed.
- **The lock is taken on the freshest curve available at lock time**, per
  the existing convention. At the time of writing that is the 15 September
  curve, on which m0 p_hike reads 28.92%. That choice follows the rule, not
  the resulting number; the rehearsal's 25.17% is recorded here so the
  difference is on the record.

### Finding: the meeting-plus-three read clips to the first maturity node

- `market_probs_for_meeting` reads the forward at meeting plus
  `LOCK_OFFSET_DAYS` (3) days. On a curve dated 15 September, meeting plus
  three (20 September) is **0.164 months** out, below the curve's first
  node at 1.000 month, and the read is **clipped to that node**: a forward
  dated 15 October 2026 (3.8035% on the 15 September curve). The
  probability is therefore taken from a forward about one month out, not
  at meeting plus three, whenever the curve is less than a month old at
  lock time. The first four nodes on that curve: 15 October 3.8035%,
  15 November 3.9483%, 15 December 4.0902%, 15 January 4.2245%.
- Recorded as a finding only. No code is changed before the lock; the
  September call's rationale addresses it in words, and whether the read
  should change is a question for after the September outcome, under the
  forward-only rule.

### Lock-commit addendum: two site-layer fixes the fresh lock exposed

- **`build_fallbacks.build_call` crashed on an unscored lock.** Line 435
  read `lock["scores"]["m0_market_only"]["brier_score"]` unconditionally;
  it was written on 10 August (`e340cbf`) when the only lock on disk was
  July's, already scored, so the locked-but-unscored state that every fresh
  lock passes through was never exercised. The lookups are now guarded and
  the outcome block is emitted empty and `hidden` until `score_outcomes`
  has run - the same rule the page script applies - so the static and
  scripted card agree in both states.
- **`test_static_fallback.py` pinned `lock-2026-07.json` by name.** It now
  reads the lock through `site_figures.prediction_file()`, the newest-lock
  rule the generator uses, so it follows each new lock. Its outcome test
  skips, as designed, until the September call is scored.
- Suite: 178 passed, 1 skipped. The lock file itself was written by
  `pipeline.predict.lock` and then had only `point_call` and `rationale`
  filled in by the author; nothing in it was touched by either fix.

## 2026-09-17 — structure pass landed from the stash; the lock-commit false alarm in the stamp guard fixed

Site layer only, the morning of the announcement. `lock-2026-09.json`,
`lock-2026-07.json` and both tags are untouched; no science module, no
schema. Tests 179 -> 196 (195 passed, 1 skipped until September is scored,
plus the new episodes-page test).

### The structure pass, set aside on 16 September, lands

- The stash "structure pass (stat strip, takeaways, episodes.html) - set
  aside 2026-09-16 before the contrast/disclosure pass" was the author's
  front-page restructuring, based on `c0c7695`, complete with its untracked
  template and test. Applied on a throwaway branch over the four lock-day
  commits: one conflict, inside the generated `call` region, resolved by
  taking the stashed markup and regenerating. As landed:
  - **A stat strip under the masthead**: Bank Rate and the next decision,
    locked calls, the best tone model's skill against the curve, the corpus
    size. Every figure from `site_figures.figures()`.
  - **The episode notes move to their own page, `episodes.html`**, with a
    contents list; the front page keeps a standfirst per episode linking
    through. `episodes.html` joins the link, draft-marker, process-comment,
    figure-census and screenshot sweeps.
  - **The call card shows the point call and first sentence, with the full
    rationale in an open disclosure** beneath it; the static/JavaScript
    parity test covers the split.
  - The pass's own citations read "DECISIONS.md 2026-09-02, structure
    pass", an entry that was never written. They now cite this one.
- **One wording change to the pass.** The strip's locked-calls sub-label
  read "1 correct" against a count of 2, which with September unscored
  reads as one miss. `site_figures.locked_calls()` now returns the scored
  count as well, and the sub-label reads "1 correct of 1 scored" - the
  strip never counts an unscored call as a hit or a miss.
- The stash is dropped once this is pushed and seen live.

### The stamp guard's false alarm on the lock commit

- `test_build_info_fresh.py` allowed one unstamped state: HEAD is a
  stamp-only commit for the commit `build_info.json` names. LOCKDAY rule 4
  creates a second on purpose - the lock commit is left unstamped so the
  `lock-*` tag sits on it and the stamp follows - and on 16 September the
  suite reported that as a failure on the tag ref and on the `main` push
  that carried it (173 passed otherwise). A test that reports a problem
  that is not one is worse than none, the day before it is run under time
  pressure.
- The guard now recognises a commit that **adds a
  `data/predictions/lock-*.json`** and holds it to the lock shape instead:
  `build_info.json` must name HEAD~2 and HEAD~1 must be a stamp-only
  commit. Checked both ways in a worktree: the `lock-2026-09` commit passes;
  `97e8180`, an unstamped records commit with the same HEAD~2/HEAD~1 shape
  and no lock file, still fails with the original message.
- **And a second false alarm, found when this entry reached CI.**
  `test_decisions_dates.py` compared entry dates with the runner's own
  date, which is UTC: at 23:25 UTC on 16 September it rejected this entry,
  dated 17 September from `date` on the author's clock, as future-dated.
  The guard now takes "today" in Europe/London, the clock CLAUDE.md's rule
  refers to. It still catches what it was written for - dates invented on
  an assumed cadence run days ahead, not an hour.

## 2026-10-04 — September outcome scored; the shaded and vote-split distributions scored by hand

The post-announcement entry the 2026-09-16 pre-registration calls for.
`lock-2026-07.json` and both tags are untouched; no science module, no
schema, no code.

### The outcome

- At the meeting ending 16 September, announced 17 September 2026, the MPC
  voted **6–3 to maintain Bank Rate at 3.75%**; Greene, Mann and Pill voted
  to raise it by 0.25 percentage points, to 4%. Checked against the Bank's
  own page (`monetary-policy-summary-and-minutes/2026/september-2026`) before
  the outcome was written.
- `score_outcomes` was run with `hold`. `git diff` on `lock-2026-09.json`
  touches `outcome` and `scores` only, the documented exception (LOCKDAY.md,
  rule 3). A byte-identical scored copy of the file was already sitting
  uncommitted in the working tree from an earlier run; re-running the scorer
  reproduced it exactly (blob `9c90d18`).
- Scored 17 days after the announcement, not on the day. Nothing in the
  record depends on when the scorer runs; the `lock-2026-09` tag fixes the
  call as it stood before the announcement.

### Scores (Brier summed over outcome bins; lower is better)

| forecast | distribution | Brier | log |
|---|---|---|---|
| m0, market only (pipeline) | cut 0 / hold 71.08 / hike 28.92 | 0.1673 | 0.3414 |
| the author's shaded call (by hand) | cut 0 / hold 80 / hike 20 | 0.0800 | 0.2231 |
| always-hold reference (pipeline) | hold 100 | 0.0000 | 0.0000 |

- **Vote split, scored for the first time** (by hand, against the
  distribution pre-registered on 2026-09-16; outcome: three votes for a
  hike): 0–2 at 0.10, **3 at 0.50**, 4 at 0.20, 5 or more at 0.20 gives
  Brier (0.5)² + 0.1² + 0.2² + 0.2² = **0.3400**; log score −ln 0.5 = 0.6931.
- The shading below m0 lowered the Brier score from 0.1673 to 0.0800 at this
  meeting. That is one outcome; it is not evidence that the shading reason
  (the one-month clip) is right, which remains to be tested against the
  November lock as the rationale says.
- The schema holds m0 only, so the two hand scores live here, not in the
  lock file. Computed with `score_outcomes.brier_score` / `log_score`
  imported read-only.

### Finding, recorded only: the contribution sentence's month token rolls with each lock

- index.html's Summary says "the {fig:lock_month} episode found that the
  vote turned on forward-risk language the lexicon does not measure". As
  written on 2026-09-02 the token rendered "July 2026", and the July episode
  makes exactly that claim. `lock_month` is the newest lock's month, so the
  September lock commit (`4f38477`) re-rendered it as "September 2026", and
  the November lock will make it "November 2026". Left as it stands at the
  author's instruction pending the September episode; not changed here.

### Index reading

- The September minutes are not yet ingested (corpus 95 documents, last
  `minutes-2026-07`), so the reading is unchanged from the lock: 0.6667
  (`minutes-2026-07`) against a trailing four-document mean of 1.2203.

## 2026-10-05 — a generated figure reassigned a finding to the wrong month; episodes page joins the build stamp

Site layer only. No science module, no schema, no data file; both lock files
and both tags untouched. Tests 196 -> 197.

### The contribution sentence: July, hard-coded

- **What happened.** On 2026-09-02 the Summary's contribution paragraph was
  written as "the {fig:lock_month} episode found that the vote turned on
  forward-risk language the lexicon does not measure". `lock_month` is the
  month of the newest `data/predictions/lock-*.json`. It rendered "July 2026",
  which was true: the finding is the 30 July episode's. When the September
  lock landed (`4f38477`, 16 September) the generator re-rendered it as
  "September 2026", and it stood live for nineteen days attributing July's
  finding to an episode that had not been written. Nothing failed. At the
  November lock it would have moved again.
- **Why the guards missed it.** The figure census exists to catch prose
  drifting from data, but it checks that every number is *generated*; this
  one was. The census was satisfied by exactly the binding that caused the
  error. A finding belongs to the episode that made it, which is a fixed
  fact, not a figure that follows the newest file. Binding it to a moving
  figure is the error; regenerating it faithfully is how the error spread.
- **The fix.** index.html now reads "the July 2026 episode" as plain text.
  `lock_month` had no other use and is removed from `site_figures.figures()`
  rather than left for the dead-figure test to pass by accident ("September
  2026" is a substring of the call card's "17 September 2026"). The phrase is
  in the census allowlist (`NOT_A_FIGURE`) with this reason, so any other
  digit in that sentence still fails.
- The 2026-10-04 entry recorded the sentence as "left as it stands"; this
  supersedes that, at the author's instruction.
- The rule this leaves: **a generated figure is for a quantity, not for the
  identity of the evidence behind a claim.**

### episodes.html joins the build stamp

- `episodes.html` arrived with the structure pass (2026-09-17) carrying both
  stamp regions, but `build_build_info.PAGES` and the stamp guard's
  `STAMP_ONLY_FILES` listed only index.html and methodology.html. Its footer
  had read "2 September 2026 (`e8df517`)" since it was created, and its own
  comment claimed `test_static_fallback.py` would fail on that drift; the
  test did not cover it. On 2026-10-04 the gap failed CI once, when a stamp
  commit carried a regenerated episodes.html stamp the guard did not allow.
- Now covered in all four places: `build_build_info.PAGES`,
  `STAMP_ONLY_FILES`, `test_build_info_fallback_matches_json` (parametrised
  over all three pages), and `test_status_and_pending.PAGES` (its two
  "both pages" tests renamed "every page"). Both new checks failed on the
  stale stamp before it was regenerated - the guard working, not a defect.

## 2026-10-05 — dated claims: no generated figure inside a statement about what a figure said at a past date

Site layer only; no science module, schema, data file or lock file touched.
Tests 197 -> 198.

### The rule

- **A generated figure must never appear inside text that makes a dated
  claim about what a figure said at a past date.** A `{fig:}` token always
  renders the current value; placed under an old date it turns a true
  historical statement into a false one at the next rebuild, silently and
  with every guard satisfied. Dated claims are typed, with the value as it
  stood on that date, and they stay typed.
- Generated figures remain the rule for *current* claims ("the ladder reads
  ..."), which is what they are for. The test is the sentence, not the
  number: if the sentence carries a date the value belongs to, the value is
  history.

### This is the second instance

- **First** (entry above, same date): the Summary's "{fig:lock_month}
  episode found ..." reassigned the July episode's finding to September when
  the September lock landed.
- **Second**: the July episode's editor's note, added in September, reads
  "The ladder was re-run on 10 August after the July minutes were ingested
  and now reads {fig:l3_skill} / {fig:spec2_p} — Ed., September 2026." The
  September ingest (run locally on 2026-10-05, not yet published when this
  was written) moves L3 skill to −0.6250 and Spec 2 to p = 0.4997; republished
  as it stood, the note would have said the 10 August re-run produced them.
  Caught by reading the failing `test_annotations_json_carries_resolved_figure_tokens`
  before regenerating, not by any guard designed for it.
- **The fix**: the note's figures are typed as the 10 August values,
  −0.6712 / 0.4894, in `site/annotations/2026-07-the-minority-grew.md`.
  The rendered page does not change in this commit, because those are still
  the published values; the difference appears when the ingest lands.

### The guard, and why it is not a census allowlist entry

- The author asked for both figures to be allowlisted in the census
  (`NOT_A_FIGURE`). They cannot be: the census strips every generated region
  before counting, and the episode bodies on `episodes.html` sit inside the
  generated `episodes` region, so the census never reads them - which is
  also why the note's neighbouring typed figures (−0.6729, 0.4918) have
  never needed entries. An entry would match nothing, and
  `test_the_allowlist_has_no_stale_entries` fails on exactly that.
- Instead, `test_no_figure_token_inside_a_dated_editors_note` reads the
  episode sources directly: no `{fig:}` token inside any `[... — Ed. ...]`
  note, and the July note carries −0.6712 / 0.4894. Checked both ways: it
  finds the note (one match) and fails on the old tokenised text.
- It holds the rule only for editor's notes, the one form a dated claim takes
  that a test can recognise. A dated claim written as ordinary prose is held
  by the rule above and by reading, not by a test.

## 2026-10-05 — September ingest: corpus to 96, results republished

Routine ingest. **No methodology changed**: the lexicon, the scoring rules,
the ladder specifications and the inference specifications are untouched,
and both lock files are byte-identical. What changed is the sample the frozen
methods run over. Numbers shown to the author before publication.

- **Scraped `2026-09-minutes.txt`** (meeting ending 16 September, announced
  17 September) with `pipeline.scrape.minutes 2026 september` - the per-month
  function `scrape.era` calls - not the full era run. **Deviation, and why**:
  `scrape.era` re-fetches every month from August 2015 and overwrites each raw
  `.txt`, which would replace the 52 PDF-reconstructed documents with the
  Bank's summary-only HTML while `source_kind.json` went on labelling them
  `pdf`. `data/raw/` is gitignored, so no diff would show it. `backfill_pdf`
  then recorded `source_kind: html` (dry-checked first: no file was
  summary-only, so it fetched nothing). `data/raw/` was backed up before the
  scrape and compared after: one new text file, its HTML and one
  `source_kind` key, nothing else.
- **7,739 words**, the longest 2026 document but inside the corpus range
  (Q3 6,552, max 9,606). Checked rather than waved through: minute
  paragraphs run 1-53 without a gap or repeat, the vote sentence appears
  once, and the text ends on the full membership list (nine members,
  Treasury representative); the page furniture before and after is the
  same size as July's. The length is the annual APF gilt-sales section.
  No HARD STOP.
- **Every rebuild diffed, all purely additive**: `index.json` 95 -> 96,
  0 existing documents changed; `votes.csv` 95 -> 96 meetings, 851 -> 860
  rows, 0 existing rows changed (Greene, Mann, Pill at 4.00%); 
  `market_history.csv` 95 -> 96 and `surprises.csv` 92 -> 93, 0 existing
  rows changed. `surprises.csv` is rebuilt because Spec 3 reads it.
  `test_corpus_and_voting_record_dates_match_one_to_one_within_tolerance`
  passes.
- **The benchmark's September row is not the lock's m0.** `market_history`
  gives p_hike 0.2932 (SONIA 3.7302 dated 15 September); the lock recorded
  0.2892 (SONIA 3.7312, the latest available at lock time, dated 14
  September). Same forward, 3.8035. Two documented paths, not a defect.
- **September's A&BG reading is 1.3333 - hawkish, not dovish.** The 30 July
  episode predicted the realised-inflation lexicon would read dovish while
  the hawkish minority held; at this meeting it did not. Trailing 4-document
  mean 1.2203 over the four preceding documents (the inspector's
  convention), 1.1786 including September (the lock files' convention).
  **6 hits, 4 hawkish and 2 dovish** - above the corpus Q3 of 3, still thin:
  two fewer hawkish hits would read neutral. Three of the four hawkish hits
  are conditional, forward-looking sentences ("might feed into higher wage
  settlements", "could increase inflationary pressures", "into higher prices
  if the conflict persisted"); "strong" and "weak inflationary" fire on the
  one sentence restating July's risk balance. Recorded as observation; the
  interpretation is the episode's.
- **Results republished on 96 documents. The finding is unchanged - no
  text-augmented model beats market pricing - but the skill scores moved
  materially towards zero on one meeting.** n_scheduled 61 -> 62. L1 Brier
  0.0891 -> 0.0904 (September was a poor meeting for the curve: m0 Brier
  0.1673). Skill vs L1: L2 −0.1167 -> −0.0841, L3 −0.6712 -> −0.6250,
  L4 −0.8148 -> −0.7611.
- **Spec 3 does not cross 0.05**: n 92 -> 93, p **0.0310 -> 0.0375**, moving
  less significant. The skew-controlled variant moves 0.0373 -> **0.0477**,
  0.0023 short of the line. Spec 2 stays null (0.4894 -> 0.4997). Fragility
  subsample n 24 -> 25, p 0.1221 -> 0.1777; its Spec 2 fits still do not
  converge, as before.
- **Lexicon sparsity unchanged on 96**: median 2, Q1 1, Q3 3, min 0, max 12.
- **Regenerated, not hand-edited**: index.html, methodology.html,
  episodes.html, README.md through `build_fallbacks`; `og-image.png` from
  the 96-document series. The July episode's editor's note stays at the
  10 August values (entry above).
- **Not rebuilt, deliberately, as in August**: `site_context.json` (its Bank
  Rate panel still reads "latest, 30 July 2026"), `member_behaviour_v1.json`,
  `validation_v1.json`. Flagged so the omission is on the record.

## 2026-10-06 - Interactive homepage (presentation only)

At the author's request, the homepage moves from the paper-style layout to
an interactive research dashboard, informed by the Bank of England's Bank
Rate explainer. The earlier presentation decisions remain on the record.

- The meeting selector and chart-period controls display existing minutes
  and readings from `data/index.json`. A selected meeting shows its own vote
  and dictionary-hit counts alongside the next observed decision, explicitly
  distinguished from the decision published with those minutes.
- Chart-period filters change the displayed history only. They do not
  recompute or subset the ladder, inference, or locked-call scores.
- The forecasting comparison switches between the published Brier, log and
  skill scores. Market pricing is the benchmark; the always-hold reference
  can be included. The full score table remains available, including when
  scripts or data requests fail.
- The statistical result is displayed beside the later-sample check and the
  discrete-decision test. The small live record and the untested significance
  of the skill difference remain explicit.
- No science-layer code, lexicon, data schema, stored result, annotation or
  locked prediction is changed. Existing generated figures and rationale
  text are preserved; the changes concern layout, copy and interaction.

## 2026-10-10 - Audit corrections and prospective safety guards

The author explicitly authorised changes to the science-layer code after
the redesign audit. This entry records corrections to the description of
v1 and operational safeguards, not a new experiment or revised result.

- The v1 historical benchmark requests meeting plus three days from a curve
  dated two calendar days before the announcement. Its requested maturity
  is therefore five days; the cached workbooks start at one month. The
  endpoint-clipping rule uses that first node in every historical row.
  The offset does not correct meeting-date smoothing in this backtest.
  Documentation now calls this an OIS-based proxy, not a meeting-specific
  probability distribution. The v1 calculation and stored results stay fixed.
- Curve valuation dates and SONIA reference dates are not publication times.
  The historical archive is revised and the backtest does not reconstruct
  vintage public availability at a timestamped two-day-before cutoff. A
  future release-aware benchmark requires separately versioned data and
  evaluation; none is substituted here.
- New prediction files must have safe names, precede the meeting, and be
  created exclusively. Existing files cannot be overwritten, including by
  a concurrent writer. Future-dated curves are rejected. The existing
  outcome-scoring exception remains the only way to append realised scores;
  an already scored file is left byte-identical and conflicting rescoring
  stops for an erratum rather than replacing an outcome.
- Cached minutes are preserved on routine scraping, including PDF-derived
  text. Non-404 HTTP failures stop the era run. Fresh reconstruction needs
  PDF backfill, emergency documents and the documented manual repairs;
  setup instructions no longer imply an HTML scrape alone reproduces it.
  The index builder also refuses a routine rebuild that drops or replaces
  an existing document hash or source kind.
- Missing vote splits remain missing, not imputed. Chart filters affect
  display only; decision markers denote the decision accompanying those
  minutes, not the next decision. Archived context is labelled as archived.
- Later-sample nonsignificance is described as uncertainty, not evidence
  that the coefficient disappears. L3 tests tone and vote skew jointly;
  L4 is not a tone model. Its majority-state and roster assumptions remain
  limitations of v1. Any retrospectively designed lexicon is exploratory.
- Presentation, metadata and regression tests are updated. Locked calls,
  numerical research results, handwritten episodes, earlier log entries
  and the date-integrity errata are not rewritten.
- A hypothetical probability slider illustrates the existing three-class
  Brier formula. It is not a forecast, observation or additional experiment.
  Browser regression tests now run in CI as well as locally.
- Invalid or non-finite curve inputs and probability distributions stop
  before mapping or scoring; valid inputs retain exactly the v1 arithmetic.
  PDF provenance is checkpointed after each replacement so a later fetch
  failure does not leave earlier replacements labelled as HTML.

## 2026-10-11 - Linked references and plain-language statistical explanations

Presentation only, at the author's request. The bibliography now links each
paper directly, without venue details or interpretive glosses. The Apel and
Blix Grimaldi paper is linked to the verified Riksbank archive PDF. Inline
source notes become descriptive links to the existing code, data and log.

Short explanations distinguish historical association, historical model fit
and out-of-sample forecasting. Regression slopes, ordered logit, likelihood
ratios, p-values and Newey-West uncertainty are explained before the detailed
specifications. The remaining market-benchmark summary is aligned with the
first-node clipping limitation recorded above. No new test is run, no result
is recalculated and no science-layer module, locked call, handwritten episode
or earlier decision-log entry is changed by this presentation pass.

## 2026-10-11 - Homepage project introduction

At the author's request, a short introduction now precedes the findings and
in-page navigation. It names the research question, the author, the fixed
dictionary, the market comparison and the prospective lock-and-score record.
This is explanatory copy only; no methodology, result or locked call changes.

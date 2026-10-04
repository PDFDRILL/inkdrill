# HANDOVER — inkdrill

Written 2026-08-21, last revised 2026-09-06. Read `docs/state.md` for
the full record; this is the page you need to resume.

## What this is now

Scan-event topology, stdlib only. Beyond the fifteen units, the working
surface is a **findings channel**: given a formula report (pdfdrill's
`report.pdf`) it compares each equation's *rendered* cell against its
*scan* cell and reports where a conversion and the printed page
disagree. The residual is the product.

**CLI:** `compare`, `topology`, `template`, `locate`, `residual`
(`python3 -m inkdrill <cmd>`). **Harnesses:** `tools/reportcompare.py`,
`mathpixcoverage.py`, `noisefloor.py`, `abdiff.py`, `bookprofile.py`,
`inkfit.py`, `punctprofile.py`, `threeway.py`, gated by
`tools/corpusgate.py`, vocabulary in `tools/findings.py`.

**Three modules are off the CLI path on purpose** and recorded with
their reason in `tests/test_reachability.py`'s `OFF_THE_CLI_PATH`:

| module | what it is |
|---|---|
| `skeleton.py` | Zhang-Suen thinning, the junction count and `parts()` (491, 498). Measured across 20 font-blocks and NOT wired in — 26% of glyphs change their junction count with size |
| `rowjoin.py` | a report's table manifest joined to its text layer: `(table, row) -> (page, identifier)` (597). Takes TEXT, not a path |
| `cellrect.py` | a cell's rect from emitted rule positions (602). Numbers in, `Rect` out; no raster |

**Suite:** 1,188 tests, 37 skipped (opt-in corpus/font modules).

## The measured constants — quote the population with the number

| constant | value | population it was measured on |
|---|---|---|
| `NOISE_DISTANCE` | **7** | p95 of 813 rows where the MathPix LaTeX equals the author's AND carries no multi-line/array environment, render-vs-scan |
| `NOISE_COMP_DELTA` | **2** | same control; 1.6% false positives |
| cell floor | 3× median component height | a cell is bigger than the text in it |
| stacked gap bound | 1.5× median component height | without it the count measures line spacing |
| column floor | 2% of table span, **content-decided** | width is a pre-filter only |
| report lattice dpi | **≥200** | below it, scan cells merge with their rules |
| MathPix's render | **250 dpi** | derived from page raster / MediaBox, exactly 250.0 on four of four comparable documents (591). NOT 300, and a crop carries no usable density of its own |
| ring channel floor | **p99 0.890 holes/component** | 400 crops from 93,028 across 856 documents; not one reaches 2.0, against the ~3.4 where hole counts become speckle (591) |
| `\mathcal` junction cut | **4** | derived from the exception (txfonts G) not the gap; holds on CM, LM and XITS, fails on txfonts (495, 497) |

Current findings, 49 of 49 P13 documents: **4,262 rows, ~399 findings
(9.4%), 228 in the component channel.** STALE — see open item 9: 32 of
37 sampled documents have a compare TSV older than their report.pdf,
so this describes a corpus that has since been rebuilt more than once.
Treat it as history until a fresh pass lands.

**Every measured figure since 495 is in `out/NNN.txt`, 63 files, one
per task, each carrying its population, its split rule and the command
that reproduces it.** `git log --diff-filter=A -- out/NNN.txt` dates
one; do not use `git log -1` on it, which returns whatever retrofit
last touched the file.

## Open items

1. **`tools/threeway.py` hardcodes a session `/tmp` path** (lines
   51–52). Broken for any other session; give it `reportcompare.py`'s
   `$INKDRILL_WORK` treatment. Until then `scratchpad/p13cmp` (1.4G)
   cannot be deleted. See `out/074.txt`.
2. **`docs/units.md` states 635 tests** (now 1,072) and documents none
   of the five subcommands. See `out/076.txt`.
3. **`docs/state.md` S5 states the retired floor of 6 in the present
   tense.** Correct as history, wrong as a claim; mark it superseded,
   do not delete it.
4. **`1511.08771` is still in `~/pdfdrill-library/P13-arxiv-reports.txt`**
   so every consumer filters it at use. Whether the roster should mean
   the operative corpus is the user's call; neither session edits it
   unilaterally.
5. **`prune()` unused by `emit`**; CFG parser undecided; `group()`
   absorbs an inline limit — all need symbol identity.
6. ~~The compare probe still selects 5-column pages~~ **CLOSED.**
   `pagedetect.target_columns` reads the count from each document's
   own `report.tex` (the header carrying both `Rendered` and `Scan
   image`), so both eras work. 496 measured 843 documents at 6 and
   492 with no scan column at all. **And 595 then made the whole
   mechanism unnecessary** — see the manifest section below: a run's
   column count cannot identify a table anyway, and 601 §4 showed the
   count is not even stable, reading 6 at 300 dpi where it reads 5 at
   150.
7. **`0902.0431`'s render cache has a 16-page hole** (113–115,
   118–130), so `overrun.py` withholds identifiers for its 320
   flagged rows and three of the four cases pdfdrill confirmed by eye
   are unverifiable. Every one of those pages carries maths objects —
   the gap is the cache, not the document. Sixteen ghostscript calls.
8. **`out/102.txt` is measured against the render cache as it stood
   at 14:11 on 2026-08-22.** pdfdrill's tail-split fix (their open
   item 9) changes crop rectangles corpus-wide; when it lands those
   numbers describe a corpus that no longer exists and must be
   re-measured. There is no mtime to compare here — **an artifact can
   be stale against its source and a RESULT can be stale against the
   artifact it was measured on**, and only the first has a guard. It
   is held by a message between sessions, which is why it is written
   down.

9. **The corpus figures are stale against the corpus.** 496 found
   **32 of 37** sampled documents with a `report.compare.tsv` OLDER
   than their `report.pdf`, and the corpus-wide `A_eq_B` rate of
   58.6% therefore describes a previous build. Any number quoted from
   `report.compare.tsv` needs its freshness checked first;
   `tools/comparestale.py` does it.

10. **`warp.py`'s docstring prints the numbers of the defect it
    fixed**, under a heading reading `FIXED`. It has now been read as
    current twice, once as the premise of a whole task. The table is
    marked in place and points at `out/581.txt`, but the general
    lesson is in the failure classes below.

11. **The five-tuple's stability is measured and it is not good.**
    496: at 300 vs 600 dpi, **36.2% of rows** change their hole count
    and **16.6% change their finding class**. It concentrates at the
    weakest boundary — 96% of class changes are noise/clean or
    noise/weak, and the `component` class keeps its verdict on 94.3%.
    The cause is the render, not the resolution: the rendered column
    is drawn with anti-aliasing OFF (2 grey levels against the scan's
    256), and turning it on takes hole instability from 75.0% to
    9.4%. **Not acted on** — it moves every recorded distance in the
    corpus, and whether it moves them toward the scan is unmeasured.

12. **The whitespace grid (`tools/wsgrid.py`) is a premise on TWO
    expressions** (out/666, out/667). For the planned Ghostscript overlay
    of empty array cells before MathPix. On 0902.0431 EQ0756 it finds
    two independently aligned blocks (6x14, 4x7), three gutter-width
    classes rather than two, and ZERO empty cells at 300/400/600 dpi,
    agreeing with an eye count. On Johnston EQ0486 (an open linear
    system) it finds one 5x11 block and 8 empty cells, the same 8 as by
    eye -- and that expression exposed two defects (a split taken at
    any leading; a width cut inside one class), both fixed. No suite
    test yet.
    **Then 132 pdfdrill candidates (out/668, `tools/wsgridbatch.py`):
    22 checked by eye, 10 right, 5 partly, 7 wrong.** Six failure
    shapes, named not counted: the region is the display line rather
    than the array (F1), lines fragment on subscripts and dots (F2), one
    continuous width class cuts symbols (F3), merged alignments turn
    margins into empties (F4), the host line is one row of a split
    display (F5), an unaligned row erases the columns under it (F6).
    The `agree` gate held 8 of 8 but selects rows MathPix already reads
    right, so it cannot choose overlay targets. F1, F2 and F6 are the
    next work; only eye-verified grids are handed over. The output record must carry BLOCKS: forced onto one
    lattice, EQ0756 reports 20 "empty" cells that are margins of a
    centred block. What it did find is a residual: ink 14 cells per
    upper row against MathPix's 13, so the last digit column is dropped in
    six rows. Next premise: an array with genuinely blank entries.

13. **More than one LaTeX reading per row** (user, 2026-09-14): the best
    available reading takes the standard field name and every other one
    is kept under its own field name; only the current best is copied
    to the standard fields. pdfminer's reading, when it arrives, has
    correct symbol names. So a residual must NAME the reading it was
    measured against, or it goes stale silently when the standard field
    is re-pointed. Nothing here does that yet.

14. **`formulafind.rows` lost the page of 3,745 equation rows and 23
    formula rows** (out/669, fixed 2026-09-15, found by pdfdrill). The
    page match allowed only `\lowconf{...}` between `\ident{...}` and
    the page cell; pdfdrill also writes `~\eqnum{(11.4)}` and
    `~{\tiny\textbf{[refined: census]}}`. The page is now the first
    cell after the id cell whatever it carries; `eqnum`, `refined` and
    `source` (the un-escaped source cell, the only reading of a
    not-rendered row) are new fields. The formula files never had
    `\eqnum`, so marks and the crop check lost at most the rows pdfdrill
    tagged `[refined: ...]` -- 0707.4470 FO0175 on the 09-12 build.
    **The shape: a producer adds a cell decoration, a parser keyed on the
    old decoration returns None, and None reads as "the producer gave
    none".** A missing page should have been counted, not trusted.

15. **A refined reading needs `formulamarks update`, never `run`**
    (out/670, out/671). The host line is found by equality with
    MathPix's text, so a row pdfdrill refined is looked up by MathPix's
    reading from `*.tiddlers.json` (`formulafind.MATHPIX_FIELD`, today
    `latex`; pdfdrill will rename it `latex_mathpix` -- change that one
    constant when they say it landed). `update` measures only changed
    rows at the STORED scale; a fresh `run` re-votes, and on mielke a
    0.64 -> 0.65 re-vote flipped 8 of 184 marks on rows that had not
    changed. A mark is a function of the vote as well as of the row.
    `classify` takes a pinned `line_h` for the same reason. mielke after
    update: 189 marks, 1,746 unchanged rows identical, 10 new rectangles
    9 right and 1 off by eye. Not handled: 65 rows corpus-wide whose
    shown reading is neither `latex` nor `latex_refined` (fong-spivak's
    `\mathbf` for `\boldsymbol`).

19. **Anti-aliasing is off on the marks path, and the page renders are
    two-level -- except where they are scans** (out/676). `gs` with
    `pgmraw`/`png16m` defaults to no anti-aliasing: `formulafind.render`'s
    output is BYTE-IDENTICAL with and without `-dTextAlphaBits=1
    -dGraphicsAlphaBits=1` (300 and 600 dpi, gs 10.07.1), and both differ
    from `=4`. The flags are now passed anyway, because the default
    belongs to the DEVICE (`pngalpha` anti-aliases) and a template with
    grey edges correlates differently against a hard-edged page.
    `scriptink.py` and two calls in `premise/measure.py` turn it ON
    deliberately; `dpialias.py` compares both.
    THE POPULATION, sampled 5 pages per document over the 21: 26 of 105
    carry real grey. penev_A and penev_B are grey on EVERY sampled page
    (84-96 levels) -- they are SCANS, not renders -- and many first pages
    are scanned covers. "We measure two-level ink" is true of most
    documents and false for those. Item 11's open question (AA on took
    hole instability 75.0% -> 9.4%) is still open and still not acted on.

30. **Verify on the population where the bug CAN appear.** The
    equation-list mapping was checked by eye on four sigma26 rows and
    all four landed exactly on their equations — while the mapping was
    wrong. sigma26's page frames are (1.6, 1.6, 0, 0), so the broken
    mapping and the correct one are IDENTICAL there; the four documents
    that would have exposed it (cardona, voloshin, gilmore,
    kohlhase-omdoc) were not in the check. 181 rows then read as "no
    ink in the declared region" and would have gone to a peer as a
    defect in THEIR list (out/691).
    An eye check is only as good as the sample it runs on, and a sample
    drawn from the easy population cannot fail. Before trusting a
    verification, ask which documents would show the error and whether
    any of them is in it.

29. **Check that the instrument did not CREATE the quantity being
    measured — especially when the first answer is a round 100%**
    (out/690). "How much grey is on these pages" came back as *248 of
    248, 100%*, from `magick -resize 25%`: a resampler that interpolates
    and so puts a grey pixel at every glyph edge, measuring renders
    deliberately produced WITHOUT anti-aliasing. `-sample` is
    nearest-neighbour and gives 32%. The corpus never changed.
    100% of anything should be assumed to be about the method until
    shown otherwise.
    **And narrow the question before answering it.** "How much grey is
    there" has no decision attached and 32% answers nothing. "Is there a
    band blank at 128 and not blank in fact" does — and its answer is a
    RATIO, band density against page density, because a scan is grey
    everywhere: an absolute cut on band greyness would have flagged all
    six scans and been wrong six times.

28. **An identity that changes when the content changes cannot
    detect a content change.** pdfdrill's `equations.json` carries
    `ident = sha(bibkey | page | region | latex)`, unique on 34,317 of
    34,317 rows with zero collisions — and still the wrong key for a
    mark, because the LaTeX is IN it. Re-read a slot, get different
    LaTeX, and the row does not read as "same slot, new content": it
    reads as a NEW row with the old one vanished and any mark on it
    orphaned against an id that exists nowhere. Nothing in the artefact
    says so, and every test that asks only "is it unique?" passes.
    The split is three fields doing three jobs: **identity**
    (bibkey, page, region) — unique by construction, survives a
    re-read; **label** (EQnnnn) — human-facing, renumbers freely;
    **stability** (sha of the content) — same identity with a different
    hash is a stale measurement. One field doing two of these is good
    at neither. Same family as `measured_against`: a measurement must
    be able to notice that its own subject moved.

27. **A PLAUSIBLE AGREEMENT is its own failure class** (out/686 §5).
    I concluded from `counts.not_measured` that marks.json carried no
    per-id reasons and needed a schema change. The ids were in the same
    file one level up, in all 39 sets, 237 rows — and pdfdrill AGREED
    while holding the disproof: they had printed both fields that
    morning and built their reader against the per-id one, replying
    "my reader takes `{id: reason}` already" in the message that
    accepted the premise.
    A plausible number is caught by looking at the artifact; a
    plausible agreement is not, because both sides see a real symptom
    and the stated cause fits it. **A check written from the same
    misreading is not a second opinion** — mine read the same summary
    field and would have agreed forever. Nearly cost a 39-file
    re-emission against evidence already built from it; the correct
    number of files to touch was zero.

26. **A coverage check is a LOWER bound: it cannot see the failure
    that makes coverage look perfect** (out/685, `PAR_SPLIT_FLOOR`).
    683 added "how far down the source did the gold reach", flagged
    under 60%, because sigma26-077 stopped at 27.1% and nothing said
    so. pdfdrill implemented the same check and measured that it would
    NOT have caught their own defect: a CRLF file that came back as one
    chunk SPANS everything, so it scores ~100% — above the healthy
    median, not below it. Their five CRLF documents held the five
    HIGHEST coverage figures.
    The complementary instrument is the paragraph COUNT against source
    SIZE, since a body of several kilobytes is never one paragraph.
    Floor measured over 29 documents: healthy minimum **0.52**
    paragraphs per KB, a single chunk at most **0.029**, so the cut is
    **0.1** — in the MIDDLE of the gap, which is the gutter-constant
    lesson from one task earlier. A test asserts it lies strictly
    between the two populations.
    **The first candidate signal was rejected by its own measurement**:
    the longest paragraph as a share of the body reaches 60.8% in a
    HEALTHY document against 100% for the defect, a 1.6x gap with no
    room for a cut; paragraphs-per-KB gives 18x. Also: this walk is
    CRLF-safe only by accident (`split("\n")` then `.strip()`), so a
    CRLF fixture now asserts it, and the `max(1.0, ...)` divisor is
    tested against the 0-byte source that would otherwise divide by
    zero and stop the run.

25. **"A standard name in a CMEX font is a fallback" is safe — for
    FOUR fonts, and ruinous for the fifth** (out/684,
    `measure.py fallbacks`). pdf2mmd proposed it after a dvips PDF
    rendered a display Sigma as the glyph `X` in `TeX-cmex9`; a
    Claude.ai chat listed it as unverified, so it was measured here.
    cmex7/8/9/10 carry exactly ONE StandardEncoding name, `space`,
    against 113 in cmr10, 59 in cmmi10 and 37 in cmsy10 — so the rule
    is safe for the Computer Modern extension fonts and would distrust
    every italic letter of every formula one family over.
    **But `cmex` is not a family, it is a substring.** `yhcmex` carries
    149 standard names and `lcmex8` 122, legitimately, and FIVE corpus
    documents embed `Yhcmex`. The family has to be resolved before the
    rule is applied; `tests/test_fontnames.py` pins the real name
    shapes, including a subset tag with NO `+` (`VpqhhbCMEX10`), a
    tilde suffix, and `CMEX1048`, which is CMEX10 instance 48 and not a
    1048 pt font.
    **It matters beyond the one paper**: 939 of 2,555 probed documents
    embed a cmex font and 19 name it the dvips way, 18 of them other
    than the paper. 18 instances declare a WinAnsi/MacRoman/Identity-H
    encoding on a maths extension font — a contradiction, and the
    place to look first.
    inkdrill opens no PDF here by design: this is the TeX tree plus
    each document's `pdffonts` probe. Whether a given embedded subset
    exposes a fallback name is pdf2mmd's measurement.

24. **The union of two weak channels transferred; neither channel did**
    (out/683, `measure.py paragraphs`). Paragraph boundaries from ink,
    against the authors' own `\par` structure read from the `.tex`
    beside the PDF. Indent OR gap: 86.5% recall on 20 SIGMA documents,
    88.2% on 13 single-column documents from elsewhere in the library --
    two points apart. The channel CARRYING it swaps over: indent 52.4%
    -> 27.7%, gap 54.0% -> 70.0%. Tuning either alone would have been
    retuned by the next publisher and looked well-founded both times.
    **Two columns break the row-profile band model and it does not
    degrade gracefully** -- single-column recall median 92.9%,
    two-column 18.8%, no overlap. That is the instrument, not the page;
    it is now units.md assumption 10.
    **The residual is the product here too**: a gap below a display with
    no indent is 421 real boundaries against 1,081 continuations on
    SIGMA. The vertical space belongs to the display, and LaTeX sets no
    indent in exactly that case -- nor after a heading, nor under
    `\noindent`. That is where under-segmentation comes from; it is not
    a threshold waiting to be tuned.
    **Three instrument defects came first, two of them producing the
    SAME false conclusion** ("paragraph starts are not indented", which
    is untrue of LaTeX): a gold that broke a paragraph at every display
    (-17%), anchors containing `\cite`/`\ref`/environment names the
    page prints differently (27% -> 90% located), and matching a
    boundary by the reader's box TOP, which includes the leading, so it
    landed on the line above (median indent at a boundary 0.02 -> 1.32).
    Each was found by the measurement disagreeing with the page -- one
    crop settled the third -- never by a test.
    A fourth sat in the SPLIT RULE: the column estimate counted centred
    display equations as a second column, so a one-column maths paper
    was filed under "the instrument cannot see this" with a 93.3%
    recall. Misfiling a result as unmeasurable hides it as well as any
    filter does. Count prose lines only.
    **A sixth, found by pdfdrill's cross-check and not by me**: the
    gold's environment walk counted DEPTH, and sigma26-077 line 261
    writes `\end {pmatrix}` WITH A SPACE. One missed close is
    unrecoverable for a counter, so 83% of that document was skipped in
    silence — 30 paragraphs where there are 107. It now pops a STACK by
    name and prints how far down the source it reached, per document.
    Their mirror defect was a separator regex that did not admit the
    `\r` of a CRLF file, returning a whole paper as ONE paragraph. Same
    class, one character apart, both silent, both returning a plausible
    count. Gold 2,954 -> 3,032; the headline moved 86.5% -> 86.3%.

23. **A reader's geometry is not only its LINES** (out/682). Measuring
    ink against `lines[].region` alone called a full-page TikZ figure
    "100% uncovered"; pdf2mmd records it as a page-level `diagram` plus
    511 `fills`, and six documents' apparent residuals were that blind
    spot, not the reader's. Any new producer: read its page-level keys
    before quoting a residual.
    The sigma26 round (20 documents, 597 pages, a publisher never
    measured here): pdf2mmd covers 99.99-100% of ink, MathPix 98.46% --
    and the whole MathPix residual is the journal's header rule and
    footnote separator, 10,590 px on every page, which only ink finds.
    **The vocabulary defect worth remembering**: pdf2mmd's `math` meant
    PROSE while MathPix's means DISPLAY, so 79.2% of inline spans were
    invisible to the span scanner that skips `math`. pdfdrill fixed it
    at the export boundary (their 844); re-measured here 79.2% -> 17.7%,
    the rest being real display maths. A shared field NAME with an
    inverted meaning is worse than a missing field -- `font_size` had
    the same shape (points vs 250-dpi pixels).
    sigma26-075 keeps BOTH readings for comparison.

22. **`nest` is now checked by a third rule: containment** (out/681,
    `tests/_containment.py`). Parent = the innermost region whose
    ENCLOSED set contains it, where enclosed = what a flood of the
    complement cannot reach from the bounding-box ring. No raster order,
    no neighbour-of-an-extreme-pixel lookup, so it is independent of
    both `nest` and `_hole_attribution`. 0 disagreements over 12
    fixtures, 20 noise masks, 2 checkerboards, 16 corpus windows and 6
    framed-real-ink windows reaching depth 3.
    **The mutation gate is the reason to keep it**: crediting every hole
    to the first ink component is caught by this oracle (16 failures)
    and by `test_nest` (6), and MISSED entirely by `_hole_attribution` --
    its docstring's warning, demonstrated.
    Corpus finding: ink at depth >= 2 lives only inside page-wide frames
    and grids (1,779 and 1,822 px), too large for a pixel oracle in
    Python, and a window cut from one is no longer enclosed. So the
    depth-3 case uses REAL glyph ink inside a DRAWN rectangle -- the one
    semi-synthetic input, stated in the test.

21. **A green suite is not evidence that a file RAN** (out/680).
    `tests/test_pnm_stream.py` imported pytest. Where pytest is missing
    the suite is red; where it is INSTALLED (9.1.1 here) the import
    succeeds, its plain functions are not `TestCase`s, and unittest
    collected ZERO tests from it while reporting OK. Every "full suite
    green" in out/666-679 was green over a file that ran nothing.
    Measured by loading each version by path and asking unittest's own
    loader: old 0 tests, new 9; the suite moved 1,293 -> 1,306.
    **Watch the test COUNT, not the word OK** -- it is the cheapest
    guard against a file that is never collected, and stdlib-only is
    the rule that keeps the question from arising.
    Two new oracles came with it: He/Chao/Suzuki 2013 totals (246 masks
    here, 0 disagreements) and per-component hole attribution (32
    comparisons on real corpus windows, 0 disagreements). The second
    shares `nest.py`'s parent rule, so it can never check nest.

20. **An eye verdict can remove one mark, by id** (out/679).
    `work/suppressed.json` maps a row id to what was SEEN, and `marks`
    reports `suppressed by eye verdict (...)` and draws nothing. Two
    rows carry one: gilmore FO2420 (reading `\alpha`, rectangle over
    `alpha -> Z alpha`) and fong-spivak-seven-sketches FO2524 (half its
    reading). **FO2420 scores 0.9338**, above every threshold in the
    policy, which is the argument for the instrument: moving a constant
    to catch two rows is tuning, a verdict is evidence and travels with
    the mark set for a reader to disagree with. The policy's five
    clauses stay measurements.

18. **DECIDED AND IMPLEMENTED 2026-09-16 at 0.60** (out/677):
    `formularesidual.MARK_SCORE`, the policy's fifth clause, verified on
    27 of the 132 rows it suppresses (9 right, 7 off, 11 wrong).
    NOT PLACED yet -- pdfdrill's host set changes next (diagram, chart,
    page_info, qed_symbol, equation_number, pseudocode out; footnote
    stays), and ONE re-emit per document will carry both.
    The measurement that decided it:

18a. **The fit score is the channel the marking policy lacks** (out/675,
    `tools/marksample.py`). 45 marked rows, banded by score, drawn on
    their host line and judged with the score hidden: every WRONG mark
    is below 0.60, every off-by-a-token below 0.70, and 24 of 24 at
    0.70+ are right. In all six wrong rows MARGIN EQUALS SCORE -- the
    template matches nothing else on the line either, so out/658's
    "position not unique" clause passes them by construction. Margin
    asks how much better the best position is; score asks whether it is
    a match at all. A cut at 0.60 would suppress 132 of 8,383 marks
    (1.6%) and remove every wrong one sampled, costing ~3 right per 13
    (small display matrices, whose rendered template differs from the
    print). NOT ACTED ON: out/658's constants change only with eye
    verdicts, these are 45 of them, and the decision is the user's.

17. **The host-line rule is pdfdrill's and DRIFTED for four days**
    (out/673, out/674). Their 09-12 change -- a span counts only on a
    line that can host a transclusion, and the scan reads
    `text_display or text` -- was not followed here, so 515 rows were
    measured on a line pdfdrill does not crop and it refused 62 marks
    rather than drawing them wrong. Now matched
    (`formulafind.NON_PROSE_HOSTS`, 17 types in their five families) and
    pinned by a test against `docmodel.line_types` when
    `INKDRILL_PDFDRILL_SRC` names their src. `update` gained a host-moved
    trigger; without it a re-hosting cannot be applied, because the
    reading is unchanged. All 21 documents re-emitted and placed: 8,413
    -> 8,383 marks, 0 refused, 29 of 31 new rectangles right by eye.
    **A rule reproduced from another program is a dependency with no
    version.** Only their refusal count made the drift visible.
    Exposed and NOT acted on: the marking policy never looks at the fit
    score (1,850 of 8,383 marks are below 0.80; fong-spivak FO2204 is
    marked at 0.47 on a `diagram` line), and `page_info` is not in their
    excluded set, so a running head can host a formula (8 rows, 4
    marked).

16. **`\FitMath{\emph{(not rendered)}}` is not a reading** (out/672).
    33 rows corpus-wide; `rows()` took it as maths and `update`
    measured the words. Only `$...$` is a reading now (`placeholder`
    keeps the rest), and `marks` says "not rendered" before looking for a
    record. Re-emitting all 21 documents changed no mark. Also found: 15
    of pdfdrill's 136 census-verified refinements do not compile where
    MathPix's reading did -- bracket promotions across `&`, into a brace
    group, or across over/underbrace -- so those rows print the
    placeholder. Reported to pdfdrill; the repair is theirs. Cardona's
    re-emit is not placed until its rebuild finishes.

## Known failure classes — every one cost real time here

- **A control group is only as good as the rule that built it.** The
  floor of 23 survived a doubled sample, 42 documents and an
  independent render route, and was still wrong: 45% of its
  "content-identical" rows were `\begin{aligned}` blocks that another
  tool's metric could not compare. Strong corroboration, about the
  wrong thing.
- **Measure the noise of the comparison you gate, not a neighbouring
  one.** The floor of 6 came from rasterizer-vs-rasterizer.
- **A row with no rendering is not a finding.** Demoted rows print
  `(not rendered)` — 13 components, 6 holes, whatever the equation was
  — and produced 16% of the component class, including its largest
  value. Detect them from the report **tex**, not a compile counter:
  the counter sees 5 of 51.
- **Correct on the small case, wrong on the large one.** Four
  instrument defects this week, each caught by reading data rather
  than a summary: a `(page,row)` diff key reporting reflow as ink, a
  five-field unpack, an `^!` error counter, a brace-blind regex.
- **A pattern verified on a sample lacking the disambiguating case
  cannot fail.** Anchor on something stable; read the residue bucket.
- **Two subtractions of equal size are not a chain** (93−21=72,
  72−21=51; the two 21s are unrelated).
- **An empty result is a defect, not a silence** — P16; and **an
  unexplained delta is a finding** (a +15% page count was a bug).
- **Warn or refuse is decided by what the failure costs, not by how
  bad it sounds.** The same staleness condition: the producer WARNS
  (the user asked for a `.tex` and got one; refusing a successful
  command over a neighbouring file is the tool overriding the
  instruction) and the consumer REFUSES (a stale input silently
  corrupts a two-hour batch). Same rule, opposite output, three times
  in one day — it also settled whether an absent file is named
  (expected for a producer's first run, a real problem for a
  consumer) and whether a message may scroll past.
- **Ask "is there a report to measure", not "is there a file here".**
  `pdf.is_file()` refuses a directory named `report.pdf`;
  `pdf.exists()` calls an old one stale and sends the reader to
  recompile it. The phrasing of the question excluded a case the
  other phrasing admits — accident here, not foresight, and recorded
  as accident because that is the useful part.
- **A fixture must contain the class the rule discriminates against**,
  and its dimensions must come from a measured value.
- **A pooled ratio and a per-unit paired test can point opposite
  ways.** 117: the deficit near a rule was 17.2% against an 11.5%
  null — enrichment — and per row against each row's OWN density it
  inverted, sign test z = -4.88, below its null on 80 rows of 110.
  Sixteen rows carrying 10% of the deficit and 60% of the near count
  is the mechanism. A row with one rule and two missing marks scores
  1.000 by arithmetic, not by evidence. Ask the paired question
  before quoting the pooled one.
- **A ratio whose denominator excludes most of the population is a
  subgroup, not a rate.** 316 of 117's 426 rows had no rule to be
  near. Counting and naming them is what made the 17.2% readable at
  all; dropping them would have quoted a quarter of the population as
  the corpus.
- **Measure the null before quoting the rate.** "17% of missing
  components are near a rule" is unreadable without "and 11.5% of all
  components are". Inherited from pdfdrill's variant B, where 1 of 19
  crops contained the notation the hint addressed, so its +196
  measured the cost of an irrelevant hint rather than the hint.
- **An absence reported as a result is always the reassuring one.**
  Three instances in one day, each a tempting collapse of two states
  that look alike from one end: a table region found with NO SURVIVING
  CELL is not "no table on this page" (it was an empty dict past a
  `is None` guard, and it raised `ValueError` four frames down); a
  ZERO-VS-ZERO comparison is not "clean" (distance 0, the best
  possible score, from a comparison that did not happen); a file
  measured BEFORE a provenance stamp existed is not "verified
  current". Every time, the collapsed reading is the flattering one,
  and every time it is invisible from inside the artifact. Name the
  two states separately even when one of them is rare.
- **Guard the derived side, not only the source side.**
  `check_fresh` refuses a `report.pdf` older than its `report.tex` --
  the source direction -- and nothing compared the DERIVED
  `report.compare.tsv` against the pdf it came from. 100 of 352 were
  stale, carrying `report_page` indices into a build that no longer
  existed, all of them in range and plausible. An asymmetric guard
  looks complete from either end on its own; ask which direction is
  unwatched.
- **Identity claims need an identity, and position does not supply
  one.** Per-component correspondence between a LaTeX render and a
  scan of the same expression is not recoverable by position:
  residual p5 -34, p50 -6, p95 +16, agreeing on 61 of 426 rows, even
  with a threshold-free overlap test. Different typeface, different
  scale, and ink decomposes differently — a scanned `i` merges its
  dot into its stem. Count claims survive this; identity claims do
  not, so say which one you are making.

- **A number in a comment is not a measurement, and it outlives the
  code it described.** `warp.py`'s docstring carries a table of the
  hatching defect — (436, 180) → (408, 2238), an order of magnitude of
  new holes — under a heading reading `FIXED: transport used to hatch
  solid regions`. The heading is accurate and the table is the
  *before*. It was read as current by two readers, and a task (581 A2)
  was written to explain growth that has not existed since the fix:
  transport now *shrinks* cycles on every page and angle measured.
  A comment describing a defect should not print the defect's numbers
  without printing the fixed ones beside them, and a measurement that
  matters belongs in `out/` with a re-runnable subcommand, not only in
  a docstring. Ask of any number in prose: which commit produced it,
  and has the code it measured changed since?

- **A guessed pattern reports a whole class as absent.** 597's first
  identifier regex was `<bibkey>_[A-Z]{2,4}[0-9a-f]+`, which misses
  `0049_DIA_0001` — an underscore before the digits — and reported all
  six rows of that table as MISSING. Nothing distinguished a reader
  bug from a report finding. The fix is not a better guess: extract
  permissively and let the MANIFEST decide membership, then RETURN the
  leftovers. `Join.unknown` exists for exactly that and is asserted
  on both sides, because a permanently non-empty diagnostic is noise
  nobody reads.
- **A long identifier wraps and disappears.** `0049_EQ0001` fits a
  report's Identifier column; `Geometric_topology_EQ0145` does not and
  breaks after the underscore. `pdftotext` plain found 0 on such a
  page, `-layout` found 0 — it preserves the visual row, so the halves
  are separated by the rest of the line — and `-raw` found 14. Without
  the un-wrap, **6,485 of 6,717 rows read as missing**, and did.
- **Reading order is not row order.** Plain `pdftotext` returned
  0049's image rows as 1, 3, 4, 5, 2: the right SET in the wrong
  SEQUENCE, which mispairs every row while the counts look perfect.
  Take the sequence from the manifest, never from the page.
- **A raw byte scan cannot tell a stripped attachment from a
  compressed one.** 580's first probe reported ghostscript stripping
  an embedded file in the same row where `pdfdetach` said the file was
  still there. Three of seven passes were false strips, and the
  conclusion "write the channel after the last PDF pass" would have
  been drawn from a reader artefact. Extract and compare the BYTES.
- **An incidental refusal stops working when the numbers line up.**
  `cell_rect` refused a page-break row because its two y values came
  from different pages and so were not ordered — the ordering guard
  caught it, not the page-break flag. A row breaking near the top of a
  page would have passed. Refuse by name (602's G7), then the refusal
  survives the coincidence ending.
- **The header and the row are built in two places.** Reordering
  `compare`'s header list alone, leaving the row-building untouched,
  passed the whole suite while every label pointed at another
  column's data. Assert position AND name together.
- **A tolerance asserted as an equality fails honestly.** 602's first
  test asserted the emitted y edges EQUAL to the lattice's; the
  measurement said 0 or -1. Pin the exact part exactly, the tolerant
  part to its measured tolerance, and the SIGN separately — three
  claims of different strength rather than one standing in for all.
- **A number in a comment outlives the code it described.** See open
  item 10.
- **`pkill -f` matches the shell running it.** It killed this session
  twice (exit 144), orphaning children both times. Collect PIDs with
  `pgrep`, then `kill` them.
- **Wait on process exit, not on log growth.** 589's analysis ran when
  six logs had stopped growing; one row finished afterwards and the
  published figures were one row short. `while ps -eo args | grep -q
  <pattern>; do sleep N; done` is the form. Launch it ONCE — layering
  a fresh waiter at each progress check left four orphans for one job.

## Chat reports open and close with a Berlin timestamp

    2026-08-27 10:56 (MESZ, +02:00)
       ... the report ...
    2026-08-27 11:14 (MESZ, +02:00)

CONSOLE OUTPUT ONLY. Nothing under `out/` carries a stamp -- files
are dated by git, and stamping them was a misread that cost three
rounds of work and displaced the measurement eleven documents were
waiting on.

The pair gives the duration, which the harness's "Worked for 6m 55s"
line does not, because that does not survive being pasted. The offset
follows daylight saving and the abbreviation follows it too: MEZ at
+01:00 from late October to late March, MESZ at +02:00 otherwise.

## Two sessions consume this project's output format

Recorded here because neither side wrote it down and each assumed the
other held it. Nothing is frozen — a QC instrument that cannot change
its classes is worse than one that breaks consumers who fail loudly —
but a rename is now a DELIBERATE act with a known blast radius.

| consumer | reads | fails how |
|---|---|---|
| pdfdrill-7b's refine metric | `ink.components`, `ink.holes` from `emit`'s lines.json | asserts on key PRESENCE, not value: `"holes": 0` is a hole-free page, a missing key raises `InkUnavailable` naming the field |
| pdfdrill.github.io deploy gate | `rows` and each row's `flag` from `report.ink.json` | a sixth flag value fails the deploy by name, telling whoever sees it the legend needs updating in the same commit |

The flag vocabulary they depend on is `tools/findings.py`'s `FLAGS`,
now **six: absent, clean, noise, weak, stable, component**. That tuple
is the published legend of a website. Adding a class is allowed and
breaks the deploy loudly; it must not be added silently.

`absent` was added by 238 and this page said "exactly five" until
2026-09-06 — a stale count in the one place that documents a
published contract. If you add a seventh, change this line in the
same commit as `FLAGS`, or the next reader inherits the same defect.

**`absent` before `clean` is the whole point of it.** A row with no
ink on either side scores distance 0 and component delta 0 —
arithmetically a perfect match, from a comparison that did not
happen. Reading it as `clean` reports an absence as the best possible
result.

Key presence over key value is the distinction worth keeping: a
genuinely hole-free page and a renamed field are the same number and
different keys, and only the second is a defect.

## The row manifest — the interface being built with pdfdrill

A live piece of work, spread over out/590, 595, 597, 598, 601, 602,
606, 608, 610, 624, 626. The state on 2026-09-06:

**WHY.** `inkmeasure` had to infer which table a lattice run belonged
to, and could not: 595 measured a run holding TWO tables (0049's
equations and formulas are both 5 columns and contiguous) and a table
spanning TWO runs. 608 of 717 documents have two tables sharing a
column count, so an ordinal has nothing to fall back on.

**THE JOIN, which needs nothing new.** `rowjoin.join(manifest, pages)`
takes `report.tables.json` — 717 documents already have one — and the
identifiers in `report.pdf`'s text layer, and returns every row's
page. 6,717 of 6,717 rows on a 300-page report, 34 of 34 on a 4-page
one, zero missing. Reading the TEXT LAYER is not a G6 violation: G6
forbids reading text off a RASTER.

**THE RECT SPEC** (601, 602, 610). Per TABLE `column_rules_bp`
(ncols+1, ascending, once); per ROW `page`, `rule_above_bp`,
`rule_below_bp`; per document `page_height_bp` and `rule_width_bp`.

| decided | because |
|---|---|
| **centrelines**, not edges | a derived number must not sit where a measured one belongs, and an edge cannot afterwards be told from a centreline half a rule away. `cell_rect` insets by `rule_width_bp/2` |
| **bp**, not sp or px | `bp = sp / 65536 * 72 / 72.27`. Skipping the 72/72.27 is worth 13 px at 300 dpi and is PROPORTIONAL, so it looks right at the top of a page and drifts down it |
| **rule positions**, not content | the lattice cell is the hole BETWEEN rules; emitting rules makes the two sides agree by construction rather than within a tolerance |
| **per row**, not per cell | column boundaries are constant across every page a table occupies, measured to the pixel |
| **no `run`** | 601 §4: the same pages are 2 runs at 150 dpi and 1 at 300. A run is not a property of the document |

**THE RESIDUAL METHOD.** Four signed per-edge deltas in raster px,
reported as median/min/max and fraction within 1 px, **never as a
pass**. A SYSTEMATIC offset is a converter bug and fixable; a
SCATTERED one is a real difference between the detections and a reason
to change the spec. That distinction found a constant -1 in
inkdrill's own consumer over 60 cells, and later a +6.177 bp origin
error and a missing rightmost rule in the emitter.

**TOOLS.** `tools/tablejoin.py` (join over a document),
`tools/manifestcheck.py` (residual against an emitted manifest, pairing
rows to lattice rows BY GEOMETRY because a page's lattice includes the
printed header and the manifest does not), `tools/cellcheck.py` and
`tools/pdfrules.py` (the same against the PDF's own vector content —
an independent source, which is the point), `tools/rulediff.py`
(emitted bp against the PDF's, no raster and no dpi).

**WHAT REMAINS.** The join places a row on a PAGE, not on a lattice
ROW. Within a run the pairing of the k-th identifier to the k-th
lattice row is still positional, and pages are 28 rows deep on
Geometric_topology. A manifest carrying the CELL rect closes it; that
is 598 #4 and #2's remaining half.

## Formula evidence — the marks contract with pdfdrill

Built over out/630–659; the state on 2026-09-11.

**WHAT PDFDRILL PUBLISHES.** `evidence-formula.tex`: one row per
DISTINCT inline formula — id, page, the producer's confidence, the
maths rendered (`\FitMath`), and a crop of the line it first occurs on
(`report-crops/`, scaled copies in `report-crops-b/`). 21 documents,
37,610 rows.

**WHAT INKDRILL ADDS: where the expression sits in its line.**
`tools/formulafind.py` renders the maths, cuts the host line LOSSLESS
from `inspect/pages` and places the rendering along it (blob ink/gap
profiles, a bigint Jaccard scan, a document scale voted by rows with
≥ 6 gaps, a per-row refit). Never measured on a published crop: those
are downsampled, and out/641 measured what that moves. The user's
rule: a residual report is a few rows and never holds downsampled data.

`tools/formularesidual.py` classifies and HOLDS THE MARKING POLICY,
closed in out/658 on 155 eye verdicts over two documents. A rectangle
is drawn only if the host region is a line (≤ `NON_LINE`=3 median line
heights), gaps ≥ 2, margin ≥ `MARK_MARGIN`=0.15, and NOT (gaps ≤
`MARK_GAPS`=7 and edge cuts ≥ `MARK_CUTS`=1): 66.2% of rows marked,
~1.7 wrong marks in 2,240, a mark right 99.89%. The RED flags are
evidence-table detail, not the residual report: every error they found
in those 155 verdicts was inkdrill's own placement. The residual
report is the producer's own low confidence (`LOW_CONFIDENCE`=0.80).

**THE INTERFACE** is `tools/formulamarks.py` — `run <bibkey> --work
DIR` measures, `marks` re-emits — one JSON document on stdout, the
`reportpages` convention. Per row: `mark`, `why_no_mark` (the clause),
`rect` (MathPix px relative to the host region's top-left, i.e. a
pixel of pdfdrill's full-size crop), `rect_frac`, `host_page`,
`region`, `flags`.

| decided | because |
|---|---|
| **pdfdrill's host-line rule**, copied (`first_occurrence_lines` = `inlinectx.load_spans` + `first_occurrences`) | a rectangle is meaningless on another line. The copy and inkdrill's old per-page cursor agree on 37,503 of 37,503 rows both place, but a copy can drift: **pdfdrill must compare `region` with its own host line and draw nothing on a mismatch** |
| **MathPix frame**, not inkdrill page px | pdfdrill's crop is the region resized to its MathPix pixel size |
| **page frames per page and per axis, CropBox-aware** (`page_frames`, `frame_of`) | MathPix's page is the CropBox, `inspect/pages` the MediaBox. 4 of 21 documents are inset (cardona, voloshin, gilmore, kohlhase-omdoc); one width ratio cut the wrong strip there, correlation −0.014 against +0.924 once mapped |
| **staleness: `lines.json` per document, the reading per ROW** — not the bytes of `evidence-formula.tex`, and not a digest over all rows | pdfdrill rewrites that file to insert the marks and to render rows it once could not; a byte hash, or a digest over every row, would refuse every mark for one corrected row. A changed row goes to `not_measured` as "reading changed"; each row carries the `math` it was measured on |

**IT BINDS TO A `lines.json`-SHAPED FILE, NOT TO MATHPIX.** Every tool
here reads page records with typed line regions and their text; the
producer is incidental. pdfdrill is moving to pdfminer.six (or
`pdftotext` with page separators) for exactly that file, and to an
additive structure where front matter, titles and repeating frames are
EXCLUDED from formula transclusion. Two things rest on the `type`
vocabulary and will move with it: the exclusion rule, and the marking
policy's "is this region a line" clause. Measured 2026-09-13: 158 of
the 461 wrong crops sit on lines that exclusion removes (115
`table_of_contents_item`, 31 `figure_label`, 10 `section_header`), so a
third of that residual disappears by the rule change alone (out/665).

**A THRESHOLD IS A RESULT, AND GOES STALE LIKE ONE.** `cropcheck.WRONG`
was placed by eye on 09-11 inside an interval that was EMPTY on that
build (highest wrong 0.262, lowest right 0.413). The 09-12 rebuild
scaled crops per document (1.0, 0.85, 0.6, 0.5, 0.42), which pushes
correct crops down to 0.30, and the interval filled with 599 rows. The
constant had to be re-placed at 0.30 and the two classes now OVERLAP --
one verified-wrong row sits at 0.304 -- so the count is a FLOOR. Re-place
it whenever the corpus is rebuilt; do not quote it across one (out/665).

**NOT INKDRILL'S: stale published crops.** pdfdrill's `render_crops`
caches by TITLE (`if f.is_file() and f.stat().st_size > 500: cached`),
so a crop rendered under the old host-line join (before their
`42b92d15`) is never re-rendered. 0902.0431 FO0068 is the right
rectangle cut from page 177 instead of page 4. `tools/cropcheck.py`
finds them by CONTENT — a size check passes FO0068 — and the corpus
count is in out/659.

**THE TOOLS' OWN DEFECTS, fixed and pinned** by
`tests/test_formulatools.py`: `rows()` let a crop-less row steal the
next row's picture and swallow that row, and let `\lowconf{…}` into
ids; the width-only ratio above; rows split on `\\ \hline`, which an
`array` in the maths holds too.

**OPEN, in the four workstreams out/658 separated.** (1) marking: 663 measured the placement edges over 250 marked rows and
found NO lean -- both edges sit on the ink they cover within a pixel
(medians 0.0 to -1.0 px on spans of ~470 px), so the 7-of-12 left
lean is a property of the twelve known ERRORS, not of the placed
population. out/660 found two limits the books expose. `margin` is blind when an expression fills
more than half its line (no non-overlapping rival fits, so margin =
score), and one document scale cannot serve a book set in two type
sizes (johnston's refit scales peak at 0.50 and 0.60). The user
DECIDED (2026-09-11): publish as measured — 658 stands, the two
limits are known and not acted on. The corpus marks and their work
directories are in `~/inkdrill-marks/` (`index.json`, `README.md` for
pdfdrill, `stale-crops.json`); re-emit with `formulamarks marks
<bibkey> --work <dir>`.
pdfdrill REBUILT every document on 2026-09-12 (lines.json untouched,
so host regions still hold): the marks were re-emitted from their
stored work directories -- 0 documents refused, 0 readings changed,
8,453 -> 8,408 marks, every loss on a row no longer in the
evidence (out/663). `table-rows.json` there lists the 88 rows whose
host line is a table. (2) MathPix errors: the first ones FOUND. 15
instances in mielke read `\downharpoonleft` for the `⌋` interior
product; the ink stands at 80.5 deg where a real barb at that size
reads 50-58 (out/661, harness `tools/glyphangle.py`, the angle and
drift of an arm against its stem, read off run spans). Two more in the
same book: an Arabic ل (U+0644) and a CJK 十 (U+5341) emitted inside
physics formulas. pdfdrill's containment/overprint test does NOT
transfer to a raster -- it misses the composed arrow it was proved on
and fires on radicals at 14% of display lines (out/662), so it stays a
text-layer test on their side; parked 2026-09-12. (3) whitespace in large open expressions — with
MathPix, who fixed a de-tokenizer bug inventing invisible brackets;
re-run `tools/fuzzyalign.py` on their next build. (4) matrix-arrangement
repair, for low-confidence equations only. (5) page-wide table detection:
MEASURED AND NOT BUILT (out/664). Three routes over 1,277 pages reproduce
only 58% of MathPix's tables and 20% of its diagrams, and the misses
are BLINDNESS, not disagreement about edges -- 927 of 1,422 missed
diagrams have zero overlap with anything found, and 980 have nothing of
ours inside them. `grid` fires on the glyph `⫫`, `rules` on an `=`.
What survives is narrow and worth keeping: the `frame` route (a
sprawling component holding under 5% ink in its box) finds boxes
MathPix never labelled -- 10 of 10 judged by eye are real, including a
ruled table and a captioned figure, and 41 of the 47 pages carrying a
caption with no box carry one. `tools/pagetables.py`.

## Coordination

pdfdrill runs in `~/MX/PDFDRILL` as a peer session, owns the reports
and the corpus, and holds regeneration while a compare is in flight.
Standing contract: it runs this project's probe as its acceptance test
before handing reports over; neither session edits a shared artifact
the other is reading.

**A manifest must name the build it describes.** 606 measured one 14
seconds OLDER than the `report.pdf` beside it, whose rows were not in
that PDF at all. `pdfdrill-rows.json` now carries
`measured_against: {pdf, sha256}` and `manifestcheck` refuses on a
mismatch. This is the same class as `report.compare.source`: an
artifact can be stale against its source AND a result stale against
the artifact, and only the first had a guard.

**Each session is the only possible auditor of the other's METHOD.**
pdfdrill cannot see this pipeline and this session cannot see theirs, so
a result arrives as a fact in a message that looks like every other
message. The `-resize` figure above would have reached them as "every
page in the corpus carries grey content", measured, from me — and they
had no way to find it. The exchanges that caught things this week all
have the same shape: the method was reported, not just the number. Send
how it was measured, and the population, even when the result looks
dull.

**Tasks arriving here that are pdfdrill's** (563, 564, 66, 483-485)
are reported as theirs rather than executed. `ListAgents` shows no
pdfdrill session reachable from this one, so relaying is not possible
and saying so is the useful answer.

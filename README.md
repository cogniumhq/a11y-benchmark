# a11y-benchmark

[![Validate corpus](https://github.com/cogniumhq/a11y-benchmark/actions/workflows/validate.yml/badge.svg)](https://github.com/cogniumhq/a11y-benchmark/actions/workflows/validate.yml)

An accessibility fixture corpus: small pages with **known WCAG outcomes**, for
measuring what an automated accessibility scanner finds, what it misses, and
what it reports that is not there.

Engine-agnostic by design. Nothing here knows about any particular scanner.

The canonical public repository is
[`cogniumhq/a11y-benchmark`](https://github.com/cogniumhq/a11y-benchmark). Pin a full
commit SHA for every published run. The default branch is development state;
tagged releases are immutable benchmark references.

## Releases and reproducibility

The first release candidate is **v0.1.0**. Its scope and known limitations are
recorded in [the versioned release notes](releases/v0.1.0.md). The tag and
attached checksum bundle will be published only from a reviewed, green default-
branch commit by the tag-gated workflow described in [RELEASING.md](RELEASING.md).

For a reproducible comparison, pin the published tag or its full commit SHA,
record the SHA-256 digest of `corpus-manifest.json`, and validate evidence against
the schema versions named in the release metadata. Do not use a moving default
branch as a benchmark identity.

## Interoperability contract

`corpus-manifest.json` is the canonical index of the 13 fixture families and
their stable content digests. It currently covers 266 cases. The digest ignores
only each family's generated date; expected outcomes, IDs, paths and notes all
participate.

`schemas/benchmark-result.schema.json` defines a product-neutral result format.
It preserves engine lineage, tool interface, state reach, target observability,
examined counts, explicit errors and `cannot-tell`. This prevents wrappers from
being counted as independent engines and prevents a failed or empty execution
from being reported as a clean pass. See [schemas/README.md](schemas/README.md).

Public fixtures and contracts live here. Credentials, raw production evidence,
private selectors, customer traceability and competitive result history do not.

## Contribute and publish results

Tool vendors, accessibility consultancies, auditors, researchers and community
projects are welcome. Participation has two separate paths:

- **Improve the benchmark.** Open a fixture proposal or corpus-defect issue,
  fork the repository, add the smallest synthetic fixture/control pair and open
  a pull request. Cite the public standard or reviewed task, preserve stable IDs,
  declare any relationship to a product affected by the change, and run the
  checks in [CONTRIBUTING.md](CONTRIBUTING.md). Contributions are submitted
  under Apache-2.0 unless clearly identified third-party terms apply.
- **Publish product results.** Run against a tagged release or full commit SHA,
  record the manifest digest, product version, engine lineage, configuration,
  environment, state reach, observability and every error or unsupported case.
  Encode the run with the
  [benchmark-result schema](schemas/benchmark-result.schema.json), validate it
  with `node check/validate-result.mjs`, and publish the immutable result bundle
  outside this corpus repository. The complete protocol and comparison rules are
  in [PUBLISHING_RESULTS.md](PUBLISHING_RESULTS.md).

A copy-and-fill [starter kit](starter/README.md) produces a bundle that
validates, scores and lists: it pins the corpus revision, manifest digest,
product version, engine lineage, environment and repetition count by
construction, and ships a worked multi-case example with its method note,
mapping code, raw-output disclosure and licence.

`check/score.mjs` is the reference scorer and regression runner. It turns the
manifest plus schema-valid results into recall, false-positive,
pipeline-integrity, execution and examined-count metrics, every rate published
with its numerator and denominator, and refuses to compare runs measured
against different corpus revisions or scoring policies. See
[SCORING.md](SCORING.md).

After publishing, a third party may open a **Published benchmark result** issue
to make the bundle discoverable. Listing confirms disclosure and schema validity
only; it is not Cognium endorsement, product certification, a legal opinion or a
WCAG conformance claim.

## Human and assistive-technology evaluation

Repeatable task scripts for JAWS, NVDA, VoiceOver, TalkBack, keyboard, switch
and voice operation, media alternatives, display adaptation, comprehension and
task completion are published in [protocols/](protocols/README.md). Each
protocol fixes the prerequisites, environment fields, steps, expected
observations, evidence and safety stops while keeping human-guided,
interoperability, user-task and automated metrics separate.

The protocol result vocabulary is `pass`, `fail`, `inapplicable`,
`cannot-tell` and `not-tested`. Independent reviewers keep their original
decisions; agreement and disagreements are reported without forced consensus.
Only public synthetic fixture evidence belongs in a published bundle.

## Why it exists

Most accessibility corpora test whether a *rule* is right. This one also tests
whether the scanner's **pipeline** — crawl, capture, hydrate, sample, walk —
ever hands that rule anything to judge.

That distinction is the point. A scanner can score full marks on a corpus of
isolated HTML snippets while being unable to observe a real single-page
application, because a snippet never stresses capture, hydration or sampling.
See [FOUNDATION.md](FOUNDATION.md) for the evidence and the two-tier design
that follows from it.

## Layout

```
wcag/criteria.json   WCAG 2.2 success criteria — slim index derived from W3C's published JSON
act/testcases.json   W3C ACT Task Force test cases (1,213 cases, 87 rules)
catalog.json         ground truth for the local fixtures — what a correct scanner should say
corpus-manifest.json stable family index, case counts and content digests
sources.json         provenance for every standards-derived input: url, licence, upstream digest
coverage.csv/.json   every WCAG 2.2 criterion x available ground truth
schemas/             JSON Schema contracts and validated examples
pipeline.json        pipeline-integrity ground truth and execution boundaries
build.mjs            regenerates every fixture
pipeline.mjs         regenerates the pipeline sites, controls and assertions
coverage.mjs         regenerates the coverage files
manifest.mjs         regenerates the canonical corpus manifest

pipeline/            capture, sampling, observation and execution-accounting cases
keyboard/            matched defective/corrected controls for keyboard and focus behaviour
capture/             pages that stress capture and hydration rather than rule logic
static/              single-page defects readable from served HTML
delivery/            ONE constant defect, delivered eleven different ways
wiring/              ONE constant defect, with its handler attached four different ways
patterns/            APG component patterns as matched broken/correct pairs
taxonomy/            the enumerated test space
aaa/                 matched pairs for the automatable and stateful WCAG AAA criteria
native/              real PDF and OOXML artifacts for non-web surfaces
surface-contracts.json  native artifact format, harness and standard per unrepresented surface
evidence/            the execution and verification evidence ledger
starter/             copy-and-fill kit for publishing a result bundle
delivery.mjs         regenerates the delivery matrix
wiring.mjs           regenerates the event-wiring matrix
patterns.mjs         regenerates the pattern pairs
taxonomy.mjs         regenerates the taxonomy
aaa.mjs              regenerates the AAA classification and its fixture pairs
native.mjs           regenerates the PDF and OOXML artifacts
surface-contracts.mjs   regenerates the native artifact contracts
maturity.mjs         represented / executable / executed / verified states
ingest-results.mjs   derives ledger records from published result bundles
adjudicate.mjs       reconciles a multi-engine baseline against reviewed ground truth
adjudication.json    reviewed decisions about assertions no engine reports
refresh-sources.mjs  reviewed refresh of the WCAG, ACT and APG inputs
space-coverage.mjs   coverage against the whole space, not just WCAG
```

### Surfaces beyond the web

Eleven of eighteen surfaces were unrepresented, and the tempting fix — an HTML
page that resembles a PDF or a mobile screen — measures nothing. A control
reading that page is reading HTML.

[`surface-contracts.json`](surface-contracts.json) fixes, per surface, what the
native artifact actually is, what parses or drives it, which standard applies,
and where software stops. Seven surfaces need physical evaluation for part of
the answer: a kiosk's reach and a hardware control's detent are not simulable,
and the contract says so rather than pretending otherwise.

`native/` ships the two surfaces whose artifacts are reproducible without a
device lab:

```sh
node check/pdf-structure.mjs   native/pdf/safe_tagged.pdf
node check/ooxml-structure.mjs native/docx/safe_structured.docx
```

These are real PDF and Office Open XML byte streams, generated deterministically
by `native.mjs` and pinned by SHA-256. Each defect has a matched control whose
*visible* content is identical and whose structure differs only in what the
criterion requires.

**A contract is not coverage.** A surface with a contract and no artifact is
still unrepresented, and `space-coverage.json` reports it as missing. Proxy
representations — an HTML transcript standing in for a voice interface, say —
are labelled `proxy` and excluded from `represented_natively`.

### Adjudicating ground truth

Two independent engines over every HTML fixture detect 14 of 202 true-positive
assertions between them. **193 assertions are reported by no engine** — and an
assertion nothing detects is not thereby wrong, nor thereby right. It is a
question.

[`adjudication.json`](adjudication.json) records the answers: one of
`correct-unimplemented`, `correct-manual-only`, `correct-pipeline-dependent` or
`wrong`, each with a named reviewer and a public source.

```sh
node adjudicate.mjs result-one.json result-two.json
```

An assertion is **never** changed to match current tool behaviour alone — that
would make the corpus track the tools instead of the standard. Two engines
agreeing on silence flags a question; it does not settle one.

Decisions expire per fixture family rather than per corpus, so an unrelated
addition does not invalidate unrelated review. See
[ADJUDICATION.md](ADJUDICATION.md), which also assesses the GOV.UK tool audit
and W3C ARIA-AT as external sources.

### Standards sources

`sources.json` records where every standards-derived input came from, under
what licence, at which upstream digest. `refresh-sources.mjs` re-derives the
vendored snapshots and reports what moved: added, removed and changed ACT rule
and test-case ids with their expected outcomes, changed WCAG transformed
fields, and the local fixtures each change affects.

```sh
node refresh-sources.mjs --check     # report drift, write nothing
node refresh-sources.mjs --apply     # re-derive the snapshots
```

It fails closed. An upstream that returns 404 or 410, or whose declared licence
has changed, stops the run rather than re-vendoring under terms nobody checked.
The scheduled workflow opens a pull request for review and never pushes to the
default branch. Releases keep referencing the committed snapshot, not live
upstream content.

Project decisions and compatibility follow [GOVERNANCE.md](GOVERNANCE.md).
Contributions follow [CONTRIBUTING.md](CONTRIBUTING.md), and sensitive reports
follow [SECURITY.md](SECURITY.md). Coverage maturity and the evidence ledger
are described in [EVIDENCE.md](EVIDENCE.md), and scoring in
[SCORING.md](SCORING.md). Third-party result publishers follow
[PUBLISHING_RESULTS.md](PUBLISHING_RESULTS.md).

### Pipeline integrity

`pipeline/` turns four failure signatures into eight public synthetic cases:
each failing execution shape has a narrowly matched control. The deep-site and
entry-sampling cases are actual linked sites whose manifests declare `entry`
and every `step`; the other pairs isolate zero-examined passes and flow criteria
run without a declared task.

`pipeline.json` makes the execution oracle explicit for every case: required
status, declared state, whether that state was reached, target observability,
examined-count boundary, error requirement and verdicts that are forbidden. A
sampling mismatch, omitted entry, zero-examined execution or missing flow can
therefore never be silently normalized to a pass.

### Component patterns

16 patterns from the [ARIA Authoring Practices
Guide](https://www.w3.org/WAI/ARIA/apg/patterns/), each as a broken implementation
and an APG-correct one: disclosure, accordion, tabs, modal dialog, combobox, menu
button, switch, alert/status, data table, tooltip, breadcrumb, slider, listbox,
form errors, required fields, media captions.

Custom widgets are where scanners are weakest and where products actually break —
a native `<button>` is hard to get wrong, a div-based combobox is hard to get
right. The **correct** half of each pair is the load-bearing one: any scanner can
flag everything, only an accurate one leaves APG-conformant markup alone.

### Flight-search regression shapes

The `keyboard/` and `patterns/` families include a reusable regression slice
derived from 21 findings in a human review of a production flight-search flow.
The public corpus retains only synthetic interface shapes and declared ground
truth; it does not retain the production URL, page content, screenshots,
selectors or session data.

The 21 review rows reduce to nine distinct scenarios. Each scenario has one
known-defect fixture and one corrected control:

| Scenario | Known-defect fixture | Corrected control | Criteria |
|---|---|---|---|
| Travel-mode tabs | `keyboard/role_tab_no_tablist.html` | `patterns/safe_tabs.html` | 2.1.1, 2.4.3, 4.1.2 |
| Route fields | `keyboard/div_text_field.html` | `keyboard/safe_native_text_field.html` | 1.3.1, 2.1.1, 4.1.2 |
| Date controls | `keyboard/div_date_fields.html` | `keyboard/safe_native_date_fields.html` | 2.1.1 |
| Traveller disclosure | `keyboard/div_travellers.html` | `keyboard/safe_native_travellers.html` | 2.1.1 |
| Checkbox selection | `keyboard/div_checkbox.html` | `keyboard/safe_native_checkbox.html` | 2.1.1, 4.1.2 |
| Fare-option cards | `keyboard/div_fare_cards.html` | `keyboard/safe_native_fare_options.html` | 2.1.1 |
| Search action | `keyboard/div_button.html` | `keyboard/safe_native_button.html` | 2.1.1, 4.1.2 |
| Focus indicator | `keyboard/focus_not_visible.html` | `keyboard/safe_focus_visible.html` | 2.4.7 |
| Focus obstruction | `keyboard/focus_obscured.html` | `keyboard/safe_focus_not_obscured.html` | 2.4.11 |

The private comparison repository owns row-level traceability and tool results.
This repository owns only the executable fixtures and expected outcomes.

### Functional scenario expansion

The corpus also includes narrowly matched pairs for page language, page title,
text contrast, common input purpose, link purpose, descriptive headings and
labels, persistent field labels, and keyboard-trap escape. These pairs keep one
declared criterion constant between the known-defect page and its corrected
control, making criterion-level comparisons less prone to crediting an
unrelated finding on the same page.

Dynamic behavior is represented at the smallest honest unit. For example,
`scenarios/keyboard_trap.html` does not claim that a page-load scan can settle
2.1.2; a runner must open the panel and exercise Tab and Escape. Media quality
and meaning remain human-review boundaries even when track presence is
machine-observable.

### The delivery matrix

Accessibility defects live in the rendered DOM, not in the server language — PHP,
ASP and a static file all emit HTML, and the same bad markup is equally bad from
any of them. What varies for a *scanner* is how the content reaches the browser.

So every page in `delivery/` carries the **same two defects** — a div acting as a
button (2.1.1) and an image with no accessible name (1.1.1) — and differs only in
delivery: server-rendered, injected on DOMContentLoaded, injected on a timer,
inside a same-origin iframe, inside `srcdoc`, inside a sandboxed iframe, two
iframes deep, in an open shadow root, in a closed shadow root, in a custom
element, and server-rendered-then-replaced-by-script.

Holding the defect constant is the whole point. A scanner that reports
`server_html` and not `shadow_dom_open` has not found a rule bug; it has a
delivery coverage gap, and the matrix names which one.

`closed` shadow roots are deliberately included. `element.shadowRoot` returns
null there, so script cannot see in — but the content is still in the
accessibility tree and still reaches users, and real design systems ship closed
roots. It is the hardest row and a fair one.

## Display conditions are a test axis

A scan fixes one display condition — viewport, colour scheme, scale, motion
preference — and reports as if the answer generalised. It does not. Several
criteria are **defined** against a condition a single config cannot create:
1.4.10 Reflow is specified at 320px, 1.3.4 needs portrait, 2.5.8 is about touch,
1.4.1 and 1.4.11 need forced colours.

```sh
docker compose run --rm configs     # six conditions, reports only what CHANGES
```

`check/configs.mjs` measures the same pages under six conditions and prints only
the observations that differ. A fixture that reads the same everywhere is
condition-independent; one that flips is **undetectable at every condition except
where it flips**.

The sharpest result so far:

```
reduced-motion
   static/anim_no_reduced_motion.html    running_animations: 2 → 0
   static/safe_anim_reduced_motion.html  running_animations: 1 → 0
```

With `prefers-reduced-motion: reduce` active, a page whose defect is an unguarded
infinite animation reports **zero running animations** — identical to the page
that guards it correctly. Any checker running in that state cannot tell them
apart, so 2.2.2 and 2.3.x are unobservable, not merely unchecked.

It also fails loudly rather than quietly: a condition that could not load its
pages aborts the comparison. An earlier run had three of six conditions dead with
`ERR_NAME_NOT_RESOLVED` and reported their silence as "nothing changes" — which
is the same shape of error as counting a control that examined nothing as a pass.

## Functional needs are the primary index

Every rule maps to the functional needs it serves
(`taxonomy/criterion-needs.json`), and a fixture inherits needs from the criteria
it exercises. This is the index that matters for product decisions, because one
requirement usually serves several groups at once:

```
4.1.2  Name, Role, Value   13 needs
2.1.1  Keyboard            13 needs
1.3.1  Info and Rel'ships  13 needs
1.4.1  Use of Colour       12 needs
```

Keyboard access alone supports non-visual operation, alternative input, switch
access and voice-control workflows. A criterion-first report cannot show that one
fix improves many functional needs; `node needs-index.mjs` can.

Mapping rules rather than fixtures is deliberate — hand-annotating every case
drifts, and the rule-level mapping stays the single source of truth.

### Journeys

`journeys/` holds nine multi-page tasks — booking, sign-in, consistent help,
a destructive action, cookie consent, navigation, signup, checkout and session
recovery — each as a broken and a correct variant of the same task, step for
step.

This family exists because **some criteria cannot be tested on a single page by
definition**. 3.2.3 Consistent Navigation, 3.2.4 Consistent Identification,
3.2.6 Consistent Help and 3.3.7 Redundant Entry are statements about the
relationship *between* pages. A corpus of isolated pages cannot express them —
not because the rule is hard, but because the unit of test is wrong.

Every step is individually clean apart from the journey-level defect. That is
the point: a page-by-page scan can report every page as fine while the task is
unusable. In the booking journey the navigation order changes between steps, the
email given in step 1 is asked for again in step 2, and the card is charged with
no review — and no single page is wrong.

A journey case is a **set** of pages with an entry point, not one page, so the
case records `entry` and `steps` rather than a single path.

### Flash and seizure thresholds

> **Seizure warning.** `flash/` can produce flashing light. **Nothing flashes on
> load.** Every fixture needs an explicit button press, stops itself after 3
> seconds, and does nothing at all under `prefers-reduced-motion`.

This family is different from the rest of the corpus. Everywhere else the worst
case of a bad fixture is a wrong measurement; here it is a seizure. So the
gating is not a convenience and must not be removed. The keyframes and timings
stay in the document while dormant, so **the defect is detectable without ever
playing it** — a scanner reading styles or the animation API finds it with the
page sitting still.

Covers 2.3.1 (A), 2.3.2 (AAA) and 2.3.3 (AAA): a 10Hz full-width flash, a
saturated-red flash at 6Hz, a small-area 8Hz flash, exactly three flashes in one
second, and parallax on interaction with no reduced-motion guard.

`three_flashes_exactly` is the pair worth noting — it **passes 2.3.1 and fails
2.3.2**. A corpus that only tests Level A never distinguishes the two.

`flash_small_area` expects **cannot-tell**, and the reason is substantive. 2.3.1
is not simply "faster than 3Hz": content also passes if it stays under the
general and red flash thresholds, and the general threshold is defined over a
proportion of the **visual field** — which depends on screen size and viewing
distance, something a page cannot know. A tool can measure frequency and the
fraction of the viewport. It cannot measure the visual field. Guessing either
way would be wrong.

### Media and captions

`media/` covers captions, transcripts, audio description, live captioning and
sound-only signalling. The media files are real — a 1-second black H.264 clip
and silent MP3s, all under 2KB, emitted by the generator rather than committed
as loose binaries.

That is not fussiness. They were once references to files that did not exist,
and a `<video autoplay>` pointing at a missing source makes the browser wait out
its load timeout on every scan — about 20 seconds per page on one engine, on
three fixtures, every run. **A fixture must not be pathological for the tools
under test.** With real files those pages now load in roughly half a second. Two of the eight pairs are deliberately **cannot-tell**
rather than fail — `captions_present_but_poor` ships a real, parseable caption
track that says only `[inaudible]` across the whole runtime, identifies no
speaker and is not synchronised. A presence check passes it. That is the point:
presence of a track is not conformance, and the honest automated outcome is
"examined, needs a person", not "pass".

### UI states

`ui-states/` holds one journey — choosing a seat — constant across ten states:
loading, empty, invalid, corrected, submitted, error, offline,
permission-denied, timed-out and busy. Holding the journey constant makes any
difference attributable to the state rather than to different content.

Three of these cannot be reached by following links — `timed-out`,
`permission-denied` and `offline` have to be driven. A corpus that only tests
crawlable pages never tests them at all, which is why a form can be perfectly
labelled when blank and still lose focus on submit and announce nothing when
validation fails.

### Colour-independent information

`color-independent/` holds eight pairs covering the checks a contrast test cannot
reach: error and status by colour alone, red/green pairings, chart series
separated only by hue, links distinguished only by colour, placeholder and
disabled contrast, and selection state by colour alone.

Contrast ratio does not catch any of these. Two colours can each clear 4.5:1
against the background and still be indistinguishable from each other.

`color-independent/simulate.html` renders a fixture through three colour-perception
transformations and a monochrome transformation, so "can you still tell?" is a
question you can put to a screenshot rather than take on trust.

## The test space

`taxonomy/` enumerates the space this corpus is a slice of:

```
surface x user need x journey x UI state x input/AT x standard
```

18 surfaces · 23 functional user needs · 25 journeys · 12 UI states · 12 input/AT
pairings · 15 validation methods · 5 outcomes · 13 standards.

It is written down so representation and execution evidence can be measured
against an explicit scope. Run `node space-coverage.mjs` for the current
picture:

```
dimension       repr  exec        run  verif / total
surfaces          7     7    0      0 / 18
journeys         25    25    0      0 / 25
ui-states        12    12    0      0 / 12
user-needs       23    23    0      0 / 23
input-at         12    12    0      0 / 12
methods          15    15    0      0 / 15
```

**Read those with care.** Four states, strictly nested: a value is
`represented` when a manifest names it, `executable` when a route to evidence
exists, `executed` only when `evidence/ledger.json` holds a current record
saying it ran, and `verified` only when a reviewer or an independent
reproduction confirmed that run. A guided screen-reader prompt represents a
pairing and makes it executable; it does not execute or verify it.

The `run` and `verif` columns are zero because no execution evidence has been
recorded yet. That is the honest state, and separating it from representation
is the whole point — see [EVIDENCE.md](EVIDENCE.md).

The 64,800 figure is the product of four applicability axes — surface, journey,
UI state and input/AT. Functional needs and standards are mapped attributes,
not independent Cartesian axes. Even within those four axes, most combinations
are inapplicable; coverage must be calculated over a declared, risk-based test
plan rather than treating every mathematical combination as required.

Two things are deliberately not complete, and should stay that way:

**`surfaces 7 / 18`.** PDF, native iOS/Android, desktop, office documents,
kiosk, hardware and immersive surfaces need different artefact formats and
different parsers. An HTML file pretending to be a PDF measures nothing, so
they are enumerated as gaps rather than faked.

**`methods 15 / 15` represented, `0` executed.** Every method is now named by
some fixture, including `regression` via the pipeline family. That is exactly
the kind of full-looking row the maturity model exists to qualify: all fifteen
are represented and executable, and none has been executed. The three that no
harness can run — `guided-manual`, `at-testing`, `user-testing` — are
executable only because a versioned human protocol covers them.

Two notes that matter more than the numbers:

**Outcomes are five, not two.** `pass`, `fail`, `inapplicable`, `cannot-tell`,
`not-tested`. `cannot-tell` and `not-tested` are results, not failures to hide —
collapsing either into `pass` is exactly how a scanner that examined nothing
looks healthy.

**Conformance, severity, confidence and coverage are separate axes.** A high
automated conformance score over low coverage says almost nothing, and averaging
them into one figure destroys the information.

**Three methods cannot be automated at all** — guided manual review, AT testing
and user task testing. No fixture corpus can cover them; they need people. A
representation figure that quietly presents them as executed is not a coverage figure. W3C is explicit
that [automated tools cannot validate every
requirement](https://www.w3.org/WAI/test-evaluate/tools/selecting/).

## Accessible scaffolding

Corpus rule: **the only accessibility defect on a page is the one it declares.**

If the chrome contributes its own — small tap targets, low contrast, a missing
focus ring — a scanner reports that too, and the result is no longer
attributable to the fixture. That is a measurement error, not a finding.

`fixture.css` therefore satisfies 1.4.3 (16.6:1 body text), 1.4.4, 1.4.10
(reflows to 320px), 2.4.7 and 2.5.8 (24x24 minimum targets with spacing), and
honours `prefers-reduced-motion`. Pages are responsive by construction: relative
units, `clamp()` type, fluid iframes, no fixed pixel widths.

This was not cosmetic. Before the stylesheet was written,
`capture/link_heavy.html` — 450 links, a fixture about *tab order* — tripped a
target-size control because the links were small and tightly packed. That
finding was real, and entirely an artefact of the scaffolding.

Every fixture family has a generator, so a page does not need to drift out of
sync with its ground truth. Edit the generator, regenerate the outputs and let
the pull-request workflow verify that the committed artifacts match.

## Ground truth

`catalog.json` carries only what a **correct** scanner should report. It
deliberately contains no measured results: if truth and measurement live in the
same file, a regression can be hidden by editing the truth to match the engine.
Record measured behaviour in a separate baseline file and diff against it.

Cases come in pairs wherever it is meaningful:

| mode | meaning |
|---|---|
| `tp` | a scanner **should** report the listed criteria |
| `safe` | a scanner **must not** report the criteria in `must_not_report` — flagging one of those criteria is a false positive |

266 local cases: 130 `tp`, 121 negative controls and 15 guided checks. The 44
keyboard, capture and static cases are the core catalog; the remaining cases
live in twelve additional family manifests loaded through `fixture-families.mjs`.

The negative controls matter more than the positives. `keyboard/safe_roving_tabindex.html`
is APG-correct markup in which `tabindex="-1"` is the *right* answer; a scanner
that calls it "not keyboard reachable" is wrong, and corpora without such cases
cannot tell a sensitive scanner from an inaccurate one.

## Coverage

WCAG 2.2 has 86 live success criteria (4.1.1 Parsing was removed in 2.2 and is
retained in the index with `in_2_2: false`).

```
ACT only                     12
local fixtures only          41
ACT + local                  26
manual only                   7
neither                       0
```

Every criterion now has ground truth of some kind. `manual only` is the
category that matters: seven criteria are covered by a guided check because no
tool can decide them, and collapsing that into `neither` conflated *nobody has
built this yet* with *this cannot be automated at all*.

The twenty criteria that previously reported `neither` were all AAA. Each is
now classified into an evidence lane in
[`wcag/aaa-classification.json`](wcag/aaa-classification.json) with its public
W3C source: thirteen got matched broken/corrected pairs in `aaa/`, and seven
got guided checks. **Covering every AAA criterion here is not an AAA
conformance claim** — these are single-purpose fixtures, not a sampled site.

Regenerate with `node coverage.mjs`. If `act/testcases.json` is absent the ACT
columns come back empty and the command tells you how to fetch it.

## Running it locally (Docker)

The pipeline-tier fixtures need a *served* site and a *real* browser, so the
corpus ships both, pinned.

```sh
docker compose up -d corpus      # serves the fixtures on http://localhost:8080
docker compose run --rm browser  # measures them with a pinned Chromium
docker compose down
```

`corpus` is a Node Alpine image running `serve.mjs` — about forty lines of
`node:http`, no dependencies. Point any scanner at `http://localhost:8080/`.

`browser` runs `check/reference.mjs` against every case in the eleven family
manifests and writes `check/reference.json`: per fixture, the number of tab stops a real browser
finds, how many elements are natively focusable, how many are pointer-operable
but not keyboard reachable, and how much of the page exists only after script
runs (measured by loading twice, with JavaScript off and on).

It then runs `check/scenario-interactions.mjs`, which executes the five A/AA
interaction contracts: visual versus DOM sequence, pointer-down cancellation,
focus and input context changes, and actionable error suggestions.

Those are **facts about the pages, not judgements about any scanner** — which is
what makes them usable as a reference. For example:

```
capture/link_heavy          451 tab stops, 451 focusable
keyboard/safe_roving_tabindex 2 tab stops,   4 focusable
capture/client_mounted        1 element exists only after script runs
```

A scanner that reports examining 0 elements on `link_heavy` is provably wrong,
and now there is a number to say so with. The roving-tabindex row is the
counterpart: 4 focusable but only 2 tab stops is the *correct* result, so a
scanner flagging those as unreachable is equally provably wrong.

The browser image is pinned deliberately — a Chromium upgrade changes focus and
layout behaviour, which would move the reference numbers without any fixture
changing.

## Using it

Point any scanner at the directory, or at a single fixture, and compare its
output to `catalog.json`. Two numbers are worth reporting separately:

- **recall** — of the `tp` cases, how many listed criteria were reported
- **false positives** — any finding on a `safe` case; the ceiling is zero

A third is worth recording for pipeline-tier cases: the **examined count** — how
many elements the rule actually looked at. A rule that reports "pass" having
examined nothing has not passed; it has not run. Counting that as a pass is how
an incomplete scanner looks healthy.

## Provenance and licences

Except for the third-party material identified below and in
[THIRD_PARTY_NOTICES.md](THIRD_PARTY_NOTICES.md), original code, schemas,
documentation and synthetic fixtures are licensed under the
[Apache License 2.0](LICENSE). Contributions intentionally submitted for
inclusion are accepted under the same terms unless explicitly marked otherwise.

- **WCAG 2.2** — <https://www.w3.org/TR/WCAG22/>. `wcag/criteria.json` is a
  mechanically derived index (criterion number, name, level, placement). The
  normative text is at the source. W3C Document License.
- **ACT Rules test cases** — <https://www.w3.org/WAI/standards-guidelines/act/rules/>,
  by the W3C ACT Task Force, redistributed under the
  [W3C Software and Document Notice and License](https://www.w3.org/copyright/software-license-2023/),
  which permits reuse with attribution. `act/testcases.json` is an unmodified
  copy of the published catalogue.
- **WAI-ARIA Authoring Practices** — <https://www.w3.org/WAI/ARIA/apg/>, the
  basis for the component-pattern controls, under the W3C Software and Document
  License.
- **WAI abilities and barriers guidance** —
  <https://www.w3.org/WAI/people-use-web/abilities-barriers/>, the source used to
  organize the functional-needs taxonomy, under the W3C Document License.

The synthetic fixtures and generators are original unless a file or
`THIRD_PARTY_NOTICES.md` says otherwise. They reproduce *shapes* commonly found
in production interfaces—a div acting as a button, a client-mounted widget—and
are not copies of any particular site.

## Status

Active fixture corpus. The capture and delivery families will continue to grow,
but the repository already contains matched controls, multi-page journeys,
state-driven cases and explicit manual-review outcomes. Treat every coverage
number as a description of this corpus, never as a statement of WCAG conformance
or universal scanner quality.

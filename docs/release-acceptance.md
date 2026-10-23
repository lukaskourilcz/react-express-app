# Release acceptance matrix

## Current state (22 October 2026)

This file is an append-style evidence ledger. Each dated entry records what someone checked that day, and later entries leave earlier ones as they were. The entries from 15 October back to 8 September sit at the top; from "2026-09-11 — eight free-tool recommendations" on, the file runs oldest to newest, so the newest entry is at the end.

Released:

- `main` is at `1f5a3b11`, the merge of PR #559 (B14, #510). Vercel deploys `main` to https://devshark.app.
- Supabase project `rvlybcjdpafwyeuojvhl` has every migration through 066 (`accept_learning_path_quota_result`); see "Migration 066 in production".
- Learn has three sections: Web Developer, Software Engineer and Forward Deployed Engineer. DSA lives in Learn as the topics `dsa` and `dsa-advanced`. The standalone DSA path is retired, and `/roadmap/paths/dsa-foundations/*` answers 308 to `/learn/software-engineer?topic=dsa`.
- The FDE path is built and merged (epics A to E are closed) but switched off: Production does not set `LEARNING_PATH_FDE_ENABLED`. No Vercel environment sets an FDE or marketing-export variable, so the OwnDashboard marketing export stays inactive too.
- devShark has shipped English only since 21 October 2026. Entries before that date describe a second language (Czech) that no longer exists.
- Merchandise stays paused behind `MERCH_ENABLED`, and Stripe billing (#221) is not live.
- Content review totals live in the "Current state" section of `docs/audit/devshark-content-audit.md`.

Open, all owner items (`NEEDED.md` carries them):

- Set `LEARNING_PATH_FDE_ENABLED=true` in Vercel Production and redeploy. The entry "B14 FDE release verification — 22 October 2026" is the evidence.
- Approve new Terms wording: `legal.terms.plans.premium` still promises "the FDE and DSA learning paths".
- #190: confirm that GitHub Actions failure e-mails reach you, and add an external uptime monitor for `/api/health`. The scheduled health workflow ran 6 of 96 times in 24 hours.
- #391: the remaining owner decisions, including whether to publish the reviewed system-design track. #236: production-data decisions. #221: Stripe billing.
- Optional: escalate vercel/vercel#16109, the source of the DEP0169 warning (#477, closed).
- Nobody has run an authenticated walk-through on production or a preview, checked physical devices, or seen real learners' FDE data yet.

Of the issues these entries name, only #190, #221, #236 and #391 are still open. A "remains open" or "pending" line about any other issue or PR records the state on that entry's date. On 22 October 2026 the owner dropped Cloudflare Turnstile (#202), the workbench handoff with the unmerged `claude/elegant-cori-h9cdgb` work (#208; the branch survives as tag `archive/2026-10-22/claude/elegant-cori-h9cdgb`), the StudyShark promo video and the October marketing plan (#239). Entries that mention them describe past work, not plans.

## 15 October — local structuredClone own-key correction (#403)

Actual QuickJS probes reproduce loss of an own __proto__ key, changed clone
prototype/inherited data and a circular-prototype exception for a self-referential
own data key. The native Run realm passes these cases. The copy loop now uses
its captured native defineProperty with ordinary writable/enumerable/configurable
data descriptors, preserving aliases/cycles without invoking inherited setters.
No grading-result authority, isolation, handler, reward or access policy changes.

Four final focused cases pass in both the native Run realm and the freshly built
Submit worker: ordinary keys/descriptors/shared aliases, a self-referential key,
array prototype retention and a learner replacement of Object.defineProperty.
Three independent native Chromium API probes also pass; they do not constitute
an authenticated workbench flow. Existing full grading/Learn integrity suites
pass; the final added captured-intrinsic case was verified by the focused suite.
API/script types, launch, build, both production dependency audits (zero
vulnerabilities) and diff checks pass. The earlier post-edit probe used the old
worker artifact and is excluded; final evidence uses a rebuilt worker.

This is a local source fix. #403 stays open until a checked merge/release.
No production/account, XP, score, generated-name or owner-data fixture was used.

## 15 October — PR #401 exact production

PR #401 is merged at a4e934948e8522a036726868da89669bca6c1316. Frozen head
148c6100646b7359e0a1b43378cfd6606053f8c7 passes required run38681978040:
verify30m32s, SQL41s. READY preview dpl_9HgmaeZyZW4wM5ws9RGQt1yR3ujg passes
eleven general guest checks. READY production dpl_85vvsbrVkywqmGMUD674eSWhb7kA
matches the merge SHA, owns devshark.app, has no alias error and passes eleven
general guest checks at zero XP/null progress. No Challenge score, name, owner
progression or authenticated account fixture was created. Issue #397 closes with
the trusted diagnostic fix. Its actual authenticated production acceptance stays
separate from these public checks and the isolated local report fixtures.

The first verify failed the initial budget by182gzip bytes. The route-local
English dictionary correction retained the243000limit and passed the complete
new required run. Production now carries100coding and all263current individual
native model reviews. B015–b021 add35newer local coding reviews (135/725current,
590remaining). These are same-session model records, not independent/human,
full-catalogue, physical-device or authenticated native/Premium acceptance.

## 15 October — PR #401 initial-load correction

The first required verify run38679526564 failed the production-shaped initial
bundle budget:243182gzip bytes against243000. SQL passed38s; the earlier exact
preview passed eleven general checks, but neither result overrides failed verify.
The overview now loads its English-only route copy with the existing lazy path
screens, following the established privacy/draft dictionaries. Strings and
access/assessment behavior are unchanged; the budget was not raised. The full
client suite passes104files/1002tests after the diagnostic dictionary move.
Focused rechecks pass29tests; the final production-shaped build and both
isolated report browser tests pass. The measured initial download is242983gzip
bytes against the unchanged243000limit. An attempted extra move of archived-key
copy was reverted after a type check; archived Czech files remain untouched.

B014 adds five individual coding reviews:100/725current,625remaining. N042finishes
263/263current native records, adding3new and revising2existing records with
preserved history. These local reviews are not shipped by PR #400 and do not
establish independent/human or authenticated production acceptance.

## 15 October — local diagnostic competency follow-up (#397)

The diagnostic records trusted gradeCheck correct/item counts per competency in
namespaced numeric JSON through the existing accepted-evidence RPC. Progress
reads the latest accepted diagnostic revision with user/enrollment/activity scope,
so a weaker retake can inform recommendations without demoting prior module
completion. Multi-tag items contribute to each tagged area. Aggregate-only older
results are not assessed until a retake; unknown areas have null scores/zero
assessed items. Internal counts are omitted from public gated-domain labels.
No schema, RLS, handler-count, reward or completion-rule change is required.

A visible overview distinguishes demonstrated/gap/unassessed evidence and links
back to the optional diagnostic only when access is available. Sixteen focused
client contracts and the complete104file/1002test client suite pass. Full path
and launch contracts, API/script types, production-shaped placeholder build,
both production dependency audits (zero vulnerabilities) and diff checks pass.
Tests cover10/12overall success with1/3integration, multi-tags, missing/malformed
legacy data, unavailable evidence, persistence parameters, scoped latest-revision
read, replay contract, bridge ordering and no new completion gate.

Two isolated browser tests pass: light/dark at360,390,768,1024,1280,1440,200%text,
focus/Shift-Tab/Tab and scoped Axe checks. Reviewed narrow dark/wide light report
screenshots. Auth and wire data are entirely local fixtures, not authenticated
production acceptance. A production read-only query of the exact filtered latest-
revision shape succeeds with zero rows; no owner data, enrollment, evidence,
progress, score or account fixture was written. Supabase order/maybeSingle docs
and changelog were checked; the announced future legacy TLS cipher retirement
requires no query/API change for this Node24 implementation. #397 remains open
until the fix is merged. The final three native records have since received
individual reviews in n042. This source follow-up is not in production PR #400.

## 15 October — PR #400 exact production

PR #400 merges thirty individually reviewed FDE records (n032–n037) at
9a7b1ab982d147b1709475338070ed40fb133972. Frozen head c550b98a passes required
run38675872924: verify24m31s, SQL54s. READY preview dpl_GhKsXaErxgxjmmSXwpC82aihRLuq
passes eleven general checks. READY production dpl_ANq6kFzBzDrpmFNVH21DcNDRGz6t
matches the merge SHA, owns devshark.app and reports no alias error. Eleven
general production checks pass with guest grading at zero XP/null progress.
No owner progression, Challenge score or generated-name fixture was written.
Shipped review coverage is95 coding/240 native. This is bounded source and
same-session model evidence, not authenticated native/Premium, keyboard/zoom,
physical-device, independent/human or full-catalogue acceptance. N038–n041
remain local; diagnostic runtime follow-up #397 is not included in #400.

## Forty native FDE reviews — 2026-10-15

PR #399 merged at `cabbaac4f9cf6378dcce5661b4178c5cb03bf549` after exact
d3064e1f passed required run 38672068466 (verify29m57s, SQL40s). Production
`dpl_2GeuJuFShFhFrhHKnWEsAxPdRZer` is READY at that merge SHA, owns
devshark.app and has no alias error. Eleven general public health/Big O and
correct/wrong coding checks pass with guest zero XP/null progress. No owner-
progress, Challenge or name fixture was created. Authenticated native/Premium
acceptance, physical devices and activation are not inferred.

N024–n031 add forty individual FDE reviews. Local isolated schema examples,
metric/policy arithmetic and the mapping bridge's real sandbox/compiler verdicts
pass; six public DSA catalogue probes per theme pass at360–1440 with explicit
coverage limits. Shipped coverage is95/725 coding and210/263 native. Local
coverage through n037 is95/725 and240/263, leaving630 coding and23native.
The diagnostic parent still awaits #397. Evidence:
`/tmp/devshark-audit-2026-10-15/prod399-general.log`. Same-session model review
is not independent/human approval or full-catalogue acceptance.

## Forty-five native reviews — 2026-10-15

PR #398 merged at `46e0dd6372606e2a3912aa3395b1b60db9fc5112` after exact
5f0145fa passed required run 38668758560 (verify 25m14s, SQL 38s). Production
`dpl_DTiUbPTR5PELasM5gYD1o4diEreK` is READY at that merge SHA, owns
devshark.app and has no alias error. Eleven general public health/Big O and
correct/wrong coding checks pass with guest zero XP/null progress. No owner-
progress, Challenge or name fixture was created. Authenticated native activity,
Premium access and activation are not inferred.

N015–n023 add forty-five individual native reviews, including the final four
DSA activities and FDE diagnostic/incident/bridge/discovery/integration checks.
Exact preview, real sandbox verdicts, Python/HTTPX synthetic examples and local
release evidence are recorded in the merged review records. All 129 DSA records
now have current individual model reviews. Shipped coverage is 95/725 coding
and 170/263 native. Local coverage through n031 is 95/725 and 210/263, with
630 coding and 53 native remaining. The FDE diagnostic parent awaits #397.
Evidence: `/tmp/devshark-audit-2026-10-15/prod398-general.log`. Same-session
model review is not independent/human approval or full-catalogue acceptance.

## Thirty native reviews and five existing targets — 2026-10-15

PR #396 merged at `4b5b777cd0a7d0de55c998c3e8385a805b577973` after exact
758d1bbb passed required run 38665436277 (verify 30m20s, SQL 37s). Production
`dpl_53iTBLx23PzkgngidqaNJamoFnTQ` is READY at that merge SHA, owns
devshark.app and has no alias error. Eleven general public health/Big O and
correct/wrong coding checks pass with guest zero XP/null progress. There were
no Challenge/name/owner-progress fixtures, and no authenticated native activity
or activation is inferred.

N008–n014 bind thirty new native records plus five existing-target revisions.
The latter retain complete prior evidence without increasing unique coverage.
Sorting/tree worker verdicts, sealed-version changes, valid base-reward analyses,
individual lesson/question checks, local release gates, zero-vulnerability
production dependency audits and documented catalogue responsive probes pass.
Coverage shipped is 95/725 coding and 125/263 native. Local coverage through
n023 is 95/725 coding and 170/263 native; 630 coding and 93 native records remain.
FDE diagnostic issue #397 remains open and its parent record is unaccepted.
Evidence: `/tmp/devshark-audit-2026-10-15/prod396-general.log` and exact committed
review records. Same-session model evidence is not independent/human approval.

## Twenty-five native and five coding reviews — 2026-10-15

PR #395 merged at `1c8c04341a14f6463c38dfa458a6276386ca3747` after exact
61900610 passed required run 38661780936 (verify 30m52s, SQL 38s). The first
run's stale grader-privacy fixture assumptions were corrected without changing
production grading; full final checks include the deterministic phase-isolation
regression. Production `dpl_A7o9JHZ1pV14hDnPnkTF4urbYvaM` is READY at that
merge SHA, owns devshark.app and has no alias error.

Eleven general checks and twenty selected correct/wrong submissions across
four accessible b013 tasks pass, with guest zero XP/null progress. The fifth
binary task returns 402; authenticated Premium/native activity acceptance is
not inferred. No Challenge/name/owner-progress fixtures were created. B013 has
40/40 selected worker verdicts and 20 no-false-penalty checks; n003–n007 bind
25 individual native reviews to exact source/grading hashes and model readings.
Ninety-five coding and ninety-five native records are now shipped. Current local
coverage through n014 is 95/725 coding and 125/263 native, with 630 and 138
remaining respectively. N010's five goal revisions add no duplicate coverage.
Evidence: `/tmp/devshark-audit-2026-10-15/prod395-*.log` and committed reviews.
Same-session model evidence is not independent/human or authenticated native
acceptance.

## Twenty coding and ten native reviews — 2026-10-15

PR #394 merged at `158cf64adad473bc50125a682af86480d3795520` after required
verify and SQL run 38658122812 passed on exact 70803596 (verify 30m28s).
Production `dpl_89oFHcKJWc4rbZF5foU8hv95r7t1` is READY at that merge SHA,
owns devshark.app and has no alias error. Eleven general public checks and
five selected correct/wrong submissions on the accessible task pass, with
zero guest XP and null progress. Nineteen other tasks return guest 402;
authenticated Premium/native activity acceptance is not inferred. No
Challenge/name or owner-progress fixtures were created.

B009–b012 each have forty selected worker verdicts and twenty no-false-penalty
checks. N001–n002 have exact native bindings and manually read/executed entry,
diagnostic, recursion/stack and factorial examples. Local release gates,
dependency audits (zero vulnerabilities) and documented responsive probes
pass. Ninety coding and seventy native records are shipped. Current local
coverage through b013/n008 is 95/725 coding and 100/263 native: 630 coding
and 163 native records remain. Same-session model review is not independent
or human sign-off. Evidence: `/tmp/devshark-audit-2026-10-15/prod394-*.log`.

PR #395 freezes the next five coding/twenty-five native records. Its first
required run exposed stale privacy-test fixture assumptions; a follow-up
preserves complete hidden-case checks and exact visible-only logging, with a
deterministic fresh-program phase marker. Full grading/Learn integrity and
script types pass locally; required checks rerun on 61900610. N008 is outside
that frozen head.

## Thirty JavaScript content reviews — 2026-10-15

PR #393 merged at `3c5d0abcfe6ee2220c3dc9544cf376ceea3e4944` after required
verify and SQL run 38654051545 passed on exact c91873a6. Production deployment
`dpl_8FZR1sD41REBVFcNuVcmJUuzVyRL` is READY at that merge SHA with the
devshark.app alias and no alias error. Eleven general checks and twenty
selected correct/wrong submissions across four accessible tasks pass, with
zero guest XP and null progress. Twenty-six other tasks return guest 402;
authenticated Premium grading is not inferred from those denials. Pacing
respects the existing task-open limit. No Challenge score/name or owner
progress/coins were used as disposable fixtures.

Six five-item commits b003–b008 have 42/42, 40/40, 40/40, 45/45, 40/40 and
40/40 selected worker verdicts, 120 authored-target/base-reward probes, local
release gates and documented light/dark responsive probes. The scroll-clip
measurement fix retains six actual-visible-overlap regressions and the same
threshold. Seventy coding and sixty native records are deployed. Current
local coverage through n004 is 90/725 coding and 80/263 native; the remaining
635 coding and 183 native records still need individual review. Same-session
model evidence is not independent/human or authenticated native acceptance.
Evidence: `/tmp/devshark-audit-2026-10-15/prod393-*.log` and committed batch
candidates/reviews; PR #394 freezes the next twenty coding/ten native records.

## Ten JavaScript content reviews — 2026-10-15

PR #392 merged at `c7e8e7de5627447282c17df4e124d746749a5747` after required
verify and SQL checks passed in run 38650942972 on reviewed head 0797626c.
Production deployment `dpl_AHXHkdxthYSGMAzLDeUpHkBgAJrY` is READY at that
merge SHA and owns the devshark.app alias. Eleven general public checks and
25 selected correct/wrong coding submissions pass there with zero signed-out
XP and null progress. Five of the ten selected tasks return 402 to guests;
authenticated Premium grading remains unverified. No Challenge score, guest
name, owner progress or coins were used as disposable fixtures.

The two five-item commits record 47/47 and 40/40 selected final-hash QuickJS
verdicts, twenty authored-target/reward probes each, API types, launch
contracts, builds, registry/index freshness, both production dependency audits
(zero vulnerabilities), copy sweeps and sixty light/dark responsive probes per
batch. Full protected verify and SQL passed. A puzzle-enumerator regression
fix retains undecided prefixes before Boolean/arithmetic/string wrappers
consume the sentinel; wrong complete arrangements still fail and the step
budget stays unchanged. One helper EOF blank line found in the branch-wide
whitespace check is removed in the follow-up PR #393.

Forty coding reviews and sixty native records are now deployed. This does not
complete #176: thirty further reviews through b008 are in PR #393 and b009 is
local; individual review coverage is 75/725 coding and 60/263 native records.
The ledger is same-session model review, not independent/human sign-off.
Evidence: `/tmp/devshark-audit-2026-10-15/prod392-*.log` and the b001/b002
candidate and review records committed in the repository.

## OwnDashboard source integration (#364) — 2026-10-13

The owner integration can read current English question overrides, curation
eligibility and active coding tasks through one resource on the existing quiz
handler. Packets carry canonical content hashes, revisions and retained
ineligible tombstones. Fresh counted override reads run twice and hold on DB
failure, truncation or changing observations; daily selection binds the date
and checks the served wording. Coding packets contain no answer reveal, tests
or solution modules. OwnDashboard owns the usage ledger and post approvals.

Node 24.19.0 validation: API and script types, full launch contracts, the standalone
marketing producer and HTTP handler tests, production build, unused-code and security
policy checks, both production audits
(zero vulnerabilities), twelve-handler count and diff whitespace pass. Marketing
tests cover all 2,447 authored questions and 725 active tasks, edits/custom items,
deletes/retired items, stable pagination and supersession, two-page override
reads, changing/truncated/error DB responses, authentication and dated daily
selection. The handler uses a local PostgREST stand-in; production DB overrides
and integration secrets were unavailable and no production proof is claimed.

The clean full `test:launch` rerun passes, including Play and verified-caller
contracts. PR #365 CI caught the integration's invalid learner-limit identity;
verified exports now consume a dedicated shared operation budget after bearer
verification, with no learner identity supplied. Regression tests prove invalid
bearers cannot spend that budget, different verified caller addresses share its
twenty requests, and an exhausted export does not consume a learner quiz budget.
The identity verifier is unchanged. The build retains its existing mixed-import
and chunk-size warnings.
The responsive sweep passed 320px route probes before it was stopped to focus
on unchanged quiz/daily pages. The focused browser then timed out at startup;
no completed final responsive matrix is claimed. Logs live under
`/tmp/devshark-marketing-*.log`. No new visual run applies to this server-only
rate-limit fix; CI's full browser matrix still needs verification before merging.
No client UI, grading, XP, entitlement, production configuration
or publishing activation changed. The owner setup item is in `NEEDED.md`.

## Premium Start free thank-you tooltip — 2026-10-12

The existing English thank-you copy now has a newline before "Thank you! 💙".
The comparison CTA scopes `white-space: pre-line` to its existing Astryx tooltip;
the button remains disabled and keyboard-focusable. The navbar tooltip is separate.
API typecheck, launch contracts, build, 23 existing Premium page tests, both
production dependency audits (zero vulnerabilities) and diff whitespace pass.
Six authenticated local browser cases at 360/768/1440px in light/dark verify the
literal newline/emoji, the second sentence below the first, hover/focus visibility,
disabled Enter activation, and no horizontal overflow. The initial scripted click
was correctly blocked by the disabled button; the probe now uses keyboard Enter.
Responsive checks pass five light and three dark homepage probes (360–1440px).
The first protected CI browser run exposed the existing launch-offer regression's
old `<3` expectation. Its copy assertion now matches the newline/blue heart and
checks `pre-line`; the focused browser regression passes locally without timeout
changes. The first run's types, full application tests, build and audits passed.
Evidence: `/tmp/devshark-premium-thanks/`. Protected CI and exact production
verification are recorded on the associated PR before release.

## Navbar Premium tooltip — 2026-10-12

The navbar diamond uses the existing `nav.premium` translation for its tooltip
for every account. Its Premium member accessible name and gold icon remain.
Local API typecheck, launch contracts, build, ten existing shell tests, both
production dependency audits (zero vulnerabilities), and diff whitespace pass.
Eight authenticated fixture browser cases cover free/Premium, light/dark and
1280/1440px: mouse and focus tooltips read exactly "Premium" and the gold member
icon remains. Navbar icons are hidden at 768px by the existing compact layout;
that initial visibility probe was corrected to the supported desktop widths.
Responsive homepage checks pass five light and three dark probes from 360–1440px.
Evidence: `/tmp/devshark-premium-tooltip/`. Protected CI and exact production
verification are recorded on the associated PR before release.

## Restore the original homepage content width — 2026-10-12

Restores the homepage's centred 1000px maximum from `bb96f3c`, the mainline
version live on 10 October, replacing the later 1600px limit. Other routes
retain their existing 800px/1200px limits. The JavaScript sample stays interactive.

Validation: API typecheck, launch contracts, production build and diff whitespace
passed. Both production dependency audits report zero vulnerabilities. The existing
homepage browser test now verifies the centred 1000px cap at 1440px and 2560px,
keyboard answer feedback, absence of the video and 360px reflow; both light and
dark cases pass. Responsive checks pass all 14 homepage probes (360 through 1440px,
both themes), with no overflow or clipped content. Desktop light and mobile dark
screenshots were visually reviewed. The responsive script rejects 1920/2560px as
unsupported inputs; the wide-screen cap is covered by the Playwright test instead.

Evidence: `/tmp/devshark-width-browser`, `/tmp/devshark-width-responsive-light.log`
and `/tmp/devshark-width-responsive-dark.log`. Existing build chunk warnings remain.

## Restore the single homepage JavaScript sample — 2026-10-11

Issues #353 and #352 restore the original `2 ** 3` sample using the existing
SampleCard. All four answers and immediate correct/incorrect explanations work
without signup. The question stays JavaScript when the learning path changes.
The hero keeps its wider headline and a compact 480px question column, stacking
below 1024px. Existing path actions and the Apple/dark appearance are retained.
The rejected eight-image gallery is preserved locally on
`archive/homepage-feature-gallery-2026-10-11` at `505f7c9`; its images, component,
provenance and tests do not ship in this branch. The saved video component remains
available in Storybook, but is not mounted on Home.

| Check | Actual local result |
|---|---|
| API, client/tooling and script types | PASS |
| Home and saved video tests | PASS — 8 tests, including correct/wrong answers, one answer per visit, and fixed JavaScript sample after path selection |
| Launch/play-room/verified-caller contracts | PASS — the first run hit the existing photo-preview subprocess timeout under concurrent builds; rerun passed without changing the contract |
| Production build | PASS |
| Root/client production dependency audits | PASS — zero vulnerabilities |
| Responsive sweep | PASS — 14 probes across `/` and `/learn` at 360/390/430/768/1024/1280/1440px; no overflow or unprobed routes |
| Route accessibility | PASS — 4 existing browser tests, including light/dark WCAG 2.2 AA and keyboard path navigation |
| Restored sample browser flow | PASS — 2 tests, light/dark, keyboard answer, disabled answered options, desktop headline at least 720px in a 1440px viewport, and 360px reflow |
| Test corrections | Initial sample assertions included an unrelated global status region and used an exact answer name that changes after the success tick appears. Scoped status and stable answer matching passed on rerun. |
| Unused-code check | PASS — zero findings |
| Visual inspection | PASS — built homepage screenshots reviewed; original question, four answers, retained dark background and wide headline visible |
| Live Chrome control | BLOCKED — Computer Use reported `Sky Computer Use native pipe startup failed`; screenshots from normal browser tests were used for local review |
| Diff whitespace | PASS |

Evidence: `/tmp/devshark-restore-*.log` and the `home-sample` browser artifacts.
Required GitHub checks and the exact production deployment are tracked on the
associated PR. Brand exploration is separate and does not replace the site logo.

## Homepage video banner and learning path — 2026-10-11

Issues #347–#349 replace the practice carousel with a 16:9 product-video
placeholder on every viewport. No new recording is available yet. The banner
makes no media request; a WebM source, poster and optional MP4 fallback can be
supplied later, with explicit native playback and no autoplay or loop.
The selected path uses the full panel width, wraps to three columns on phones,
and ends with a bottom-right “Start learning {topic}” action. Homepage
progress-storage copy is removed. Normal exercises and grading are unchanged.
The dated tool comparison records official sources, prices, export-format
uncertainty and a proposed 30-second capture plan; no recording or purchase
was performed.

| Check | Actual local result |
|---|---|
| API and tooling types | PASS |
| Homepage and video component tests | PASS — 6 tests: guest/account copy, selected-path navigation, honest empty banner, explicit playback, poster and source fallback |
| Production build | PASS |
| Launch/play-room/verified-caller contracts | PASS |
| Root/client production dependency audits | PASS — zero vulnerabilities |
| Public HTML and unused-code checks | PASS — no new unused findings |
| Responsive sweep | PASS — `/` and `/learn`, 8 probes at 360/768/1024/1440px |
| Manual appearance and topic selection | PASS — dark desktop/mobile, light tablet; all seven featured topics update their Start learning label; long CSS labels remain within the 360px page |
| React component review | PASS — existing primitives/tokens, stable label keys, derived selection, no new effect/data request; named list and video region; decorative placeholder symbol has no fake action |
| Browser accessibility and keyboard path | PASS — 4 route-axe tests, light/dark WCAG 2.2 AA, long CSS steps inside the phone panel, and Enter opens the selected TypeScript path |
| Initial full CI | All content/client/types/security/build/audit and Storybook/performance checks passed; the browser step failed only because its old path test required the removed horizontal scroller. That test now verifies reflow and keyboard navigation; final required CI is rerun. |
| Diff whitespace | PASS |

Local evidence: `/tmp/devshark-banner-{tests,types,tooling,launch,build,responsive,public,unused}.log`
and `/tmp/devshark-banner-{root,client}-audit.log`, `/tmp/devshark-banner-final-{axe,build,responsive}.log`. Required GitHub checks and
production deployment are verified on the associated PR before merge/release.

## Compact homepage coding sample — 2026-10-11

Issues #339 and #341–#346 replace the large palindrome sample with the free JavaScript
`js-double-numbers` challenge. Its complete prompt is a short sentence; the
landing editor is 160px tall. Two dots below the card stack replace the named
buttons and counter, and the first desktop/tablet card is random per visit.
Three example tests sit at the bottom of the results panel; grading retains the
full suite. Big O space targets and explanatory guidance move to an accessible
info tooltip. Run and Format become named icon buttons only on the homepage;
Submit, Solution, the report flag and the scratch-pad instruction are removed
from that preview. The normal Coding editor keeps its existing size and actions.

| Check | Actual local result |
|---|---|
| API types; launch/play-room/verified-caller contracts | PASS |
| Sample/workbench tests | PASS — 29 tests, including random first card, dot switching, draft retention, three examples with full-suite execution, named tooltip content and landing-only icon commands |
| Production build; root/client production audits; diff check | PASS — zero production vulnerabilities |
| Responsive sweep | PASS — homepage, full double-numbers challenge and palindrome workbench, 12 probes at 360/768/1024/1440px |
| Live coding execution | PASS — Format and Run, 5 public tests; before removal of preview Submit, 4 hidden checks and O(n) estimate also passed, signed out |
| Prompt size and appearance | PASS — two lines at 600px, one at 768/1024px; light/dark reviewed; mobile mounts only the quiz |
| Dot controls and Big O tooltip | PASS — Enter switches the card; tooltip opens by click and closes with Escape; three idle/Run examples align to the bottom at 600px |
| Homepage command icons | PASS — 44px targets at 600px, no overflow; named Run/Format tooltips; full workbench retains command text |
| Client/tooling types after icon tests | PASS — removed unsupported Testing Library role-query options reported by CI; 29 focused tests pass again |
| Final preview simplification | PASS — 29 tests, tooling types, build and 8 responsive probes; homepage omits scratch-pad instruction, Submit, Solution and report; submit shortcut does nothing; full exercise retains those actions |

GitHub required checks and deployment are tracked on the follow-up PR. Local
evidence: `/tmp/devshark-compact-{tests,types,launch,build,responsive}.log` and
`/tmp/devshark-compact-{root,client}-audit.log`.
Final dot/tooltip validation additionally uses `/tmp/devshark-dot-{tests,types,build,responsive}.log`.
Final icon validation uses `/tmp/devshark-icon-{tests,build,responsive}.log` and
`/tmp/devshark-home-icons-final.png`.
Final simplified preview validation uses `/tmp/devshark-simple-{tests,tooling,build,responsive}.log`
and `/tmp/devshark-home-simple-final.png`.

## Apple design rollout — 2026-10-11

Owner requested the default Apple design, retaining Deep End dark backgrounds,
complete navigation borders, no Save on inaccessible coding tasks, homepage copy
cleanup, a desktop/tablet quiz + palindrome workbench carousel, advisory Big O
feedback, and the Instagram footer copy. Issues #330–#337 are tracked by
[PR #338](https://github.com/lukaskourilcz/react-express-app/pull/338).

| Check | Actual result before merge |
|---|---|
| API and scripts types | PASS |
| Client/tooling types | PASS after correcting the new test's role-query options |
| Launch, play-room and verified-caller contracts | PASS |
| Coding authorization | PASS — locked saves/collection additions refused, open task saved, existing locked bookmark removable |
| Complexity contracts | PASS — linear, nested, fixed and logarithmic traversal, sorting; unknown recursion, external calls, growing strings and regex backtracking. Deep parser nesting fails closed |
| Grading and Learn integrity | PASS — advisory parser errors preserve the grading verdict; adversarial grading and retained progression contracts pass |
| Carousel and workbench tests | PASS — mobile does not request a task/editor; switching and resizing retain code; request retry works |
| Full client suite | PASS — 104 files / 987 tests on Node 24. Initial footer matcher corrected; four load-related timeouts in a concurrent run passed on isolated retry before the full passing run |
| Production build and public HTML | PASS — 725 coding share pages, no Czech in coding chunks |
| Production CSS and bundle | PASS — Apple root token retention asserted by the build; removed obsolete application web-font imports. 240,908 gzip bytes / 243,000 budget |
| Security and unused code | PASS — no new findings |
| Root/client production audits | PASS — zero vulnerabilities |
| Visible browser story | PASS — Format, Run 11/11, Submit 11 visible + 5 hidden checks; server verdict includes O(n); navigation border visible in light/dark |
| Visible tablet/mobile | PASS — 768px editor available, 360px quiz only, no horizontal overflow |
| Automated responsive sweep | PASS — 248 route/width probes clear after a settled recheck of the single transient 430px /challenge load failure; latest build also passes 12 homepage/coding/challenge probes at 360, 768, 1024 and 1440px |
| Reduced motion/transparency/high contrast | Existing fallbacks retained; OS preferences not changed |
| Diff whitespace | PASS |
| GitHub quality and deployment | Required final checks and deployment SHA recorded by PR #338; merge waits for verification |

Big O is a structural estimate under explicit assumptions, not a proof or a
measured benchmark. Extra space targets are authored guidance, not measured
memory. Unsupported, type-only and React code requires manual review. Estimates
never alter correctness, XP or access. Account data and billing were not modified
by the local browser story; bookmark authorization used contract fixtures.

## Challenge launch audit — 2026-09-15

Status: **not yet approved for production launch**. The fixes in
[PR #192](https://github.com/lukaskourilcz/react-express-app/pull/192) were merged
to main as `541941e`, with the devShark production deployment READY.
All 13 evolving/full-stack projects now contain 136 smaller cumulative stages;
existing completion and drafts are retained. React restart/submit/results,
QuickJS expectations, account-bound sessions and accessible workbench controls
were repaired. Server React execution now uses disposable isolated VMs.

| Check | Result |
|---|---|
| Catalogue references, including actual QuickJS | PASS — 385 tasks |
| Built React iframe suites/protocol | PASS — 129 assertions |
| Client regressions and all-project draft transitions | PASS — 42 tests |
| devShark browser flow, EN/CS and light/dark | PASS — 9 checks |
| StudyShark public browser coverage | PASS — 5 checks |
| Responsive layout | PASS — 93 local StudyShark + 63 devShark dark/CS probes; production sweep and settled recheck recorded in report |
| Types, launch contracts, learning paths, public HTML, bundle budget | PASS |
| Full GitHub CI for both products, including browser/component/performance checks | PASS — `a0e332a`, run 35025211720 |
| Production dependency audits | PASS — zero vulnerabilities |
| Live database idempotency, retained pass, isolated drafts | PASS — synthetic transaction rolled back |
| Real isolated VM forms, storage, network/credential isolation, loop termination | PASS — 6 integration checks |
| Deployed API submissions (first stage of every project) | PASS — 13/13 on `a0e332a`, including the OIDC-backed React VM runner |
| Two-account API/browser flow, permissions, draft separation and deletion | PASS — disposable users; multiplayer/Classroom completed, reconnect/reload recovered |
| Bounded React concurrency | PASS — 10/10 at maximum concurrency 3; p50 5.767 s, p95/max 14.933 s; launch-capacity acceptance still OPEN |
| Recovery | OPEN — RPO 24h/RTO 1h accepted; latest observed backup ~19h old; restore credential handoff pending |
| Alert delivery and physical-device acceptance | NOT RUN — #190 |
| Hostile submission verdict integrity | QuickJS regression PASS; React OPEN — #191; VM isolation alone does not resolve this |

The mobile workbench still requires a larger screen for editing, as before.
The hardening follow-up (`docs/launch-hardening-2026-09-16.md`) and the full audit (`docs/launch-audit-2026-09-15.md`),
both deleted on 22 October 2026 and kept in Git history, recorded the exact scope, live-account changes, preview evidence and outstanding gates.
[Operations](./react-grading-operations.md) covers snapshot maintenance.

## Keyboard shortcut keycaps — 2026-09-15

The right-aligned shortcut guide uses inline SVG keycaps for Control, Enter,
Shift, Escape and Tab. Run and Submit chords share the first row; Escape then
Tab occupies the second row. The SVGs are decorative and the group exposes the
complete existing EN/CS instruction to assistive technology. The exit label is
localized in both dictionaries. No keyboard handlers changed.

Production build, API types, launch contracts, nine workbench tests, both
production dependency audits (zero vulnerabilities), and diff checks passed.
Responsive checking remains blocked by missing Chrome/Chromium; live visual
verification remains outstanding.

## Compact failure feedback — 2026-09-15

Automatic failure feedback (including “Nothing came back”) now sits below the
verdict at the bottom of the Results board, visible only on the Results tab.
The compact treatment uses 0.8rem type, 8px/10px padding, tight line spacing,
and a sentence-case label. Explicitly requested hints remain below the toolbar.
EN/CS text and the accessible status announcement are retained. Commands use
a fixed 12px gap with no space-between distribution. The toolbar no longer
shows the solution hint-count availability message.

Production build, nine workbench tests, API types, launch contracts, both production dependency
audits (zero vulnerabilities), and diff checks passed. Local responsive checking
could not run without Chrome/Chromium; live visual verification is outstanding.

## Workbench command spacing and guidance — 2026-09-15

Desktop commands share one left-aligned row, including Focus and Report.
The command column receives at least two thirds of the available row width
with larger gaps; contextual hint guidance and keyboard instructions occupy
the right-aligned text column. Narrow layouts wrap controls to avoid overflow.
Existing EN/CS guidance and hint accessibility relationships are retained.

Production build, API/tooling types, launch contracts, 15 targeted client tests, diff checks, and both
production dependency audits passed (zero vulnerabilities). Responsive checking
is blocked by missing Chrome/Chromium; narrow/zoom/light/dark visual acceptance
has not been established for this spacing change.

## Evolving stage code handoff — 2026-09-15

The workbench sends the exact submitted snapshot to the route. Evolving drafts
remain available locally after saving/passing, and the next stage falls back to
the previous local draft if the server has no draft. Existing next-stage local
and account drafts retain priority. Inactive task cache entries are discarded
rather than initializing the editor from a stale response.

Six route regression checks cover JS/TS/React advancement, successful autosave,
next-stage cache eviction, preservation of existing local/account drafts, and
the FullStack API-to-React scaffold transition. These and nine workbench checks
passed (15 tests). Production build, API/tooling types, launch contracts and both production
dependency audits and diff checks passed (zero vulnerabilities). Responsive checking could not
run because Chrome/Chromium is unavailable. Authenticated live cross-device
advancement has not been verified. No layout, translations, schema or grading
rules changed.

## Workbench layout, hints and calculator feedback repair — 2026-09-15

The full-width brief now precedes a shared editor/results grid row. Both panes
stretch to the same height and scroll with the page. Removing sticky positioning
prevents results from overlaying the controls; explicitly hidden panes remain
hidden despite the flex display rule. Hints start at zero on every mount rather
than restoring old localStorage counts. Regression checks verify closed hints,
one-click reveal, reset, and sibling editor/results placement.

The reported stage-1 hidden check requires a valid sum without spaces. The
prompt already allows optional whitespace. Two labeled visible tests now cover
unspaced and mixed-spacing input, and hidden-check failures have EN/CS explanatory
text. Server sandbox regressions prove that valid addition passes all visible
and hidden cases while space-dependent tokenization fails publicly.

Production build, API and tooling types, launch contracts, 18 client tests,
all 323 task content/reference-solution contracts, both production dependency
audits (zero vulnerabilities), and diff checks passed. Local responsive checking
remains blocked by missing Chrome/Chromium.

Production verification confirmed the repaired calculator passes 6/6 visible
and 1/1 hidden checks on the server. Browser geometry confirmed equal-height
editor/results panes, controls below both, no horizontal overflow and zero
revealed hints on entry. CI's unused-code gate found the two orphaned Shark
Cards client files from the earlier removal; removing them restores both the
unused-code and security gates without changing the application bundle.

## Activity-only application scrollbars — 2026-09-15

Native scrollbar tracks and idle thumbs are transparent across the app. A
single delegated listener set reveals the nearest scrollable container during
pointer movement, scrolling or scrolling-key input, then hides its thumb after
1.1 seconds idle. Dragging keeps it visible. The implementation batches pointer
work with requestAnimationFrame and disposes listeners/timers during hot reload.
Chromium/WebKit use 4px bars; Firefox uses native thin bars. High-contrast mode
keeps a visible thumb, and reduced-motion mode removes its color transition.
Coding and roadmap-specific scrollbar overrides were removed.

Production build, API typecheck, launch contracts, both production dependency
audits (zero vulnerabilities), and diff checks passed. Local responsive
verification remains blocked by missing Chrome/Chromium.

## Waterline variation and themed scrolling — 2026-09-15

The evolving list uses a thin rounded scrollbar with shared surface, text and
brand tokens, including WebKit styling. `generateWaterline()` varies wavelength,
amplitude, direction, phase and speed once per mounted component. Coding track
waves opt into zero, one or two decorative fins, with separated positions,
varied sizes, opacity and gentle movement that stays in the water. Progress
fill remains accurate and its clip no longer drifts with the wave. Quiz and
typing retain their endpoint markers.

Hover fins never start above the button. Dives now move diagonally downward;
all vertical offsets stay at or below the bottom baseline. Reduced-motion
rules continue to freeze the decorative movement.

Production build, API typecheck, launch contracts, 18 client tests, both
production dependency audits (zero vulnerabilities) and diff checks passed.
Local responsive verification is blocked by missing Chrome/Chromium.

## Five-row evolving challenge list — 2026-09-15

Lists longer than five projects now scroll internally. A ResizeObserver measures
the first five rows so the viewport follows translated text, zoom, font loading
and narrow layouts. The named region is keyboard-focusable with a visible focus
ring; native scrolling also brings tabbed Continue buttons into view. Shorter
lists, including the three FullStack projects, retain their natural height.

Production build, API typecheck, launch contracts, both production dependency
audits (zero vulnerabilities), and diff checks passed. The local responsive
command remains blocked by missing Chrome/Chromium.

## Coding discovery and production hover fix — 2026-09-15

The live Continue button reproduced `:hover = true` with fin opacity still zero.
PurgeCSS removed its compound activation selector despite the class safelist.
Flat hover/focus selectors and a narrowly scoped safelist retain it; the production build
fails if a fin stylesheet loses its hover activation rule. Swimming fins stop
inside the button instead of exiting its clipped area.

Coding discovery now uses a featured next challenge, a compact track directory,
numbered evolving-project rows with stage meters, a distinct FullStack feature,
and divided technique lists. EN/CS copy stays paired. Mobbin references reviewed:
[Coursera resume hierarchy](https://mobbin.com/screens/18683325-d982-4756-b06e-4ed52c933b06),
[Codecademy skills density](https://mobbin.com/screens/597bbefb-e6cf-401c-abc6-47789b29e5b7),
and [Uxcel learning hierarchy](https://mobbin.com/screens/519c99ca-f49e-4509-b6db-57a74154d859).
These informed layout only; no external artwork was copied.

Production build (including the hover-retention gate), API typecheck, launch contracts, 18 client tests and both production dependency
audits passed (zero vulnerabilities). Local responsive execution remains
blocked by missing Chrome/Chromium.

The initial CI run exposed existing test-only TypeScript errors in coding-actions:
missing `initialCode` props and unsupported `exact` options on RTL role queries.
The follow-up supplies null drafts and uses RTL's default exact name matching.
Tooling typecheck and all 18 client tests pass after this correction.

## Coding controls and randomized fins — 2026-09-15

Stage links now appear in Resources. The compact, full-width action bar uses
Hint / Next hint, Solution and Focus labels in both locales. Collection no
longer exposes Shark Cards. Shared `generateFinHover`, `FinButton` and `SwimCta`
assign stable random fin motion, shade, size, direction and speed, with keyboard
focus support and static reduced-motion decoration.

Verified: API typecheck, launch contracts, 18 client tests, production build,
both production dependency audits (zero vulnerabilities), and diff whitespace
checks. The live homepage's fade and swim effects were inspected in a remote
browser as the animation reference. Local responsive verification remains
blocked by missing Chrome/Chromium; the changed UI has not been visually
verified in a local browser.

## Evolving / FullStack update — 2026-09-15

This update expands the original ten projects to five stages each and adds
three eight-stage FullStack apps at `/coding/fullstack`. All 74 stages have
individual EN/CS descriptions and targeted references. Prior requirements
remain available; legacy IDs and saved progress are preserved. Help controls
move below the 480px-minimum desktop editor, with an ordered revealed-hint list.

| Gate | Result |
| --- | --- |
| API TypeScript check | Pass |
| Production app and isolated sandbox builds | Pass |
| Launch contracts | Pass, including twelve API handlers and answer isolation |
| Coding content contract | Pass: 323 reference solutions; starters rejected; cumulative stage checks; EN/CS parity; answer-free payloads |
| Client tests | Pass: 16 tests, including toolbar placement, hint/reset state, TSX formatting and FullStack draft/track transitions |
| Unused-code regression check | Pass: no new findings |
| Both production dependency audits | Pass: zero vulnerabilities |
| Whitespace validation | Pass |
| Responsive/visual browser sweep | Blocked: `check:responsive` exits because no Chrome/Chromium binary is installed |
| Authenticated cross-device draft/completion acceptance | Not run: local tests prove transition logic, not live account synchronization |

FullStack API requests execute the learner's own handler through the shared
network-free adapter. This is an in-memory teaching environment, not a deployed
backend or a production-auth/database exercise. TypeScript stages 2–4 are
compiler-checked; React stages transpile TSX and test API/UI behavior. No new
tables, migrations, database permissions or external network access were added.
React review preserved semantic controls, accessible names, effect cleanup,
stable IDs, derived view state and narrow-layout access to learning actions.

## Earlier modernization acceptance

What was verified for the modernization epic, what was not, and why. Every row
is pass, fail or **not run** — never "should be fine". A row that could not be
checked in this environment says so and names what would check it.

Recorded on 2026-09-08 against `ccee58b`, and extended on 2026-09-09 after a
full code, design, content and architecture review. Both commits are on `main`.

## Repository gates

| Gate | Result |
| --- | --- |
| `npm run typecheck:api` | **Pass** — clean |
| `cd client && npx tsc -b` | **Pass** — clean |
| `npm run test:launch` | **Pass** — product identity, scope, token confidentiality, stable attempts, fairness-neutral rewards, rate limiting, health, the twelve-handler budget, the progression graph, failure hints, retired sections, curation claims, spaced practice, interleaving, lesson figures, and an unconfigured shop |
| `npm run test:coding` | **Pass** — 249 tasks (javascript 97, typescript 42, react 65, system-design 45), solutions proven, payloads answer-free |
| `npm run test:paths` | **Pass** — dsa-foundations v1 (10 modules, 18 lessons, 36+10 checks, 30 exercises); fde v1 (11 modules, 20 lessons, 40 checks, 17 exercises, 3 artifacts) |
| `npm run build` | **Pass** |
| `npm audit --omit=dev` (root) | **Pass** — 0 vulnerabilities |
| `npm audit --omit=dev --prefix client` | **Pass** — 0 vulnerabilities |
| `git diff --check` | **Pass** — clean |
| `npm run test:harness` | **Pass** — 23 assertions against the built sandbox in Chromium (needs `CHROME_BIN`; it skips itself silently without one) |
| `npm run check:responsive` | **Pass** — see below |
| `npm audit --omit=dev` (both, re-run 2026-09-09) | **Pass** — 0 vulnerabilities |

## Responsive sweep

The sweep renders each route at seven widths (360, 390, 430, 768, 1024, 1280,
1440) against a local `vite preview` build and reports horizontal overflow and
child boxes escaping their parents.

Run over the routes this change touched — `/`, `/quiz`, `/learn`, `/today`,
`/curation`, a coding task and a DSA module — at all seven widths in
light/English: **49 probes, 0 with issues.** No horizontal overflow, no child
escaping its parent, nothing under the ocean footer. The wider default sweep of
all thirty routes exceeds this container's per-command time budget at roughly
thirty seconds a probe; the earlier full-set results were recorded in
`docs/DEEP_END_HANDOFF.md`, removed on 2026-09-28 and kept in Git history.

A second pass in **dark theme and Czech** over the four surfaces this change
added or altered (`/`, `/learn`, `/today`, `/curation`) reached **18 probes with
zero issues** — every one of the four at 360, 390, 430 and 768, plus two at
1024 — before it was stopped for time. The three desktop widths are therefore
covered in light/English and not in dark/Czech for these routes; the earlier
full-set dark/Czech results were recorded in `docs/DEEP_END_HANDOFF.md` (removed on
2026-09-28, kept in Git history). Recorded as
partial rather than rounded up.

**Its limit, stated plainly: it renders signed out.** Every graded workspace,
the coding editor beside its brief, the trace player and the review session are
therefore probed as the guest preview, not as the thing a signed-in learner
sees. Confirming those is an owner check, and it is in `NEEDED.md` rather than
counted here.

`/today` and `/curation` were added to the default route list in this change,
because Today gained a review-due card and `/curation` is a new page.

## Epic children

Every row below is implemented and covered by the repository gates above unless
its note says otherwise.

| # | What it delivers | State |
| --- | --- | --- |
| 151 | Versioned learner profile, required at onboarding and editable in Profile | Implemented |
| 152 | One server-side progression graph; start and submit refuse a locked step | Implemented; asserted by `test:launch` |
| 153 | Only eligible paths shown; Roadmap, Today and navigation tailored | Implemented |
| 154 | Code-ordering puzzles for mobile and tablet | Implemented; accepted orders stay server-side |
| 155 | Task resources before hints | Implemented; asserted by `test:launch` |
| 156 | Authored failure hints that name no input or expected value | Implemented; asserted by `test:launch` |
| 157 | Bookmarks and named collections | Implemented (migration 027) |
| 158 | Curated approaches after a verified pass | Implemented |
| 159 | Short practice sessions from time, topic and plan | Implemented |
| 160 | Skip reasons and next steps, no mastery awarded | Implemented |
| 161 | Search and combined filters over eligible challenges | Implemented |
| 162 | Tiny interactive examples in lessons | Implemented (trace player) |
| 163 | Debugging as a discoverable format | Implemented; four authored tasks |
| 164 | Focused, resizable, accessible workspace | Implemented |
| 165 | System Design out of Coding, kept in Learn and FDE | Implemented; asserted by `test:launch` |
| 166 | Sibling-platform promotion off the devShark footer | Implemented; asserted by `test:launch` |
| 167–173 | Merchandise, wallet, orders, payment, fulfilment, crown | Implemented; **commerce ships disabled** — see below |
| 175 | Eight waterline variants with stable per-component selection | Implemented |
| 177 | Abbreviations retired; contextual term help | Implemented; asserted by `test:launch` |
| 178 | Code Snippets retired; snippet format across topics | Implemented; declared metadata now reaches delivery |
| 179 | Testing retired; foundations into General | Implemented; asserted by `test:launch` |
| 180 | HTML condensed to six levels, CSS refocused | Implemented; 96 authored questions |
| 181 | Curation methodology and evidence-bound review claims | Implemented; asserted by `test:launch` |
| 182 | Interleaving of related concepts | Implemented; asserted by `test:launch` |
| 183 | Worked examples and diagrams in Learn lessons | Implemented; asserted by `test:launch` |
| 184 | Spaced practice at concept level | Implemented (migration 030); asserted by `test:launch` |

### FDE (#128) and DSA (#129)

| # | What it delivers | State |
| --- | --- | --- |
| 130 | Shared versioned path contracts | Implemented (`shared/learning-paths.ts`, `shared/learning-path-api.ts`) |
| 131 | Enrollment, attempts, evidence, drafts, progress storage | Implemented (migration 026) |
| 132 | Guarded path APIs inside existing handlers | Implemented; no new physical handler |
| 133 | Graders adapted for path-bound exercises | Implemented; `test:paths` proves every solution |
| 134 | Two-step track and optional FDE selection, safe account sync | Implemented |
| 135 | Overview, module workspace, resumable progress | Implemented |
| 136 | Diagnostics and track-specific bridges | Implemented; advisory only |
| 137–139 | FDE M01–M10 and the staged capstone | Implemented; 20 lessons, 40 checks, 17 exercises, 3 artifacts |
| 140 | Progress in Today and Profile | Implemented |
| 141 | Readiness, reports, privacy-conscious metrics | Implemented (`/dev` → Learning paths) |
| 142 | Positioning and EN/CS UX | Implemented |
| 144, 146–148 | DSA entry plus the ten modules through trees and the assessment | Implemented; 18 lessons, 46 checks, 30 exercises |

## What is deliberately not enabled

**Commerce ships off.** The shop is unconfigured by default: no price is
invented, an incomplete quote is dropped on read, `testMode` defaults on, and
payment is only ever applied through a signed webhook. `test:launch` asserts the
unconfigured state, so a partial configuration cannot quietly start selling.
Free learning does not wait on any of it — the two rollouts are independent, and
nothing in the learning path, the practice session or the reward ladder consults
the shop.

*25 September 2026:* the paragraph above describes the product of 9 September.
The owner made devShark freemium on 25 September 2026: `shared/tiers.ts` now
decides what each account may start, and the shop still gates no learning.
Spreadshop sells the merchandise for cash, and coins redeem it for Premium
accounts; cash checkout in this app stays off.

**Learning-path features are behind their own switches.**
`LEARNING_PATH_DSA_ENABLED` and `LEARNING_PATH_FDE_ENABLED` are independent, and
the API refuses both outside the `webdev` scope regardless of the variable.

*22 October 2026:* the DSA path is retired and no application code reads `LEARNING_PATH_DSA_ENABLED`. `LEARNING_PATH_FDE_ENABLED` stays unset in Production until the owner switches FDE on.

**The item-level content audit has run over the whole question bank.** All
2,128 served devShark questions have been read twice, rewritten or retired,
translated from the final English, and recorded in the ledger. All sixteen
categories are complete, so the gate withholds any item without a current
passing record rather than serving it with no claim: 1,974 are served on a
recorded review, 152 are retired and 2 quarantined. The 319 items in the
retired sections have each been read once; the unreferenced banks and the
legacy core bank have no delivery path and get a bank-level disposition
instead. The review is model-performed with recorded evidence and the product
says so rather than calling it a human review.
`docs/audit/devshark-content-audit.md` reports what was found and what a human
still has to decide; `docs/curation-claims.md` records what the product may
say.

## Not run in this environment, and what would run it

A Supabase connection was available on 2026-09-09, so the migrations and the
policy checks below moved out of this table and into **Applied and verified**.
The rest still needs a deployment, a signed-in session or a real payment
provider, and is honestly **not run** rather than assumed:

| Check | What it needs |
| --- | --- |
| Guest → sign in → diagnostic → practical pass → resume → capstone | A preview deployment with Supabase configured |
| Payment webhook replay | A configured payment provider in test mode |
| Account switching and deletion end to end | Two real accounts |
| Rollback (disable the feature, retain the data) | The same preview environment |
| Signed-in responsive layout | A signed-in browser session — the sweep renders signed out |

These are the owner's deployment checks, and each already has an entry in
`NEEDED.md` with an owner and an estimate. **None of them is claimed as passing
here.** An unchecked box in an issue is not evidence, and neither is this
document: it records what the commands actually printed.

## Review of 2026-09-09: what it found

A code, design, content and architecture pass over the shipped epic. Everything
below was reproduced before it was fixed, and the fix was measured afterwards.

### Features that ran but did not reach the learner

**Spaced practice selected nothing.** The review handler worked out which
concepts were due, built a due-first pool, and handed it to a ranking that sorts
by its own total order — so the ordering was discarded. Verified with two
learners, one with nothing due and one with two concepts due: byte-identical
ten-question sessions, neither containing a due concept. Slots are now taken out
of the count before the ranking runs, which is the one arrangement the ranking
cannot undo. The contract asserts both halves.

**Hinted answers counted as independent recall.** The submit payload reported
which hint popovers were *open* at submit time. They never are — the popover
light-dismisses on the same click that picks an answer — so `hinted` went out
empty and every hinted answer climbed the interval ladder, which is exactly what
spaced practice exists to see through. The flag is sticky now.

**Levels fed nothing into the ladder.** Only quiz submits recorded a concept
review, and levels are where a devShark learner spends most of their time, so
nothing was ever due for them. Level completion records the same way now.

**The AI topic was unreachable.** Twenty levels and 160 questions, planned only
by the FDE bridge, so every learner who did not take that specialisation was
refused it as "not in your plan". It now closes all three base tracks, and the
contract fails if any deployable topic is planned by no track.

### Design defects

**The theme and language were applied after the bundle rendered.** A learner who
chose dark got a white page until the entry bundle had downloaded, parsed and
rendered — on a phone on a slow connection, a second or more, every cold load.
The document also stayed `lang="en"` while showing Czech, which a screen reader
reads in an English voice. Both are set before first paint now.

The ordering matters as much as the script: a pending stylesheet blocks every
script after it, so with the webfont link first the theme was never applied at
all while `fonts.googleapis.com` was unreachable. Measured in a headless browser
with the entry bundle blocked, so nothing but the bootstrap could have set the
attributes.

**Touch targets.** Measured across nineteen routes at 390px with touch
emulation on: the mobile navigation toggle at 36×36 — the most-tapped control on
a phone and the smallest thing on the page — buttons at 32px tall, segmented
control items at 28px, footer links at 14px. A coarse-pointer floor now brings
every control to 44px; re-measured across twenty-four routes in English and
Czech — 602 interactive elements each — nothing below it, no two clickable
boxes overlapping, and no clipped text without an ellipsis.

Those last two came back empty, so the instrument was checked rather than
believed: injecting two overlapping buttons and one deliberately clipped
sentence into a real page made it report all three. A zero from a measurement
that cannot produce a one is not a result.

**Toasts ignored `prefers-reduced-motion`.** The shared motion primitives each
handle it; the three components with a variant of their own slid and scaled for
everyone. One shared helper now takes the movement out and leaves opacity alone.

**An English phrase inside a Czech figure.** The HTML landmarks figure annotated
`main` with the plain value "one per page". It is a localized note now, and the
figure contract refuses any value carrying whitespace.

### Performance

**Hashed assets were revalidated on every visit.** Production served
`/assets/*` as `max-age=0, must-revalidate`, so a returning visitor made a
conditional request per chunk and got a 304. A content hash in the filename is
what makes a long cache safe; they are `immutable` for a year now, and the entry
documents still revalidate.

Measured on the live deployment: HTML 4.7kB and TTFB 0.39s; the entry bundle
300kB raw, 99kB over Brotli. The initial critical path is roughly 215kB
compressed — entry, React, router, query client and the shell stylesheet.
Routes, both translation tables, the level intros and the in-browser compiler
toolchain are all separate chunks and none is on that path.

**The coverage endpoint costs 18ms** for all 4,320 questions, edge-cached for
60 seconds with a five-minute stale-while-revalidate. Measured rather than
assumed.

**No unbounded or per-row queries were found** in the request paths. Every
learner query is keyed by `user_id` and the aggregates are bounded; the live
multiplayer view uses Realtime with polling only as a fallback.

### Tooling that was reporting more than it knew

**The responsive sweep could stall forever.** A DevTools command had no
deadline, so a wedged renderer left its promise pending and the retry loop
around it could never reach its own clock. One run sat frozen for half an hour
with the process alive. Commands have deadlines now, a route that cannot be
probed is reported as an error rather than skipped silently, a wedged browser is
restarted and the route retried once, and a sweep that failed to look at
something no longer prints "all clear".

**It was also measuring phones with a mouse's stylesheet.** `mobile: true` does
not make `(pointer: coarse)` match; touch emulation does. Every coarse-pointer
rule was invisible to it.

**And the build was deleting the app's overrides of design-system classes.** The
post-build purge keeps class names it can find as literals in the emitted JS,
and Astryx composes its `astryx-*` names at runtime. A rule that worked in `npm
run dev` was gone in production, silently. They are safelisted now, for about
2kB gzipped.

### Content

`npm run audit:devshark-content` flags **158 of 2,423 devShark questions**
(6.5%) where the correct answer is markedly longer and more detailed than its
distractors — the oldest tell in multiple choice. Not fixed here: rewriting them
is the content audit's work (#176), and this records the number so the decision
to run it has one.

EN/CS parity was re-checked mechanically: **2,038 keys each, none missing on
either side.** The 54 identical values are proper nouns, technology names,
format strings and deliberate borrowings ("skill check", declined properly in
the surrounding Czech copy).

## Applied and verified against production (2026-09-09)

| What | Result |
| --- | --- |
| Migrations 026, 027, 028, 029, 030 applied in order | **Pass** — all additive and idempotent, applied after 029 was used as a low-risk smoke test |
| Migration 031 (RLS InitPlan, duplicate index) | **Pass** |
| Row-level security on the eighteen new tables | **Pass** — enabled on every one |
| `learning_path_attempts` and `merch_stock` readable by nobody but the service role | **Pass** — zero policies, zero grants |
| Every new function service-role only | **Pass** |
| No policy re-evaluates `auth.uid()` per row | **Pass** — 0 remaining, down from 18 |
| `question_reports.content_version` exists and is nullable | **Pass** |

Two defects were found while applying them, both now fixed in the migration
files as well as in production:

**027 and 028 left Supabase's default table grants in place.** They granted
`SELECT` without revoking first, so `INSERT`, `UPDATE`, `DELETE` and `TRUNCATE`
remained for `anon` and `authenticated` on twelve tables — the token ledger,
balances, merchandise orders and cosmetic entitlements among them. The policies
masked the first three by matching no rows. `TRUNCATE` takes no rows and so
passes no policy: any signed-in browser session could have emptied a table.

**Eighteen owner-read policies evaluated the caller once per row.** Correct, but
a cost that grows with the table. Wrapped in a scalar subquery it is evaluated
once per query.

## Migration order and rollback

Additive schema first, guarded API second, client third — the order the
implementation plan sets out. Every migration in this change (027, 028, 029,
030) is additive and idempotent, so applying it twice is safe and applying it
early breaks nothing.

Rollback is **disable the feature, retain the data**. There is no
data-destructive schema rollback anywhere in this change: no column is dropped,
no table is renamed, no row is deleted by a migration. Turning a feature off
leaves its rows readable, and turning it back on finds the learner where they
were.

The one place data is deliberately not carried forward is the token wallet: the
old browser-held balances are not converted, because they cannot be audited.
`docs/rewards-launch.md` records why, and the cosmetics already owned stay owned.


## 2026-09-11 — eight free-tool recommendations

Implemented performance reporting and a 243,000-byte initial JS/CSS gzip budget, self-hosted Inter/Manrope, MSW/Vitest failure and recovery tests, reviewed Knip checks, an Astryx Storybook workshop, EN/CS public guide HTML with canonical/sitemap/schema, concrete homepage copy and activation events, shared fluid typography/spacing, and exact-hash document CSP regression checks.

Local evidence at implementation review: API typecheck, launch contracts, coding content, learning paths, nine client tests, tooling typecheck, devShark production build, Storybook build, 11 public URLs, security policy contracts and Knip's three reviewed existing files passed. Initial devShark JS/CSS was 217,926 gzip bytes. Browser execution is blocked by the local environment (`socket() failed: Operation not permitted`), so local Lighthouse, responsive and browser results are not reported as passes. Product quality CI runs the browser matrix and records reports.


Final application source `ef954d1f2414536035d9a6ad88cbaa6a68f53403` passed both product jobs in [quality run 34605485210](https://github.com/lukaskourilcz/react-express-app/actions/runs/34605485210): API/tooling types, launch/coding/path contracts, nine client tests, both builds, public HTML, bundle budget, Knip, security and both production dependency audits. Each product passed five public browser tests, 34 responsive probes with zero issues, and the 23-assertion coding-frame harness; the devShark workshop additionally passed all five browser tests, including axe contrast and keyboard focus restoration. The final initial devShark JS/CSS graph is 217,962 gzip bytes, below the 243,000-byte budget.

The final static-preview Lighthouse run scored mobile 75 / desktop 97 for performance, 100 for accessibility and SEO, and 96 for best practices. Mobile LCP was 3.53 seconds and CLS 0.222; desktop LCP was 0.80 seconds and CLS 0.090. These are individual lab runs without live API credentials, not field measurements or a demonstrated overall performance improvement. Mobile layout shift remains a measured follow-up. Complete reports and browser screenshots are retained in the workflow artifacts for 14 days; baseline and final summaries are committed under `docs/quality/`.

This release changes no database schema, scoring authority, billing or handler count. PostHog account-level funnel setup and Search Console sitemap submission remain documented owner actions. The deployment result is recorded on PR #189 after production verification.

Production verification on the initial merge confirmed both products’ guide HTML, locale metadata and HTTPS/sandbox headers, but exposed a missing-guide soft 404: the broad SPA fallback still matched unknown topic paths. The follow-up excludes `/topics/` and `/cs/topics/` from that fallback; production status verification is recorded on PR #189 after redeployment.


## 2026-09-18 — workbench rework, junior/senior solutions, the debugging path, challenge runs

What changed: Results lists every check before the first run and scrolls after eight rows; each evolving stage leads with its own checks; the keyboard guide draws real keycaps; earlier stage briefs read as context; Hint and Solution explain themselves in Astryx tooltips instead of a helper line; focus mode is gone and the save star sits in the toolbar. Every graded code task carries a junior and a senior solution, proven by the content contract and shown in a Solution tab after a verified pass. A fourteenth evolving project, the debugging path, teaches tracing-before-fixing with `console.log` across ten stages. Challenge runs (migration 037) let a signed-in learner shape a run — track, count, order — and start it now or plan it for a date and time. Two fixes were carried over from the stale modernization branch (PR #185): puzzle line ids are now presentation ids translated inside the sealed session, and the payment webhook checks the amount and currency against the order and ignores a stale failure on a paid order.

Local evidence, all executed on the merged head:

| Check | Result |
| --- | --- |
| `npm run typecheck:api` | pass |
| `npm run test:coding` | pass — 395 tasks (javascript 150, typescript 84, react 116, system-design 45); reference, junior and senior solutions proven against visible and hidden checks; Czech parity; debug-format starters fail their own tests; presented puzzle ids never sort into an accepted order (1 min 41 s) |
| `npm run test:launch` | pass — adds challenge-run queue and schedule assertions and the webhook decision table |
| `npm run test:paths` | pass |
| `npm run test:client` | pass — 7 files, 43 tests |
| `npm run build` | pass (React runner, client, sandbox page) |
| `npm run test:harness` | pass — 129 assertions against the built sandbox in Chromium |
| `npm run check:responsive` (devShark build, `/`, `/today`, `/coding`, `/coding/javascript`, `/coding/react`, three task pages, `/coding/fullstack`, `/coding/review`) | pass — 70 probes, 0 issues |
| `npm audit --omit=dev` (root and client) | 0 vulnerabilities |
| `git diff --check` | clean |

Screenshots taken with a mocked API (light and dark, English and Czech, 1440 and 390 px): the idle Results rows, the capped list, the keycaps and both tooltips, the previous-requirements block, the Solution tab, the debugging path on the Coding home, the run planner in its form, planned and active states, the planned-run card on Today, and the run line on a task page. Not exercised here, and listed in `NEEDED.md`: the account-bound flow end to end (plan a run, start it from Today, pass a queued task) and the Solution tab on a return visit. Migration 037 was applied to production later the same day through the Supabase connector: structure, privileges and a rolled-back functional exercise verified, re-application a no-op, advisor unchanged.

## 2026-09-21 — the Algorithms track, and comment-free solution boards

What changed: the Coding section lists a fourth track, `algorithms` — twenty-five interview problems in plain JavaScript, from Two sum to a promise pool and an exponential-backoff retry. It grades, awards XP and enters the review ladder like any other track, but it carries its own topic so no challenge can be drawn into a Learn level's quota, and it is unladdered, so every tier is open from the start. Widening the track union named three places where a question had been answered inline; each became one predicate (`hasLearnLevel`, `UNLADDERED_TRACKS`, the parser choice inside `formatCode`). Separately, the junior and senior boards shown after a verified pass no longer carry their authoring comments: 313 senior boards and 18 junior ones opened with a note that buried the code underneath it. Migration 038 widens the two track constraints and the two routines that record a verdict and a reveal.

Local evidence, all executed on the merged head:

| Check | Result |
| --- | --- |
| `npm run typecheck:api` | pass |
| `npm run test:coding` | pass — 420 tasks (javascript 150, typescript 84, react 116, system-design 45, algorithms 25); reference, junior and senior solutions proven against visible and hidden checks and the production QuickJS grader; Czech parity; every shipped board asserted comment-free |
| `npm run test:launch` | pass — 12-function budget unchanged at twelve handlers |
| `npm run test:paths` | pass |
| `npm run test:client` | pass — 7 files, 43 tests |
| `npm run build` | pass (React runner, client, sandbox page) |
| `npm run test:harness` | pass — 129 assertions against the built sandbox in Chromium |
| `npm run check:responsive` (devShark build, full route list including `/coding/algorithms` and a task page, 7 widths) | pass — 231 probes, 0 issues |
| `npm run check:responsive` (devShark build, Czech + dark, the four Algorithms routes) | pass — 28 probes, 0 issues |
| `npm audit --omit=dev` (root and client) | 0 vulnerabilities |
| `git diff --check` | clean |

Rendered and asserted in Chromium against the devShark preview, English and Czech: the Coding home lists the track with its blurb and "0 of 25 passed"; `/coding/algorithms` lists all twenty-five under four tier headings (Foundations, Fluency, Combine, Interview / Základy, Jistota, Kombinace, Pohovor) with nothing locked, every row linking into the track, and no row claiming a Learn level.

Not exercised here, and listed in `NEEDED.md`: anything account-bound, since no Supabase project is reachable from the build container — a recorded pass on an Algorithms challenge, and the Solution tab showing the two stripped boards after that pass. Migration 038 has not been applied to production; until it is, a signed-in pass on an Algorithms challenge is graded correctly and then refused by `record_coding_verdict`.

## 2026-09-21 — English only, wider challenge coverage, migration 038 applied

What changed, after the Algorithms track landed earlier the same day:

- **English only.** `ENABLED_LANGS` in the client's LanguageContext lists what the build ships. While it holds one entry the footer and profile language buttons do not render, a stored preference, a browser preference and a prerendered locale are all ignored, `setLang` refuses a language the build does not carry, and the lazy Czech chunk is never requested. Nothing Czech is deleted: the dictionary is now `Partial`, the launch contract no longer demands a Czech string for every English key, and the coding content contract checks Czech parity only under `CODING_REQUIRE_CS=1`. CLAUDE.md, AGENTS.md, the skills, the agents and the commands no longer ask for Czech copy or EN/CS parity.
- **Every Algorithms challenge now shows 10 to 12 visible checks**, up from five or six. The additions are the cases the first pass left to hidden checks or missed: a size that is negative and one that is fractional, a rotation of two whole turns, tabs as whitespace, a priority of 10 against 9, an empty array between two values, `undefined` returned unchanged by a deep clone, a route the long way round a cycle, a pool limit of one that must never overlap.
- **Migration 038 applied to production.**

Three of the new checks failed on first run, which is what they were for:

| Failure | Cause | Fix |
| --- | --- | --- |
| `reverseWords("\tone\ttwo\t")` | The junior reading split on a single space, so a tab-separated line came back as one word. A real defect in a shipped board, invisible to the old tests. | Split on whitespace, keeping the longhand filter and reverse. |
| `deepClone(undefined)` | The check expected `null`; the function returns `undefined`, as the brief says it should. | Corrected the expectation. |
| `retryWithBackoff` elapsed time | `elapsed >= 100` against a 100 ms timer sits exactly on the boundary, and a real timer may fire a fraction early. | Banded each wait so it separates no wait from one wait from two, without hugging the edge. |

Local evidence, all executed on the merged head:

| Check | Result |
| --- | --- |
| `npm run typecheck:api` | pass |
| `npm run test:coding` | pass — 420 tasks; run three times for the timing-sensitive async checks, stable each time |
| `npm run test:launch` | pass — 12-function budget unchanged |
| `npm run test:client` | pass — 7 files, 43 tests |
| `npm run build` | pass (React runner, client, sandbox page) |
| `npm run check:responsive` (devShark build, full route list, 7 widths) | pass — 231 probes, 0 issues |
| `git diff --check` | clean |

Verified in Chromium against a devShark build: a visitor with a stored `cs` preference on a cs-CZ browser gets `<html lang="en">` and English throughout, `/`, `/coding` and `/profile` render no language control between them, and the Czech chunk is never fetched.

Migration 038 was applied to production (`rvlybcjdpafwyeuojvhl`) through the Supabase connector: both track checks admit `algorithms` with exactly one check per table, both routines remain SECURITY DEFINER with an empty `search_path` and `service_role`-only execute, and a rolled-back exercise recorded an `algorithms` verdict and reveal, confirmed both rows carried the new track, and confirmed an unknown track is still refused. No probe rows survived and the advisor reports only the pre-existing RLS notices.

Not exercised here: anything account-bound, since no Supabase project is reachable from the build container. The prerendered Czech topic guides at `/cs/topics/:slug` still render and are still indexed; what to do about them is an owner decision in `NEEDED.md`.

## 2026-09-24 — Algorithms submits, a quieter quiz, drafts on Run, the fin in the water

What changed:

- **Algorithms submits no longer expire.** `decodeCodingSession` checked a sealed session's track against its own list of four tracks, and the Algorithms track never joined that list. Every Algorithms session therefore decoded to nothing, and every Submit answered `invalid_session`, which the workbench shows as "This session expired. Reload the task and submit again." The decoder and the coding handlers now read the track list from `shared/coding-catalog`, and the launch contract seals and opens a session on every track. Replaying the reference solution to `alg-two-sum` through the real handler returned HTTP 400 `invalid_session` before the fix and 200 `passed` after it; `alg-promise-pool`, `alg-retry-backoff` and `js-double-numbers` also pass. A session still expires after three hours, and signing out mid-task still invalidates it; both are intended.
- **Quiz.** The rotating coaching line ("Before choosing, name the behavior or requirement being tested", and four others) is gone, with its strings and the `RotatingTip` component. The keyboard tip no longer shows under a coarse pointer or below 600px. The hint popover no longer carries the design system's hidden "Close popover" button, which a tap revealed and which then hid itself instead of the hint. A visible × icon button now closes the hint, and it measures 44×44 on touch. The popover is aligned to the end of its trigger and capped at `min(320px, 100% − 16px)`, so it stays on screen at 360px.
- **Drafts.** The coding workbench no longer saves while the learner types or when they leave, and it says nothing about saving. Run and Submit hand the current code to the draft store: the device, and the account when signed in. Edits made after the last Run or Submit are not kept.
- **Results height.** From 1024px up, the output pane takes the editor's height and its checks scroll inside it, so Run and Submit sit directly under the editor. At 1280px the panes of `alg-deep-clone` went from 1035px to 538px and those of `alg-two-sum` from 804px to 538px; `js-double-numbers` stayed at 538px. The same held at 1024px and 1440px, with the last check still reachable by scrolling the pane.
- **The fin mark.** `SharkFin` sweeps back to a hooked tip, and its base is cut into a wave, so the fin sits in the water. The wave's mean height stays on the old base line, so fins placed on waterlines still sit on them. `client/public/favicon.svg` repeats the same paths.
- **Docs.** The visual QA matrix and the brand voice no longer ask for Czech.

Local evidence, all executed on the branch head:

| Check | Result |
| --- | --- |
| `npm run typecheck:api` | pass |
| `npm run test:coding` | pass — 440 tasks (javascript 170, typescript 84, react 116, system-design 45, algorithms 25) |
| `npm run test:launch` | pass — includes the new every-track session round trip; 12-function budget unchanged |
| `npm run test:paths` | pass |
| `npm run test:client` | pass — 7 files, 45 tests; the draft test now checks that typing and leaving save nothing and that Run and Submit save the current code |
| `npm run build` (devShark) | pass (React runner, client, sandbox page) |
| `npm run test:harness` | pass — 129 assertions against the built sandbox in Chromium |
| `npm run check:responsive` | pass — 231 probes, 0 issues |
| `npm audit --omit=dev` (root and client) | 0 vulnerabilities |
| `git diff --check` | clean |

Rendered in Chromium against a devShark build, with the API mocked from real handler payloads: the quiz at 1280, 768, 390 and 360px, with and without touch (no coaching line, keyboard tip only with a fine pointer, hint popover on screen, × closes it); the workbench at 1024, 1280 and 1440px (Run directly under the editor); the header fin in light and dark at 1280px and on a phone, and the favicon at 16 to 48px.

Not exercised here: anything account-bound, since no Supabase project is reachable from the build container. A signed-in Algorithms pass and the account copy of a draft are listed in `NEEDED.md`.

## 2026-09-24 — devShark alone: StudyShark moves to its own repository

What changed (#211, #213, #216):

- **This repository builds devShark only.** `client/product-catalog.ts` holds one entry. `resolveCatalogProductId` returns devShark when no product is set and throws when `VITE_PRODUCT` or `VITE_LOCK_SUBJECT` names anything else, and the message names `lukaskourilcz/studyshark`. The StudyShark Vercel project built this same code, so its builds now fail and its last deployment keeps serving until the owner removes it (#214).
- **Removed:** the six general subjects' 158 bank files with their Czech overlays, and their slices of the shared tables and unions; the subject picker, `/subjects`, the subject glyphs and switcher; the family rows of the footer; the Profile link to StudyShark; the AI wiring devShark never switched on (`lib/ai-provider.ts`, Sharkira, the `hint` and `explanation` resources, the AI settings block); 425 keys from each dictionary. In all, 170 files deleted and about 58,500 lines.
- **Kept:** the `webdev` subject key everything is stored under, the compatibility storage keys (`studyshark:*`), every applied migration and the database's seven-subject checks. The production database still holds StudyShark's rows; what happens to them is #215.
- **Fixed on the way:** `typecheck:tooling` had failed CI on every push since 2026-09-18, on a React verdict fixture without `solutions`. The home page's comparison table and founder note said "StudyShark" on devShark; they say devShark. The Czech guides at `/cs/topics/:slug` hydrate into the English interface, so their article now carries `lang="cs"`; a screen reader had been reading them with an English voice.
- **CI** runs one devShark job. The launch contracts run in `webdev` scope and assert that StudyShark, geoShark and a geography lock are refused.
- **Documentation, skills, agents and commands** describe devShark alone, with one line saying where StudyShark went.
- **StudyShark** lives in `lukaskourilcz/studyshark`: private, deployed nowhere, started from a snapshot of `d71150c`. #195, #196, #198 and #199 moved there as studyshark#1 to #4.

Local evidence, all executed on the branch head:

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | pass |
| `npm run test:launch` | pass — twelve handlers; StudyShark, geoShark and a geography lock refused |
| `npm run test:coding-auth`, `test:grading-integrity`, `test:coding`, `test:paths` | pass |
| `npm run test:client` | pass — 7 files, 45 tests |
| `npm run check:unused`, `npm run check:security` | pass |
| `npm run build` (devShark), `check:public`, `check:bundle` | pass — 11 public URLs |
| `npm audit --omit=dev` (root and client) | 0 vulnerabilities |
| `tests/browser/public.spec.ts`, `tests/browser/evolving.spec.ts` | pass — 7 tests |
| `npm run check:responsive` (the two CI sweeps) | pass — 28 and 6 probes, 0 issues |
| `npm run check:responsive` (full route list, 7 widths) | pass — 224 probes, 0 issues; seven fewer than before because `/subjects` is gone |
| `npm run test:harness` | pass — 129 assertions |
| `npm run audit:performance` | runs; mobile 0.91, desktop 0.75 with CLS 0.98 (the open desktop-CLS item in `NEEDED.md`) |
| `npm run build:storybook`, `tests/browser/storybook.spec.ts` | pass — 5 tests |
| Browser pass over `/`, `/learn`, `/quiz`, `/coding`, `/roadmap`, `/today`, `/profile`, `/leaderboard`, `/play` at 1280 and 390 px, light and dark | pass — 36 checks: devShark title, `lang="en"`, no other product named, no overflow, no page errors |
| Before/after: the `d71150c` devShark build beside this one, 20 routes at 1280 and 390 px, signed out | 34 of 40 pairs identical in text, headings, footer placement and width. The home page, and `/profile`, which sends a signed-out visitor home, name devShark instead of StudyShark in the comparison table and the founder note. `/typing` differs only in its randomly drawn snippet. No page errors on either build |
| `VITE_PRODUCT=studyshark npm run build` | fails as intended when Vite loads its config, before any client output is written: "This repository builds devShark only, but the environment asks for product "studyshark" and subject lock "". StudyShark lives in lukaskourilcz/studyshark." |
| `git diff --check` | clean |

Not exercised here: anything account-bound, since no Supabase project is reachable from the build container, and nothing on Vercel, since the Vercel connector needs re-authorizing.

## 2026-09-25 — StudyShark off Vercel and out of the database

At the owner's request StudyShark runs nowhere.

- **Vercel.** The `studyshark-app` project is paused; `https://studyshark-app.vercel.app/` and its `/api/health` answer 503 `DEPLOYMENT_PAUSED`. It had no custom domain. The connector can pause a project but not delete one, so deletion is an owner step in #214. Before it, the StudyShark URL has to leave the Supabase Auth redirect list, because a deleted project's `vercel.app` subdomain can be claimed by anyone.
- **Supabase.** A scan of every public table for StudyShark subjects, question ids and the product name found two sets of rows. The first was three multiplayer matches from July, stored as `webdev`, whose question lists held StudyShark questions: one all capitals, two mixed from before questions were scoped by subject. Deleting them removed five participants and eleven answers by cascade. The second was eight anonymous geography Learn attempts, with their 32 answers. Both sets were deleted from production and from the `devshark-recovery-20260915` copy. The same scan finds nothing afterwards in either project. No account held StudyShark rows, and none was deleted: production has two accounts.
- **Unchanged.** devShark's own rows: 5 matches, 8 Learn attempts, 59 question-history rows, 60 coding awards and 12 progress rows. `/api/health` reports the database, service role and rate limiter healthy, and `/learn` answers 200. The schema's subject checks still list the six StudyShark subjects; the API's subject scope refuses them.
- **StudyShark repository.** Its CI workflow is deleted at the owner's request; the checks run locally only.

## 2026-09-25 — the Challenge and the daily set load again

What was broken: on 2026-09-08 (`a132ba6`) Testing, Abbreviations and Code Snippets were retired as sections, and the server began refusing a retired category in any request for questions. One retired category gets the whole request refused with 400 `invalid_subject_scope`. The Challenge and the daily set built their requests from the full category catalogue, which keeps the retired sections so that old rows still resolve. From then on every challenge board, challenge run and daily set on devShark failed: the board said "Today's board could not be loaded", and "Enter the challenge" could not load a batch. Replayed against production, the client's 19-category list got 400 on all three requests. The 16 categories the server still serves got 200: 25 challenge questions, 5 daily questions and the board.

What changed:

- `shared/subject-catalog.ts` gains `deliveryCategories(subject)`: the catalogue without its retired sections. The server's default scope and the client's requests for questions both use it.
- The Challenge, for its batch and its board, and the daily set send `deliveryCategoriesForSubject`.
- The Quiz restores a saved or linked category only if the server still serves it. An old setup, or an old link naming a retired section, no longer gets the quiz refused.
- The challenge board is validated as a read. A browser still running the old bundle gets its board back as soon as this deploys; its runs recover on the next reload.
- A client test replays the three requests through the server's own check; it failed 3 of 3 against the old client. The launch contract asserts that the delivery list is requestable and that the full catalogue is not.
- The relaxed-pace option on the Challenge intro is its natural height. It borrowed the track-card flex basis, which in a column made it a 220px box with empty space under the text.

Local evidence, all executed on the branch head:

| Check | Result |
| --- | --- |
| Every CI step: types, launch contracts, coding auth, grading integrity, coding content, paths, client tests, unused, security, devShark build, public HTML, bundle, both audits | pass; client tests 8 files, 48 tests; coding content 440 tasks |
| `client/tests/delivery-scope.test.ts` against the old client | fails 3 of 3, as it should |
| Built client in Chromium with every `GET /api` replayed against production | board loads ("No one has set a score yet"), a run shows a question with four options, the daily set shows its questions |
| `npm run check:responsive` on `/challenge` and `/quiz`, 7 widths, then dark at 360, 390 and 1280 | 14 and 3 probes, 0 issues |
| `git diff --check` | clean |

## 2026-09-25 — the Custom paths join the sections, and every section gets its own

The owner asked for the Custom category to be split into JavaScript, TypeScript, React, Algorithms and FullStack, with no path longer than five levels: a Map path first, then a Set path, then a new path that uses Map and Set together, and the Custom category gone.

What changed:

- `shared/evolving.ts` drops the `custom` category and gains short paths: five levels (`<path id>-1` to `-5`), no checkpoints, each level one function or feature added to the same code, with every earlier check run again.
- JavaScript lists five: Map basics, Set basics, Map and Set together (new), Objects and grouping, and Lookups and crawling. The two ten-step Custom paths were split into the first, second, fourth and fifth. Three of their levels are new (`difference`, `duplicates`, `crawlDepths`); three small Custom steps were folded in or dropped (`countsToPairs` into `topK`, `firstUnique`, `totalRuns`).
- New paths: two in TypeScript (Generic collection helpers; Unions and narrowing), two in React (State and lists; Effects and loading), two in Algorithms (Two pointers and windows; Stacks and queues), and a link shortener in FullStack that goes from a JavaScript input check through a typed API to a React client.
- Each section page lists its paths between the header and the challenge list, and the FullStack screen puts the link shortener first. The Coding home loses the Custom block; its gallery keeps the ten longer projects. Short paths read "Level 2 of 5" where the longer projects read "Stage".
- The FullStack React scaffold is appended at each path's own first React stage. Before, the first FullStack app's index was used for every app.
- Progress on the removed `js-custom-*` stages, which existed for a day, no longer maps to a task. XP already earned stays.

Local evidence, all executed on the branch head:

| Check | Result |
| --- | --- |
| Every CI step: types (API and tooling), launch contracts, coding auth, grading integrity, coding content, paths, client tests, unused, security, devShark build, public HTML, bundle, both audits | pass; coding content 480 tasks, every solution proven; client tests 8 files, 61 tests; initial JS and CSS 203,781 gzip bytes of 243,000; 0 vulnerabilities in both audits |
| Mutation check: 21 broken variants of reference solutions (a missing stale-answer guard, a missing JSON header, a duplicate guest still added, operands swapped, and so on) | 18 caught at once; two gaps closed with new visible checks (`twoSum([1, 1, 5], 6)`, a search with one unknown word); the last variant (`<` for `<=` in the sliding maximum) is still correct |
| Reference solutions run in the browser's own runners on 17 levels from every kind of path (JavaScript, TypeScript, Algorithms, React, FullStack) | all pass; the first run failed Effects and loading level 5 (6 of 8) because the title effect lands a moment after the list, fixed by waiting for the title |
| React levels in the browser, reference, junior and senior, three runs each (State and lists 5, Effects and loading 4 and 5, Link shortener 4 and 5) | all pass every run |
| Built client in Chromium: `/coding`, the four section pages and `/coding/fullstack`, light and dark, 1280 and 390 | no Custom block; section paths in the requested order between the header and the filters; "0 of 5 levels completed"; the Link shortener first on FullStack; no overflow, no page errors |
| Browser specs `public` and `evolving`, the harness check, Storybook, Lighthouse | pass; harness 141 assertions; Storybook 5 of 5; performance 0.86 mobile and 0.99 desktop, accessibility 1 |
| `npm run check:responsive` on the CI routes at 7 widths and in dark Czech, then on `/coding`, the four sections and `/coding/fullstack` at 7 widths and in dark at 360, 390 and 1280 | 28, 6, 42 and 9 probes, 0 issues |
| `git diff --check` | clean |

In production after the deploy of `5f865a0`, whose "Product quality" run passed on GitHub:

| Check | Result |
| --- | --- |
| `GET /api/quiz/roadmap?resource=coding-task` for new levels in every section, and for `js-custom-mapset-1` | 200 for the new levels; 404 for the Custom id |
| Anonymous submit of the reference solution to level 1 of a JavaScript, TypeScript, Algorithms, React and FullStack path (graded, never recorded) | all passed; React levels 1 of both React paths went through the isolated grader in about 5 s |
| The same for a level above 1 | refused as designed: a signed-out visitor gets `locked: "evolving"` and no session |
| Chromium on the deployed pages, with every GET replayed through curl | `/coding` has no Custom block; each section lists its paths in the requested order; the Link shortener leads FullStack; `js-path-mapset-1` loads as "Level 1 of 5"; no page errors |

## 2026-09-25 — billing with Stripe (D2, #221)

What changed: Premium can be sold once the owner's Stripe account exists. Checkout, the Customer Portal, the signed webhook and the public cancellation page are `op=` branches of `api/user/[op].ts` (`lib/billing/`), so the handler count stays at twelve. `/premium/success` and `/premium/cancel` ship in the client, with `PremiumCheckoutButton` for the `/premium` page (#222), "Manage billing" on the Profile plan line and "Cancel Premium" in the footer's legal links. Migration 039 gained section 5 (the consent table and four routines). Everything stays behind `BILLING_ENABLED`, off by default, and no test reaches Stripe. The design is in `docs/product-architecture.md` under "Tiers and billing".

Local evidence, all executed on the lane branch head:

| Check | Result |
| --- | --- |
| `npm run typecheck:api` | exit 0 |
| `npm run test:launch` | exit 0; adds the billing structure: off by default, the canonical origin, four ops inside the twelve handlers, the webhook outside the limiter, no Stripe script or CSP host, no billing file touching learning, score or wallet data |
| `npm run test:billing` | exit 0; 24 checks over the nine fixture event types signed with `stripe.webhooks.generateTestHeaderString` |
| The same 24 checks against Postgres 16 with migrations 001 to 039, through a local PostgREST stand-in | passed; the real `is_premium`, upsert, event and consent routines |
| Migration 039 on Postgres 16 | applied twice from scratch and twice over the D1 copy, exit 0 each; the D1 and D2 rolled-back exercises pass, nothing left after rollback |
| `npm run test:client` | exit 0; 10 files, 86 tests (17 new in `client/tests/billing.test.tsx`) |
| `npm run build`, `npm run check:bundle` | exit 0; 209,176 of 243,000 gzip bytes |
| `npm run check:security` | exit 0; `vercel.json` unchanged |
| `npm run check:public`, `npm run check:unused` | exit 0 |
| `npm run check:responsive` at 360, 390, 768 and 1280, light and dark, with `/premium/success` and `/premium/cancel` added to the inventory | exit 0; 136 probes each, 0 issues |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client` | exit 0; 0 vulnerabilities (`stripe` 22.6.2 has no dependencies) |
| `git diff --check` | clean |
| Chromium, 360 and 1280, light and dark, the real handlers against the local database and a fake Stripe | the cancel page's form, email error, confirmation (focus on its heading) and receipt, generic for another address and exact for the signed-in owner; the success page done, pending, expired (two checkout buttons with the price) and signed out; Manage billing on the plan line; the footer link; no page errors and no horizontal overflow |

Billing simulation, run locally rather than in Stripe: `npm run test:billing` moves one subscription through `invoice.payment_failed` with the live subscription `past_due` and its period three days past (Premium stays, the plan line's `inGrace` is true), then eight days past (Free), then `customer.subscription.deleted` (canceled). The run with a Stripe test clock against a sandbox needs the owner's account and is listed in `NEEDED.md`. So are the fixture payloads: they were written from Stripe's API reference for `2026-08-26.dahlia`, not captured, because no account exists yet.

Not verified here: anything against Stripe itself (Checkout's rendering of the consent and the order-button text, Managed Payments approval, the portal configuration, real webhook delivery through Vercel's raw-body replay), and production. Each is an owner item in `NEEDED.md`.

## 2026-09-25 — public copy, `/premium` and the legal pages (D3, #222)

What changed: the landing stops saying devShark is free. The hero reads "Free to start", the `$0` stat became the three free topics, and the pledge, the footer line, the plan table (Free against Premium, without the AI and bilingual rows) and the founder note carry the handoff's section 4.1 copy. `/premium` shows both plans with "VAT included", the renewal, the waiver sentence and the 14-day refund beside the buttons, what Premium opens, the plan table and six questions; Premium sits next to Leaderboard in the header's icon group, and `/support` redirects to it. The Terms and the privacy policy were rewritten for Premium, Stripe and Link, and Spreadshop. The trader's details render from `TRADER` in `client/product-catalog.ts` only when set, and none is set yet. The build prerenders `/premium` and `/premium/cancel`, which the sitemap now lists (13 URLs).

Local evidence, all executed on the lane branch head:

| Check | Result |
| --- | --- |
| `grep -rn "free forever\|Free forever\|is free\|zdarma" client/src --include=*.ts --include=*.tsx` | 11 matches, all in the retained `translations.cs.ts` |
| `npm run typecheck:api` | exit 0 |
| `npm run test:launch` | exit 0; adds the public copy contracts: no English string promising free, the waiver on `/premium` equal to the one Checkout stores, "VAT included" beside every price, no urgency copy, the routes, rewrites, `noindex` and Premium schema, `TRADER` null or real |
| `npm run test:billing` | exit 0; 24 checks, now with the seller of record in the public settings |
| `npm run test:client` | exit 0; 11 files, 99 tests (13 new in `client/tests/premium-page.test.tsx`) |
| `npm run build`, `npm run check:bundle` | exit 0; 214,735 of 243,000 gzip bytes (209,176 before; the legal copy lives in the English dictionary) |
| `npm run check:public` | exit 0; 13 URLs; `/premium` is a LearningResource with `isAccessibleForFree: false` and both prices as offers with VAT included, the guides keep `true` |
| `npm run check:security`, `npm run check:unused` | exit 0 |
| `npm run check:responsive` over `/`, `/premium`, `/premium/cancel`, `/terms`, `/privacy` at 360, 390, 768 and 1280, light and dark | exit 0; 20 probes each, 0 issues |
| `npm run check:responsive`, every route at 360, 390, 768 and 1024 (the header gained an icon, text fields gained a touch floor) | exit 0; 68 probes each, 0 issues |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client` | exit 0; 0 vulnerabilities |
| `git diff --check` | clean |
| Chromium, the same five routes and eight width and theme pairs, phones with touch | every link, button and disclosure at least 44px tall on a phone, a focus ring on each text link and question; the Astryx email field is 32px with a mouse, by the same desktop-density rule as the buttons, and 44px on touch; at 360px all three plan-table columns show with no sideways scroll |

Not verified here: production, the Stripe Checkout page itself, and the legal wording, which waits for the owner's lawyer. The trader's name, IČO, registered address and email are owner items in `NEEDED.md`; there is no EU ODR link because the platform closed on 20 July 2025.

## 2026-09-25 — coins (D8, #227)

What changed: the server ledger of migration 028 is the only wallet, and the UI calls it coins. Every verified XP source credits it: quiz and daily results and Biggest Shark Challenge runs as before, plus a Learn level or part test passed for the first time and a coding challenge's first pass. Every account earns 10 % of that XP, Premium earns double at credit time, and one account earns at most 400 coins a day from XP, after the doubling. Premium milestones (streak 7, 30 and 100 days; a finished Learn topic; a finished evolving project or short path; the top three of a finished month) pay once per account. The welcome coins arrive on the first wallet read. The browser no longer awards or shows a `localStorage` balance. `/shop` reads Rewards in the navigation, a free account gets 402 when it redeems merchandise, and "Find devShark elsewhere" links to the profiles in `client/product-catalog.ts` with no reward unless the owner sets `socialVisitGrant`. Migration 041 also restates `record_coding_verdict`: its award id named only the task, so only the first account ever to pass a task received that task's XP.

Local evidence, all executed on the lane branch head:

| Check | Result |
| --- | --- |
| Migration 041 on Postgres 16 (template with the shim and 001–038, then 039) | applied twice with `ON_ERROR_STOP=1`, exit 0 both times |
| Rolled-back exercise of 041 | exit 0: free 100 XP → 10, replay → 0; Premium 100 XP → 20; 1,000 → 200, then 180 at the cap, then 0, recorded with no ledger line; a credit made before 041 is not paid again; milestones streak:7 25, topic:html 100, project 150 once, again → nothing; a free account and a stale streak get progress and no credit; milestones sit outside the cap; the month board reports `no_board` without 040's table, `open` for the current month, settles August once (ranks 1 and 2 Premium paid 300 and 200, rank 3 free paid nothing), `already` on the second call; the social grant pays nothing at 0, 5 once at 5, refuses an unknown platform; two accounts passing the same task both get coding XP; `authenticated` reads only its own credit rows and cannot read settlements, call a credit routine or write the table; all routines SECURITY DEFINER with an empty `search_path` and service_role only; deletion removes the credit rows and anonymises a settlement |
| Real handlers against that database through a PostgREST/Auth stand-in | 34/34: the welcome coins once; a quiz result 10 and its replay nothing; a coding pass 10 % of its XP, a second pass nothing; a first Learn pass 5, a replayed completion and a re-pass nothing; a free redemption 402 `merch-redemption` before the address check; the crown answers 409 and never 402; Premium coding and Learn credits double; a Premium redemption of 100 coins, and a second one refused `out_of_stock` with nothing charged under a cap of one; a 7-day streak pays 25 on the wallet read, once; a free 30-day streak pays nothing; social claims pay nothing at 0 and ignore an amount in the body; any other claim is refused; 5 coins once after the owner sets 5; account deletion removes the ledger and the credit rows |
| `npm run typecheck:api` | exit 0 |
| `npm run test:launch` | exit 0; adds the coin contracts: the handoff's rates, replays that credit nothing, service-role-only credit routines that write no learning table, the doubling inside the credit routine with the cap after it, 402 before the address, the browser wallet gone, coins in the copy, no reward for a follow, the four streak-protection bounds |
| `npm run test:billing`, `npm run test:coding-auth` | exit 0 |
| `npm run test:client` | exit 0; 12 files, 111 tests (12 new in `client/tests/rewards.test.tsx`) |
| `npm run build`, `npm run check:bundle`, `npm run check:unused` | exit 0; 215,700 of 243,000 gzip bytes |
| `npm run check:responsive` over `/`, `/shop` and `/profile` at 360, 390, 768 and 1280, light and dark | exit 0; 12 probes each, 0 issues |
| Chromium, `/shop` signed in against the real handlers, free and Premium, 360 and 1280, light and dark | no page errors, no horizontal overflow; How to earn reads "Streak 7 days: 4 of 7", "JavaScript: 21 of 25 levels" and "Expression engine: 3 of 10 stages"; Show all works from the keyboard; a free account's Redeem is focusable, `aria-disabled` and opens the upgrade sheet with "Premium members redeem coins for merchandise."; a Premium account with enough coins reaches the address form with a visible focus ring |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client` | exit 0; 0 vulnerabilities |
| `git diff --check` | clean |

Not verified here: production and migration 041 there, which are owner items in `NEEDED.md`, and the month settlement against 040's real table, which lives on the other lane (the proof used a table of the same shape from handoff section 5.1).

## 2026-09-25 — invitations (D8b, #228)

What changed: every account has an invite link, `/?ref=<code>`. The browser keeps the code from the link and offers it after sign-in; the server binds it once, and only while the account is at most 48 hours old by the creation time Supabase Auth reported. When the invited friend finishes a first Learn level, both accounts get 100 coins, once. An inviter is paid for at most 20 friends; past that the friend is still paid. Rewards gains "Invite a friend" with the link, a copy button and the counts, and the ledger reads "Referral: a friend finished their first level". Migration 042 adds `referral_codes`, `referrals`, the `referral` ledger reason and four service-role routines.

Local evidence, all executed on the lane branch head:

| Check | Result |
| --- | --- |
| Migration 042 on Postgres 16 (template with the shim and 001–038, then 039 and 041) | applied twice with `ON_ERROR_STOP=1`, exit 0 both times |
| Rolled-back exercise of 042 | exit 0, 59 checks: the reason check keeps `milestone` and `social`; one stable eight-letter code per account; a bind inside the window, a second bind and a move to another inviter refused, the account's own code and a reversed pair refused (`self`), an unknown or malformed code, an account older than 48 hours and a missing creation time bind nothing; `waiting` before a passed level and for a failed one; then 100 to each side, the friend under `referral:<account>` and the inviter under `referral:friend:<random key>` with no trace of the friend's id; a second completion `already`, balances unchanged; no XP, stats, award or XP-credit row written; 21 friends of one inviter: 20 paid, the 21st `capped` and still paid, raising the cap later reopens nothing, a friend's deletion frees no place; `authenticated` and `anon` cannot call any routine or read `referrals`, and read only their own code; deletion removes the code and the account's own row and pays a waiting friend of a deleted inviter (`orphaned`) with nothing for the deleted account |
| Two sessions at once, committed scratch database | the same friend settled twice: `credited` and `already`, 100 each; two friends competing for the inviter's last place under the cap: `credited` and `capped`, the inviter ends at exactly 20 lines |
| Real handlers against that database through a PostgREST/Auth stand-in | 31/31: the link carries a code and counts and no account id; a 5-minute-old account binds an upper-case code, a second bind is `already`; the inviter sees one waiting and nobody's id; own code `self`; a 5-day-old account `closed`, also with a creation time in the body; malformed 400; unknown `unknown`; nothing paid before a level; a first HTML level pays the friend 5 XP coins plus 100 and the inviter 100, with the inviter's wallet showing no friend id; a replayed completion, a re-pass, a second level and a wallet read pay nothing more; an inviter at 20 is not paid while the friend is; grant 0 turns the link off and a claim answers `off`; account deletion of inviter and friend |
| `npm run typecheck:api` | exit 0 |
| `npm run test:launch` | exit 0; adds the invitation contracts: the defaults and the clamp, service-role routines with a pinned `search_path`, no browser policy on `referrals`, `credit_referral` writing only ledger tables (the referral row, and the wallet through `credit_tokens`), the replay guard, the passed-level wait, the cap lock, the self check and the window, and the handler against a stand-in (counts without ids, a body creation time or amount ignored, a malformed code reaching no routine); two were mutation-checked to fail when their rule is removed |
| `npm run test:client` | exit 0; 13 files, 127 tests (16 new in `client/tests/referral.test.tsx`) |
| `npm run build`, `npm run check:bundle`, `npm run check:unused` | exit 0; 216,675 of 243,000 gzip bytes |
| `npm run test:billing`, `npm run test:coding-auth` | exit 0 |
| `npm run check:responsive` over `/shop`, `/profile` and `/` at 360, 390, 768 and 1280, light and dark | exit 0; 12 probes each, 0 issues |
| Chromium, the real client build signed in against the real handlers, 360 and 1280, light and dark | no page errors, no overflow; the headings run Your coins, How to earn, Invite a friend, Merchandise; the link field holds `/?ref=<code>`, "Copy link" works from the keyboard with a 3px focus ring and the clipboard holds the link; "3 of 20" and one waiting; nothing in the section under 44px; a new account opening the link signed in sees "Invitation accepted", the address bar loses `ref`, the stored code is cleared and the row names the inviter; its Rewards shows the invited note and a 46px "Go to Learn" |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client` | exit 0; 0 vulnerabilities |
| `git diff --check` | clean |

Not verified here: production and migration 042 there, which are owner items in `NEEDED.md`, and a real Google sign-up carrying the code through the OAuth redirect (the browser check restored a session instead of running Google's consent screen).

## 2026-09-25 — merchandise through Spreadshop (D9, #229)

What changed: Spreadshop (sprd.net AG) prints, sells and ships devShark merchandise, and the app links out to it without any script, iframe or CSP change. `MERCH_SHOP` in `client/product-catalog.ts` holds the shop's URL and one per item, all null until the owner sets them. Each Rewards tile shows the mockup the build found under `client/public/merch` (none yet), "Buy at the devShark shop" when its URL is set, and a "With coins" group with the coin price and Redeem; the cash price left the tile, and an unconfigured item still reads "Not on sale yet". The hoodie joins the catalogue in the t-shirt sizes. The redemption form takes focus, fills from shipping autofill and says the address goes to sprd.net AG and is deleted with the account. `/dev` gains a Merchandise tab for quotes and coin prices, this month's caps and the fulfilment queue. Spreadshop's own monthly promotion appears when `SPREADSHOP_API_KEY` and `SPREADSHOP_SHOP_ID` are set, read on the server and kept 30 minutes. Migration 043 widens both SKU checks, adds `set_merch_stock`, and restates `advance_merch_order` and `cancel_merch_order` so a claimed learning-path package, which 035 leaves awaiting payment at zero, can be sent without releasing a redemption's reservation.

Local evidence, all executed on the lane branch head:

| Check | Result |
| --- | --- |
| Migration 043 on Postgres 16 (template with the shim and 001–038, then 039, 041 and 042) | applied twice with `ON_ERROR_STOP=1`, exit 0 both times; also exit 0 on the 001–038 template alone, where a hoodie stock row fails the old check before 043 |
| Rolled-back exercise of 043 | exit 0: both checks carry the hoodie; caps set, re-set and refused for a wrong size, an unknown SKU and a negative figure; a hoodie redemption paid 10,000 coins, reserved one unit and left 2,000; a cap below the reserved unit refused (`below_reserved`), the next hoodie refused `out_of_stock` with nothing debited; submitted, then shipped with carrier and tracking, using the unit up; a claimed package submitted and shipped from `awaiting_payment`, using the mug budget and keeping a redemption's reservation; cancelling a second package released nothing; an unpaid cash order refused `order_not_paid`; the three routines definer, empty `search_path`, service role only; `merch_stock` still has RLS and no policy, and a signed-in learner can neither set nor read it |
| Real handlers against that database through a PostgREST/Auth stand-in | 30/30: `op=shop` lists five items with the hoodie in S to XXL, the mug and cap `unconfigured`; a learner cannot set a cap (403); a wrong size refused (400); a free account's hoodie answered 402 `merch-redemption`; a Premium mug answered 409 "That item is not on sale yet" with no coins taken; cash checkout 409; the Premium hoodie redemption paid, debited and reserved, its ledger line a purchase; the picking list shows it with the address and items and no account id, plus the caps; submitted, shipped, and the learner sees the tracking; a claimed package appears marked, a look-alike unpaid cash order does not, and the package ships straight from the queue; `/api/settings` returns `merchPromo: null` without the keys and Spreadshop's offer, fetched once, with them |
| `npm run typecheck:api` | exit 0 |
| `npm run test:launch` | exit 0; adds the merchandise contracts: the hoodie's sizes, nothing priced by default, cash checkout off, 043's checks equal to `MERCH_SKUS` and its routines service-role only with no policy or learning table, one https URL slot per SKU in `client/product-catalog.ts` and no Spreadshop URL or API call anywhere in `client/src`, no Spreadshop host in the CSP, mockup file names, the promotion parser (404, expired, malformed, zone-less UTC), the 30-minute cache and no fetch without configuration, and no shop or rewards copy promising a discount; two were mutation-checked to fail when their rule is removed |
| `npm run test:client` | exit 0; 14 files, 141 tests (14 new in `client/tests/merch.test.tsx`) |
| `npm run build`, `npm run check:bundle`, `npm run check:unused` | exit 0; 217,418 of 243,000 gzip bytes |
| `npm run check:security`, `npm run check:public` | exit 0; the security policy is unchanged |
| `npm run test:paths` | exit 0 |
| `npm run check:responsive` over `/shop` and `/dev` at 360, 390, 768 and 1280, light and dark | exit 0; 8 probes each, 0 issues (signed out, without the API) |
| Chromium, a test build with `MERCH_SHOP` filled and two stand-in mockups, signed in against the real handlers, 360 and 1280, light and dark, free and Premium | no page errors, no overflow; five tiles, the two images loaded with alt text and only those two `/merch/` requests; two "Buy at the devShark shop" links, new tab, `noopener noreferrer`, 44px; "Visit the devShark shop"; the promotion and its note; nothing in the section under 44px; Premium: the hoodie opens on a size with units left, Redeem moves focus to "Redeem: Hoodie (L)" in view, autofill `shipping name`, Cancel returns focus to the tile; free: Redeem is `aria-disabled`; the claimed package reads "Claimed, waiting to be sent". The same run as an admin on `/dev?section=merch`: the queue shows the package with its address and the caps table, no overflow |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client` | exit 0; 0 vulnerabilities |
| `git diff --check` | clean |

Found and fixed during the check: the hoodie tile opened on a size with none left, so Redeem sent a request the cap refuses.

Not verified here: production and migration 043 there, the owner's real Spreadshop URLs and mockups, a live call to Spreadshop's Public Shop API (the parser was fed the documented payload), and a real sample order; all are owner items in `NEEDED.md`.

## 2026-09-25 — the next challenge beside the Coding heading, the brief inside the code pane

The owner asked why reloading `/coding` first showed "Your next challenge: Digit sum" and a second later "Largest number", and asked for that banner to become a small card to the right of the page heading holding only the next challenge and Continue. On a challenge page, the banner above the playground (track, tier, level, name, prompt) was to move into the code container in place of "Your code", with a green first line and no wave, the action buttons at the foot of that container, and the printed keyboard shortcuts removed. Then the footer was to lose "Learning stays free. Optional support never changes access, XP or rankings."

The cause of the swap: the Coding home worked out the next task before the account and its progress had loaded. With no progress every task is open, so it named the first task in the catalogue until the progress request returned.

What changed:

- The next-challenge card waits for the account and the progress. While they load it shows a placeholder and a disabled Continue; if progress fails it says so and offers Try again; otherwise it names the challenge. It sits to the right of the heading and moves under it below 860px. The track line and the due count are gone; the count linked to `/coding/review`, which redirects to `/coding`. The sign-in hint waits for the account too.
- The code pane opens with the green line (track, tier and level, or a path's level, then a rule and the task's name as the page heading), the prompt and the rest of the brief, then the editor, then the action bar. Hints, the skip form, confirmations and errors follow in a pane under the grid, only while they hold something. Below 1024px the puzzle or the pending note carries the brief and the actions.
- The keyboard guide and its keycaps are gone. The shortcuts still work, and the editor's `aria-describedby` points at them.
- The footer line is removed, and its key with it in English and in the retained Czech file, as the launch contract requires of an orphaned Czech key. The same goes for `coding.review.count` and `coding.shortcuts.leave`.

Local evidence, all executed on the branch head:

| Check | Result |
| --- | --- |
| Every CI step: types (API and tooling), launch contracts, coding auth, grading integrity, coding content, paths, client tests, unused, security, devShark build, public HTML, bundle, both audits | pass; coding content 480 tasks; client tests 9 files, 65 tests; initial JS and CSS 203,640 gzip bytes of 243,000; 0 vulnerabilities in both audits |
| New `client/tests/coding-home.test.tsx`: progress loading, the account loading, a visitor, a failed progress request, the card's contents | 4 of 4 pass; while loading the card names no task and Continue is disabled |
| Built client in Chromium with API fixtures: `/coding` and `js-largest-number`, `js-path-map-2`, `ts-path-generics-3`, light and dark, 1440 and 390 | the card beside the heading on desktop and under it on the phone; the green line, the prompt, the editor and the actions in one pane; no "Your code", no keyboard guide, no footer line; no overflow |
| Run, Hint and Skip at 1024, 1180 and 1440 | the action bar is one row at the foot of the pane; the results pane ends level with it; the hint and the skip form open under the grid; Ctrl+Enter still runs; the editor's description reads the shortcuts |
| A puzzle task (`js-sum-array`) at 390 | brief, puzzle and actions in one pane; ids unique; no overflow |
| Browser specs `public` and `evolving`, the harness check, Storybook | pass; harness 141 assertions; Storybook 5 of 5 |
| `npm run check:responsive` on the CI routes at 7 widths and in dark Czech, then `/coding`, `/coding/javascript`, two challenge pages and `/coding/fullstack` at 6 widths, and dark `/coding` and a challenge page at 3 widths | 0 issues (the sweep has no API, so there the challenge pages show their load-error state; the workbench itself is covered by the fixture runs above) |
| Lighthouse on `/` | mobile 0.85, accessibility 1. Desktop varies on one build: 0.99 with CLS 0.066 in two of three repeat runs, 0.75 in the third, where `main#main-content` shifts (CLS 0.98). The July baseline recorded the same shift in production (0.959). This change touches the home page only through the footer line. |
| `git diff --check` | clean |

In production after the deploy of `0910d1e`, whose "Product quality" run passed on GitHub (the run for `9ecaf04` was cancelled by that newer push, which carries the same code):

| Check | Result |
| --- | --- |
| Chromium on devshark.app with every GET replayed through curl, at 1440 and 390, bundle `main-Dkp2Rm6y.js` | 20 of 20 checks pass. The card reads "Your next challenge", the task and Continue, beside the heading on desktop and under it on the phone. The brief line reads "JavaScript · Foundations · Level 6", then "Largest number", in `rgb(45, 122, 45)` with no kicker wave. The brief and the actions sit in the pane that shows. No "Your code", no printed shortcuts. The footer holds Support, How we curate, Privacy, Terms and the two controls. No overflow, no page errors. |
| Signed in | not checked here; the owner step is in `NEEDED.md` |

## 2026-09-25 — the freemium lanes together (INT, #219 to #230)

What changed: one branch now carries both freemium lanes and main. Lane A brings tiers and the 402 locks, Stripe billing, the public Premium copy, coins, invitations and Spreadshop merchandise (D0 to D3, D8, D8b, D9). Lane B brings the 30-day leaderboard, difficulty labels, the debugging paths and the Easy waves (D4 to D7). Main brings the kickoff, the webdev-bank contract and the Coding card and code pane. On top of the merges:
- The free coding set is re-picked for 695 tasks: 75 standalone challenges plus stage one of the 29 projects and paths, 104 tasks or 15.0 %.
- Migration 044 erases an account with one `delete_user_data` and adds the `question_edits` importance check.
- `deleteAccount` calls the four later erasure routines in one loop that tolerates PostgREST's "Could not find the function" answer.
- The Coding home's next-challenge card also waits for the plan.

Local evidence, all executed on the integration branch:

| Check | Result |
| --- | --- |
| Migrations 039 to 044 on Postgres 16 from the 001–038 chain | 039, 040, 041, 042, 043 and 044 applied in order with `ON_ERROR_STOP=1`, then 044 again, exit 0 each. This was done twice: once as the chain leaves `question_edits`, and once with its check dropped first, which is production's shape. The whole 039–044 chain applied a second time over the first database also exits 0. Both databases end with exactly one `question_edits_importance_check` |
| Rolled-back exercise of 044, on both databases | exit 0, identical output. Importance NULL, 1 and 10 are stored; 0 and 11 are refused. `delete_user_data` is a definer with an empty `search_path`, executable by `service_role` only; `authenticated` and `anon` are refused. An account with rows in the 039–042 tables, the wallet, two merchandise orders and two package claims keeps no row under its id anywhere in the catalog, and a second account's rows are unchanged. A settled month keeps the rank as `deleted-account`, and a referral it made keeps the friend under `deleted-account`. Its never-sent order, the order's items and the order's claim are gone. Its order already with Spreadshop is redacted, and that claim reads `deleted-account:<order id>` and still ships through `advance_merch_order`. A second call and the four older routines afterwards delete nothing. Nothing is left after rollback |
| Catalog coverage | every table in the 001–044 schema with an account column is named by `delete_user_data`; in the 001–038 chain, `path_reward_claims` (035) was not |
| The real `api/user/[op].ts` deleting an account through a PostgREST/Auth stand-in that answers a missing routine as PostgREST does | 039 to 044: 200, no row left, the second account unchanged. 039 to 043 without 044: 200, only the two package claims left, which is what 044 adds. 039 and 041 to 043 without 040: 200. The code before this step on that last shape answers 500 after `delete_user_data` has run, because its calls for 040 and 039 did not recognise PGRST202 |
| `npm run typecheck:api` | exit 0 |
| `npm run test:launch` | exit 0. Adds `erasureContracts()`: the newest `delete_user_data` keeps 033's tables and erases every table a later migration creates with an account column; a settlement loses the person; the routine stays definer, pinned and service-role only; the importance check is guarded; the API ends billing first, calls `delete_user_data` and then the four later routines, and tolerates a missing one. Three mutations were checked to fail: dropping the 040 line, dropping the 035 lines, and `isRpcMissing` in the loop |
| `npm run test:coding` | exit 0; 695 tasks: JavaScript 281, TypeScript 146, React 168, system design 45, Algorithms 55. Easy 462, Medium 151, Hard 82. Coverage is enforced |
| `npm run test:paths`, `npm run test:grading-integrity`, `npm run test:billing` (24 checks), `npm run test:coding-auth` | exit 0 each |
| `npm run test:client` | exit 0; 18 files, 181 tests. New: the Coding home card waits for a free account's plan and then names a free challenge; the stage list keeps its difficulty runs and draws later stages as Premium that open the sheet; a Premium row sits inside its difficulty band; the code pane's first line carries the difficulty. Each was checked to fail without its merged line |
| `npm run typecheck:tooling --prefix client` | exit 0 |
| `npm run check:security`, `npm run check:unused` | exit 0 |
| `npm run build`, `npm run check:public`, `npm run check:bundle` | exit 0; 13 public URLs; 218,351 of 243,000 gzip bytes |
| `npm run check:responsive` over `/coding`, `/coding/javascript`, a task page, `/leaderboard`, `/shop` and `/premium` at 360, 390, 768 and 1280, light and dark | exit 0; 24 probes each, 0 issues |
| `tests/browser/evolving.spec.ts` against the built preview, light and dark | 2 passed, axe included; the code pane's first line shows the stage, the title "Form wizard · 2" and the Easy badge, and the stage list shows its Easy, Medium and Hard runs |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client` | exit 0; 0 vulnerabilities |
| `git diff --check` | clean |

Not verified here: production, where migrations 039 to 044 are not applied, and any signed-in check against the real Supabase and Stripe. These are owner items in `NEEDED.md`.

## 2026-09-25 — the cleanup sweep (CLEAN, #231, #234, #235)

What changed: five fixes from the audit report (#231), the markdown sweep (#234) and the dead-code sweep (#235).
- The CSS purge keeps the runtime-composed `lp-state--*`, `lp-criterion--*` and `lp-trace__cell--*` classes, and the build fails if a listed runtime-composed class goes missing.
- The CSP `connect-src` allows `https://*.ingest.de.sentry.io`, so browser errors can reach Sentry.
- Submit returns only the visible checks' console output: `runInSandbox` starts hidden calls after the shown ones settle and cuts the logs there. The learning-path grader uses the same split.
- Every segmented control shows the track through an unselected segment in both themes; the rule lives in Astryx's `astryx-base` layer.
- Stale Markdown is corrected or deleted, `NEEDED.md` carries valid markers on every task, and the exports, scripts and the one file that nothing imports are gone.
- Not ported: the Classroom rate-limit fix `fa884b7` from `claude/elegant-cori-h9cdgb`. `git cherry-pick -n fa884b7` conflicts in `lib/rate-limit.ts` (D2 already added an `identity` argument with another key scheme) and in `scripts/test-launch-contracts.ts`. `NEEDED.md` carries it as an agent task.
  *22 October 2026:* the fix landed by hand on 26 September ("Classroom rate limits (ported from `fa884b7`)" below). The owner dropped the branch's other work (#208, closed not planned) and archived it as tag `archive/2026-10-22/claude/elegant-cori-h9cdgb`.

Local evidence, all executed on the final tree:

| Check | Result |
| --- | --- |
| Client build without `/^lp-/` in the safelist | exit 1, naming the ten `lp-` modifier classes |
| Client build with it | exit 0; all ten ship in the ActivityViews stylesheet. Of 828 source classes, the 20 still missing from the build are dead CSS no TS or TSX file names |
| `npm run check:security` with the old `vercel.json` | exit 1 on the Sentry ingest assertion; with the new one, exit 0 |
| `npm run test:grading-integrity` | exit 0. New: without a split every log returns; with one, a hidden call prints nothing, whether it settles first or hangs; an anonymous Submit of `js-digit-sum` that logs its argument passes 3 of 3 hidden checks and returns the five visible inputs only. With `shownCalls` removed from `gradeCode` the Submit case fails |
| `npm run test:coding` | exit 0; 695 tasks, every reference solution proven under the split grader |
| `tests/browser/segmented.spec.ts` (`/roadmap`, `/leaderboard`, light and dark, 1280 px) | against the previous build the two `/roadmap` cases fail (unselected segments `rgb(239, 239, 239)` and `rgb(107, 107, 107)`); against this build 4 passed: transparent at rest, Astryx's hover still paints, axe color-contrast clean |
| `tests/browser/segmented.spec.ts`, `evolving.spec.ts`, `public.spec.ts` against the final preview | 11 passed |
| `npm run check:responsive` over `/`, `/quiz`, `/roadmap`, `/leaderboard`, `/premium`, `/coding` at 360, 390, 768 and 1280, light and dark, `--block-external` | exit 0 each; 24 probes, 0 issues |
| `npm run typecheck:api`, `npm run test:launch`, `npm run test:paths`, `npm run test:coding-auth`, `npm run test:billing` (24 checks) | exit 0 each |
| `npm run test:client` | exit 0; 18 files, 181 tests |
| `npm run typecheck:tooling --prefix client`, `npm run check:unused` (1 reviewed finding left) | exit 0 each |
| `npm run build`, `npm run check:public`, `npm run check:bundle` | exit 0; 13 public URLs; 218,305 of 243,000 gzip bytes |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client` | exit 0; 0 vulnerabilities |
| `git diff --check` | clean, on the tree and on the step's range |

Not verified here: Sentry receiving a real browser event after deploy, and anything signed in.

## 2026-09-25 — the freemium steps without a section of their own (D0, D1, D4 to D7)

D2, D3, D8, D8b, D9, INT and CLEAN have sections above. This one records the rest from the step reports of the lane sessions: lane A ran D0 to D3, D8, D8b and D9 on `wip/dev-lane-a`, lane B ran D4 to D7 on `wip/dev-lane-b`, and INT merged both. Each result is the command's exit code on that lane's head at the end of the step.

### D0 (#219): the protected invariant

`CLAUDE.md`, `AGENTS.md`, the header of `shared/rewards.ts` and `docs/product-architecture.md` ("Tiers and billing") state the freemium rule (`a0a9843`, `438e724`). The permission classifier of that session refused three edits (the product-context skill, the design auditor, the implement-screen command); `4dded3d` made them before INT.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run test:launch` | exit 0 each |
| `git diff --check e668c67 HEAD` | exit 0 |
| D0's acceptance grep over `CLAUDE.md`, `AGENTS.md`, `shared/rewards.ts` and `.claude/` | one match at the end of D0 (the product-context skill, line 18); no match after `4dded3d` (exit 1, run by INT) |

Not run: the build, the responsive sweep and the audits; D0 changed documentation and comments only.

### D1 (#220): tiers, the 402 locks and manual grants

`shared/tiers.ts`, migration 039 (three tables, one private live-grant helper and the service-role routines around it), `lib/access.ts` with a 402 at every call site that starts content, `op=entitlement`, admin `op=entitlements`, and the client locks and upgrade sheet. At the time 70 of 480 coding tasks were free; INT re-picked 104 of 695.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run test:launch`, `npm run test:paths`, `npm run test:coding-auth` | exit 0 each |
| `npm run test:coding` | exit 0; 480 tasks, index fresh |
| `npm run test:client` | exit 0; 9 files, 69 tests (8 new) |
| `npm run build`, `npm run check:bundle` | exit 0; 207,057 of 243,000 gzip bytes |
| `npm run check:responsive` at 360, 390, 768 and 1280, light and dark | exit 0; 128 probes each, 0 issues |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client`, `git diff --check` | exit 0 each |
| Migration 039 on Postgres 16 from the 001–038 chain | applied twice with `ON_ERROR_STOP=1`, exit 0 both times; the rolled-back exercise covered grant and regrant, revoke, an expired promotion, a provider grant from active through `past_due` in and past the seven-day grace to canceled, a sticky revoke, a manual revoke that leaves provider grants, owner conflicts, a duplicate event, a customer link and its conflict, a past `validUntil` refused, owner-only reads, refused writes for `authenticated` and `anon`, and deletion; nothing left after rollback |
| Real `api/quiz/roadmap.ts`, `api/user/[op].ts` and `api/admin/[op].ts` through a PostgREST/Auth stand-in | 37/37: 402 `premium_required` with the right `kind` and `ref` from every locked call site, 200 for open content, cleared content of a lapsed account, a paused path and guest previews; a manual grant opens the same account without a restart and a revoke closes it again |
| Chromium, a free account signed in, 360 and 1280, light and dark | 15 Premium nodes on React parts 2 and 3 read "…, Premium" with `aria-disabled`; Enter opens the sheet with the price and VAT; 75 Premium rows on the JavaScript track; the locked task page and stage notes; the plan line reads "Free". The 360 px map label crowding it showed was fixed in `23d7bd3` |

### D4 (#223): the 30-day leaderboard

Migration 040 dates every verified answer in `user_activity_days`, `window_leaderboard` ranks the last 30 days, and the rebuilt `/leaderboard` opens on that board.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run test:launch`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:client` | exit 0; 8 files, 71 tests |
| `npm run build`, `npm run build:storybook` | exit 0 each |
| `npm run test:browser` (Storybook and the local preview) | exit 0; 13 passed. An earlier run failed once on `evolving.spec.ts` after a partial build had dropped `dist/sandbox`; after a full build the spec passed twice alone and in the suite |
| An axe sweep of every leaderboard story in dark mode at 360 and 1280 | 10 tests, 0 violations |
| `npm run check:responsive -- --routes /leaderboard` at 360, 390, 768 and 1280, light and dark | exit 0 each |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client`, `git diff --check e668c67..HEAD` | exit 0 each |
| Migration 040 on Postgres 16 from the 001–038 chain | applied twice, exit 0; the rolled-back exercise: a quiz receipt counts once, a daily retry adds nothing, a Learn answer counts once and an anonymous one not at all, a challenge run counts once and a zero-XP run not at all, the 30-day edge, the category filter, the five-answer minimum, ties sharing a rank, `friend_list` ordered by correct answers, eight definer routines for `service_role` only, owner-only reads and erasure |

Not done in D4: the country flag on each row (an owner decision in `NEEDED.md`), a pinned own row on All time and Today, and folding the erasure into `delete_user_data` (INT did that in 044).

### D5 (#224): Easy, Medium and Hard

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run test:launch`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:coding` | exit 0; 480 tasks: 257 Easy, 142 Medium, 81 Hard |
| The coverage matrix with enforcement switched on (`CODING_COVERAGE_ENFORCED=1`) | exit 1 as intended, 42 Easy-band gaps; D7 closed them and switched enforcement on |
| `npm run test:client` | exit 0; 9 files, 80 tests |
| `npm run build` | exit 0 |
| `npm run check:responsive` over seven coding routes at 360 and 1280, light and dark | exit 0; 14 probes each, 0 issues |
| `tests/browser/evolving.spec.ts` and `public.spec.ts` | exit 1 on the first run (the dark React harness case timed out at a load average near 7 on 4 CPUs), then `evolving.spec.ts` alone exit 0 twice |
| A one-off axe pass over `/coding`, a track, a Hard stage and a task page, 360 and 1280, light and dark | 0 violations |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client`, `git diff --check` | exit 0 each |

Not run: `tests/browser/storybook.spec.ts` (no Storybook build; D5 changed no story), so `npm run test:browser` as a whole did not run.

### D6 (#225): the debugging paths

| Check | Result |
| --- | --- |
| `npm run test:coding` | exit 0; 495 tasks, every solution proven; 262 Easy, 151 Medium, 82 Hard |
| `npm run typecheck:api`, `npm run test:launch`, `npm run test:grading-integrity`, `npm run test:paths` | exit 0 each |
| `npm run test:client` | exit 0; 10 files, 93 tests (10 new) |
| `npm run build`, `npm run check:bundle`, `npm run check:unused`, `npm run check:security` | exit 0 each; 204,176 of 243,000 gzip bytes |
| `npm run check:responsive` over `/coding` and Log it right level 1 at 360 and 1280, light and dark | exit 0; 4 probes each, 0 issues |
| The shared console in a real Chromium worker and in the QuickJS sandbox | the same table, groups and counts in both |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client`, `git diff --check` | exit 0 each |

Not run: `npm run test:browser` (no browser spec covers these screens). Found and left for later: the Console could show the inputs of hidden checks after Submit; CLEAN fixed it in `ed5ce6f`.

### D7 (#226): the Easy band doubled

Eight waves on `wip/dev-lane-b`, each checked on its own head. In every wave `npm run test:coding`, `npm run build:coding-index`, `npm run typecheck:api`, `npm run test:launch`, `npm run test:client` (10 files, 93 tests), `npm run build`, `npm run check:bundle`, `npm run test:grading-integrity`, `npm run test:coding-auth`, `npm run check:unused`, both production audits and `git diff --check` exited 0, and a planted break of the content contract exited 1 as intended.

| Wave | Commits | Tasks after it | Also |
| --- | --- | --- | --- |
| JavaScript 1 | `8c69515`, `797037e`, `6c603f0` | 525 (292 Easy) | one content contract for every Easy wave |
| JavaScript 2 | `8dc24c7`, `ead21fb` | 555 (322 Easy) | |
| JavaScript 3 | `da7241d`, `230fc80` | 585 (352 Easy) | |
| TypeScript 1 | `fb202df`, `4f8be82` | 610 (377 Easy) | the enforcement preview listed no TypeScript gap |
| TypeScript 2 | `1f2cea8`, `e94e5f9` | 635 (402 Easy) | |
| React 1 | `a16e547`, `d3b9002`, `8ca2b4e` | 655 | React challenges gain hidden cases; two `test:launch` bites exit 1 as intended |
| React 2 | `d1caa9a`, `04759e0` | 675 | |
| Algorithms | `ac200a5`, `143d1d2`, `77e6285` | 695 (462 Easy, 151 Medium, 82 Hard) | coverage enforced; removing the wave exits 1; a one-off run of 103 wrong answers and 10 correct alternatives against the 20 starters exits 0 |

Not run in the waves: `npm run check:responsive` and `npm run test:browser` (no layout, component or story changed; React 1 added one `<small>` to the results summary), `npm run build:curation-registry` (`CODING_TASKS_AUDITED` is false), and `npm run test:react-isolation` for the React waves (it needs Vercel Sandbox credentials).

A ninth wave, twenty-five Medium and Hard JavaScript challenges (`af8df50`, `3933db9`, `5f08ecd`, 720 tasks), sits on `wip/dev-c`. Its checks exit 0 there; once, between two of ten complete runs of its one-off wrong-answer harness, QuickJS aborted on a GC assertion and the process exited before its summary. It is not merged into this integration branch, whose index holds 695 tasks. MERGE-C merged it on 2026-09-26 with the two waves that followed it; see the section after this one.

## 2026-09-25 — the freemium sweep (D10, #230)

What changed: the files that still called devShark free now describe the free tier and Premium, and the history documents keep their words with a line dated 25 September 2026. The brand system's rule, the design thesis, three September plans, the UX audit, the visual QA checklist, the runbook, the growth notes and one paragraph above were swept; `README.md` states both tiers in one paragraph; `about-project.md` makes its Stripe row true; `monetization.md` records Premium as the decision with the handoff's fee arithmetic; `scaling.md` adds Stripe's fees and the base cost of a merchandise redemption. `NEEDED.md` carries each owner item of the handoff's section 11 and of every step report once. `HANDOFF.md` was already gone (CLEAN, `acb91fa`). In code:

- The quiz prompt that asked for voluntary support after every tenth good quiz is gone with its module; `test:launch` now fails if any client file links to `/support`.
- The Rewards fairness note said no purchase changes streaks, while the same page sells a streak protection; it now says what a protection changes. The `quiz.support*` values (unrendered, kept for the Czech parity rule), the Rewards subtitle and the comments in `Shop.tsx`, `lib/topic-grants.ts` and migration 035 (a dated note; the SQL is unchanged) say the same.
- The landing printed "2,487 questions", a count set on 3 September. The bank holds 2,447 authored questions; the audit's gate withholds 154 and the three retired sections hold 319 that the server refuses to deliver, which leaves 1,974. `questionCount` is 1,974 and `test:launch` recomputes it.

Local evidence, on `2abfd35` (the commit after it adds this section only):

| Check | Result |
| --- | --- |
| The #230 acceptance grep over every Markdown file | three lines: the dated history lines in `docs/design/brand-system.md` and `docs/design/design-thesis.md`, and line 389 of `SECOND-HANDOFF-25-9-2026.md` (deleted on 22 October 2026, kept in Git history), the dated handoff that orders this sweep and names the old heading |
| `npm run typecheck:api` | exit 0 |
| `npm run test:launch` | exit 0; with a planted `navigate('/support')` in `Quiz.tsx` exit 1, and with `questionCount` back at 2487 exit 1 |
| `npm run build`, `npm run check:bundle` | exit 0; 218,282 of 243,000 gzip bytes |
| `npm run check:public` | exit 0; 13 URLs |
| `npm run check:security`, `npm run check:unused`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:client` | exit 0; 18 files, 181 tests |
| `npm run check:responsive` over `/`, `/quiz`, `/shop` and `/premium` at 360, 390, 768 and 1280, light and dark (vite preview, `--block-external`) | exit 0; 16 probes each, 0 issues |
| Headless Chromium on the preview | the landing stat reads "1,974 questions"; `/shop` shows the new subtitle and fairness note |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client` | exit 0; 0 vulnerabilities |
| `git diff --check`, and over `94102c6..2abfd35` | exit 0 each |
| `needed_lint.py` (the own-dashboard marker parser) over `NEEDED.md` | 75 open, 20 ticked, 0 violations |
| The month settlement of 041 against 040's real table: Postgres 16, `rea_base` plus 039 to 044 in order (exit 0 each), then a rolled-back exercise | exit 0: 040's upsert sums two writes for one day; the open month reports `open`; August settles once with ranks Q (Premium, 300 coins), P (Premium, 200) and F (free, nothing), an account under five answers is left out, and a second call answers `already`; 044's erasure leaves rank 1 as `deleted-account` and no row of the erased account in 040's table or the ledger. D8 had proved this only against a stand-in table |

Not run for D10: `npm run test:coding`, `npm run test:paths`, `npm run test:billing` and `npm run test:browser`; D10 changed no coding content, path, billing code or story. The markdown checkup covered the four root files and the documents above; CLEAN's whole-repository pass of the same day stands for the rest.

## 2026-09-25 — freemium checks that could not run here

Every row below is **not run**, and each has an owner item in `NEEDED.md`.

| Check | Why it could not run | What runs it |
| --- | --- | --- |
| Migrations 039 to 044 in production, and their rolled-back exercises there | the steps may not write to production | the owner, through the Supabase connector, in the order 039, 040, 041, 042, 043, 044 |
| Every signed-in flow against production: the locks and a manual grant, Rewards and coins, an invitation, the fulfilment queue, the 30-day board, the debugging paths | production has 001–038 only and no test account session exists here | the owner's checks in `NEEDED.md` |
| A Stripe test-clock simulation, fixtures captured with `stripe trigger`, Checkout's rendering of the consent and order-button text, Managed Payments approval, the Customer Portal, and real webhook delivery through Vercel's raw-body replay | no Stripe account exists; the webhook tests use fixtures written from the API reference | the owner's Stripe sandbox |
| A live call to Spreadshop's Public Shop API, and a real sample order | no API key and no shop yet | the owner's Spreadshop account |
| A Google sign-up carrying an invite code through the OAuth redirect | the browser check restored a session instead of running Google's consent screen | production |
| `npm run test:react-isolation` | needs Vercel Sandbox credentials and a snapshot id | CI or a machine with those credentials |
| `npm run build:curation-registry` for coding tasks | `CODING_TASKS_AUDITED` is false, so coding tasks are outside the audit's scope | a coding audit |
| Sentry receiving a browser error after the CSP change | needs a deploy | the owner, after the next deploy |
| The lawyer's review of the Terms, the privacy policy, the checkout wording and the public cancel page | legal advice | the owner's lawyer |

## 2026-09-26 — the Medium and Hard waves merged (MERGE-C, #226)

What changed: `wip/dev-c` is merged into the integration branch (`0a72de1`). It carries the three Medium and Hard waves of #226: JavaScript A (`js-mh-*`, 15 Medium and 10 Hard), TypeScript A (`ts-mh-*`, 6 and 4) with React A (`react-mh-*`, 9 Medium, 4 Hard and 2 tier 5 capstones), and Algorithms A (`alg-mh-*`, 8 and 7) with JavaScript B (`js-mh2-*`, 10 Medium). On top of the merge:

- `shared/coding-index.ts` was regenerated rather than merged by hand: 770 tasks.
- The free coding set was re-picked (`5fcf196`). The waves added 75 tasks and no Easy one, so the share had fallen to 104 of 770 (13.5 %). Twelve Easy standalone tasks joined `FREE_CODING_TASK_IDS`, each on a technique the new challenges combine most and the free set had least of. 116 of 770 tasks are free, 15.1 %; every earlier pick stays.
- README, `about-project.md` and the architecture restate the counts from the index (`8e9c789`).
- `NEEDED.md` takes the lane's three items into the D4 to D7 block: the extended tier-ladder decision, a preview check of the two slowest React challenges, and the React timer item.

Where #226 ended: 549 standalone tasks, which is the issue's "about 550". The Easy standalone challenges of the four section tracks went from 73, 26, 33 and 11 to 163 (JavaScript), 76 (TypeScript), 73 (React) and 31 (Algorithms), exactly the +90, +50, +40 and +20 it asked for. The Medium and Hard waves added 75. Coverage is enforced and passes in all four tracks with no short tag. The fewest Easy challenges behind a tag on a Medium challenge is 3 in JavaScript, TypeScript and React, and 5 in Algorithms.

Local evidence:

| Check | Result |
| --- | --- |
| `npm run build:coding-index` | exit 0; 770 tasks. Regenerated after the merge and again after the re-pick |
| `npm run test:coding`, three full runs (the tree of `8e9c789`, then `8e9c789` twice) | exit 0 each, 4 min 2 s, 4 min 9 s and 4 min 2 s. 770 tasks: JavaScript 316, TypeScript 156, React 183, system design 45, Algorithms 70; Easy 462, Medium 199, Hard 109. The matrix: JavaScript 163 Easy, 41 Medium, 38 tags; TypeScript 76, 22, 25; React 73, 26, 20; Algorithms 31, 18, 9; 0 short. The React timer check that failed five of eight runs on the lane did not fail here |
| Coverage bite: one Easy challenge taken out of its task file, with `CODING_ONLY='^zzz' CODING_SKIP_INDEX=1` | exit 1 in each track. JavaScript without `js-easy3-form-complete`: `every` has 2 Easy, and `js-mh-sudoku-check`, `js-mh-deep-equal` and `js-mh-match-route` fail the band check. TypeScript without `ts-chunk-a-list`: `slice`, and `ts-mh-page-after-cursor`. React without `react-easy3-dispatch-through-context`: `useReducer`, and `react-mh-basket-context`. Algorithms has at least five Easy challenges behind every tag, so three had to go (`alg-easy2-binary-strings`, `alg-easy2-mirror-tree`, `alg-easy2-path-sum`): `recursion`, and six `alg-mh-*` challenges. Each file was restored with `git checkout`; the tree was clean after each |
| One-off count check: every task count in README, `about-project.md` and the architecture against the index | exit 0; 8 of 8 statements match |
| `npm run typecheck:api` | exit 0, after the merge and on the final head |
| `npm run test:launch` | exit 0, after the merge (104 free), after the re-pick and on the final head |
| `npm run build` | exit 0 (the existing warning about chunks over 500 kB) |
| `npm run check:bundle` | exit 0; 218,390 of 243,000 gzip bytes |
| `npm run test:client` | exit 0; 18 files, 181 tests |
| `npm run test:coding-auth`, `npm run test:grading-integrity`, `npm run test:paths`, `npm run check:unused` | exit 0 each |
| `git diff --check` | clean, for the tree and for `214c2f4..HEAD` |

Not run: `npm run test:react-isolation` (needs Vercel Sandbox credentials; the two slowest new React suites have an owner check in `NEEDED.md`), `npm run build:curation-registry` (`CODING_TASKS_AUDITED` is false), `npm run check:responsive` and `npm run test:browser` (no layout, component or story changed), and the dependency audits (no dependency changed).

## 2026-09-26 — the review's fixes (FIX, #219 to #235)

What changed: three reviewers read `origin/main...HEAD` for integrity, data and product defects, verifiers kept 24 findings, and this step fixed each one. A container restart stopped the first run after twelve commits (`5c7cc5f` to `5d95c77`); the resumed run checked each of them against its finding and test, then did the rest. Every code finding has a test; each test this run added was checked to fail without its fix.

| Finding | What was wrong | Fixed in | Proven by |
| --- | --- | --- | --- |
| integrity-1 (high) | the public cancel endpoint refunded, cancelled and revoked for anyone who knew a subscriber's email | `fce0b21`, `f2b3370`, `eea07fd` | `test:billing` (anonymous request makes no Stripe call and answers the same either way; the emailed link acts once, expires, survives an outage; three links an hour; a signed-in owner acts at once); client tests of the page; the SQL exercise below; the privacy policy names what the page keeps |
| integrity-2 (high) | the 14-day refund was measured per subscription, so withdrawing and subscribing again restarted it | `fce0b21` | `test:billing` "the voluntary refund is taken once per account"; SQL exercise |
| integrity-3 (medium) | a refund, dispute or withdrawal kept milestone coins, doubled coins and unsent redemptions | `fce0b21`; the retroactive payout is an owner decision (`2f5b530`) | `test:billing` (refund, dispute, fraud warning, withdrawal; a failing routine is retried); SQL exercise |
| integrity-4 (high) | a request without a token skipped every Premium gate | `5d95c77`, `bace111` | `test:launch` (a guest gets 402 for a Premium level, part test, topic, task, stage two, and for coding-submit and coding-reveal with a guest session) |
| integrity-5 (medium) | replaying a passed Learn level added unlimited correct answers to the 30-day board | `ba86a6e` | `test:launch`; SQL exercise |
| integrity-6 (low) | two accounts could invite each other at the same moment | `ab83766` | two-session race below |
| integrity-7 (low) | any subscription on a linked customer opened Premium | `fce0b21` | `test:billing` "only a subscription that bills a devShark Premium price opens Premium" |
| data-1 (high), data-2 (medium) | PostgREST's PGRST202 did not read as a missing routine, so no fallback before 039 and 040 fired | `5c7cc5f`, `f2bcc09`, `8475898` | `test:launch`, `test:billing`, and the new `test:fallbacks` (the real leaderboard, challenge and tier gate against a PGRST202 stand-in; fails with the old matcher) |
| data-3 (medium) | re-running 041 after 042 dropped the `referral` ledger reason | `78fb5e5` | `test:launch`; 041 and 042 re-applied below |
| data-4 (low) | 044 applied early broke every deletion, and 040 without 044 left erased accounts' dated answers | `6418441`, `2f5b530` | `test:launch`; the production-shape run below |
| product-1 (high) | merging locked the owner out, and NEEDED.md's two escapes did not work | `2f5b530` | the first item of NEEDED.md's D1 block |
| product-3 (medium) | the grace window counted from a period end Stripe has already moved on | `fce0b21`, `1a6e5d4` | `test:billing` "past_due keeps Premium for seven days from the failed renewal"; SQL exercise |
| product-4 (medium) | deleting a paid account did not say it ends Premium without a refund | `325d053` | client test |
| product-5 (medium) | the withdrawal page promised an immediate end it gives only within 14 days | `f2b3370` | client test |
| product-6 (medium) | Premium was sold with merchandise that ships closed | `555f203` | `test:launch` |
| product-7 (medium) | the docs understated what a guest could use | `5d95c77` | `test:launch`, client tests |
| product-8 (medium) | the privacy policy said people wrote the hints by hand | `555f203` | `test:launch` |
| product-9, product-11 (low) | owner checks and the Stripe setup left steps out | `2f5b530` | NEEDED.md |
| product-10 (low) | Manage billing only for a winning provider grant | `fce0b21`, `bf7319d` | client tests; SQL exercise |
| product-12 (low) | the success page kept promising checks after the last one | `bd9d2ba` | client test |
| product-13 (low) | a loading plan marked every coding row Premium | `5d95c77` | client test |
| product-14 (low) | "Change the email" dropped focus to the body | `f2b3370`, `e4c782d` | client test |

Also: `about-project.md` uses "## Tech stack" and "## Third-party libraries" like the other repositories (`ec3f594`); NEEDED.md asks for the Vercel plan decision before `BILLING_ENABLED=true` (`2f5b530`); the architecture, README, runbook and UX audit describe the new billing behaviour (`1a6e5d4`, `0373b40`); CI now runs `test:billing` and `test:fallbacks` (`f2bcc09`); the React timer item of #226 is done (`d53f4ce`, `a7befdc`); `isRpcMissing` counts Postgres's 42883 only when it names a function (`8475898`); the cancel page's client test waits for its focus move (`e4c782d`); and the preview's fetch stub serves the photos the load-more challenge asks for (`705cff7`).

### Migration proof (local Postgres 16, template `rea_base` = the Supabase shim + 001–038)

The restart had also reset the local cluster, so `rea_base` was rebuilt first: the shim, Supabase's default privileges for `anon`, `authenticated` and `service_role`, then 001 to 038 with `ON_ERROR_STOP=1`, exit 0 each.

| Check | Result |
| --- | --- |
| A: 039, 040, 041, 042, 043, 044 applied in order, the six again, then 041, 042 and 041 once more | exit 0, all 15 |
| Rolled-back exercise on A (`BEGIN … ROLLBACK`, one script) | exit 0, 61 PASS lines, nothing left after rollback. past_due counts from `past_due_since` (8 days: free although the period ends in 25; 3 days: Premium, `inGrace`; a later retry and an unknown start keep the first value; a paid renewal clears it; the four- and seven-argument drafts are gone). The summary's `billingAccount` and `subscriptionLive` under a longer complimentary grant and after a subscription ended. The refund taken once per account. Cancellation links: only the hash, the typed address, the action and the times stored; three an hour per address, case-insensitive; review uses nothing; a link is used once; handed back after an outage; expired and unknown links do nothing; rows a day past expiry purged. `revoke_premium_benefits`: nothing while the grant is live; after the revoke, the redemption placed while Premium is refunded in coins and the older one stays; 100 milestone and 20 doubled coins debited once; nothing while another grant keeps Premium; coins already spent stay spent and the debit stops at 0. Learn answers: none dated on a passed level; one per question and UTC day across attempts; yesterday's answer does not block today; a guest's never. All eight ledger reasons after the re-runs, and a `referral` line accepted. Twelve new or restated routines are SECURITY DEFINER with an empty `search_path` and `service_role`-only execute; `billing_cancel_requests` has RLS, no policy, no browser grant and no account or token column |
| B, production's shape (014's check dropped): 040, then 044 | 040 exit 0; 044 exit 3, "migration 044 needs 035 and 039 to 042 first; missing: entitlement_grants, billing_customers, billing_checkout_consents, token_xp_credits, token_month_settlements, referral_codes, referrals", and `delete_user_data` is still 033's |
| B: then 039, 040, 041, 042, 043, 044 | exit 0 each; one `question_edits_importance_check` |
| B: a dated answer of an erased account and of a live one, then 044 twice | the orphan's row deleted, the live account's kept; the second run changes nothing |
| C: two sessions offering each other's invite code at once (committed scratch database) | "recorded" and "self", one row. The same race on the 042 before `ab83766`: "recorded" twice, two rows |
| `test:billing`'s 30 checks against Postgres holding 039–044 twice, through a PostgREST/Auth stand-in that runs each call as SQL | passed; 8 links (2 used) and 2 voluntary refunds recorded by the real routines |

The scratch databases were dropped. No PostgREST binary was on the machine after the restart, so the 30-check run used the harness stand-in of D1 and D2 instead of PostgREST 12.2.12.

### The React timer checks (#226)

| Check | Result |
| --- | --- |
| Stress probe (blocks the event loop for a random 0–N ms every 40 ms), suites before the change | autosave and countdown at 70 ms: 5 failing cases in 90 runs; countdown alone at 120 ms: 14 in 120 (correct solutions read -1); every timer-using React suite at 70 ms, 1,215 runs: 2 (autosave, search); search, notices, carousel and export at 120 ms: 26 in 60 |
| Same probe, the six converted suites | 0 failing cases in 90 runs at 70 ms and 0 in 90 at 120 ms |
| A wrong solution for each converted check | caught, 7 of 7 (a wait that does not restart, an interval kept to the end, one that never stops, no debounce, a click that does not restart the slide, the next question after 50 ms, index keys) |
| `CODING_ONLY` run of the six tasks (reference, junior and senior against visible and hidden cases; starters still fail) | exit 0 |
| Five consecutive full `npm run test:coding` runs on `d53f4ce` | exit 0 each; 217, 215, 219, 216 and 216 s; 770 tasks |

### Release contract on the final head

All on `705cff7`, the last code commit; the commit that records this section changes documentation only. Every command below was run, and the exit code is its own.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:launch` | exit 0. New here: a guest's coding-submit and coding-reveal refused with 402; the privacy policy's sentences on the cancellation page and the purge behind them; an operator error is not a missing routine; the load-more solution pages to the end through the preview's fetch stub |
| `npm run test:coding-auth`, `npm run test:grading-integrity`, `npm run test:paths` | exit 0 each |
| `npm run test:coding` | exit 0; 770 tasks (JavaScript 316, TypeScript 156, React 183, system design 45, Algorithms 70; Easy 462, Medium 199, Hard 109), 216 s. With the five runs on `d53f4ce` and one on `0373b40` (217 s), seven full runs in a row passed |
| `npm run test:billing` | exit 0; 30 checks |
| `npm run test:fallbacks` (new) | exit 0 |
| `npm run test:client` | exit 0; 19 files, 193 tests |
| `npm run check:unused`, `npm run check:security` | exit 0 each; knip reports no new finding |
| `npm run build` (with CI's `VITE_PRODUCT=devshark VITE_LOCK_SUBJECT=webdev`), `npm run check:public`, `npm run check:bundle` | exit 0 each; 13 public URLs; 219,540 of 243,000 gzip bytes; the existing warning about chunks over 500 kB |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client` | exit 0 each; 0 vulnerabilities |
| `git diff --check`, and `git diff --check 5ebdad7..HEAD` | clean |
| `npm run check:responsive -- --block-external` against `vite preview` on :4173, `CHROME_BIN` = Chromium 141 from `/opt/pw-browsers/chromium-1228` | exit 0 on the build of `705cff7` (and on `0373b40`'s): 238 probes (34 routes × 7 widths, 360 to 1440), 0 with issues, 0 unprobed |
| The same with `RESPONSIVE_THEME=dark` over `/premium/cancel`, `/premium/success`, `/premium`, `/profile`, `/privacy`, `/terms`, `/coding`, `/coding/javascript`, `/coding/react`, `/learn`, `/roadmap` and `/today` at 360, 390, 768 and 1280 | exit 0: 48 probes, 0 with issues, 0 unprobed |
| `npm run test:harness` (every React suite in the built sandbox in Chromium, as CI's browser step runs it) | exit 1 on `0373b40`: `react-mh-load-more`'s preview threw "next is not iterable", because the fetch stub answered `/api/photos` with its weather object (a defect of the #226 wave, not of this step; fixed in `705cff7`). exit 0 on `705cff7`: 196 assertions, which include the five visible suites that now run on the hand-moved clock |
| `npm run test:browser` for `public.spec.ts`, `evolving.spec.ts` and `segmented.spec.ts` against the same preview (`CHROME_BIN` as above) | exit 0 each; 5, 2 and 4 passed |

### Production order for 039 to 044

In one sitting, before the branch reaches `main`, in the Supabase SQL editor:

1. `supabase-schema-039.sql` — entitlements and billing, with the review's section 6.
2. `supabase-schema-040.sql` — the 30-day board. It needs nothing from 039.
3. `supabase-schema-041.sql` — coins. It calls 039's `is_premium` and must come before 042.
4. `supabase-schema-042.sql` — invitations. It uses 041's `token_account_key`.
5. `supabase-schema-043.sql` — merchandise caps and the hoodie. It needs only 028 and 035.
6. `supabase-schema-044.sql` — one erasure routine and 014's importance check. It refuses to run until 035 and 039 to 042 exist, and deletes dated answers that deletions left behind in the meantime.

Then give the owner's account an open-ended manual grant (`select public.grant_manual_entitlement(...)`, NEEDED.md), and only then merge. Re-running any file is safe: each was applied twice above, and 041 and 042 only add ledger reasons.

Not verified here: production (the steps may not write to it), anything against Stripe or Resend, the lawyer's review of the emailed confirmation under § 312k BGB, and PostgREST 12.2.12 itself after the restart. Each has an owner item in `NEEDED.md` or is listed under "freemium checks that could not run here".

## 2026-09-26 — Premium vouchers (VOUCHER)

What changed: Stripe stays off (`BILLING_ENABLED` unset), and a signed-in learner can now enter a voucher code on `/premium` that opens Premium for the account. The owner creates the codes in `/dev` → Vouchers. Migration 045 holds the codes as SHA-256 hashes with their first four characters, the redemptions, and five service-role routines; a redemption writes a `promo` grant that 039's `is_premium` already counts. Twelve handlers remain: `op=voucher` is a branch of `api/user/[op].ts` and `op=vouchers` of `api/admin/[op].ts`.

| Commit | What |
| --- | --- |
| `e95ac9d` | Migration 045: `premium_vouchers`, `premium_voucher_redemptions`, the four routines and their private JSON helper, `delete_user_data` restated (044's body, then the redemptions and an erased admin's vouchers); the erasure contract reads the guard of whichever migration restates the routine last |
| `4d6c6e1` | `op=voucher` (signed in, five attempts an hour per account and ten per address, one answer for every refused code, 409 only for "already redeemed", 503 `voucher_unavailable` before 045) and `op=vouchers` (admin only: create with a random or custom code shown once, list, revoke); launch contracts and `test:fallbacks` |
| `f0e5a63` | The plan line names a voucher grant: "Premium from a voucher, until …" |
| `ca81301` | "Have a voucher?" on `/premium`, first while checkout is off, with every state and a client test |
| `1b00d59` | The upgrade sheet offers "Redeem a voucher" while checkout is off |
| `cc01e33` | `/dev` → Vouchers: the form, the code once with a copy button, the list with revoke |
| `8bdb1d3` | The Terms and the privacy policy: how a voucher works, what a redemption stores |
| `daad647` | The voucher form uses Astryx's own field labels (found in the browser check below) |
| `47bd47b` | Astryx's `--color-on-accent` follows the theme's `--brand-on-accent`, so an Astryx primary button in dark mode reads at 6.69:1 instead of 2.77:1, on every screen (found by the axe pass below) |
| `5bb53d8` | The architecture, `shared/tiers.ts`, the README and the UX audit describe vouchers |

This record and the VOUCHER block of `NEEDED.md` are the last commit and change documentation only.

### Migration 045 proof (local Postgres 16, template `rea_base` = the Supabase shim with Supabase's default privileges + 001–038)

Before the proof, the local 039–044 chain was compared with production by read-only queries: the definitions of `delete_user_data`, `is_premium` and `entitlement_summary` hash the same (`00d58b4b…`, `44223388…`, `75141b52…`), and so does a fingerprint of the columns, defaults, constraints, policies and RLS flags of the tables 045 touches or erases (`e52b75f2…`). Production's default privileges grant EXECUTE on new functions to `anon` and `authenticated`, as the template does, so the revokes below are tested against the grants they remove. Production runs Postgres 17.6 and the proof ran on 16.13: the three definitions above hash the same on both, and 045 uses only plain DDL, PL/pgSQL, a row lock and core functions.

| Check | Result |
| --- | --- |
| 045 alone on 001–038 | exit 3, "migration 045 needs 035 and 039 to 042 first; missing: entitlement_grants, …", and nothing created |
| 039, 040, 041, 042, 043, 044, 045 in order, then 045 again | exit 0 each; the catalog fingerprint of the voucher objects (routine definitions and ACLs, columns, constraints, indexes, table ACLs, RLS) is the same before and after the second run |
| Hash cross-check | `sha256sum` and Postgres's `sha256()` agree on `K7Q2ABCD1234`; `test:launch` pins the same value for `voucherHash` |
| Rolled-back exercise (`BEGIN … ROLLBACK`, one script) | exit 0, 100 PASS, 0 FAIL, nothing left after the rollback. A 30-day redemption opens Premium (`is_premium` true, `entitlement_summary` source `promo` with the same end), one active promo grant noted "Voucher K7Q2", one redemption row, count 1. The same account again: "already", no grant and no use added; the table's key refuses a second row. Unknown, expired (moved past its date, and at its exact date), used-up and revoked codes answer the same "invalid". An open-ended voucher: no end, three uses hold at three, the table refuses a count above the maximum. A revoke keeps its first time, stops new redemptions and leaves the Premium already opened. The grant past its `valid_until` opens nothing. The list carries no hash. `delete_user_data` removes the redemption and the grant and keeps the voucher's count, anonymises an erased admin's vouchers, and 039's `delete_entitlement_data` still works through the cascade. `anon`, `authenticated` and a role holding only PUBLIC's rights are refused every routine and every read or write of both tables; `service_role` runs them. All six routines are SECURITY DEFINER with an empty `search_path` and `service_role`-only EXECUTE; both tables have RLS, no policy and no browser grant |
| R1: the last use, two accounts (committed scratch database) | session A redeems and holds its transaction for 2 s; session B, started 0.5 s later, waited 1,507 ms on A's row lock and was refused; 1 of 1 used, 1 redemption, 1 grant |
| R2: one account, two sessions at the same instant | "redeemed" and "already"; 1 use, 1 grant |
| R3: twelve accounts at the same instant, three uses | 3 redeemed, 9 refused; 3 of 3 used, 3 redemptions, 3 promo grants, 3 accounts Premium |

### The real handlers against Postgres

A scratch PostgREST/Auth stand-in ran the calls as SQL against a database holding 001–045; it answers a missing routine the way PostgREST 12 does (PGRST202, "Could not find the function … in the schema cache").

| Check | Result |
| --- | --- |
| End to end through `api/admin/[op].ts`, `api/user/[op].ts` and `api/quiz/roadmap.ts` | 36 checks passed, on `daad647` and again on `5bb53d8`. The admin creates a code; the database holds its SHA-256 and the admin's id, and a full `pg_dump` contains the code nowhere. A free learner gets 402 on a Premium challenge, redeems the code typed in lower case with spaced dashes, reads Premium from a promo grant with the right end, and opens the challenge without a restart. Again: 409. Another learner: 400 `voucher_invalid`, word for word the answer to an unknown or malformed code; a guest: 401. A custom campaign code is normalised, a duplicate refused with 409, an open-ended redemption reads no end, the list shows no hash, a revoke refuses the next learner and keeps the earlier one Premium. A learner is refused the admin route (403). The sixth attempt in an hour answers 429. Deleting the account erases the redemption and the grant and keeps the voucher's count. 49 log lines and 28 database requests, none carrying a code |
| The client build signed in, Chromium 141, light and dark at 360, 390, 768 and 1280 px | 88 cells: signed out, the form with focus, a refused code, a redemption (the plan line above updates in place), the Profile's plan line, too many attempts, the upgrade sheet from a Premium challenge, the landing on `/premium#voucher` with the caret in the field, and `/dev` → Vouchers (form, new code, list with long notes). No horizontal overflow, every control of the section at least 44 px on touch, no page or console error. The screenshots were reviewed; the form's hand-made labels were heavier than Astryx's, fixed in `daad647` and checked again. Run again on `5bb53d8`: 88 cells, 0 with an issue |
| axe-core 4.13 (WCAG 2.1 A and AA) over the same states, light and dark at 390 and 1280 px | 44 cells. On `daad647`, 17 had a finding, each `color-contrast` on an Astryx primary button in dark mode: white on the `#4caf50` accent, 2.77:1. `/premium/cancel` showed the same failure before this branch, so the fix went into the theme (`47bd47b`) rather than the voucher form. On `5bb53d8`: 0 with a finding |

### Release contract on the final head

All on `5bb53d8`, the last commit before this record; the record changes documentation only. Every command below was run, and the exit code is its own.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:launch` | exit 0. New here: 045's tables, grants and routines, no column for the plain code, the redeem routine's lock and order, and 045's `delete_user_data` starting with 044's body; the code format, the generator's spread and a pinned hash; both handlers against a fake database (one answer for every refused code, 409 only for a second redemption, 429 on the sixth try per account and the eleventh per address, 503 before 045); the real admin route's 401 and 403; no log line with a code; the client's request and copy; the legal sentences |
| `npm run test:coding-auth`, `npm run test:grading-integrity`, `npm run test:paths` | exit 0 each |
| `npm run test:coding` | exit 0; 770 tasks, 218 s |
| `npm run test:billing` | exit 0; 30 checks |
| `npm run test:fallbacks` | exit 0. New here: before 045 a redemption answers 503 `voucher_unavailable`, `/dev` → Vouchers answers 503 `migration_required`, and the plan, the learning paths and the tier gate keep answering |
| `npm run test:client` | exit 0; 21 files, 220 tests (27 new: 19 in `voucher.test.tsx`, 8 in `dev-vouchers.test.tsx`) |
| `npm run check:unused`, `npm run check:security` | exit 0 each; knip reports no new finding |
| `npm run build` (with CI's `VITE_PRODUCT=devshark VITE_LOCK_SUBJECT=webdev`), `npm run check:public`, `npm run check:bundle` | exit 0 each; 13 public URLs; 221,047 of 243,000 gzip bytes; the existing warning about chunks over 500 kB |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client` | exit 0 each; 0 vulnerabilities |
| `git diff --check 4022afd..HEAD` | clean |
| `npm run check:responsive -- --block-external` against `vite preview` on :4173, `CHROME_BIN` = Chromium 141 from `/opt/pw-browsers/chromium-1228`, over `/premium`, `/profile`, `/dev`, `/terms`, `/privacy`, `/premium/cancel`, `/premium/success`, a coding challenge and `/learn` | exit 0: 63 probes (9 routes × 7 widths, 360 to 1440), 0 with issues, 0 unprobed |
| The same with `RESPONSIVE_THEME=dark` at 360, 390, 768 and 1280 | exit 0: 36 probes, 0 with issues, 0 unprobed |
| CI's two sweeps: `/`, `/quiz`, `/topics/javascript-closures` and `/cs/topics/javascript-closures` at 360 to 1440, then `RESPONSIVE_THEME=dark RESPONSIVE_LOCALE=cs` over `/` and `/cs/topics/javascript-closures` at 390, 768 and 1280 | exit 0 each: 28 and 6 probes, 0 with issues |
| `npm run test:browser` for `public.spec.ts`, `evolving.spec.ts` and `segmented.spec.ts` | exit 0 each; 5, 2 and 4 passed |
| `npm run test:harness` | exit 0; 196 assertions |
| `npm run audit:performance` (Lighthouse on `/`, lab values, not field data) | exit 0; mobile: performance 0.85, accessibility 1, best practices 0.96, SEO 1; desktop: 0.99, 1, 0.96, 1 |
| `npm run build:storybook`, then `storybook.spec.ts` against the Storybook dev server, as CI's last step runs them | exit 0 each; 6 passed |
| The end-to-end run, the 88-cell sweep and the axe pass above | exit 0 each |

Each commit on its own: the worktree was detached at each of the ten commits from `e95ac9d` to `5bb53d8` in order, and `npm run typecheck:api`, `npm run typecheck:tooling --prefix client`, `npm run test:launch`, `npm run test:fallbacks` and `npm run test:client` exited 0 at every one.

### Production order for 045

1. In the Supabase SQL editor, run `supabase/supabase-schema-045.sql` (md5 `9e5750618d6586ba153bb31f6b7bbec9`). It needs 039 to 044, which production has had since 2026-09-26, and running it twice changes nothing.
2. Run this check. It returns one row: `t`, `t`, `5`, `t`, `t`, `0`, `t`, then `2358b9e7c57afb3eafc4af76e9e0c9f4`, `2a82520c9cd0e3845839b7703924444e` and `dc95d11afc6d30267f577cf5e359de48`, the hashes a local database with 039 to 045 gives. Then open the security advisor.

   ```sql
   SELECT to_regclass('public.premium_vouchers') IS NOT NULL AS vouchers_table,
          to_regclass('public.premium_voucher_redemptions') IS NOT NULL AS redemptions_table,
          (SELECT count(*) FROM pg_proc p JOIN pg_namespace n ON n.oid = p.pronamespace
            WHERE n.nspname = 'public'
              AND p.proname IN ('premium_voucher_json', 'create_premium_voucher', 'list_premium_vouchers',
                                'revoke_premium_voucher', 'redeem_premium_voucher')) AS voucher_routines,
          (SELECT bool_and(p.prosecdef
                           AND p.proconfig = ARRAY['search_path=""']
                           AND has_function_privilege('service_role', p.oid, 'EXECUTE')
                           AND NOT has_function_privilege('anon', p.oid, 'EXECUTE')
                           AND NOT has_function_privilege('authenticated', p.oid, 'EXECUTE'))
             FROM pg_proc p JOIN pg_namespace n ON n.oid = p.pronamespace
            WHERE n.nspname = 'public'
              AND p.proname IN ('premium_voucher_json', 'create_premium_voucher', 'list_premium_vouchers',
                                'revoke_premium_voucher', 'redeem_premium_voucher', 'delete_user_data')) AS routines_service_role_only,
          (SELECT bool_and(c.relrowsecurity) FROM pg_class c
            WHERE c.oid IN ('public.premium_vouchers'::regclass, 'public.premium_voucher_redemptions'::regclass)) AS rls_on,
          (SELECT count(*) FROM pg_policies
            WHERE schemaname = 'public' AND tablename IN ('premium_vouchers', 'premium_voucher_redemptions')) AS policies,
          (SELECT bool_and(NOT has_table_privilege(r, t, 'SELECT') AND NOT has_table_privilege(r, t, 'INSERT')
                           AND NOT has_table_privilege(r, t, 'UPDATE') AND NOT has_table_privilege(r, t, 'DELETE'))
             FROM unnest(ARRAY['anon', 'authenticated']) AS r,
                  unnest(ARRAY['public.premium_vouchers', 'public.premium_voucher_redemptions']) AS t) AS no_browser_grant,
          md5(pg_get_functiondef('public.delete_user_data(text)'::regprocedure)) AS delete_user_data_md5,
          md5(pg_get_functiondef('public.redeem_premium_voucher(text,text)'::regprocedure)) AS redeem_md5,
          md5(pg_get_functiondef('public.create_premium_voucher(text,text,text,integer,integer,timestamptz,text)'::regprocedure)) AS create_md5;
   ```

3. Merge. Until the deploy, nothing calls the new routines; after it, `/premium` and `/dev` → Vouchers use them.
4. Create vouchers in `/dev` → Vouchers (NEEDED.md). A voucher needed before the deploy can come from the SQL editor instead: this statement draws a random twelve-character code, stores only its hash and first four characters, and shows the code once, in its own result. Edit the note, the days (`NULL` for no end) and the uses first.

   ```sql
   WITH c AS (
     SELECT string_agg(
              substr('0123456789ABCDEFGHJKMNPQRSTVWXYZ', 1 + (get_byte(r.b, i) & 31), 1),
              '' ORDER BY i) AS code
     FROM (SELECT sha256(convert_to(gen_random_uuid()::text, 'UTF8')) AS b) AS r,
          generate_series(0, 11) AS i
   )
   SELECT substr(c.code, 1, 4) || '-' || substr(c.code, 5, 4) || '-' || substr(c.code, 9, 4) AS code_shown_once,
          public.create_premium_voucher(
            encode(sha256(convert_to(c.code, 'UTF8')), 'hex'),
            left(c.code, 4),
            'First voucher: <who it is for>',
            30,    -- Premium days, counted from the redemption; NULL = no end
            1,     -- how many accounts may redeem it
            NULL,  -- last moment it can be redeemed, or NULL
            NULL)  -- created_by: NULL, or the admin's account id
          AS voucher
   FROM c;
   ```

   An empty `voucher` column means the code already existed; run it again. On a local database with 039 to 045 it returned `K156-F7BT-06EM` and the voucher's row; that code, typed as `k156 f7bt–06em` with spaces around it and put through `normalizeVoucherCode` and `voucherHash`, redeemed a 30-day promo grant noted "Voucher K156".

Not verified here: production (this step may not write to it), PostgREST 12.2.12 itself (the stand-in answers a missing routine as it does), Upstash's sliding window (the checks ran the in-memory bucket; production maps five and ten tries onto a 3,600-second window), and a real Google sign-in. The NEEDED.md item "Check a voucher end to end on production after 045" runs the real stack, sign-in included.

## 2026-09-26 — three `[owner:ai]` items: the erasure loop and migration 046, the retired support settings, Classroom rate limits

What changed: account deletion calls `delete_user_data` alone, and migration 046 drops the four erasure routines that 044 folded into it; the `SUPPORT_ENABLED` flag, the `support` block of the game settings and its `/dev` fields are gone; and the Classroom rate-limit fix of `fa884b7` (`claude/elegant-cori-h9cdgb`) now runs on this tree's `user:<id>` identities, ported by hand. Twelve handlers remain. This step applied no migration outside local scratch databases.

| Commit | What |
| --- | --- |
| `6c3ec0b` | `deleteAccount` calls `delete_user_data` alone. The launch-contract lines that asserted the loop become stricter ones: every statement of the four routines is in the newest `delete_user_data`, the deletion makes one RPC call, and no file under `api/`, `lib/`, `shared/` or `client/src/` names the four |
| `f555ccc` | Migration 046 and its guard; `erasureContracts()` holds 046 to that shape; `test:fallbacks` deletes an account through the real handler while the four answer PGRST202 |
| `a4bf1fd` | `docs/product-architecture.md`: account erasure is one routine, and 046 follows the deploy |
| `84f1407` | The retired support settings removed, with `retiredSupportContracts()` and `client/tests/dev-settings.test.tsx` |
| `d9b40d4` | Classroom rate limits, ported from `fa884b7`, with its five contract assertions adapted |
| `a7315f1` | `NEEDED.md`: the three items ticked, the owner step for 046, a follow-up for the Classroom state reads |
| `1f459f9` | `test:fallbacks` checks the deletion's order: `delete_user_data`, then the sign-in identity, nothing else |
| `f9fe47b` | README and `docs/launch-runbook.md` name migrations through 046; a wording fix in `NEEDED.md` |

This record is the last commit and changes documentation only.

### The four routines inside 045's `delete_user_data`

045's `delete_user_data` (`supabase/supabase-schema-045.sql:321`) holds every statement of the four routines word for word:

| Routine | Its statements | The same statements in 045's `delete_user_data` |
| --- | --- | --- |
| `delete_entitlement_data` | `039:514–516`: `entitlement_grants`, `billing_customers`, `billing_checkout_consents` | `045:402–404` |
| `delete_user_activity_days` | `040:810`: `user_activity_days` | `045:407` |
| `delete_coin_data` | `041:649`: `token_xp_credits`; `041:650–659`: the settled month's `deleted-account` rewrite | `045:411`, `045:412–421` |
| `delete_referral_data` | `042:318–320`: `referral_codes`, the account's own `referrals` row, `deleted-account` as the inviter | `045:425–427` |

044 held the same lines (`044:163–188`), and 045 restated 044's body unchanged before adding the voucher lines. No later migration redefines any of the four. Run inside `delete_user_data` or after it, they leave the same rows, and after it they find nothing to delete or rewrite; the rolled-back exercise below checks that. `erasureContracts()` now reads the four bodies out of 039 to 042 and fails when one of their statements is missing from the newest `delete_user_data`.

In the migrations the four names appear only in their own definitions and grants, in comments of 040 and 044, and in 046. In code only `scripts/test-launch-contracts.ts` names them, to check them; nothing under `api/`, `lib/`, `shared/` or `client/src/` does after `6c3ec0b`.

### Migration 046 proof (local Postgres 16.13, template `rea_base` = the Supabase shim with Supabase's default privileges + 001–038)

`supabase/supabase-schema-046.sql`, md5 `566a74a85a6dec85ef63d946e2b0ceb1`, every file run with `ON_ERROR_STOP=1` on fresh scratch databases.

| Check | Result |
| --- | --- |
| A: 039, 040, 041, 042, 043, 044, 045 in order | exit 0 each. `delete_user_data` hashes `2358b9e7c57afb3eafc4af76e9e0c9f4`, the value the production check for 045 expects |
| A, before 046: what else names or depends on the four | no other routine's source names one, `pg_depend` holds nothing on them, and no policy, view or column default names them |
| A, before 046, rolled back: an account seeded across the eight tables the four touch and the voucher tables, `delete_user_data`, then the four routines | exit 0, 4 PASS: `delete_user_activity_days` deletes 0 rows, and the four together change no row of the ten tables |
| A: 046, then 046 again | exit 0 both times; the second run prints four "does not exist, skipping" notices. The four are gone. `delete_user_data`, the other 107 public routines (definitions and grants), every table (columns, constraints, grants, RLS) and every policy fingerprint the same before 046, after it and after the second run |
| A, after 046, rolled back: accounts A, B and C (a friend A invited) seeded, then `delete_user_data(A)` | exit 0, 28 PASS, 0 FAIL. Each of the four answers `undefined_function` (42883). A's three grants (manual, provider, the voucher's promo), billing link, consent, dated rows, XP credit, invite code and own referral row are gone; the settled month keeps A's rank as `deleted-account` in its place; the friend A invited keeps the referral under `deleted-account`; A's redemption is gone and the voucher keeps its count of 2 without A as its creator; B's rows are unchanged; no text column in the public schema holds A's id; nothing left after the rollback |
| B: 039 to 044 without 045, then 046 | exit 3, "migration 046 needs 045 first; missing: premium_vouchers, premium_voucher_redemptions, delete_user_data erasing premium_voucher_redemptions". The four stay and the catalog fingerprint is unchanged |
| C1: 039 to 045, then 044 again (the body loses 045's line), then 046 | exit 3, "missing: delete_user_data erasing premium_voucher_redemptions"; the four stay |
| C2: 045 again, plus a routine that calls `delete_coin_data`, then 046 | exit 3, "migration 046 drops routines that proof_caller(text) still call"; the four stay |
| C3: a `cron.job` table whose job names `delete_referral_data`, then 046 | exit 3, "migration 046 drops routines that the cron jobs proof-referrals still call"; the four stay |
| C4: that job removed and an unrelated one kept, then 046 twice | exit 0 both times; the four are gone |
| `test:fallbacks`, after 046's shape (the four answer PGRST202, `delete_user_data` answers) | the real handler answers 200 after two calls and no others: `delete_user_data`, then the Auth deletion of the sign-in identity. The handler before `6c3ec0b` fails that check, and so does one that deletes the identity first. The old handler still answers 200 there, because it skips a routine PostgREST reports missing, so a 046 run before the deploy would not break a deletion; the order below does not rely on that |

The proof ends by dropping its scratch databases. Production runs 17.6. 046 uses a `DO` block, catalog reads, `to_regclass`, `to_regprocedure`, a regular expression and `DROP FUNCTION IF EXISTS`, and when 045 went to production its objects, `delete_user_data` among them, matched this local chain by fingerprint (`NEEDED.md`).

### Production order for 046

1. Merge, and wait until Vercel shows the deployment that contains `6c3ec0b` ("Stop calling the four erasure routines after delete_user_data") as production. Until then the deployed code calls the four routines on every account deletion.
2. In the Supabase SQL editor, run `supabase/supabase-schema-046.sql` (md5 `566a74a85a6dec85ef63d946e2b0ceb1`). A refusal changes nothing: "needs 045 first" means 045's tables or its `delete_user_data` are missing, and "still call" names the routine or cron job to fix first.
3. Run this check. It returns one row, `0`, `2358b9e7c57afb3eafc4af76e9e0c9f4`, `t`, as a local database with 039 to 046 does. Then open the security advisor.

   ```sql
   SELECT (SELECT count(*) FROM pg_proc p JOIN pg_namespace n ON n.oid = p.pronamespace
            WHERE n.nspname = 'public'
              AND p.proname IN ('delete_entitlement_data', 'delete_user_activity_days',
                                'delete_coin_data', 'delete_referral_data')) AS dropped_routines_left,
          md5(pg_get_functiondef('public.delete_user_data(text)'::regprocedure)) AS delete_user_data_md5,
          (SELECT p.prosecdef
                  AND p.proconfig = ARRAY['search_path=""']
                  AND has_function_privilege('service_role', p.oid, 'EXECUTE')
                  AND NOT has_function_privilege('anon', p.oid, 'EXECUTE')
                  AND NOT has_function_privilege('authenticated', p.oid, 'EXECUTE')
             FROM pg_proc p WHERE p.oid = 'public.delete_user_data(text)'::regprocedure) AS delete_user_data_service_role_only;
   ```

4. Optional: sign up a throwaway account, delete it from the Profile, and confirm the request answers 200.

Applied on 2026-09-26, after `8a045a5` (containing `6c3ec0b`) was production (`dpl_J4DZYmf9XdGCcErxyvdjLBS9BLy7`): before the file, production held the four routines, `delete_user_data` hashed to `2358b9e7c57afb3eafc4af76e9e0c9f4` and nothing else named them; the file ran in one transaction through the Supabase connector; the check above returned `0 | 2358b9e7c57afb3eafc4af76e9e0c9f4 | t`; the security advisor lists INFO notices only (RLS on without a policy, on the service-role-only tables). Step 4 was not run: it needs a throwaway Google account.

### The retired support settings

`normalizeSettings` builds its result from the fields it knows, so it drops a stored row's `support` key on read, and `saveGameSettings` writes that result, so the next save from `/dev` stores the row without it. A `/dev` tab opened before the deploy runs the old form, which reads `settings.support` and fails until it is reloaded.

| Check | Result |
| --- | --- |
| `retiredSupportContracts()` in `npm run test:launch` | a row with the old block reads the same as one without it and saves without it; the real `/api/settings` handler answers without `support`; the seven files that held the flag, the block or the fields keep none of them; no file under `api/`, `lib/`, `shared/` or `client/src/` reads the switch |
| `client/tests/dev-settings.test.tsx` | `/dev` → Settings loads current settings, and settings that still carry the block, shows no support field, and saves every section except `support` |
| Mutations (each file restored from `01fdfc9` in turn, or a stray read planted) | all 8 fail: the old `lib/settings-store.ts`, `api/settings.ts`, `DevSettings.tsx` (contract, and the client test, where the old form throws on the new response), `client/.env.example`, `README.md` and `gameConfig.ts`, and a `process.env.SUPPORT_ENABLED` read added to `lib/billing/config.ts` |

### Classroom rate limits (ported from `fa884b7`)

| Play action | Before, per address | After |
| --- | --- | --- |
| create | 5 a minute | 20 per address, then 5 per account |
| join | 12 | 48 per address, then 12 per account |
| state | 60 | 600 per address, then 60 per account, or 60 per address signed out |
| control, answer, heartbeat | 30 | 200 per address, then 30 per account |
| distribution (the classroom host's) | no limit | 90 per account |

The other 31 entries of `RATE_LIMITS` are unchanged, compared entry by entry with `01fdfc9`'s.

Reconciled with this tree: identities keep D2's scheme, `${key}:${identity ?? ip}` with `user:<id>`, so no existing bucket key changes. `fa884b7` kept the namespaces apart with `u:` and `ip:` prefixes; here `clientIp` moves an address that starts with `user:` (a client-set header where no proxy overwrites it) to `ip:user:…`, which keeps the same guarantee. One deliberate difference: `fa884b7` charged the host's distribution reads to the 60-a-minute state bucket. The presenter polls distribution every 1.5 s beside its own state reads, and a simulated round through the real limiter (30 pupils and the host on one address, Realtime up, ten questions 30 s apart) refused 40.3 % of the host's state reads and 15.0 % of its distribution polls that way; with distribution in its own bucket, none.

The five assertions of `fa884b7`, adapted, run as eleven groups; a scratch harness ran each on its own against the unported files and the port:

| Group | Unported (`01fdfc9`) | Port | Targeted mutation run through `npm run test:launch`, caught by this group |
| --- | --- | --- | --- |
| 1a two accounts on one address keep separate budgets | pass: D2 already keys by identity | pass | address-only keys, as before D2 |
| 1b an account is bounded once its budget is spent | pass, same reason | pass | identity buckets that never run dry |
| 2a namespaces never meet, even for a `user:` header | fail | pass | `clientIp` without the `ip:` move |
| 2b every identity passed anywhere is `user:<verified id>` | pass: the old handler passes none | pass | a bare `sub` in `join` |
| 3 account limits equal the pre-split values; distribution has its own bucket, sized from `Play.tsx`'s poll | fail | pass | `playJoinPerUser` at 13; distribution on the state key; a 500 ms presenter poll |
| 4a the address buckets hold 32 seats (capacity) | fail | pass | `playState` at 400 |
| 4b a class of 32 joins, polls a minute and answers through both tiers | fail at seat 13 | pass | none needed |
| 4c one account stops at 12 joins while the address has room | fail | pass | none needed |
| 5a each action takes its account token with `user:<verified subject>` | fail | pass | the identity unwired from `state` |
| 5b the signed-out `state` branch keeps its own address bucket | fail | pass | the branch removed |
| 5c each action takes its token after verifying the caller and before any read | fail | pass | `join`'s token moved after its match read |

The unported pair of files, run through `npm run test:launch` as a whole, stops at the bundle: `lib/rate-limit.ts` exports no `SHARED_NETWORK_SEATS`. `fa884b7`'s own two negative tests, loosening `playJoinPerUser` and unwiring the identity argument, both fail the ported contract.

Classroom answers still outrun the state bucket while Realtime is up. Every answer broadcasts `match_updated` on a channel with `broadcast.self = true`, and every client reads state once per broadcast, about 930 reads per question for a class of 30. The same simulation refused 6,134 of the class's 9,610 state reads (63.8 %) at the 600-a-minute address bucket, against 9,252 (96.3 %) with the unported limits; with Realtime down and every client on the 4 s poll, the case `fa884b7` sized for, it refused none of 2,635. `NEEDED.md` has the follow-up: coalesce those reads in `Play.tsx`.

### Release contract on the final head

All on `f9fe47b`, which adds documentation only to `1f459f9`; this record changes documentation only. I ran every command below, and each exit code is its own.

| Check | Result |
| --- | --- |
| The same list on `01fdfc9` (`origin/main` when the step began), before any change | exit 0 each, 13 of 13; 22 client test files, 226 tests; 221,068 of 243,000 gzip bytes |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:launch` | exit 0. New here: the erasure lines of `6c3ec0b` and `f555ccc`, `retiredSupportContracts()`, and the eleven Classroom groups |
| `npm run test:fallbacks` | exit 0. New here: after 046, a deletion calls `delete_user_data` alone |
| `npm run test:client` | exit 0; 23 files, 228 tests (2 new in `dev-settings.test.tsx`) |
| `npm run test:billing` | exit 0; 30 checks |
| `npm run check:unused`, `npm run check:security` | exit 0 each; knip reports no new finding |
| `VITE_PRODUCT=devshark VITE_LOCK_SUBJECT=webdev npm run build`, `npm run check:bundle` | exit 0 each; 220,965 of 243,000 gzip bytes, 103 fewer than on `01fdfc9`; the existing warning about chunks over 500 kB |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client` | exit 0 each; 0 vulnerabilities |
| `git diff --check origin/main..HEAD`, `git diff --check 01fdfc9..HEAD` | clean |
| Each commit on its own | the worktree detached at each commit from `6c3ec0b` to `a7315f1` in order: `npm run typecheck:api`, `npm run test:launch`, `npm run test:fallbacks`, `npm run typecheck:tooling --prefix client` and `npm run test:client` exit 0 at every one. At `1f459f9`, `npm run test:fallbacks` and `npm run typecheck:api` exit 0; `f9fe47b` is the head above |

`origin/main` moved to `2e6b8ba` during the step (a CI change to two browser specs this branch does not touch); `git merge-tree` merges the branch into it without a conflict. Not run: `npm run check:responsive` and the browser suites. The one screen that changed is `/dev` → Settings, which the responsive sweep would render signed out, without the form; `client/tests/dev-settings.test.tsx` renders it.

Not verified here: production (this step may not write to it), PostgREST 12.2.12 itself (the fallbacks stand-in answers a missing routine as it does), Upstash's sliding window (the checks ran the in-memory bucket), a real classroom on one school network, and the Vercel project's environment (whether `SUPPORT_ENABLED` is still set there).

## 2026-09-26 — a click draws the next page once (GLITCH)

The owner reported that clicking Coding "always" showed a glitch and then rerendered, and asked for the same check on the other sections.

What a click did, measured frame by frame in Chromium on devshark.app at `4f93988` as a signed-out visitor, and on a local build of the same commit with a signed-in Premium account simulated by a fake session and API fixtures answering after 250ms:

1. 30 to 60ms after the click the page went empty and the footer rose into view.
2. 200ms later the route loader appeared.
3. The next page drew no sooner than about 330ms after the click, even with every chunk in the HTTP cache, and 400 to 900ms from a cold cache.
4. Signed in, Coding then drew a second time: the new-run form became the run card, "0 of 222 passed" became "2 of 222 passed", the next-challenge placeholder became a title, and the page lost 255px. Today, Learn, Roadmap and Rewards redrew the same way once their data arrived.

Causes:

- In `client/src/App.tsx` the route `Suspense` boundary sat inside the `m.div` keyed by `location.pathname` (lines 640 to 651 at `4f93988`). Each navigation mounted a fresh boundary, and React shows a fresh boundary's fallback at once, even inside the router's transition. `RouteLoader` drew nothing for 200ms and then the loader, and the empty route box kept `flex: 1 0 auto`, which pulled the footer up. After a fallback, React reveals the content no sooner than 300ms later: the floor under step 3.
- `/coding` waited longest because `CodingSection.tsx` imported the task workbench (CodeMirror and the test runner) statically: 32 chunks, 259KB gzipped, against 115KB for Learn, the next heaviest section.
- Pages drew defaults before their data. `ChallengeRunPlanner` shows the form while the open run loads, the Coding counts read zero until progress arrives, `CodingTrackScreen` and Roadmap show a full loader until the plan or the structure loads, Today and Learn show skeletons, and on Rewards the test-mode notice arrived after the page and pushed the wallet down 64px (a layout shift of 0.03).
- The Coding paths list measured its five rows after paint: it drew at its 460px fallback, then grew to 591px (927px at 390px wide).
- `/collection` opens on a lazily loaded Flashcards inside its own boundary, so once navigation stopped blanking the page it showed a loader in its body for a beat.

| Commit | What |
| --- | --- |
| `99fdf58` | The route boundary moves outside the keyed route box, so the router's transition keeps the current page until the next one can render; the fallback shows only for the first page of a visit. The nav marks the destination at once, the waiting page carries `aria-busy` and fades to 0.55 opacity after 200ms (in one step with reduced motion), and each new path opens at the top of `<main>` |
| `d8f239c` | `lib/routePreload.ts`: every lazy route has one loader, registered with its paths; a mouse resting on a link for 65ms, a focus, a touch or a press starts it |
| `2810215` | `lib/routeData.ts`: `useFirstData` holds a page's first render until the named reads are cached, for 1.2s at most and not at all offline; `readOnce` answers from the cache and fetches a missing read once, without the retry delay. The Coding home, track list and FullStack use it, and the paths list measures before paint |
| `5419ea2` | Today, Learn, Roadmap and Rewards hold their first render for the structure, the plan, the catalogue and the account's coins, orders and invite |
| `fb98724` | The workbench loads beside the task instead of with the section: `/coding` now waits for 14 chunks, 43KB gzipped. The lists fetch it when the browser is idle, a task link preloads it, and a failed load shows the existing error with Try again |
| `38aeb7c` | `tests/browser/navigation.spec.ts` holds every chunk back for 600ms and records each frame of eight section visits and a phone drawer visit; it fails on `4f93988` and passes here. CI runs it |
| `cd56c46` | Merge of `origin/main` at `2e6b8ba`; the one conflict, in `quality.yml`, keeps both browser specs |
| `6d59a96` | Collection imports Flashcards (2KB gzipped) directly |
| `4dfec56`, `0402391` | This record and the navigation rule in `DESIGN_RULES.md` §8 |
| `7ee97e5` | The Rewards and merchandise tests take the render result from `act` itself; `npm run typecheck:tooling`, which covers the tests, had failed on their helper with TS2322 twice |
| `938c29c` | Merge of `origin/main` at `47a7ee2` (the three `[owner:ai]` items); the one conflict, at the end of this file, keeps both sections |

The loader, the empty page and the footer jump were the same on every section, so the measurements below are medians of the first visit to each section in a fresh page load, at 1280 and 390px, light and dark (signed in: light only). "Empty frames" count animation frames whose route box held nothing; "content states" count the distinct texts the new page showed in the 3 seconds after the click. The last column is when the new page first drew: before, after the empty beat and the loader; after, when the old page gave way to the complete new one.

Production, `4f93988`, signed out, cold cache (the section's chunks from the network):

| Section | Empty frames | Loader frames | Footer in view on an empty page (frames) | Roots drawn | Content states | New page drawn (ms) |
| --- | --- | --- | --- | --- | --- | --- |
| `/coding` | 13 | 36 | 48 | 2 | 1 | 860 |
| `/today` | 13 | 11 | 25 | 2 | 2 | 439 |
| `/quiz` | 13 | 23 | 36 | 2 | 1 | 642 |
| `/learn` | 13 | 26 | 39 | 2 | 2 | 715 |
| `/challenge` | 13 | 17 | 30 | 2 | 2 | 550 |
| `/play` | 13 | 16 | 29 | 2 | 1 | 511 |
| `/collection` | 12 | 11 | 23 | 2 | 2 | 403 |
| `/roadmap` | 13 | 40 | 52 | 3 | 2 | 920 |
| `/leaderboard` | 13 | 11 | 24 | 2 | 2 | 437 |
| `/premium` | 13 | 14 | 27 | 2 | 1 | 478 |
| `/shop` | 13 | 11 | 24 | 2 | 2 | 445 |
| `/` | 12 | 6 | 18 | 2 | 1 | 327 |

With the chunks in the HTTP cache the pattern held: 12 or 13 empty frames, 5 or 6 loader frames and the new page at 328 to 383ms on every section. A second visit in the same page load, with the chunk already loaded, drew at once with no empty frame: only first visits glitched.

Local build, signed out, before → after (the API forwarded to devshark.app, so the data waits include that round trip):

| Section | Empty frames | Loader frames | Footer in view on an empty page | Roots drawn | Content states | New page drawn (ms) |
| --- | --- | --- | --- | --- | --- | --- |
| `/coding` | 13 → 0 | 5 → 0 | 18 → 0 | 2 → 1 | 1 → 1 | 375 → 117 |
| `/today` | 12 → 0 | 6 → 0 | 18 → 0 | 2 → 1 | 2 → 1 | 330 → 152 |
| `/quiz` | 13 → 0 | 6 → 0 | 18 → 0 | 2 → 1 | 1 → 1 | 343 → 103 |
| `/learn` | 13 → 0 | 6 → 0 | 18 → 0 | 2 → 1 | 2 → 1 | 343 → 367 |
| `/challenge` | 13 → 0 | 6 → 0 | 18 → 0 | 2 → 1 | 2 → 2 | 348 → 114 |
| `/play` | 13 → 0 | 6 → 0 | 19 → 0 | 2 → 1 | 1 → 1 | 332 → 90 |
| `/collection` | 13 → 0 | 6 → 0 | 19 → 0 | 2 → 1 | 1 → 1 | 337 → 102 |
| `/roadmap` | 12 → 0 | 12 → 0 | 25 → 0 | 3 → 1 | 2 → 2 | 471 → 210 |
| `/leaderboard` | 12 → 0 | 6 → 0 | 18 → 0 | 2 → 1 | 2 → 2 | 342 → 63 |
| `/premium` | 13 → 0 | 6 → 0 | 19 → 0 | 2 → 1 | 1 → 1 | 349 → 99 |
| `/shop` | 13 → 0 | 6 → 0 | 19 → 0 | 2 → 1 | 2 → 1 | 350 → 734 |
| `/` | 12 → 0 | 6 → 0 | 18 → 0 | 2 → 1 | 1 → 1 | 326 → 134 |

Local build, signed in with Premium (fixtures after 250ms), before → after:

| Section | Empty frames | Loader frames | Footer in view on an empty page | Roots drawn | Content states | New page drawn (ms) |
| --- | --- | --- | --- | --- | --- | --- |
| `/coding` | 12 → 0 | 5 → 0 | 17 → 0 | 2 → 1 | 2 → 1 | 437 → 470 |
| `/today` | 13 → 0 | 6 → 0 | 19 → 0 | 2 → 1 | 3 → 2 | 343 → 615 |
| `/quiz` | 13 → 0 | 6 → 0 | 19 → 0 | 2 → 1 | 1 → 1 | 354 → 177 |
| `/learn` | 13 → 0 | 5 → 0 | 18 → 0 | 2 → 1 | 2 → 1 | 350 → 475 |
| `/challenge` | 13 → 0 | 6 → 0 | 18 → 0 | 2 → 1 | 2 → 2 | 339 → 98 |
| `/play` | 13 → 0 | 6 → 0 | 19 → 0 | 2 → 1 | 1 → 1 | 350 → 126 |
| `/collection` | 13 → 0 | 6 → 0 | 18 → 0 | 2 → 1 | 2 → 2 | 366 → 104 |
| `/roadmap` | 13 → 0 | 25 → 0 | 38 → 0 | 3 → 1 | 2 → 2 | 684 → 598 |
| `/leaderboard` | 13 → 0 | 6 → 0 | 19 → 0 | 2 → 1 | 2 → 2 | 351 → 90 |
| `/premium` | 13 → 0 | 6 → 0 | 19 → 0 | 2 → 1 | 2 → 3 | 370 → 135 |
| `/shop` | 13 → 0 | 5 → 0 | 18 → 0 | 2 → 1 | 4 → 1 | 357 → 1139 |
| `/` | 13 → 0 | 5 → 0 | 18 → 0 | 2 → 1 | 1 → 1 | 327 → 181 |

The pages that now wait for their data draw later than their first paint used to, and finish no later: the signed-in Coding page used to be complete 710 to 770ms after the click, after two draws, and now at 470ms, after one. Rewards waits longest here because its catalogue came from devshark.app through a slow proxy; the wait never passes 1.2s. While a page waits, its predecessor stays, marked busy, and fades back after 200ms.

Still drawn in two steps after this change, each a page's own loading state rather than the navigation:

- ~~`/leaderboard`: the skeleton, then the board once it loads.~~ HOLDS, below, closed it.
- ~~`/challenge`: the best-effort leaderboard line fills in; no layout shift.~~ HOLDS, below, closed it.
- ~~`/roadmap`: the optional-paths section (a lazy `PathDiscovery`) arrives below the fold.~~ HOLDS, below, closed it.
- ~~`/today`, signed in: the concept, run, due-coding and path sections load under the plan.~~ HOLDS, below, closed it.
- ~~`/premium`, signed in with Premium: the plan arrives after the page and adds "Your plan" above the plans; the page redraws twice and grows 180px. Its tests (`premium-page`, `voucher`) would need an awaited mount to hold it with `useFirstData`.~~ HOLDS, below, closed it.
- `/collection`, signed in: the saved cards. The fixtures did not answer the flashcards read, so this one is not measured. HOLDS, below, measured it: the cards still arrive after the page.
- The route box still fades in from opacity 0 over 140ms, with each page's `ss-pop` on top, so the first frame after the swap is almost empty. That entrance is the existing design.
- A chunk that fails to load still replaces the whole app with the root error screen. It happened once on devshark.app during the measurements, when the proxy aborted `objectWithoutPropertiesLoose-*.js`.

Checks on `938c29c`, the second merge, covering every step of `quality.yml` that needs no secret:

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 and exit 0. The tooling typecheck failed on `4dfec56` with two TS2322 in the Shop test helper that `5419ea2` added; `7ee97e5` fixes it |
| `npm run test:launch` | exit 0; the twelve-function budget holds |
| `test:coding-auth`, `test:grading-integrity`, `test:coding`, `test:paths`, `test:billing`, `test:fallbacks` | exit 0 each |
| `npm run test:client` | exit 0; 24 files, 238 tests, 10 of them new in `route-loading.test.tsx` |
| `npm run check:unused`, `npm run check:security` | exit 0 and exit 0 |
| `VITE_PRODUCT=devshark VITE_LOCK_SUBJECT=webdev npm run build`, then `check:public` and `check:bundle` | exit 0 three times; 13 public URLs; 221,847 of 243,000 gzip bytes (`4f93988` built the same way: 221,047) |
| `npm audit --omit=dev`, root and client | exit 0 twice; 0 vulnerabilities |
| Browser specs `navigation`, `public`, `evolving`, `segmented`, `on-accent` against `vite preview` | exit 0 each; 2, 5, 2, 4 and 12 passed |
| `npm run check:responsive` with CI's routes and widths, light, then dark with `RESPONSIVE_LOCALE=cs` | exit 0 twice; 28 and 6 probes, no issues |
| `npm run check:responsive -- --routes` the twelve sections plus `/coding/javascript`, `/coding/javascript/js-double-numbers` and `/coding/fullstack` `--widths 360,390,768,1280 --block-external`, light and dark | exit 0 twice; 60 probes each, no issues |
| `npm run test:harness` | exit 0; 196 assertions in Chromium |
| `npm run audit:performance` with `CHROME_PATH` set to the local Chromium | exit 0; performance 0.58 on the phone profile and 0.98 on desktop, lab numbers that swing with the first-load shift below |
| `git diff --check`, the worktree and `origin/main` against `HEAD` | exit 0 twice |
| Each of the six commits before the first merge, checked out alone: client `tsc -b` and `vitest run` | exit 0 each; 220, 225, 230, 230, 230 and 230 tests. `tsc -b` leaves the tests out, so it missed the helper's typing |

Not run: the Storybook build and its spec. No story imports a module this change touches.

Lighthouse found a layout shift on the first load of the landing page that predates this change: the whole `<main>` moves by almost a viewport. Against `vite preview`, `origin/main` at `2e6b8ba` scored a CLS of 0.979 in two of three desktop runs and 0.959 in all three phone runs. This branch (`7ee97e5`, then `938c29c`) scored 0.979 in two of five desktop runs and 0.959 in one of five phone runs; every other run stayed at 0.066 or below. Its cause is untraced. It happens before any navigation, so this change does not address it.

Not verified: this change on devshark.app (not deployed), a real Supabase session (the signed-in runs used a fake session and fixtures), and physical phones. The measurement harness stayed out of the repository; `tests/browser/navigation.spec.ts` is the regression check that remains.

## 2026-09-26 — Supabase on demand (BUNDLE)

What changed: a first visit no longer downloads `@supabase/supabase-js`. `client/src/lib/supabaseClient.ts` imports the library once, the first time one of these holds: a session is stored under supabase-js's default key (`sb-<first label of the project host>-auth-token`), the URL carries an OAuth return (`access_token`, `error`, `error_description` or `error_code`, or a PKCE `code` whose verifier this browser stored), the visitor starts a sign-in, or another tab signs in. A stored session and an OAuth return start the download while the module evaluates, before React renders. A visitor with none of those is signed out from the first render and downloads nothing: `AuthProvider` starts with `isLoading` false, `apiFetch` sends no token, and the language and track writers and the match channel skip the account. The key stays supabase-js's default, so every stored session still restores. No server file changed; twelve handlers remain.

| Commit | What |
| --- | --- |
| `b0f9abe` | `lib/supabaseClient.ts` loads the client on demand; `auth.tsx`, `api.ts`, `trackPref.ts`, `languagePref.ts`, `realtime.ts` and `supabase.ts` use it. The boot deadline (8 s) and the token timeout (4 s) now include the download. `AuthProvider` reports a `SIGNED_IN` only after `INITIAL_SESSION`: supabase-js announces a restored session as `SIGNED_IN` while it initializes, the eager client did so before the provider subscribed, and a client loaded on demand can attach the provider first |
| `0bf926e` | `client/tests/supabase-lazy.test.tsx` (19 tests) and `client/tests/supabase-session-key.test.ts` (6, against the real supabase-js 2.110) |
| `4c27225` | `tests/browser/lazy-auth.spec.ts`; the Product quality workflow builds with the placeholder Supabase project from `docs/quality/bundle-budget.json`, as `check:bundle` does, and runs the spec in the browser checks |
| `f528b7d` | `docs/quality/bundle-budget.json` and `docs/quality/README.md` record the measurement and say who downloads the library; the comment in `scripts/check-bundle.mjs` follows |

This record is the last commit and changes documentation only.

### The first visit

`npm run check:bundle` (the production-shaped build), gzip bytes of each initial request of `index.html`:

| Request | `332ce69` | `f528b7d` |
| --- | --- | --- |
| entry script | 110,788 | 111,447 |
| `react` | 56,849 | 56,849 |
| `supabase` (the library) | 54,881 | not requested |
| stylesheet | 25,056 | 25,056 |
| `router` | 18,064 | 18,064 |
| `tanstack` | 12,139 | 12,139 |
| Total | 277,777 in 6 files, 34,777 over the 243,000 budget | 223,555 in 5 files, 19,445 under |

The library is now a lazy chunk (`supabase-B5YuwSPF.js`, 55,304 gzip bytes); the built `index.html` names no `supabase-*` file. A dynamically imported chunk keeps all of supabase-js's exports, 423 bytes more than the static chunk, and the loader adds 659 bytes to the entry, so a signed-in visitor downloads 1,082 bytes more than before, and the library arrives one fetch after the entry instead of beside it. A second chunk also starts with `supabase-`: the app's own `lib/supabase.ts` API calls, about 400 gzip bytes, which `/learn` and `/quiz` load before and after this change. The browser spec tells the two apart by the `GoTrueClient` string in the library's body.

### Evidence

| Check | On `332ce69`'s code | On `f528b7d` |
| --- | --- | --- |
| The two new client test files, copied into a checkout of `332ce69`, each test run alone | 17 failed, 8 passed. The signed-out and sign-in cases fail because the first render is `loading` and supabase-js loads at module evaluation; the three tests that hold the download time out, because the old static import waits for the library before anything runs; a failed download fails the whole module; the key tests fail because `sessionKeyFor` does not exist. The 8 that pass are the stored-session restore, its token, sign-out, the preference refresh, the match channel, the OAuth error return and PKCE, which must behave the same before and after. Run as one file, 22 fail, because a timed-out test's import resolves during the next test | 25 passed, alone and as files |
| `tests/browser/lazy-auth.spec.ts` against `vite preview`, both builds with the placeholder Supabase project, Chromium 141 | 3 failed, 2 passed: `/`, `/learn` and the sign-in click each find `supabase-BEHl1rMg.js` requested at page load; the stored session and the OAuth return pass | 5 passed |

The browser spec plants a well-formed fake session through `addInitScript` and answers `**/auth/v1/**` locally, so nothing reaches Supabase. A signed-out visit to `/` or `/learn` requests no library chunk, contacts no Supabase host and never shows the account skeleton. With the stored session the chunk is requested, the account menu appears, and no sign-in is reported. The sign-in click downloads the chunk and leaves for `/auth/v1/authorize?provider=google`. The OAuth return makes supabase-js call `GET /auth/v1/user`, store the session under the default key, clear the fragment, and `/api/user/authevent` receives one report with the token.

I broke each rule in `lib/supabaseClient.ts` and `AuthProvider` on purpose, one at a time, and `supabase-lazy.test.tsx` failed every time: reporting every `SIGNED_IN` (2 tests failed), ignoring the stored session (8), starting the provider in `loading` (3), loading on any `?code=` (1), letting the token path load without a session (1), dropping the other-tab watch (1), attaching waiting subscribers 50 ms after the client is created (2), and dropping the import at module evaluation (2).

### Release contract on the final head

All on `f528b7d`; this record changes documentation only. I ran every command below, and each exit code is its own.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:launch`, `npm run test:fallbacks` | exit 0 each |
| `npm run test:client` | exit 0; 25 files, 253 tests (25 new) |
| `npm run check:unused`, `npm run check:security` | exit 0 each; knip reports no new finding |
| `VITE_PRODUCT=devshark VITE_LOCK_SUBJECT=webdev npm run build`, then `npm run check:public` | exit 0 each; the build emits the library as a lazy chunk |
| The workflow's build step as committed: the Supabase placeholders from `docs/quality/bundle-budget.json`, then `npm run build && npm run check:public && npm run check:bundle` | exit 0; 223,555 of 243,000 gzip bytes |
| `npm audit --omit=dev`, `npm audit --omit=dev --prefix client` | exit 0 each; 0 vulnerabilities |
| `public.spec.ts`, `evolving.spec.ts`, `segmented.spec.ts`, `on-accent.spec.ts`, `lazy-auth.spec.ts` against `vite preview` of that build on :4473, `CHROME_BIN=/opt/pw-browsers/chromium` | exit 0 each; 5, 2, 4, 12 and 5 passed |
| `npm run check:responsive -- --routes /,/quiz,/learn,/today,/roadmap,/profile --widths 360,390,768,1280 --block-external`, light, then with `RESPONSIVE_THEME=dark` | exit 0 each; 24 probes, 0 with issues, 0 unprobed |
| `git diff --check origin/main..HEAD`, `git diff --check 332ce69..HEAD` | clean |
| Each commit on its own | the worktree detached at `b0f9abe`, `0bf926e`, `4c27225` and `f528b7d` in order: `npm run typecheck:api`, `npm run typecheck:tooling --prefix client`, `npm run test:launch`, `npm run test:fallbacks` and `npm run test:client` exit 0 at every one (228 client tests at `b0f9abe`, 253 after) |

`origin/main` moved to `b74d7ae` (GLITCH) during the step. `git merge-tree` finds one conflict, in `.github/workflows/quality.yml`, where both sides add a spec after `on-accent.spec.ts`; keep both lines. This record will meet GLITCH's record at the end of this file the same way. A scratch copy of `b74d7ae` with this branch's changes applied and both lines kept passed `npm run typecheck:api`, `npm run typecheck:tooling --prefix client`, `npm run test:launch`, `npm run test:client` (26 files, 263 tests) and the workflow's build step (224,479 of 243,000 gzip bytes), and the six browser specs of the merged workflow, `navigation.spec.ts` among them, passed against its preview.

One report changes on purpose. With the eager client, a signed-out tab that stayed open while the learner signed in elsewhere heard that tab's broadcast and posted its own `/api/user/authevent`. That tab now has no client; it restores the session from storage through the `storage` event and posts nothing, and the tab that signed in still reports.

On main and in production: the merge commit `7b4bc8f` passed every step of the Product quality workflow, locally and in CI (run 61), and `check:bundle` read 224,479 of 243,000 gzip bytes in five requests in both. Vercel deployed that commit to devshark.app (`dpl_2dNcA8f6ugbUbybWikA8tk2zgjUS`). Measured the way `check:bundle` measures, the `/assets/` requests that `index.html` starts, each gzipped with Node's `gzipSync`, devshark.app then served 224,511 gzip bytes in five requests; before the deploy it served 278,773 in six, supabase-js among them. The 32 bytes between CI and production are all in the entry script (112,347 against 112,315), which carries production's real Supabase, Sentry and PostHog values where the check has placeholders of the same length. The library chunk `supabase-B5YuwSPF.js` answers 200 for the visitors who need it.

Not verified here: a real Google sign-in and a real Supabase project (the OAuth return and the stored session ran against supabase-js 2.110 with Auth answered locally); a token refresh near expiry, which stays supabase-js's own; two real browser tabs (the cross-tab sign-in ran in the client test with a dispatched `storage` event); Lighthouse.

## 2026-09-26 — a page that fails to load keeps the shell (ERRBOUND)

The owner reported that a page chunk that fails to load reaches the only error boundary, around the whole app in `client/src/main.tsx`: the header, the nav and the footer go, and the learner sees "Something went wrong" with Try again and Reload page. It happened on devshark.app on 2026-09-26 during the GLITCH measurements, when the proxy aborted `objectWithoutPropertiesLoose-*.js` during a first click on Coding (at `4f93988`, when Coding still imported the task workbench) and the whole app went about 1.4s after the click.

On `b74d7ae` and on `7b4bc8f`, a chunk that failed:

1. replaced the app with the root screen. Four of the checks in `tests/browser/route-errors.spec.ts` fail on builds of both commits, with the root screen on the page;
2. left a Try again that could not bring the page back. React.lazy keeps a rejected load for good, so rendering the app again threw the same error without calling the loader. Only Reload page helped.

### What devshark.app answers for a missing chunk

`curl -sS -o /dev/null -w '%{http_code} %{content_type}\n' https://devshark.app/assets/does-not-exist-0000.js` prints `200 text/html; charset=utf-8`. The catch-all rewrite in `vercel.json` does not exclude `assets/`, so a missing hashed file gets `index.html`, and the `/assets/(.*)` header rule adds `cache-control: public, max-age=31536000, immutable` and `x-content-type-options: nosniff` to it. A module script refuses `text/html`, so after a deploy a stale chunk fails the way a dropped request does. The browser may keep that HTML under the chunk's URL for a year, so no retry in place can fetch the file; a reload works, because the new `index.html` names new files. `vite preview` also answers a missing asset with `200 text/html`, which the browser spec relies on. This step leaves `vercel.json` alone (see the hand-off below).

A deploy during this step showed the case live. At 20:45 UTC devshark.app served the entry `main-Ctu2GPhq.js`; after `7b4bc8f` went out it served `main-sb7BNA-6.js`, and the previous build's `main-Ctu2GPhq.js` and `CodingSection-DVDpGXcJ.js` then answered `200 text/html`. `objectWithoutPropertiesLoose-Cv5OCJ0e.js`, unchanged between the two builds, still answered JavaScript. A tab still running the earlier build would get the root screen on its first click on Coding; the spec shows that failure on local builds of `b74d7ae` and `7b4bc8f`.

### Does a second `import()` ask the network again?

Measured in Chromium 141.0.7390.37, the Chromium in `/opt/pw-browsers`, with a local server that fails one module request once and counts every request (a scratch harness, not committed). In every row the first `import()` rejected with `TypeError: Failed to fetch dynamically imported module:` and the page chunk's URL, also when the chunk it imports failed.

| The failure | The page chunk fails | A chunk the page imports fails | The same, after a `<link rel="modulepreload">` of that chunk |
| --- | --- | --- | --- |
| Network error: two resets in a row, a body cut short, or Playwright's `route.abort` | the second `import()` rejects at once, with no request | the same | the same |
| HTTP 404 | the same | the same | the same |
| `200 text/html` under `nosniff`, as devshark.app answers | the same | the same | the same |
| After `location.reload()` | loads; both chunks requested | loads | loads |

A single reset never reached the page: Chromium repeated the GET on a new connection and the import succeeded.

The other browsers, from primary sources; Firefox and Safari are not installed here, and `playwright install` is off limits:

- The standard: [whatwg/html#6768](https://github.com/whatwg/html/issues/6768) asked that a failed dynamic import not stay cached. [whatwg/html#10327](https://github.com/whatwg/html/pull/10327), "Don't cache HTTP errors in the module map", merged 2026-07-15, stops caching network errors, HTTP error statuses and MIME type mismatches. Parse errors stay cached, and imports running in parallel still share one fetch.
- Chromium: [issue 534781954](https://issues.chromium.org/issues/534781954). [CL 8102202](https://chromium-review.googlesource.com/c/chromium/src/+/8102202), "Do not cache failed module imports", landed behind the `ModuleMapDoNotCacheFailedFetch` flag at main@{#1695318} on 2026-09-10, and [CL 8403905](https://chromium-review.googlesource.com/c/chromium/src/+/8403905) turned the flag on at main@{#1701404} on 2026-09-19. Chrome 155 branched at #1697595 (chromiumdash), so 155 (stable 2026-10-06) ships the flag off, and 156 (branch 2026-09-28, stable 2026-10-20) is the first with it on. The [Intent to Ship](https://groups.google.com/a/chromium.org/g/blink-dev/c/lG4iYotq5EA/m/fNtZZbo-BQAJ) named 155, and Gerrit lists no merge of the enabling CL to the 155 branch. Chrome 154, stable since 2026-09-22, keeps the failure, as Chromium 141 does above.
- Firefox: [bug 2055211](https://bugzilla.mozilla.org/show_bug.cgi?id=2055211), fixed in Firefox 155, released 2026-09-01. Its [release notes](https://developer.mozilla.org/en-US/docs/Mozilla/Firefox/Releases/155): "A module that fails to load because of a network error or an incorrect MIME type is no longer cached as a failure, so importing the same module specifier again can succeed once the server recovers", for static and dynamic imports alike. Firefox 154, older releases and ESR keep the failure.
- Safari: [WebKit bug 319492](https://bugs.webkit.org/show_bug.cgi?id=319492), fixed on 2026-08-19 as 319474@main ([WebKit PR 69559](https://github.com/WebKit/WebKit/pull/69559)). [Safari Technology Preview 252](https://webkit.org/blog/18304/release-notes-for-safari-technology-preview-252/) (2026-09-11) covers 319252@main to 320112@main, so it has the fix, though its notes do not mention it. [Safari 27.0](https://webkit.org/blog/18325/webkit-features-for-safari-27-0/) rewrote the module loader and says nothing about failed fetches. I found no Safari release with the change, so Safari counts as keeping the failure.
- [MDN browser-compat-data#30304](https://github.com/mdn/browser-compat-data/issues/30304) tracks the compatibility entry.

So Try again first renders the page again in place, which is enough in Firefox 155 and Chrome 156 and later, and reloads the current address when the same failure comes straight back: in Chrome up to 155, in Safari, in older Firefox, and after every stale deploy on devshark.app.

### Vite's `vite:preloadError`

Vite 6.4.3's preload helper (`preload()` in `client/node_modules/vite/dist/node/chunks/dep-Dm0c1Wj2.js`) dispatches `vite:preloadError` on `window` for each dependency stylesheet that fails and for the rejection of the dynamic import itself. It does not wait for a JavaScript `modulepreload` link, so that failure arrives through the import. `preventDefault()` makes the helper swallow the error, and the import resolves to `undefined`. The helper also remembers every dependency it added, so it never adds a failed stylesheet link again. The intent preloads of `lib/routePreload.ts` go through the same helper, so a pointer resting on a link during a network blip fires the event. The listener in `lib/routeRecovery.ts` therefore only remembers which errors were chunk failures. It never reloads and never calls `preventDefault()`.

### How the page comes back

| Situation | What happens |
| --- | --- |
| A page chunk, or a chunk the page imports, fails on a visit | While the current page (or, on the first page of a visit, the loader) stays on screen, `lazyPage` fetches `/` with `cache: 'no-store'` and compares its entry script with the page's. Another entry means a newer build, and the tab reloads: at most once a minute per tab (a `sessionStorage` stamp), and not at all when storage throws. Otherwise the panel shows in the route box: "Something went wrong", "Network error. Check your connection and try again.", Try again |
| Try again | The page renders again in a transition, with a fresh lazy component, so the panel stays until the page can draw. When the same failure comes straight back and the server answers, the address reloads; the learner's press reloads even within the minute |
| Offline (`navigator.onLine === false`) | No check and no reload; the panel waits. The `online` event renders the page again and, if that fails, reloads once, within the same budget |
| A page's stylesheet fails | Try again and the `online` event reload, since the page would otherwise draw unstyled |
| The nav while the panel shows | Each path mounts a fresh boundary, so another page opens without a retry; the failed page is asked for afresh on the next visit |
| A page throws | The root screen's text and both of its buttons, inside the shell |
| A preload on hover fails | Nothing: `routePreload` swallows it, and the listener only remembers the error |
| supabase-js fails on a sign-in click | The button says "Sign-in failed. Please try again."; no reload, no route panel |

The boundary reports each failed chunk once per page load through `reportError` (Sentry, when a DSN is set) with the component stack and `chunkLoad: true`; the message names the chunk's URL and nothing personal. A preload started by a hover never reaches it. A page that throws is reported every time, as the root boundary does.

`RouteErrorBoundary` sits inside the route `Suspense` and inside the `m.div` keyed by the path, around `<Routes>`. Outside the `Suspense`, catching would unmount it, and the remounted `Suspense` would show its fallback at once: the blank beat GLITCH removed. Inside the keyed box each path mounts a fresh boundary, so leaving a failed page needs no retry, and the router's transition keeps the panel until the next page can draw. The boundary renders no element of its own, so the route box stays the wrapper's first child, which `navigation.spec.ts` samples.

The panel is the root screen's card (`ErrorPanel`), announced as an alert, with `aria-busy` while it checks or reloads. A navigation still moves focus to `<main>` 230ms after the page changes, and the next Tab reaches Try again. When the page that held focus disappears without a navigation, focus moves to the card. Try again uses Astryx's interruptible loading state, so it stays enabled and keeps focus through a retry that fails. An active quiz hides the chrome, and a failure brings it back.

| Commit | What |
| --- | --- |
| `7481302` | `ErrorPanel`: the root screen's card, shared; its buttons now wrap at a narrow width |
| `899719d` | `lib/routeRecovery.ts`: which errors are chunk failures, the reload and its guard, the build check, `lazyPage` and `renewFailedPages`, with unit tests |
| `08a509d` | `RouteErrorBoundary`, its place in `App.tsx`, the listener in `main.tsx`, and the boundary's unit tests (14 in `client/tests/route-errors.test.tsx`) |
| `8ea86c3` | `tests/browser/route-errors.spec.ts`; the "Browser checks" step runs it after `navigation.spec.ts` |
| `f496fe1` | Merge of `origin/main` at `7b4bc8f` (Supabase on demand). The one conflict, in `quality.yml`, keeps both specs, `lazy-auth.spec.ts` first |
| `b7358e2` | The browser spec drops the supabase-js chunk on a sign-in click |
| `4b99f11` | This record, a rule in `DESIGN_RULES.md` §8 and P1.9 in `docs/design/product-ux-audit.md` |
| `10c9e3e` | Merge of `origin/main` at `d2d9085` (documentation only: the bundle record for `7b4bc8f`). The one conflict, at the end of this file, keeps main's lines first, then this section |
| this commit | The live stale deploy above, and the checks on the second merge |

### Evidence

| Check | Result |
| --- | --- |
| `tests/browser/route-errors.spec.ts` against `vite preview` of this branch, built as CI builds (the placeholder Supabase project from `docs/quality/bundle-budget.json`), Chromium 141 | 6 passed. The page chunk, the imported chunk and the offline test each came back by a reload, the path Chromium 141 takes; the second sign-in click after a failed supabase-js download made no request and failed again |
| The same spec against builds of `b74d7ae` (five tests then) and `7b4bc8f` | 4 failed on each: the page chunk, the imported chunk, offline and the newer build, each with the root screen in place of the app. The hover and supabase-js tests pass there too, because they guard against a reload that neither commit makes |
| The hover test against a build that reloads on every `vite:preloadError`, the handler Vite's documentation suggests | fails: the hover reloads the page |
| 13 mutations of `routeRecovery.ts` and `RouteErrorBoundary.tsx`, one at a time, against `client/tests/route-errors.test.tsx` | each fails at least one test: no renewal (5 fail), `preventDefault()` in the listener (1), a reload offline (1), no cooldown (3), an automatic reload without storage (1), a build check offline (1), no `online` listener (2), the learner's press on the cooldown (1), a reload on every visit the server answers (3), a stylesheet failure rendered again (1), no report dedupe (1), the build comparison inverted (1), no build check before the error (1) |
| The panel at 360, 390, 768 and 1280px, light and dark, after a dropped Coding chunk | header and footer in place, no horizontal overflow; focus on `<main>`, then Tab reaches Try again; Try again 86×44 with a touch pointer and 86×32 with a mouse, the root screen's Astryx size |
| `npm run check:bundle`, both builds made as CI makes them | 226,027 of 243,000 gzip bytes; `7b4bc8f` measures 224,479, so the recovery code adds 1,548 to the entry |

### Release contract on the final head

The code is that of `b7358e2`; the commits after it change documentation only. I ran every command below, and each exit code is its own. Browser runs used `CHROME_BIN=/opt/pw-browsers/chromium` and `vite preview` on port 4511. After the second merge (`10c9e3e`, which brings a new `docs/quality/bundle-budget.json`), `npm run check:bundle` ran again: exit 0, 226,027 gzip bytes.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:launch` | exit 0; the twelve-function budget holds |
| `npm run test:client` | exit 0; 27 files, 277 tests (14 new in `route-errors.test.tsx`) |
| `test:coding-auth`, `test:grading-integrity`, `test:coding`, `test:paths`, `test:billing`, `test:fallbacks` | exit 0 each |
| `npm run check:unused`, `npm run check:security` | exit 0 each; knip reports no new finding |
| `VITE_PRODUCT=devshark VITE_LOCK_SUBJECT=webdev npm run build` | exit 0 |
| The workflow's build step: the Supabase placeholders, then `npm run build`, `npm run check:public`, `npm run check:bundle` | exit 0 each; 13 public URLs; 226,027 of 243,000 gzip bytes |
| `npm audit --omit=dev`, root and client | exit 0 each; 0 vulnerabilities |
| Browser specs `route-errors`, `navigation`, `public`, `lazy-auth`, `evolving`, `segmented`, `on-accent` against that build | exit 0 each; 6, 2, 5, 5, 2, 4 and 12 passed |
| `npm run check:responsive -- --routes /,/coding --widths 360,390,768,1280`, light, then with `RESPONSIVE_THEME=dark` | exit 0 each; 8 probes, 0 with issues |
| `npm run test:harness` | exit 0; 196 assertions in Chromium |
| Each commit before the merge on its own (`7481302`, `899719d`, `08a509d`, `8ea86c3`, from `git archive`): client `tsc -b`, the tooling typecheck, `vitest run` | exit 0 at every one; 238, 243, 252 and 252 tests |
| `git diff --check`, `git diff --check origin/main...HEAD` | clean |

Not run: the Storybook build and its spec, since no story imports a module this change touches, and Lighthouse.

### Hand-off

Found on the way and left alone, because the request did not cover them:

- `vercel.json`: the catch-all rewrite serves `index.html` for a missing `/assets/` file, and the assets header rule marks that answer `immutable` for a year. Excluding `assets/` from the rewrite would turn a missing chunk into a 404 that no cache keeps.
- supabase-js since `7b4bc8f`: `loadSupabase()` forgets a failed download, but Chromium up to 155 keeps the failed module fetch. Measured here: after one dropped download, a second sign-in click makes no request and shows "Sign-in failed. Please try again." again, until a reload. The sign-in path needs its own fallback in those browsers; this change does not reload for it.
- The Coding task screen's own Try again for the workbench (`useWorkbench` in `CodingSection.tsx`) calls `loadWorkbench()` again, which fails the same way in those browsers.
- `AuthButton` in the header and `UpgradeSheet` are lazy chunks outside the route boundary, so their failure still reaches the root screen.
- Lazy parts inside pages (Today's four sections, `PathDiscovery`, `FriendsPanel`, the code highlighter, `PathRewardClaim`, the Learn workbench) use `React.lazy`. A failure there shows the route panel, and Try again gets them back only through the reload.

Not verified: Firefox and Safari, whose rows come from the sources above; the in-place path in a real browser, since Chromium 141 always takes the reload (the unit tests cover it); a real deploy (the spec fakes one by answering the chunk with `index.html` and `/` with another entry script); Sentry, which has no DSN here (the unit tests check the calls to `reportError`); devshark.app, where this is not deployed; physical phones and screen readers (the alert role and the focus order were checked through Playwright's role queries and the focused element).

## 2026-09-26 — the first load of a page holds still (CLS)

The owner asked me to find and remove the layout shift on devShark's first page load, and to add a check that fails if it comes back. Lighthouse named `<main id="main-content">` as the only shifting node and scored 0.979 on the desktop preset (1350×940) and 0.959 on the phone profile (412×823), in some runs and not in others. GLITCH recorded it above with its cause untraced.

### What moved

I recorded `layout-shift` entries with a `PerformanceObserver` (`buffered: true`) on cold loads of `/` from a `vite preview` of `7b4bc8f`, in Playwright's Chromium 141 at Lighthouse's two sizes. Each load had one entry, 0.9793 on the desktop and 0.9592 on the phone, with these sources (`previousRect` → `currentRect`, CSS pixels):

| Node | Desktop, 1350×940 | Phone, 412×823 |
| --- | --- | --- |
| `main#main-content` | top 73, height 867 → top 57, height 883 | top 73, height 750 → top 61, height 762 |
| `footer.ss-brand-footer` | 1000×69 at top 787 → out of view | 376×137 at top 614 → out of view |
| The header's slots | left slot and nav up 8px, right slot down 4px and 9px wider | left slot up 6px, right slot 9px wider and 12px shorter |

`<main>` moved 16px on the desktop and 12px on the phone. Two changes shared one frame:

1. The header shrank from 73 to 57px (61px with a touch pointer). The account widget is a lazy chunk, and its `Suspense` placeholder was a 56px square, the height of the avatar row and of the widget's loading skeleton, so the toolbar stood 72px tall under it. A signed-out visitor's widget is the 32px "Log in" button (44px with a coarse pointer), and the toolbar settled at 56px (60px). Since `7b4bc8f` a visitor with no stored session is signed out from the first render, yet the header drew the placeholder until the chunk arrived. Before `7b4bc8f`, `AuthProvider` started in `loading`, so the placeholder and then the widget's 56px loading skeleton held the header at 73px; a build of `2e6b8ba`, where the owner first measured the shift, drops from 73 to 57px the same way.
2. The footer fell out of view. Until the first page's chunk arrived, the route `Suspense` showed its fallback, a box that fills the content area, and the footer sat under it at the bottom of the first viewport. The landing page then pushed it from 787 to 3,417px (614 to 5,347px on the phone).

A frame's score is the area that moving nodes covered before and after, as a share of the viewport, times the longest move as a share of the viewport's larger side, capped at 1. `<main>` and the header slots covered 97.9% of the desktop viewport and 95.9% of the phone's; the footer moved farther than either side is long, so the distance factor was 1. Apart, the header change scores 0.012 on the desktop (0.014 on the phone) and the footer's move 0.054 (0.152).

### Why it came and went

- React 19 reveals a `Suspense` boundary's content no sooner than 300ms after the boundary showed its fallback (`FALLBACK_THROTTLE_MS` in react-dom 19.2.7) and commits every retry that resolved in the meantime together. When the account widget and the landing page both arrived within that window, as they did on a quick local load, the header and the footer moved in one frame: 0.979. When the page came later, the two moves fell into separate frames, 0.012 and 0.054, which is the 0.066 of the runs that missed it. Holding every lazy chunk for 800ms split them every time.
- Under phone emulation Chromium flagged the shift as recent input. A saved Lighthouse trace of `3a8cf13` holds a `LayoutShift` event of 0.9592 at 634ms with `had_recent_input: true` and `last_input_timestamp` at 102ms, the time of the first viewport event, which the emulation causes. Lighthouse keeps a flagged shift only within 500ms of that event, so it dropped this one and scored the run 0 while the page moved. A shift that landed a little earlier, or late enough to go unflagged, counted. Lighthouse's `--throttling-method=devtools` applies real CPU and network throttling, which moves the shifts past both windows.

The same mechanism hit the first load of every page: each drew its footer under the loader, and each signed-out header shrank.

### The fix

| Commit | What |
| --- | --- |
| `2805907` | `SignInButton` holds the signed-out "Log in" button and its failure toast, and ships in the entry. The header renders it whenever `useAuth()` reports no user and nothing loading, which it knows at the first render. The lazy `AuthButton` and its 56px placeholder stay for a stored session or a sign-in in progress, where the placeholder, the skeleton and the avatar row all stand 56px tall; its own signed-out branch renders `SignInButton`. A signed-out first visit no longer requests the `AuthButton` chunk, nor the wallet read (`GET /api/user/[op]?op=wallet`) the widget sent without a session |
| `b05c3c9` | `BrandFooter` renders inside the route `Suspense`, after the keyed route box, so it arrives with the first page and never sits under the loader. A navigation keeps both, as before |
| `28b9ab7` | `tests/browser/first-load.spec.ts`, which the "Browser checks" step runs |
| `a264cea` | Merge of `origin/main` at `d2d9085` (documentation only) |
| `d902d8c` | The first-frame rule in `DESIGN_RULES.md` §8 |
| `b4747a0` | Merge of `origin/main` at `3a8cf13` (ERRBOUND). Three conflicts, each resolved by keeping both sides, main's first: the spec list in `quality.yml`, the two rules in §8, and the comment above the route `Suspense` in `App.tsx`. The code merged without conflict: `RouteErrorBoundary` wraps the routes inside the keyed box, and the footer follows the box inside the `Suspense`, outside `RouteErrorBoundary` |
| `6624e8a` | This record |
| `fec41e4` | The CLS item in `NEEDED.md`, marked done |
| `a659c59` | Merge of `origin/main` at `f4e7cbb`, which changes `scripts/test-harness.ts` only; no conflict |
| this commit | The checks on `a659c59` |

Nothing hides the page or waits for the load event. The skip link, the route focus, the loader for a slow first page, reduced motion, both themes and the waterline clearance work as before, and the final layout of `/` is identical: header 57px (61px on the phone), `<main>` from there down, footer at 3,417px (5,347px). ERRBOUND's hand-off lists a failed `AuthButton` chunk as reaching the root screen; a signed-out visitor no longer requests that chunk, and a session still does.

### The regression check

`tests/browser/first-load.spec.ts` loads `/` cold at Lighthouse's desktop size and its phone size (touch, 1.75 device pixel ratio). It lets the entry script and its preloads through and holds every other chunk for 800ms, so the shell draws alone before the page, whatever the machine's speed. It records each animation frame and every `layout-shift` entry, the input-flagged ones included, and checks that the header's height and `<main>`'s top never change, that no frame shows the footer without the page, that neither `<main>`, the header nor the footer is among the moved nodes, and that the entries add up to less than 0.01. The mechanism checks are soft, so a failure names each one that came back.

| Build | Result |
| --- | --- |
| `3a8cf13`, built as CI builds it (the placeholder Supabase project) and as the owner measured | 2 failed, twice: header 73 then 57px (61px on the phone), `<main>`'s top the same, 63 to 65 frames with a footer and no page, `<main>` and the footer among the moved nodes, 0.066 and 0.166 of shift |
| `7b4bc8f` | 2 failed, the same checks |
| The header change alone (`2805907`, on `7b4bc8f`) | 2 failed, on the footer checks only: 45 and 54 frames, 0.054 and 0.152 of shift |
| `b4747a0`, both builds | 2 passed each |
| `b4747a0`, CI's build, `--repeat-each=5` | 10 passed |
| A scratch copy of the spec that adds 4x or 6x CPU throttling, `--repeat-each=2` | `3a8cf13`: 4 failed at each rate; `b4747a0`: 4 passed at each rate |

### Evidence

Lighthouse 13.4.1 against `vite preview` of builds made with `VITE_PRODUCT=devshark VITE_LOCK_SUBJECT=webdev npm run build`, `CHROME_PATH=/opt/pw-browsers/chromium`, performance category only. "Phone" is Lighthouse's default profile.

| Build | Profile | CLS, run by run |
| --- | --- | --- |
| `3a8cf13` (`origin/main`) | desktop (`--preset=desktop`) | 0.979, 0.979, 0.979, 0.979, 0.979 |
| `3a8cf13` | phone | 0, 0, 0, 0, 0. A sixth run, saved with its trace, is the one described above: the shift happened and Lighthouse dropped it |
| `3a8cf13`, again with the container quieter | desktop; phone | 0.979, 0.979, 0.979, 0.979, 0.979; 0, 0.959, 0, 0, 0.959 |
| `3a8cf13` | phone, `--throttling-method=devtools` | 0.152, 0.152, 0.166, 0.152, 0.152 |
| `b4747a0` | desktop | 0, 0, 0, 0, 0 |
| `b4747a0` | phone | 0, 0, 0, 0, 0 |
| `b4747a0` | phone, `--throttling-method=devtools` | 0, 0, 0, 0, 0 |
| `a659c59`, the final head | desktop; phone; phone with `--throttling-method=devtools` | 0, 0, 0, 0, 0; 0, 0, 0, 0, 0; 0, 0, 0, 0, 0 |
| `7b4bc8f`, before either merge | desktop; phone | 0.979, 0.979, 0.979; 0, 0, 0.959 |
| `b05c3c9`, before either merge | desktop; phone | 0, 0; 0, 0 |

No "after" run lists a node in Lighthouse's `layout-shifts` audit. `origin/main` moved to `f4e7cbb` during the step; it changes only `scripts/test-harness.ts`, and its build is byte for byte that of `3a8cf13` (`diff -rq` of the two `dist` folders), so the `3a8cf13` rows are also its numbers.

The first load of other pages, from CI's builds of both commits, every `layout-shift` entry counted (input-flagged ones too), the API answering 503, one cold load each in Playwright's Chromium 141, the desktop at full speed and the phone with 4x CPU throttling:

| Page | `3a8cf13` desktop | `3a8cf13` phone | `b4747a0` desktop | `b4747a0` phone |
| --- | --- | --- | --- | --- |
| `/` | 0.979 | 0.959 | 0 | 0 |
| `/learn` | 0.013 | 0.119 | 0.001 | 0 |
| `/quiz` | 0.057 | 0.600 | 0 | 0 |
| `/today` | 0.012 | 0.052 | 0.0004 | 0.038 |
| `/coding` | 0.979 | 0.959 | 0 | 0 |
| `/leaderboard` | 0.053 | 0.422 | 0.004 | 0.050 |
| `/premium` | 0.980 | 0.959 | 0.0004 | 0 |
| `/topics/javascript-closures` | 0.823 | 0.959 | 0 | 0 |

What remains on `/today` and `/leaderboard` is the footer moving as the page grows after its first draw; GLITCH lists both among the pages that draw in two steps.

A signed-in visitor on CI's builds, with a well-formed fake session planted and Auth answered locally, every entry counted:

| Build | Desktop | Desktop, chunks held 800ms | Phone | Phone, chunks held 800ms |
| --- | --- | --- | --- | --- |
| `3a8cf13` | 0.088 | 0.059 | 0.152 | 0.152 |
| `b4747a0` | 0.004 | 0.004 | 0 | 0 |

The header stood 73px in every frame for a session, before and after. The 0.004 left on the desktop is the nav re-centring when the account widget, wider than the 56px placeholder, replaces it.

`npm run check:bundle`: 226,027 gzip bytes on `3a8cf13` and 226,147 on `b4747a0`, 120 more, all in the entry script, which now carries `SignInButton`. Before the ERRBOUND merge the same change measured 106 bytes (224,479 on `7b4bc8f`, 224,585 on `a264cea`).

### Release contract on the final head

I ran every command below on `a659c59`, and each exit code is its own. Its two builds, the owner's and CI's, are byte for byte those of `b4747a0`, where the other measurements above ran. Browser runs used `CHROME_BIN=/opt/pw-browsers/chromium` and `vite preview` on ports 4541 to 4549.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:launch` | exit 0; the twelve-function budget holds |
| `npm run test:client` | exit 0; 27 files, 277 tests |
| `test:coding-auth`, `test:grading-integrity`, `test:coding`, `test:paths`, `test:billing`, `test:fallbacks` | exit 0 each |
| `npm run check:unused`, `npm run check:security` | exit 0 each; knip reports no new finding |
| `VITE_PRODUCT=devshark VITE_LOCK_SUBJECT=webdev npm run build` | exit 0 |
| The workflow's build step: the Supabase placeholders, then `npm run build` and `npm run check:public`; `npm run check:bundle` | exit 0 each; 13 public URLs; 226,147 of 243,000 gzip bytes |
| `npm audit --omit=dev`, root and client | exit 0 each; 0 vulnerabilities |
| Browser specs `first-load`, `navigation`, `public`, `lazy-auth`, `route-errors`, `evolving`, `segmented`, `on-accent` against CI's build | exit 0 each; 2, 2, 5, 5, 6, 2, 4 and 12 passed |
| `first-load.spec.ts` with `--repeat-each=5` against CI's build, and once against the owner's build | exit 0 each; 10 and 2 passed |
| `npm run check:responsive` on CI's routes (`/`, `/quiz`, `/topics/javascript-closures`, `/cs/topics/javascript-closures`) at 360, 390, 430, 768, 1024, 1280 and 1440, light, then with `RESPONSIVE_THEME=dark`; then CI's dark Czech sweep | exit 0 each; 28, 28 and 6 probes, 0 with issues |
| `npm run check:responsive` on `/` and twelve section routes at 360, 390, 768 and 1280, light and dark | exit 0 each; 52 probes, 0 with issues |
| `npm run test:harness`, as `f4e7cbb` changed it | exit 0; 196 assertions in Chromium |
| Each commit of this branch on its own (`2805907`, `b05c3c9`, `28b9ab7`, `d902d8c`): client `tsc -b`, the tooling typecheck, `vitest run` | exit 0 at every one; 263 tests each |
| `git diff --check`, `git diff --check origin/main...HEAD` | clean |

On `a264cea`, before the ERRBOUND merge, `evolving.spec.ts` failed once, in its dark run: the React test ran and reported 0 of 1 passing ("Unable to find a label with the text of: Email"). It passed 2 of 2 on `b4747a0`, and 8 of 8 on each of `3a8cf13` and `b4747a0` with `--repeat-each=4`, so I could not reproduce it. The spec exercises the coding workbench, which this change does not touch.

Not run: the Storybook build and its spec; no story imports a module this change touches.

Not verified: devshark.app, where this is not deployed; Firefox and Safari; physical phones; a real Supabase session (the signed-in runs planted a fake one). Lighthouse ran on a container that other sessions shared, so its timings varied; CLS does not depend on them beyond the timing windows described above.

## 2026-09-27 — the five pages GLITCH left drawing twice (HOLDS)

GLITCH ended with a list of pages that still drew in two steps after a click. The owner asked for five of them to draw once: `/premium` signed in with Premium, `/leaderboard`, `/challenge`, `/today` signed in, and `/roadmap`. Each now holds its first render with `useFirstData` for the reads that decide what it shows, at most 1.2s and not at all offline, and the sections that keep chunks of their own load inside the same hold. While a page waits, the previous page stays on screen, marked busy, as GLITCH set up.

| Commit | What |
| --- | --- |
| `b5738f7` | `lib/routeData.ts`: `lazyPart`, a section kept out of its page's chunk whose code the page's hold can load, so it draws in the same frame as the page. A part the hold did not wait for loads on mount and draws nothing until it arrives, as `Suspense fallback={null}` did. `useFirstData` also skips the wait when the query client reports no connection, because the client pauses its reads then. `client/tests/firstDraw.ts` reads the document when a page's heading first appears |
| `e689c25` | `/premium` holds for `entitlementQuery(user.id)` when signed in; a visitor waits for nothing. The signed-in Premium and voucher tests mount inside an awaited `act` |
| `6233f06` | `leaderboardQuery(request)` in `lib/queries.ts` gives the hook and the prefetch one set of options, so their keys cannot drift. `/leaderboard` holds for `{ period: '30d', category: null, viewer }` |
| `c5518f0` | `challengeLeaderboardQuery(subject)`. `/challenge` holds for its board, which is best-effort: a failed read draws the page with its own notice |
| `063d256` | Today's four signed-in sections become `lazyPart`s. Signed in, the hold loads their code with the concepts due, the open run, the coding progress, the enrollments and, for each active enrollment, its progress and the path catalogue. The sections and the hold share `conceptDueQuery` and the learning-path query options |
| `61dc75e` | `useLoc` moves from `ActivityViews` to `paths/localized.ts`. `PathDiscovery` imported it, and with it the editor and the test runner |
| `72d1385` | `/roadmap` loads `PathDiscovery` as a `lazyPart` inside its hold, with the catalogue and, signed in, the enrollments |
| `3eb32a8` | Merge of `origin/main` at `7b4bc8f` (Supabase on demand); no file changed on both sides |
| `c9c6796` | Merge of `origin/main` at `3a8cf13` (ERRBOUND); no file changed on both sides |
| `cce099b` | A part's fallback is ERRBOUND's `lazyPage` instead of `React.lazy`: when a part's chunk fails, the route boundary's Try again asks for it afresh, and a newer build on the server reloads before the error shows. This settles Today's sections and `PathDiscovery` in ERRBOUND's hand-off |
| `7f251d9` | Today imports the run's and the coding progress's query options inside the hold, signed in only, so a visitor does not download them |
| `ca7d990` | Merge of `origin/main` at `f4e7cbb` (`scripts/test-harness.ts` only); no conflict |
| `312f910` | Merge of `origin/main` at `346a824` (CLS: the signed-out sign-in button with the shell, the footer inside the route `Suspense`); no file changed on both sides |
| this commit | This record, the rule in `DESIGN_RULES.md` §8 and a line in `docs/design/product-ux-audit.md` |

### The sections stay lazy

Gzip bytes outside the initial bundle, from the measurement builds below:

| Chunks | `346a824` | `312f910` |
| --- | --- | --- |
| `/today`, what every visitor loads | 48,059 | 48,619 |
| Today's four sections on top, signed in only | 13,901 | 14,197 |
| `/roadmap` | 35,142 | 35,437 |
| `PathDiscovery` on top | 189,646 | 4,257 |
| `/profile`, whose paths card also imported `useLoc` | 238,402 | 53,465 |
| `/premium`, `/leaderboard`, `/challenge` | 26,581, 18,782, 33,922 | 27,233, 19,119, 34,273 |

A visitor to `/today` downloads 560 bytes more, the hold and `lazyPart`, and never the sections. `PathDiscovery` used to pull the task editor and its 174,283-byte test runner through `useLoc`; now it is 802 bytes and a stylesheet, so the roadmap can wait for it. `/premium`, `/leaderboard` and `/challenge` each load `lib/routeData.ts` now, 337 to 652 bytes. `npm run check:bundle`, which measures the initial requests of a production-shaped build, reads 226,188 of 243,000 gzip bytes on `312f910` and 226,147 on `346a824`. The 41 bytes are export bindings: the entry exports four more names to the lazy chunks, and the TanStack chunk exports `onlineManager`, which `useFirstData` now reads. At `b74d7ae`, the base this work started from, the check as it stood then read 221,847, as CI did.

### The offline board

`/leaderboard` keeps its offline path. The screen stores the last board it loaded in `localStorage` (`devshark:leaderboard:v1:<period>:<category>`, without the learner's own line) and shows it, marked stale, when a read fails on the network or the query client pauses it. Offline, `useFirstData` does not wait. A failed prefetch leaves the screen to its own read, which lands on the same stored board. Three tests in `leaderboard.test.tsx` cover a network failure, a paused query client and an empty store. `useFirstData` asks the query client too: `navigator.onLine` stays true while the client is paused, and the screen would otherwise have waited out the whole 1.2s.

### Measured before and after

The GLITCH harness, copied to `.holds-evidence/` and never committed, with four changes. Every public read is fetched from devshark.app once, stored and replayed. Every API answer, signed in or not, waits 250ms. The 30-day board and the Challenge board answer populated fixtures, because production's were empty. And the two builds are served side by side on two ports and measured visit by visit, the order alternating, so load from the other sessions on this machine falls on both. Two earlier runs, on a busier machine, had put about 30ms on a signed-out `/premium` visit, which waits for nothing; its visits then ranged from 102 to 345ms, against 81 to 131ms in the run below. The signed-in account holds Premium from a voucher, an open challenge run, three concepts due, an active DSA Foundations enrollment, its own line on the 30-day board and two saved cards. Both builds are `vite build` with `VITE_SUPABASE_URL` naming their own port, so supabase-js restores the fake session from storage.

Before is `origin/main` at `346a824`, after is `312f910`, the same client code as `7f251d9` with main's first-load fix merged. Each row is the first visit to the section in a fresh page load, clicked from `/` once it settled, at 1280 and 390px, in three rounds: light and dark signed out (12 visits for each build and section), light signed in (6). Times are medians; roots and content states are the most any visit showed.

Signed out, before → after:

| Section | Empty frames | Loader frames | Footer in view on an empty page | Roots drawn | Content states | New page drawn (ms) |
| --- | --- | --- | --- | --- | --- | --- |
| `/premium` | 0 → 0 | 0 → 0 | 0 → 0 | 1 → 1 | 1 → 1 | 90 → 91 |
| `/leaderboard` | 0 → 0 | 0 → 0 | 0 → 0 | 1 → 1 | 2 → 1 | 76 → 345 |
| `/challenge` | 0 → 0 | 0 → 0 | 0 → 0 | 1 → 1 | 2 → 1 | 99 → 364 |
| `/today` | 0 → 0 | 0 → 0 | 0 → 0 | 1 → 1 | 1 → 1 | 342 → 342 |
| `/roadmap` | 0 → 0 | 0 → 0 | 0 → 0 | 1 → 1 | 2 → 1 | 398 → 408 |

Signed in with Premium, before → after:

| Section | Empty frames | Loader frames | Footer in view on an empty page | Roots drawn | Content states | New page drawn (ms) |
| --- | --- | --- | --- | --- | --- | --- |
| `/premium` | 0 → 0 | 0 → 0 | 0 → 0 | 1 → 1 | 2 → 1 | 107 → 374 |
| `/leaderboard` | 0 → 0 | 0 → 0 | 0 → 0 | 1 → 1 | 2 → 1 | 78 → 354 |
| `/challenge` | 0 → 0 | 0 → 0 | 0 → 0 | 1 → 1 | 2 → 1 | 103 → 364 |
| `/today` | 0 → 0 | 0 → 0 | 0 → 0 | 1 → 1 | 4 → 1 | 376 → 655 |
| `/roadmap` | 0 → 0 | 0 → 0 | 0 → 0 | 1 → 1 | 3 → 1 | 416 → 422 |
| `/collection` | 0 → 0 | 0 → 0 | 0 → 0 | 1 → 1 | 2 → 2 | 86 → 93 |

A page that waits draws later than its first paint used to, and is complete no later. Median time from the click to the last change in the content area, and the median layout shift after the first draw:

| Section | Last change, signed out (ms) | Last change, signed in (ms) | Layout shift after the first draw, signed in |
| --- | --- | --- | --- |
| `/premium` | 90 → 91 | 373 → 374 | 0.066 → 0 |
| `/leaderboard` | 351 → 345 | 351 → 354 | 0 → 0 |
| `/challenge` | 371 → 364 | 363 → 364 | 0 → 0 |
| `/today` | 342 → 342 | 1,178 → 655 | 0.011 → 0 |
| `/roadmap` | 928 → 408 | 936 → 422 | 0 → 0 |

Signed out, neither build shifted after the first draw. What the second draws were, at 1280px: on `/premium`, "Your plan" arrived above the plans and the page grew from 2,552 to 2,690px (3,346 to 3,502 at 390px). On `/leaderboard` the six-row skeleton became the board, 717 to 1,034px signed in. On `/challenge` the "…" beside the intro became the top five, which at 390px grew the page from 727 to 891px. Signed in, `/today` drew its plan at about 380ms, the review and run sections at about 900ms and the path at about 1,180ms, because the path's next step waits for its enrollment. On `/roadmap` the optional paths arrived at 926ms and grew the page from 2,374 to 3,113px. The roadmap now finishes about half a second sooner, since `PathDiscovery` no longer waits for the test runner.

`/collection` is not one of the five. The fixtures now answer the flashcards read, so it is measured for the first time: the saved cards still arrive after the page.

### Tests

`npm run test:client`: 28 files, 292 tests, 15 of them new. Six are in `client/tests/page-holds.test.tsx`, for `/challenge`, `/today` and `/roadmap`; five in `route-loading.test.tsx`, for the paused query client, `lazyPart` and a failed part retried through the route boundary; two in `premium-page.test.tsx` and two in `leaderboard.test.tsx`. Each first-frame test reads the document when the page's heading first appears (`client/tests/firstDraw.ts`); an awaited `act` runs every commit before it returns, so without it a test cannot tell a page that draws once from one that redraws.

A test of a page that holds mounts inside an awaited `act`, and each mount gets a history entry with a key of its own. A router inside a root that suspends mints a new random key on every retry, the hold then starts a new wait each time, and React gives up after 100 attempts. A hold that also loads code can outlast the `act`, so the page tests import the sections' modules in `beforeAll` and then await the page's heading. With the five page components put back to `origin/main`'s, the seven first-frame tests fail and the other 28 tests in those files pass. With `React.lazy` in place of `lazyPage` in `lazyPart`, the retry test fails.

### Release contract on the final head

All on `312f910`, the code of this record's commit. I ran every command below, and each exit code is its own. Browser runs used `CHROME_BIN=/opt/pw-browsers/chromium`.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:launch` | exit 0; the twelve-function budget holds |
| `npm run test:client` | exit 0; 28 files, 292 tests |
| `test:coding-auth`, `test:grading-integrity`, `test:coding`, `test:paths`, `test:billing`, `test:fallbacks` | exit 0 each |
| `npm run check:unused`, `npm run check:security` | exit 0 each; knip reports no new finding |
| `VITE_PRODUCT=devshark VITE_LOCK_SUBJECT=webdev npm run build` | exit 0 |
| `npm run check:bundle` | exit 0; 226,188 of 243,000 gzip bytes (`346a824`: 226,147, exit 0) |
| The workflow's build step: the Supabase placeholders, then `npm run build` and `npm run check:public` | exit 0 each; 13 public URLs |
| `npm audit --omit=dev`, root and client | exit 0 each; 0 vulnerabilities |
| Browser specs `navigation`, `public`, `segmented`, `on-accent`, `evolving`, `lazy-auth`, `route-errors` and `first-load` against `vite preview` of that build on :4523 | exit 0 each; 2, 5, 4, 12, 2, 5, 6 and 2 passed |
| `npm run check:responsive -- --base-url http://localhost:4523 --routes /premium,/leaderboard,/challenge,/today,/roadmap --block-external`, light, then with `RESPONSIVE_THEME=dark` | exit 0 each; 35 probes, the five routes at 360, 390, 430, 768, 1024, 1280 and 1440px, 0 with issues |
| `npm run test:harness` | exit 0; 196 assertions in Chromium |
| `npm run build:storybook --prefix client`, then `tests/browser/storybook.spec.ts` against the static build on :4524 and against `storybook dev` on :4525, as CI runs it | exit 0 each; 6 passed each time |
| Each code commit on its own: client `tsc -b`, `npm run typecheck:tooling --prefix client`, `vitest run` | exit 0 at every one: `b5738f7` to `72d1385` checked out in order (242, 244, 246, 248, 250, 250 and 252 tests), `cce099b` and `7f251d9` from `git archive` (292 each) |
| `git diff --check`, `git diff --check origin/main...HEAD` | clean |

Not verified: devshark.app (not deployed), a real Supabase session (the signed-in runs used a fake session and fixtures), Firefox, Safari and physical phones.

### Hand-off

- A direct load of a signed-in page. Since `7b4bc8f` supabase-js downloads when a session is stored, and `AuthProvider` reports no user until it has restored the session. A page that mounts before then holds for a visitor's reads and draws the account's data when it arrives, as before this change. Holding for the session restore as well would close that.
- `/collection`, signed in: the saved cards arrive after the page.
- The other lazy parts inside pages that ERRBOUND listed (`FriendsPanel`, the code highlighter, `PathRewardClaim`, the Learn workbench) still use `React.lazy`.

## 2026-09-27 — the four gaps ERRBOUND left open (HARDEN)

The owner asked me to close four gaps from ERRBOUND's hand-off, each with a test that fails on the old behaviour: devshark.app answered a missing chunk with `index.html` under a year-long cache; after one failed supabase-js download no sign-in press could work without a reload; the Coding workbench's own Try again hit the same wall; and the lazy parts of the shell took a failure to the root error screen.

| Gap | The change | The test |
| --- | --- | --- |
| The SPA rewrite caught `/assets/`, and the assets header rule marked the `index.html` it served `public, max-age=31536000, immutable` | A path under `/assets/` or `/sandbox/assets/` with no file behind it answers 404 with `Cache-Control: no-store`. Only a file that exists gets the year-long cache | `vercelRoutingContracts()` in `scripts/vercel-routing-contract.ts`, which `npm run test:launch` runs |
| Chromium up to 155 and Safari answer a second import of a failed module from memory | A second press that meets the same chunk failure reloads the page; the next document finishes that sign-in and returns to the page that asked | 7 tests in `client/tests/supabase-lazy.test.tsx` and 1 in `route-errors.test.tsx`; in `lazy-auth.spec.ts`, "a second sign-in press after a failed download reloads…" |
| The workbench's Try again imported the failed chunk again | The press reloads when the same chunk failure comes straight back | 3 tests in `client/tests/coding-workbench-retry.test.tsx`; in `route-errors.spec.ts`, "the Coding workbench that fails to load…" |
| `AuthButton` and `UpgradeSheet` were `React.lazy` chunks outside the route boundary | Each is a `lazyShellPart` inside a `ShellPartBoundary`. The header keeps a retry in the account widget's 56px row; a sheet that fails closes with a toast | 6 tests in `client/tests/shell-parts.test.tsx`; two tests in `route-errors.spec.ts` |

### A missing file under `/assets/`

I probed devshark.app with `curl` on 2026-09-26 at 22:57 UTC and on 2026-09-27 at 08:31 UTC and got the same answers both times:

| Path | Status | Type | `cache-control` |
| --- | --- | --- | --- |
| `/assets/does-not-exist-0000.js` | 200 | `text/html` | `public, max-age=31536000, immutable`; the first probe also got `x-vercel-cache: HIT` and `age: 4798` |
| `/assets/coding-worker/does-not-exist-0000.js` | 200 | `text/html` | the same, with the worker's CSP |
| `/sandbox/assets/does-not-exist-0000.js` | 404 | `text/plain` | `public, max-age=31536000, immutable` |
| `/sandbox/does-not-exist.html`, `/topics/does-not-exist-zz` | 404 | `text/plain` | `public, max-age=0, must-revalidate` |

The third row settles whether Vercel's header rules reach a 404. `/sandbox/` sits outside the SPA rewrite, so that path gets Vercel's own 404, and the `/sandbox/assets/(.*)` rule still marks it immutable for a year. Vercel's CDN caches a 404 as it caches a 200, unless `Cache-Control` carries `private`, `no-cache` or `no-store` ([CDN cache, cacheable response criteria](https://vercel.com/docs/caching/cdn-cache#cacheable-response-criteria)).

What Chromium 141 keeps, measured with a local server that counts requests, one fresh browser context per answer, twice with the same numbers (a scratch harness, not committed):

| Answer for a chunk that is gone | Requests: first visit, after a navigation, after a reload | The file comes back, the page reloads |
| --- | --- | --- |
| 200 `text/html`, `nosniff`, `immutable`, as devshark.app answers today | 1, 1, 1: the browser reuses the stored HTML | fails, with no request |
| 404, `nosniff`, `immutable`: dropping `assets/` from the rewrite alone | 1, 2, 3 | loads |
| 404, `immutable`, no `nosniff` | 1, 1, 1 | fails, with no request |
| 404, `nosniff`, `public, max-age=0, must-revalidate` | 1, 2, 3 | loads |
| 404, `nosniff`, `no-store`: this change | 1, 2, 3 | loads |

So a browser that met today's answer once keeps the chunk broken after a rollback brings the file back. Whether Chromium reuses a stored 404 depends on the other headers; `no-store` keeps it out of the browser and out of Vercel's CDN whatever they are.

`vercel.json`'s `headers` cannot tell a missing file from one that exists. `@vercel/routing-utils` 6.6.0, the version Vercel CLI 60.1.3 bundles for `vercel build`, compiles each `headers` rule into a `continue` route ahead of `{ "handle": "filesystem" }` (`getTransformedRoutes`), which is how a rule reaches the 404. `has` and `missing` match the request only ([vercel.json, `has` and `missing`](https://vercel.com/docs/project-configuration/vercel-json#conditional-matching-with-has-and-missing)). The Build Output API splits routing into phases: routes after `{ "handle": "filesystem" }` run when the filesystem misses, and routes after `{ "handle": "hit" }` when it hits ([Build Output configuration, handler route](https://vercel.com/docs/build-output-api/configuration#handler-route)). `@vercel/next` 15.0.1 sets `/_next/static`'s immutable `cache-control` in the `hit` phase and answers a missing `/_next/static` file with 404 after a miss, and Nitro gives a missing asset a 404 with `no-store` after the filesystem check ([nitrojs/nitro#4474](https://github.com/nitrojs/nitro/pull/4474), merged 2026-09-03). `vercel.json` keeps its header rules in `routes` now:

| Phase | Routes |
| --- | --- |
| Before the filesystem check | The app's security headers on every path but the worker and the sandbox; `triage-verdicts.json`'s day-long cache; the worker's CSP, `nosniff` and CORP; the sandbox's CSP, `nosniff`, referrer policy and CORS; CORS on `/assets/`. No year-long cache |
| The filesystem missed | `^/(?:sandbox/)?assets/.*$` answers 404 with `Cache-Control: no-store` before any rewrite; then the ten rewrites, whose SPA fallback now leaves `assets/` alone |
| The filesystem hit | `^/(?:sandbox/)?assets/.*$` gets `public, max-age=31536000, immutable` |

A `headers` property would land after these routes, in the `hit` phase (`mergeRoutes` files each user route under the last `handle` above it), and reach existing files only. `handle` is a deprecated route property that the schema still accepts ([vercel.json, deprecated route properties](https://vercel.com/docs/project-configuration/vercel-json#deprecated-route-properties)).

`routes` next to `rewrites`: `@vercel/routing-utils` up to 5.3.3 (2026-02-13) refused the pair with "If `rewrites`, `redirects`, `headers`, `cleanUrls` or `trailingSlash` are used, then `routes` cannot be present." 6.0.0 (2026-02-26) and every later release accept it, CLI 60.1.3 declares 6.6.0, and the documentation says "You can use `routes` alongside `rewrites`, `redirects`, `headers`, `cleanUrls`, and `trailingSlash`" ([vercel.json, routes](https://vercel.com/docs/project-configuration/vercel-json#routes)). The preview build of `820fb64` accepted it (below). Should an older builder ever refuse it, a routes-only variant, with the rewrites compiled into the filesystem phase after the 404 rule, passes 5.3.3 and 6.6.0 alike and merges into the same routes.

`scripts/vercel-routing-contract.ts` checks: no `headers` property; the phases, in order; header-only `continue` routes before the filesystem check and after a hit; no `Cache-Control` before the filesystem check on an asset path; the 404 rule first after a miss, with `no-store` and no destination; no rewrite that catches `/assets/`, `/assets/coding-worker/` or `/sandbox/assets/`; the SPA fallback still serving `/`, `/coding`, a task, `/assets` and `/profile`; the year-long cache for hashed files only; the worker's and the sandbox's own headers. It turns each rewrite source into a pattern as routing-utils does (path-to-regexp 6), and the two agree on 11 sources and 27 paths.

### Sign-in after a failed download

`loadSupabase()` now remembers a failed download (`supabaseLoadFailed()`). When a press fails with a chunk error after an earlier failure in the same document, `auth.tsx` writes a mark to `sessionStorage` (`devshark:auth-resume`, valid for 60 seconds) beside the return path and reloads through `reloadOnPress`, which reloads only while the browser is online and `/` answers. The next document reads the mark once, as its modules load; with no session stored, it starts the sign-in without a press, and Google returns the learner to the page that asked.

| Situation | What happens |
| --- | --- |
| First press, the download fails | "Sign-in failed. Please try again.", as before; nothing reloads |
| Second press, the same failure | the page reloads, leaves for Google, and comes back to the page that asked |
| Offline, or `/` does not answer | no reload; the press fails and forgets the return path |
| The reload is refused (a leave-page prompt) | the press fails after 4 seconds and forgets the return path |
| The download failed in the background (a stored session's restore) | no reload; the first press after it reloads |
| A mark older than 60 seconds, or dated in the future | dropped with the return path; nothing downloads |
| The carried-over sign-in fails again | the shell says "Sign-in failed. Please try again." and reloads nothing |

Since `346a824` the header's "Log in" is `SignInButton`, which calls the same `signInWithGoogle`.

### The workbench's Try again

`useWorkbench` in `CodingSection.tsx` reloads through `reloadOnPress` when a retry fails with a chunk error. The button stays busy (`aria-busy`, `aria-disabled`) until the new document arrives, or for 4 seconds when the reload is refused, and ignores presses meanwhile. A task's first load, which nobody pressed for, never reloads. The change sits in the lazy `CodingSection` chunk.

### Shell parts

`lazyShellPart` in `lib/routeRecovery.ts` renews a failed part as `lazyPage` does, but never checks the build or reloads on its own: the shell loads these parts without a press. `ShellPartBoundary` sits inside the part's `Suspense`, reports a failed chunk once through `reportBoundaryError`, and draws the part's fallback. Its retry renders the part again in a transition, moves focus into the part when it draws if the retry had focus, and reloads through `reloadOnPress` when the same chunk failure comes straight back. A part that throws is rendered again and nothing more. HOLDS added a `lazyPart` to `lib/routeData.ts` for sections inside a page, which fail with their page; the shell's helper became `lazyShellPart` in the merge that followed.

- The account widget. Since `346a824` the header loads it for a session only. Its retry reads "Try again", with the accessible name "Account did not load. Try again", and stands centred in the widget's 56px row. Measured with a stored session at 360, 390, 768 and 1280px, light and dark, mouse and touch: 86×32 with a mouse, 86×44 with a touch pointer; the header stays 73px with the retry and with the widget; no horizontal overflow; Shift+Tab from `<main>` reaches it, and it shows a 2px solid accent ring (rgb(45, 122, 45) light, rgb(76, 175, 80) dark).
- The upgrade sheet. A sheet whose code fails closes, and the host says "Network error. Check your connection and try again." in a toast, or "Something went wrong. Please try again." when the sheet throws. The next request asks for the sheet again.

React Query's devtools, the one other lazy component outside the route boundary, load in development only. Motion's features chunk is no component; see the hand-off.

### Evidence

"Old code" means builds of `3a8cf13` (ERRBOUND, this branch's base) made as CI makes them, or the unit tests with the change reverted in a copy of the branch. Chromium 141.

| Check | Old code | This branch |
| --- | --- | --- |
| `npm run test:launch` with `3a8cf13`'s `vercel.json` | exit 1: "vercel.json keeps its header rules in `routes`…" | exit 0 |
| `supabase-lazy.test.tsx` with `auth.tsx`, `authReturn.ts` and `supabaseClient.ts` reverted | 6 of the 7 new tests fail; the seventh guards a case the old code handled too | 26 pass |
| `lazy-auth.spec.ts`, the second press | times out: the press sends no request and fails again | passes; annotation "reloaded, and the next document signed in" |
| `coding-workbench-retry.test.tsx` with `CodingSection.tsx` reverted | 2 of 3 fail; the in-place retry passes on both | 3 pass |
| `route-errors.spec.ts`, the workbench | fails: "Could not load this task." and its Try again stay | passes; reloaded the address |
| `shell-parts.test.tsx` with `UpgradeSheetHost.tsx` reverted | the sheet's test fails; the five boundary tests cover a new component | 6 pass |
| `route-errors.spec.ts`, the account test: signed out on `3a8cf13`, with a session on `346a824` | fails: the root screen ("Something went wrong", "The page hit an unexpected error. Reloading usually fixes it.") replaces the app | passes; reloaded the address |
| The same test on `a13a6e1`, the merge of `346a824` before the retry got its row | fails: the header measures 57px with the retry and 73px with the widget | passes |
| `route-errors.spec.ts`, the upgrade sheet, on `3a8cf13` | fails: the root screen replaces the app | passes |
| The other 12 tests of `route-errors.spec.ts` and `lazy-auth.spec.ts` on `3a8cf13` | pass | pass |

Eleven mutations of `vercel.json`, one at a time, each fail the contract: the old rewrite, the immutable cache before the filesystem check, no 404 rule, a 404 without `no-store`, a 404 rewritten to `index.html`, the header rules back in `headers`, the worker's CSP gone, the sandbox's CORS gone, the hashed files' cache gone, a header rule that ends routing, and `3a8cf13`'s file.

`npm run check:bundle`: 226,984 of 243,000 gzip bytes on this branch, 226,188 on `origin/main` at `3e670be` and 226,027 on `3a8cf13`. The 796 bytes over `3e670be` all sit in the entry script: `reloadOnPress`, `lazyShellPart`, `ShellPartBoundary`, the account retry, the sign-in resume and the sheet's toast load with the shell they guard.

### Release contract on the final head

All on `820fb64`, the code of this record's commit, after merging `origin/main` at `3e670be`. I ran every command below, and each exit code is its own. Browser runs used `CHROME_BIN=/opt/pw-browsers/chromium` and `vite preview` on port 4581.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:launch` | exit 0; the twelve-function budget holds, and `api/` is unchanged since `3a8cf13` |
| `npm run test:client` | exit 0; 30 files, 309 tests |
| `test:coding-auth`, `test:grading-integrity`, `test:coding`, `test:paths`, `test:billing`, `test:fallbacks` | exit 0 each |
| `npm run check:unused`, `npm run check:security` | exit 0 each; knip reports no new finding |
| `VITE_PRODUCT=devshark VITE_LOCK_SUBJECT=webdev npm run build` | exit 0 |
| The workflow's build step: the Supabase placeholders, then `npm run build`, `npm run check:public` and `npm run check:bundle` | exit 0 each; 13 public URLs; 226,984 of 243,000 gzip bytes |
| `npm audit --omit=dev`, root and client | exit 0 each; 0 vulnerabilities |
| Browser specs `public`, `evolving`, `segmented`, `on-accent`, `navigation`, `lazy-auth`, `route-errors` and `first-load` against that build | exit 0 each; 5, 2, 4, 12, 2, 6, 10 and 2 passed |
| `npm run check:responsive` on CI's routes at 360, 390, 430, 768, 1024, 1280 and 1440, then CI's dark Czech sweep | exit 0 each; 28 and 6 probes, 0 with issues |
| `npm run check:responsive` on `/coding`, `/premium`, `/coding/javascript/js-double-numbers`, `/today` and `/roadmap` at 360, 390, 768 and 1280, light, then with `RESPONSIVE_THEME=dark` | exit 0 each; 20 probes, 0 with issues |
| `npm run test:harness`, from a copy that binds ports 4583 and 4584 in place of a random one | exit 0; 196 assertions in Chromium |
| Browser specs typechecked with a scratch `tsconfig` over `tests/browser/*.ts`; the tooling typecheck does not cover them | exit 0 |
| Each code commit on its own (`6451c61`, `1df08ee`, `0864dc5`, `10d46eb`, `1da47bd`, from `git archive`): client `tsc -b`, the tooling typecheck, `vitest run`, `test:launch` | exit 0 at every one; 277, 285, 288, 294 and 294 tests |
| `git diff --check`, `git diff --check origin/main...HEAD` | clean |

Not run: the Storybook build and its spec, since no story imports a module this change touches, and Lighthouse.

### The Vercel preview

`vite preview` answers a missing asset with `200 text/html`, so only a deployment shows what `vercel.json` does. The lead deployed `820fb64` as a preview on 2026-09-27 (`dpl_j3qvQV8zsLhVcYvkfAYLxSk7uzHp`, READY): Vercel built it with `routes` beside `rewrites`. Measured by the lead through a share link:

| Request | Answer |
| --- | --- |
| An existing `/assets/main-*.js` | 200, `public, max-age=31536000, immutable` |
| A missing `/assets/*.js`, and a missing `/assets/*.css` | 404, `no-store` |
| `/sandbox/index.html` | 200, the sandbox's CSP, no `X-Frame-Options: DENY` |
| A missing `/sandbox/assets/*.js` | 404, `no-store`; devshark.app sends the year-long `immutable` today |
| An existing `/sandbox/assets/index-*.js` | 200, `immutable` |
| `/assets/coding-worker/ts-compiler-*.js` | 200, `immutable`, the worker's CSP, `Cross-Origin-Resource-Policy: same-origin` |
| `/` | the app's CSP and `X-Frame-Options: DENY` |
| `/learn`, `/coding`, `/topics/javascript-closures`, `/robots.txt` | 200 |
| `/api/health` | 200, JSON |
| `/ingest/static/array.js` (the PostHog proxy) | 200, JavaScript |

That report does not cover a missing file under `/assets/coding-worker/` (404 with `no-store` and the worker's headers, by the same rule), `/assets/` (404) and `/assets` (the SPA's `index.html`), a repeated 404 staying out of the CDN cache, `/triage-verdicts.json`'s day-long cache, or `node scripts/check-security.mjs --url=<preview URL>`.

### Commits

| Commit | What |
| --- | --- |
| `6451c61` | `vercel.json` in routing phases; `scripts/vercel-routing-contract.ts`; `check-security.mjs` and the launch contracts read the header rules from `routes`; the newer-build spec answers a removed chunk with that 404 too |
| `1df08ee` | The second sign-in press reloads, and the next document finishes the sign-in (`auth.tsx`, `authReturn.ts`, `supabaseClient.ts`, `reloadOnPress` in `routeRecovery.ts`) |
| `0864dc5` | The workbench's Try again reloads when the failure comes back |
| `10d46eb` | `lazyShellPart` (then `lazyPart`), `ShellPartBoundary`, the account retry and the sheet's toast |
| `c1008c0` | Merge of `origin/main` at `f4e7cbb`, which changes `scripts/test-harness.ts` only; no conflict |
| `a13a6e1` | Merge of `origin/main` at `346a824` (CLS). One conflict, in `App.tsx`: main's `user \|\| authLoading` branch kept, the boundary inside its `Suspense` around `AuthButton` |
| `1da47bd` | The account retry keeps the widget's 56px row; the account test signs in; `tests/browser/fake-session.ts` holds the session helpers both specs use |
| `d7ad848` | The rule in `DESIGN_RULES.md` §8 |
| `6584f1c` | Merge of `origin/main` at `3e670be` (HOLDS); no conflict |
| `820fb64` | The shell's helper renamed `lazyShellPart`, apart from `routeData`'s `lazyPart` |
| this commit | This record |

### Hand-off

- The preview rows the lead's report does not cover (see above), and devshark.app once this is deployed.
- The upgrade sheet in a browser that remembers failed module fetches. Measured in Chromium 141: after one failed download, a second 402 in the same document asks for the sheet again, the browser answers from memory without a request, and the toast shows again; a reload opens the sheet. A 402 from a page's own read opens the sheet as often as a press does, so the host never reloads for it.
- Motion's features chunk (`lib/motion.tsx`, `LazyMotion` in strict mode). Measured on this branch's build: with that chunk dropped, the route box stays at opacity 0 on `/` and after a navigation to `/quiz`, the header shows, and the page reports `TypeError: Failed to fetch dynamically imported module`. No boundary sees it, since nothing throws during render.
- The lazy parts inside pages that still use `React.lazy` (HOLDS lists them).
- Vercel's Skew Protection ([docs](https://vercel.com/docs/skew-protection)) keeps an old deployment's files reachable for a tab still running it, through a `__vdpl` cookie, an `x-deployment-id` header or a `dpl` query; a static Vite build would need one of those wired in, and it is a project setting, so I left it alone.

Not verified by me: `vercel.json` on Vercel, which the lead checked on the preview; devshark.app, where this is not deployed; Firefox and Safari; a real Google sign-in (the specs answer Supabase locally, with a fake session where one is needed); Sentry, which has no DSN here; physical phones and screen readers.

## Instagram profile and MarketingShark source bridge — 2026-09-27

The canonical Instagram URL now points to `@devshark.app`, shared by Profile and Rewards.
BoardlessAI owns source imports, generation, approval and credentials; this app adds no API
handler or AI feature. See `docs/marketing-social-bridge.md` and issue #237.

Node 22 validation: API type checking, launch contracts, production build and responsive
checking passed (238 probes, zero issues or unprobed routes). Both production dependency
audits reported zero vulnerabilities. `git diff --check` passed. Meta OAuth and professional
account conversion remain pending; these checks do not establish a live publishing connection.

*22 October 2026:* the owner closed the October marketing plan (#239) as not planned, so Meta OAuth and the account conversion are no longer planned. This repository posts nothing to social networks.

## 2026-09-27 — one state read in flight per match client (COALESCE)

A Classroom answer broadcasts `match_updated` on a channel with `broadcast.self = true`, and each client read `/api/play/state` once per broadcast. With 30 learners on one address that came to about 930 reads per question against a bucket of 600 a minute (NEEDED.md). The server bucket stays as it is. Each client now keeps at most one read in flight and follows a burst with one trailing read.

`coalesceReads` in `client/src/lib/realtime.ts` wraps a read. A request with nothing in flight starts a read. A request during a read queues the trailing read, or joins it when one is already queued, and that read starts once the current one settles, so it always fetches the state after the last broadcast. A failed read still lets the trailing read start; `PlayMatch` counts the failure as before. `PlayMatch` makes one reader per match inside the Realtime effect, and every refresh goes through it: the two broadcasts, the healing and fallback polls, the submit resync and Try again. The effect's cleanup cancels the reader, so a queued trailing read never starts, and a flag stops a read still in flight for the old match from setting state after unmount or a change of match.

| Commit | What |
| --- | --- |
| `8573b0b` | `coalesceReads` and the `PlayMatch` wiring |
| `93d7490` | `client/tests/play-coalesce.test.tsx` |
| this commit | This record and the NEEDED.md item |

### Evidence

| Check | Old `Play.tsx` | This branch |
| --- | --- | --- |
| `play-coalesce.test.tsx`, four `coalesceReads` tests: one request reads once, 30 requests during a read add one trailing read, a failed read keeps the trailing read, cancel stops it | pass (the helper is new) | pass |
| The same file, `PlayMatch` with a stub channel: one broadcast reads once | pass | pass |
| 30 broadcasts during a read: one read in flight, then one trailing read | fails: 30 reads | pass |
| Three broadcasts, then unmount before the read settles: no trailing read | fails: 3 reads | pass |

### Checks on the final head

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:client` | exit 1 three times on a machine with a load average near 30: every failure was a 5 s test timeout in files this change does not touch (1, then 17, then 31 of 316). `npm run test:client -- --maxWorkers=2`: exit 0; 31 files, 316 tests |
| `npm run test:launch`, `npm run check:unused` | exit 0 each; knip reports no new finding |
| `VITE_PRODUCT=devshark VITE_LOCK_SUBJECT=webdev npm run build` | exit 0 |
| `git diff --check` | clean |

Not verified: a real Supabase Realtime channel and a class-sized burst against the server bucket; the tests stub the channel and the API. No test observes a stale write after unmount directly, since React 19 does not warn about one; the guard is read from the code.

## 2026-09-27 — `evolving.spec.ts` waits for the editor and the focus (SETTLE)

NEEDED.md asked why `tests/browser/evolving.spec.ts` failed about one run in five on `main`, and whether a learner who types right after the editor appears can lose that text. A learner cannot. The spec raced two things a person never races: CodeMirror's own focus handling, and the route focus that `App.tsx` moves to `<main>` 230 ms after every change of path. The fix sits in the spec; the product code is unchanged.

### What I measured

I copied the spec into a scratch file that logged, from the page and from the sandbox frame: every `.cm-editor` added or removed (a `MutationObserver`), the editor's text every 5 ms, `selectionchange`, `beforeinput` with the selection it met, `focusin` and `focusout` in both documents, and the `/App.js` each Run posted to the harness. About 280 runs against a `vite preview` of this branch's build, Chromium 141, with other sessions holding the machine's load average between 10 and 27 on 8 CPUs.

- **The editor never remounts.** Each run added `.cm-editor` once, at load, and removed nothing when the viewport went from 360 to 1440 px. `CodingWorkbench` keeps the editor pane mounted under `hidden` on a narrow screen, as its comment says.
- **Late data resets nothing.** In the four failing runs of this kind, the harness received 896 characters: the 773-character solution, then the 90-character starter untouched after it. A reset would have left the starter alone.
- **The typing went in at the caret.** In a passing run, `beforeinput` met a selection of 94 characters, the whole starter. In the failing runs it met a collapsed one; in the one failing run that also logged focus events, 11 ms after `.cm-content` took the focus. Playwright's `fill` focuses the element and then selects its contents with a DOM range. CodeMirror answers a focus with an update 10 ms later (`updateForFocusChange` in `@codemirror/view`) that forces its own selection, the caret at 0, into the page. On a busy main thread right after the resize, that update ran before CodeMirror read the `selectionchange`, so the solution landed in front of the starter. The harness got both `App` components, and the suite failed with "Unable to find a label with the text of: Email", which is what the starter's empty `<main />` gives.
- **A second failure hid behind the first.** Three runs failed later, on "Email accepted" in the stage-2 preview, with the preview showing "Invalid email" over an empty field. The logs show the frame's input taking the focus, then `<main>` in the parent taking it 7 ms later, 237 ms after Next. The typed address went to the parent page and Enter submitted an empty field. That is the 230 ms route focus in `App.tsx`; the spec clicks Run, Preview and fills within it.

A person does neither. A click or a key in the editor goes through CodeMirror's own handlers, which set its selection before any text arrives, and nobody types into a preview within 230 ms of pressing Next.

### The spec

| Commit | What |
| --- | --- |
| `9da8cee` | Focus `.cm-content`, wait for CodeMirror's `cm-focused` class, fill, and check that the starter's `return <main />` is gone before Run |
| `a69d340` | Wait for `#main-content` to hold the focus after the first load and after Next |
| `8631bc8` | Wait for the editor to be visible before `focus()`, which does not wait for the resize to unhide the pane. The first 20-repeat run of the two commits above failed once there |
| this commit | This record and the NEEDED.md tick |

### Repeat counts

Each run covers the light and the dark test, so `--repeat-each=20` is 40 runs.

| Spec | `--repeat-each` | Result |
| --- | --- | --- |
| `origin/main` (`391ca34`), the first run of the session | 20 | exit 0; 40 passed |
| `origin/main` (`391ca34`), load average near 20 | 40 | exit 1; 3 failed, 77 passed, all three on "Email accepted" |
| The instrumented copy, before any fix | about 200 runs over six batches | 4 failed on the editor, 2 on the preview |
| The instrumented copy with `9da8cee` only | 73 runs | 1 failed, on the preview |
| `9da8cee` and `a69d340` | 20 | 1 failed, 39 passed; `cm-focused` never came, fixed in `8631bc8` |
| `8631bc8` | 20 | exit 0; 40 passed |
| `8631bc8` | 40 | exit 0; 80 passed |
| `8631bc8`, a second time | 40 | exit 0; 80 passed |

### Checks

| Check | Result |
| --- | --- |
| `VITE_PRODUCT=devshark VITE_LOCK_SUBJECT=webdev npm run build` with the Supabase values from `docs/quality/bundle-budget.json` | exit 0; the client code did not change after it |
| `npm run typecheck:tooling --prefix client` | exit 0 |
| `npm run test:client` | exit 0; 30 files, 309 tests. A first run at a load average near 20, with a browser batch beside it, hit eight 5-second timeouts; the second run, alone, passed |
| `npm run check:unused` | exit 0; no new finding |
| `git diff --check` | clean |

Not verified by me: Firefox and Safari, CI's runner, and the route focus's 230 ms window for a keyboard user on a slow phone.

## 2026-09-27 — a part that fails to load keeps its page (CHUNKS)

HARDEN's hand-off left three gaps, and NEEDED.md carried them as one `[owner:ai]` item:

1. `PathRewardClaim`, the Learn workbench, `FriendsPanel` and the code highlighter used `React.lazy` with no boundary of their own. A failed chunk sent the whole page to the route error panel, and React.lazy kept the failure.
2. In Chromium up to 155 and in Safari, a second failure of the upgrade sheet repeated the toast without a request.
3. When Motion's features chunk failed, the route box stayed at opacity 0 under a working header.

| Gap | The change | The test |
| --- | --- | --- |
| The four parts | Each is a `lazyShellPart` inside a `ShellPartBoundary`, the pair HARDEN built for the account widget and the sheet. The workbench, the friends tab and the reward draw `ErrorRetry` in their place: "Could not load this task.", "Your friends did not load." or "Could not check this path's reward.", with Retry. A code block falls back to the plain `<pre>` it already drew while loading, and the next block asks again | 2 tests in `client/tests/in-page-parts.test.tsx`; in `route-errors.spec.ts`, "the friends tab's code fails to load…" |
| The sheet's second failure | When the sheet's code fails a second time in one document on a press, the host marks `devshark:upgrade-resume` in `sessionStorage` (kind and ref, valid for 60 seconds) and reloads through `reloadOnPress`. The next document opens the sheet from the mark. A 402 from the API client carries `fromResponse` and never reloads. Offline, with `/` unanswered, or with the reload refused, the toast shows as before | 4 new tests in `client/tests/shell-parts.test.tsx`; in `route-errors.spec.ts`, "a second press for the upgrade sheet…" |
| Motion | `loadMotionFeatures` catches the failure, sets `<html data-motion="off">`, reports it once with `chunkLoad: true`, and leaves LazyMotion's load pending. `lib/motion.tsx` gives every `m` element `data-m`, and one rule in `app-shell.css` shows those elements at opacity 1 with no transform. `:where()` keeps the rule at one attribute's weight, so the route box's busy fade still wins | 3 tests in `client/tests/motion-fallback.test.tsx`; in `route-errors.spec.ts`, two Motion cases, reduced and full motion |

### Choices

- I reused `lazyShellPart` and `ShellPartBoundary` rather than `lazyPart`. `lazyPart` fails with its page by design: the page's hold loads its code. These four parts load after the page draws, so they should fail alone. `ShellPartBoundary` also brings the reload on a repeated press, so the retry works in Chromium 153 too.
- The fallbacks reuse `ErrorRetry`, which now takes `busy` so its button keeps focus while a press reloads.
- A code block gets no Retry. The plain text shows the whole snippet, and a Retry beside every snippet on a page would be noise.
- The reward's fallback shows on every enrolled path, finished or not, because the page cannot know which paths have a reward until the chunk loads. Its copy says the check failed and promises no reward.
- The Motion rule depends on one fact: every `m` element in the app (the route box, three toasts, `MotionItem`, `MotionPop`) enters to full opacity and no transform. DESIGN_RULES §8 says so now.
- The Vite build's PurgeCSS pass dropped the rule the first time, because `dataset.motion` never spells `data-motion` in the bundle. `data-motion` joins the safelist, and the build now fails if the rule goes missing.

### Evidence

"Old code" means a build of `origin/main` at `391ca34`, this branch's base, made as CI makes it, or the new unit tests copied onto that tree. Chromium 153.0.8010.12 (Playwright 1.63.0), which still remembers failed module fetches.

| Check | Old code | This branch |
| --- | --- | --- |
| `route-errors.spec.ts`, the friends tab | fails: the route panel ("Something went wrong") replaces the profile | passes; annotation "reloaded the address" |
| `route-errors.spec.ts`, the sheet's second press | fails: no dialog after the press | passes; annotation "reloaded the address, and the next document opened the sheet" |
| `route-errors.spec.ts`, Motion, reduced and full motion | both fail: the route box's opacity stays "0" | both pass: opacity "1" on `/` and after a navigation to `/quiz`, transform `none`, no reload |
| `in-page-parts.test.tsx` | the code-block test fails; the generic part test passes, since it builds the boundary itself | 2 pass |
| `motion-fallback.test.tsx` | 3 fail | 3 pass |
| `shell-parts.test.tsx`, the 4 new sheet tests | 3 fail; "never reloads for a 402 nobody pressed for" passes, since the old code never reloaded | 10 pass |

In the sheet's browser case, the reloaded task page answers 402 again, so the API client opens the sheet in the next document as well as the mark. The mark's part alone is proven by the unit test, where nothing answers 402.

`npm run check:bundle`: 227,116 of 243,000 gzip bytes on this branch, 226,554 on `391ca34`. The 562 extra bytes sit in the entry script and its stylesheet: the `m` wrapper, `loadMotionFeatures`, the CSS rule, and the sheet's mark and reload.

### Checks on the final head

All on `59ce547`, the code of this record's commit, in the worktree `ds-wt-chunks`. I ran every command below, and each exit code is its own.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:client` | exit 0; 32 files, 318 tests |
| `npm run test:launch` | exit 0; the twelve-function budget holds |
| `npm run check:unused` | exit 0; knip reports no new finding |
| The workflow's build step: the Supabase placeholders, then `npm run build`, `npm run check:public` and `npm run check:bundle` | exit 0 each; 13 public URLs; 227,116 of 243,000 gzip bytes |
| Browser specs `route-errors`, `navigation`, `lazy-auth` and `first-load` against `vite preview` of that build on :4721 | exit 0 each; 14, 2, 6 and 2 passed |
| `git diff --check origin/main...HEAD` | clean |

Not run: the other browser specs, `check:responsive`, the audits and Storybook. The branch changes nothing under `api/`, `lib/` or `shared/`, and leaves `vercel.json` alone.

### Commits

| Commit | What |
| --- | --- |
| `3f2f6f1` | The four parts become `lazyShellPart`s inside `ShellPartBoundary`; `ErrorRetry` takes `busy`; two English keys |
| `f025478` | The sheet's second failure on a press reloads, and the next document opens the sheet |
| `7dad4b7` | `loadMotionFeatures`, `data-m`, and the `app-shell.css` rule |
| `fdc6f7c` | The rule survives PurgeCSS, and the build checks for it |
| `93d89f1` | Four browser cases in `route-errors.spec.ts` |
| `59ce547` | The Motion cases check opacity before the marker, so the old code fails on what a learner sees |
| this commit | DESIGN_RULES §8, this record, NEEDED.md |

### Hand-off

- Safari and Firefox. Only Chromium 153 ran here. The sheet's reload rests on the same `reloadOnPress` the sign-in uses, and Safari's module-map behaviour comes from HARDEN's sources, not from a Safari run.
- The Learn workbench and a path's reward in a browser. Their unit coverage is the shared boundary; reaching either on a page needs roadmap or enrollment data that the specs do not fake yet.
- Motion stays off for the rest of a document after its chunk fails. Nothing retries it; the next page load does.

## 2026-09-27 — the rest draws in one step (DRAW)

NEEDED.md's `[owner:ai]` item "Draw the rest in one step" named three things that still moved after the first draw: `/today` and `/leaderboard` growing (0.05 or less), a signed-in desktop header re-centring its nav (0.004), and a signed-in `/collection` drawing its saved cards after the page.

| What moved | Why | The change |
| --- | --- | --- |
| `/today`, `/leaderboard` | When a held read failed, the page's own query asked again on mount (TanStack's `retryOnMount`). The page drew its skeleton, and the same error replaced it about a second later, after the retry. The footer moved each time | `HELD_READ` in `lib/routeData.ts` (`retryOnMount: false`), spread into the page's own copy of a held read: the roadmap structure and, through `useLocks(…, { held: true })`, the plan on Today; the board on the leaderboard. The hold's attempt stands for the mount's, so the error draws with the page. Retry buttons, a changed key and the next visit's hold still ask again |
| The signed-in desktop header | The toolbar's grid centres the nav between its side columns. The widget replaced a 56px placeholder at 224px ("Test Learner"), so every nav link moved 84px at 1350px | The widget sits in `.ss-account-slot`: at least 60px wide from 1024px (the avatar, with a ring) and 240px from 1280px (the button's `max-width`). A signed-out header has no slot |
| `/collection`, signed in | Nothing held the page, so it drew `LoadingScreen` in its body and the cards replaced it | `useFirstData` holds the page for the open tab's read (`flashcardsQuery(subject)`, new in `lib/queries.ts`, or `bookmarksQuery`), with `HELD_READ` on both hooks. On a direct load the session is still being restored when the page mounts, so the hold waits for `getSupabaseSession()` too and reads only if a session comes back. A visitor waits for nothing |

### Measured before and after

A scratch Playwright script, never committed, loads each page cold in Chromium 153.0.8010.12 and adds up every `layout-shift` entry a `PerformanceObserver` reports, input-flagged ones included. "Desktop" is 1350×940 at full speed, "phone" 412×823 at a 1.75 device pixel ratio with 4× CPU throttling, the profiles of the CLS record. The API answers 503 (the CLS record's condition) or, for `/collection` and the header, fixtures 250ms late: three saved cards, a free plan and 503 for the rest. Signed in means the fake session of `tests/browser/fake-session.ts`, with Auth answered locally. Before is `aeb7da8`, this branch's base, after is `65cb2d0`, both built with the Supabase placeholders and served side by side by `vite preview` (:4782 and :4781). Two runs of each; they agreed to the fourth decimal.

| Page | Visitor, API | Desktop, before → after | Phone, before → after |
| --- | --- | --- | --- |
| `/today` | signed out, 503 | 0.0004 → 0 | 0.0378 → 0 |
| `/today` | signed in, 503 | 0.0054 → 0 | 0.0386 → 0 |
| `/leaderboard` | signed out, 503 | 0.0043 → 0 | 0.0502 → 0 |
| `/leaderboard` | signed in, 503 | 0.0105 → 0 | 0.0502 → 0 |
| `/collection` | signed in, fixtures | 0.0052 → 0 | 0.0504 → 0 |
| `/` | signed in, fixtures | 0.0041 → 0 | 0 → 0 |

On the desktop the signed-in rows include the header's 0.0041. Before, the first nav link stood at 351.9px and moved to 268.0px when the widget arrived; after, it stands at 259.9px from the first frame. With a 29-character name it stands at 259.9px too. Signed out, it stands at the same place on both builds at each of 1024, 1100, 1279, 1280, 1350, 1440 and 1920px (347.6px at 1350px). Before, `/collection` drew two states, the loader and then the cards; after, the cards are in its first frame. A click from `/` to each page, desktop, 503 and fixtures, signed in and out, recorded 0 non-input shift after the first draw on the new build; before, the 503 visits recorded 0.0004 to 0.0064.

The signed-in desktop nav now starts 8px further left at 1350px than the widget left it before (259.9 against 268.0px), because the slot reserves the widget's widest box. At 1280px with the long name the nav's `scrollWidth` equals its `clientWidth` (690px): no link is clipped.

`npm run check:bundle`: 227,155 of 243,000 gzip bytes, 39 more than the base's 227,116, in the entry's script and stylesheet (the slot's rule and the plan's `held` option).

### Tests

`tests/browser/first-load.spec.ts` gains three cases at both of its profiles, recording each frame and every `layout-shift` entry with its chunks held 800ms as before: `/today` and `/leaderboard` with every read failing, and a signed-in `/collection` whose cards answer 400ms late. Each page must keep the route box's height from its first frame and record no entry at all; the collection must show its card in every frame of the page, and on the desktop the first nav link must not move. Against the base build 5 of the 6 cases failed; the phone's collection case passed there until the cards were made to answer late, and then failed too. On the final build all 8 cases passed, and 24 of 24 with `--repeat-each=3`.

### Checks on the final head

On `65cb2d0`, the code of this record's commit, in the worktree `ds-wt-onestep`. I ran every command below, and each exit code is its own.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:client` | exit 0; 32 files, 318 tests |
| `npm run check:unused` | exit 0; knip reports no new finding |
| The workflow's build step: the Supabase placeholders, then `npm run build`, `npm run check:public` and `npm run check:bundle` | exit 0 each; 13 public URLs; 227,155 of 243,000 gzip bytes |
| Browser specs `first-load`, `navigation`, `route-errors`, `lazy-auth` and `public` against `vite preview` of that build on :4781 | exit 0 each; 8, 2, 14, 6 and 5 passed |
| `npm run check:responsive -- --base-url http://localhost:4781 --routes /,/today,/leaderboard --widths 390,1280` | exit 0; 6 probes, 0 with issues |
| `git diff --check` | clean |

Not run: the other browser specs, `test:launch`, the audits and Storybook. The branch changes nothing under `api/`, `lib/` or `shared/`.

### Commits

| Commit | What |
| --- | --- |
| `76b6e6e` | `.ss-account-slot` in the header |
| `f695976` | `HELD_READ`; Today and the leaderboard use it. It also carries `flashcardsQuery` and `useFlashcards`'s `held` option, which the next commit uses |
| `a3b4461` | `/collection` holds for the open tab |
| `6ad1b57` | The three cases in `first-load.spec.ts` |
| `65cb2d0` | DESIGN_RULES §8 |
| this commit | This record and NEEDED.md |

### Hand-off

- A slow read still draws twice: past the 1.2s cap the page draws its loading state, as HOLDS set up.
- `/cards` shows the same flashcards as `/collection` and does not hold for them.
- Today's four signed-in sections keep their own queries without `HELD_READ`, so a section whose read failed in the hold asks again on mount. The signed-in 503 runs recorded no shift from them on either build; I did not run them with data that fills a section after a retry.
- Not verified: devshark.app (not deployed), a real Supabase session, Firefox, Safari and physical phones.

## 2026-09-27 — `public.spec.ts` waits for the route fade (FADE)

The full gate failed once on `public.spec.ts`: axe read the Czech guide's "Procvičit v kvízu" button at 4.3:1, white `#fefefe` on `#438843`, where the tokens give `#ffffff` on `#2d7a2d`. A probe logged `.ss-route` mid-way through Motion's opacity entrance, between 0.08 and 0.5, in every run when axe started. Motion keeps opacity fades under reduced motion, so the page was right and the spec measured too early. The spec now waits for the finite animations on the article and its ancestors to finish, as `on-accent.spec.ts` already does.

| Build | `--repeat-each` | Before | After |
| --- | --- | --- | --- |
| `origin/main` at `3bedbbc` | 10 | 7 of 50 failed | 50 passed |
| This session's merged head | 10, then 20 | 5 of 50 failed | 100 passed |

## 2026-09-27 — accent text on its tint, a reachable levels strip, whole-route axe (PORT)

Three commits from `claude/elegant-cori-h9cdgb`, ported by hand to main at `035d853`: `9abf34a`, `1751a2c` and `d0e78e1`. SubjectPicker, `Sharkira.css`, `/sprint`, the Czech key and the other subjects' accents are gone from main or out of scope, so they stay out.

*22 October 2026:* the owner dropped the branch's remaining work (streak extras, weekly leagues, sprint mode, Lichess puzzles, the package merch cap; #208, closed not planned). The branch survives only as tag `archive/2026-10-22/claude/elegant-cori-h9cdgb`; nobody replays its migrations 038 to 042.

### Contrast

`client/src/lib/contrast.ts` derives `--brand-accent-on-soft`: the accent's hue, with lightness stepped until the text clears 4.5:1 on its own 12% tint over the worst surface of the mode. `ColorModeContext` writes it and `reset.css` carries the same values for the first paint. `--brand-accent` keeps its hex.

| Mode | Surface under the tint | Before, `--brand-accent` | After, `--brand-accent-on-soft` |
| --- | --- | --- | --- |
| light | card `#ffffff` | `#2d7a2d` 4.54:1 | `#2a712a` 5.11:1 |
| light | body `#f3f6f5` | 4.19:1 | 4.72:1 |
| light | muted `#edf2f1` | 4.06:1 | 4.57:1 |
| dark | worst of four surfaces | `#4caf50` 5.14:1 | `#4caf50` unchanged, 5.14:1 |

These are the unit suite's numbers (`client/tests/contrast.test.ts`, 11 tests). In the browser at 390px, the Home chip "Learn path · quizzes · flashcards" painted `rgb(42, 113, 42)` on `rgba(45, 122, 45, 0.12)` over a white panel in light mode, and `rgb(76, 175, 80)` over `#101c24` in dark mode.

The token replaces the plain accent where main paints accent text or a glyph on the tint: the active nav link, Home's topic tick, chip and level nodes, the sample-question chip, the quiz pills, the Deep End mode-card icon and tick, the current stage node, the identity settings hover, the typing-racer badge, the profile advisor tile and two dev-console states. The Roadmap level node paints a per-topic colour on the tint, not the brand accent, and I left it alone.

### Levels strip

`PathStrip` in `LandingKit.tsx` wraps Home's roadmap-preview strip: `tabIndex={0}`, `role="region"`, and the name `home.pathRegion` ("Learn path for JavaScript" on the default topic). `.ss-scroll-strip` draws the focus ring inset. At 390px in both modes, Tab then ArrowRight scrolled the focused strip 40px and `:focus-visible` matched.

### Axe over whole routes

`tests/browser/routes-axe.spec.ts` scans `/profile`, `/today`, `/leaderboard` and `/challenge` unscoped, with the WCAG 2.2 AA tags, at 390 and 1280px in light and dark mode. The original held dark mode to `/profile` because of two older dark failures; on main all four routes pass in dark, so the spec scans them all. The Quality workflow runs it after `first-load.spec.ts`.

With this branch's client changes reversed onto a fresh build, the spec failed 4 of 4: `scrollable-region-focusable [serious]` on `section[aria-label="Inside JavaScript"] > div:nth-child(5)` at 390px in both modes, no `--brand-accent-on-soft` on the chip, and no `.ss-scroll-strip`. axe did not flag the chip on main, because on a white card it measures 4.54:1; the failing surfaces are body and muted.

### Checks on the final head

In the worktree `ds-wt-port`, preview on :4821. I ran each command below.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| `npm run test:client` | exit 0; 34 files, 336 tests |
| `npm run check:unused` | exit 0; no new finding |
| Build with the Supabase placeholders, then `npm run check:public` and `npm run check:bundle` | exit 0 each; 13 public URLs; 228,035 of 243,000 gzip bytes |
| Browser specs `public`, `on-accent`, `first-load`, `routes-axe` | exit 0 each; 5, 14, 8 and 4 passed |
| `npm run check:responsive -- --base-url http://localhost:4821 --routes / --widths 360,768,1280` | exit 0; 3 probes, 0 with issues |
| `git diff --check` | clean |

Not run: the other browser specs, `test:launch`, the audits and Storybook. Not verified: signed-in routes, Firefox, Safari and physical phones.

## BRAND-V9

Branch `claude/brand-v9`, 2026-09-27. The owner's V9 kit sits in `client/public/brand/v9/`; the rules are in `docs/brand/brand-guidelines.md`.

- **Geometry.** `BrandLogo` in the header, rasterised at 1200 px next to `devshark-logo-compact-green.svg` in Chromium: 0 differing pixels of 95,919 inked. `SharkFin` and the share card read the same paths from `brandGeometry.ts`.
- **Header.** At 390 px the 22 px logo keeps 16 px to the menu button, 98 px to the Log in button and 19 px above and below. The 20 px menu logo keeps 16 px padding. Both links are named "devShark home". Colour: `rgb(45, 122, 45)` light, `rgb(76, 175, 80)` dark.
- **Spelling.** `document.body.innerText` on `/`, light and dark at 390 and 1280 px, contains no `DevShark` or `DEVSHARK`.
- **Icons.** `/`, `/premium` and the topic pages carry `favicon.ico`, `favicon-32.png`, `favicon.svg` (light) and `favicon-white.svg` (dark), `apple-touch-icon.png`, the manifest and `og-image.png`. Every icon URL and every manifest icon answered 200. The manifest reads name `devShark`, theme `#2D7A2D`, background `#F3F6F1`.
- **Fonts.** A first visit loads `manrope-latin-wght-normal` and `inter-latin-wght-normal` and no other font file.
- **Screenshots** (local, git-ignored `artifacts/brand-v9/`): header light and dark at 390 and 1280 px, the menu at 390 px, the route loader, the footer ocean, the icon sheet, the share card and the logo comparison.

| Check | Result |
| --- | --- |
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client` | exit 0 each |
| Build with the Supabase placeholders, `npm run check:public`, `npm run check:bundle` | exit 0 each; 13 public URLs; 230,937 of 243,000 gzip bytes |
| `npm run test:launch` | exit 0 |
| `npm run test:client` | exit 0; 34 files, 336 tests |
| `npm run check:unused` | exit 0; no new finding |
| Browser specs `public`, `navigation`, `first-load`, `on-accent`, `routes-axe` against the preview on :4901 | exit 0 each; 5, 2, 8, 14 and 4 passed |
| `git diff --check` | clean |

Not run: Storybook (no story changed), `check:responsive`, the dependency audits. Not verified: real browser tabs showing the dark-theme favicon, an installed PWA, link previews on social platforms, Firefox, Safari and physical phones.

## DESIGN-AUDIT-2026-09-27

Branches `audit/p0`, `audit/p1`, `audit/p2` (stacked), 2026-09-27 to 28. The 25 changes in the round-one design brief (`design-audit/CLAUDE_CODE_PROMPT.md`, removed on 2026-09-28 and kept in Git history), one issue (#240–#264) and one commit each. `docs/design/audit-2026-09-27-closeout.md` (deleted on 22 October 2026, kept in Git history) listed every ID with its commit and any deviation.

| Check on the final `audit/p2` | Result |
| --- | --- |
| `npm run typecheck:api` | exit 0 |
| `npm run test:client` (`--maxWorkers=2`; the default parallelism timed out under host load) | exit 0; 35 files, 337 tests |
| `npm run test:launch` | exit 0 |
| Build with the Supabase placeholders, `npm run check:public`, `npm run check:bundle` | exit 0 each; 13 public URLs; 229,332 of 243,000 gzip bytes |
| `npm run check:unused` | exit 0; no new finding |
| `npm run check:responsive` | 238 probes, 0 issues |
| `npm audit --omit=dev`, root and client | 0 vulnerabilities each |
| Browser specs `public`, `evolving`, `segmented`, `on-accent`, `navigation`, `lazy-auth`, `route-errors`, `first-load`, `routes-axe` against the preview on :4173 | 59 passed |
| `git diff --check main..audit/p2` | clean |

Not run: `storybook.spec.ts`. Not verified: signed-in Profile, Coins and the coding workbench against a live account, Firefox, Safari and physical phones.

## MARKETING-LAUNCH-239 (28 September 2026)

Issue #239, commits `6b2f416` to `ac30c86`, PR #268 (fast-forwarded into `main`).

| Gate | Result |
|---|---|
| `npm run typecheck:api`, `npm run typecheck:tooling --prefix client`, `tsc -b` | pass |
| `test:launch` (new: question-of-the-day contracts), `test:coding-auth`, `test:grading-integrity`, `test:coding`, `test:paths`, `test:billing`, `test:fallbacks` | pass |
| `test:client` | 38 files, 360 tests pass (new: analytics UTM, voucher prefill, share moments, `/daily`, `/changelog`, footer) |
| `check:unused`, `check:security` | pass |
| `npm run build`, `check:public` | pass: 15 sitemap URLs, 770 coding share pages, 72 question-of-the-day pages |
| `check:bundle` | 231,106 of 243,000 gzip bytes |
| `npm audit --omit=dev` (root, client) | 0 vulnerabilities |
| Browser specs incl. new `daily.spec.ts` (390 and 1280 px, light and dark, axe WCAG 2.2 AA) | pass; `navigation.spec.ts` failed once locally under load and passed on three reruns |
| `check:responsive` with `/daily` and `/changelog`, dark Czech sweep, `test:harness`, Storybook spec | pass |
| GitHub Actions `verify` on PR #268 | pass (run 36360052124) |
| Preview deployment `dpl_HQkTK2LdszCLqNZrzi3Z78HQaDa7` | `/daily/<date>` and `/coding/<track>/<id>` serve their own heads and PNGs; an unwritten date or task id falls through to the app (200); a real answer check against the preview API graded and explained at 390 and 1280 px |

Not checked here: link previews inside Threads and Instagram, and the PostHog person properties; both were owner items in `NEEDED.md` ("Marketing launch") until the owner dropped the marketing plan on 22 October 2026.

*22 October 2026:* the owner closed #239 as not planned. The shipped features stay (UTM on the first pageview, `/daily`, the OG images, `/changelog`, referral sharing); the remaining launch items, these two checks included, are dropped.


## Homepage launch announcement — 28 September 2026

The homepage announces the 4 October–2 November Premium launch offer, with the
55% comparison, EUR prices, Prague dates, subscription duration and Premium link.
It states the future start before launch, requires server-confirmed coupon availability
during the offer, and removes itself at expiry. The shared timer reschedules waits
longer than the browser's 24.8-day limit.

Validation: API typecheck, launch contracts (including the 12-handler budget), 31
billing checks, five targeted client tests and production build passed. Both production
dependency audits found zero vulnerabilities. Twenty responsive probes across `/` and
`/premium`, widths 360/390/768/1024/1440, light and dark, reported no overflow or footer
occlusion. Chrome visual inspection confirmed the homepage announcement. Real payments
remain disabled; Stripe sandbox integration is separate from production billing.

### 2026-09-28 — compact homepage launch announcement

Moved the homepage launch announcement directly below the Free/Premium comparison
card, aligned to its right edge and limited to 32rem (full available width on
narrow screens). Uses the owner's exact October heading, price and terms copy,
with no date strip or extra CTA. The checkout window and billing gates are unchanged.

Passed: API typecheck, launch contracts, existing launch-banner tests (4), production
build, both production dependency audits (0 vulnerabilities), and diff whitespace.
Homepage responsive checks passed all 10 probes at 360/390/768/1024/1440 in light
and dark themes. Desktop Chrome visual review confirmed card placement and copy.
The existing build chunk-size warning remains; no new runtime dependencies.

## Approved navigation wordmark — 2026-10-12

The header and mobile menu use the owner's selected plain heavy wordmark,
traced from the supplied screenshot. The V9 fin/wave geometry is retained and
its visible bounds are centred beside the lettering. The home link keeps its
translated name and 44px target; the outlined lettering has no font dependency.
The static logo has no new loading, error, auth, offline or disabled states.

| Check | Actual local result |
|---|---|
| API types | PASS |
| Launch/play-room/verified-caller contracts | PASS |
| Production build | PASS — existing large-chunk advisory remains |
| Root/client production dependency audits | PASS — zero vulnerabilities |
| Responsive sweep | PASS — `/` and `/learn`, 14 probes at 360/390/430/768/1024/1280/1440px; no overflow or unprobed routes |
| Logo browser checks | PASS — both themes at all seven widths, home accessible name, keyboard focus, 44px target, resolved ink/white fill, and no horizontal overflow |
| Visual review | PASS — light mobile, dark desktop, and settled mobile drawer screenshots; approved bold lettering, ordinary k and centred retained fin |
| Reduced motion | PASS — browser checks ran with reduced motion; logo is static |
| Diff whitespace | PASS |
| Release | Local change only; no deployment or publication performed |

Evidence: `/tmp/devshark-nav-logo/` contains build, type, launch, audit,
responsive and browser logs and the reviewed screenshots. Source and tracing
details are recorded in `docs/brand/brand-guidelines.md`.

Release follow-up: the first remote verification found the initial JS/CSS bundle
2315 gzip bytes above its 243000-byte budget. The wordmark is now a separate
hashed SVG shared by both themed use instances, keeping asset data out of the
JavaScript parser and allowing independent caching. Its fixed frame is reserved
while the SVG loads. The repeated local bundle check passes at 240769 gzip bytes,
with the 243000-byte limit unchanged; build and both-theme browser checks pass.
Remote verification passed in run 38229491791 (including browser, Storybook and performance checks). Before release, main was merged to retain the newer 1000px homepage width; the only conflict was this acceptance log, and both entries are preserved. The combined revision is verified again.

## Retire curation and centre the homepage hero — 2026-10-12

Removes the How we curate links from the footer, homepage topic picker and
learning-path overviews, and removes the public page, route loader, route title,
page-only helper and styles. Its former address uses the existing not-found page
with noindex and a working keyboard-accessible Go home action. The privacy
policy no longer lists opening the retired page as an analytics event.

The desktop headline, description, actions and stats are centred together on
the viewport. CSS reserves the same space below the hero as the floating header
uses above it; short and narrow screens can grow and scroll naturally. A third
stat displays 725 coding challenges from the subject catalogue, with a launch
contract checking it against the server’s active coding summaries. The three
stats form a responsive grid without loading another catalogue or making a request.

| Check | Actual local result |
|---|---|
| API types | PASS |
| Footer, route-head, homepage and learning-path tests | PASS — 47 tests |
| Launch/play-room/verified-caller contracts | PASS |
| Production build | PASS — existing chunk-size advisories remain |
| Root/client production dependency audits | PASS — zero vulnerabilities |
| Unused code | PASS — zero findings |
| Responsive sweep | PASS — Home, Learn and both learning-path overviews; 28 probes at 360/390/430/768/1024/1280/1440px |
| Browser checks | PASS — 20 route/theme/width combinations, no retired links or visible copy; former URL has the not-found title, noindex and keyboard return home; no coverage-page request |
| Hero browser flow | PASS — both themes, 1440/2560px width, viewport heights 729/900/1200px; the copy centre is within 2px of the viewport centre, third stat visible, keyboard sample answer and 360px reflow work |
| Bundle budget | PASS — 240629/243000 gzip bytes |
| React review | PASS — existing shell/not-found/stat primitives, no new state or effects or count request; legal/settings controls retained |
| Visual review | PASS — retired-address and centred hero screenshots in both themes and mobile/desktop |
| Diff whitespace | PASS |

Evidence: `/tmp/devshark-remove-curation/` holds the local logs and screenshots.
The hero browser regression is included in required CI. The removed UI does not
change server content eligibility, review records,
reports or grading. Required remote checks and production verification follow
on the associated pull request.

## 12 October 2026 — embedded Premium checkout and interface cleanup

Owner-selected Managed Payments uses supported `embedded_page`: Stripe's actual API refused `form` for this merchant model. The optional plain branch implements Checkout Form SDK with the supplied appearance. Required consent is collected before session creation; server metadata preserves the waiver/version/timestamp and existing signed fulfillment records it. No schema or grading changes; twelve API handlers remain.

Production Stripe/Vercel setup is prepared (live restricted key, public key, exclusive EUR 4.99/59.88 prices, forever 55% coupon through 30 November, nine-event webhook and default Portal). **Sales are disabled at the owner's request while identity verification waits.** Remaining setup is solely in [STRIPE_INTEGRATION_TODO.md](../STRIPE_INTEGRATION_TODO.md).

Premium membership disables Start free with an explanatory tooltip and colors the header diamond gold. Duplicate page kickers are replaced by green semantic main headings and the existing varied wave. Native select arrows are inset by 1rem. React success omits the complexity/first-pass/repeat-XP prose while retaining actual server XP, navigation and genuine exceptional states. Coding toolbar controls show icons and accessible tooltips below 1220px.

| Check | Actual outcome |
|---|---|
| `typecheck:api`, `typecheck:scripts`, `test:launch` | Pass |
| `test:billing` | Pass, 40 checks; explicit consent, old/new consent recording, ownership/signatures/idempotency and matching restricted live/test keys |
| `test:client` | Pass, 104 files / 996 tests |
| `build` | Pass; production-shaped Supabase placeholders used for signed-in browser tests |
| `check:bundle` | Pass, 241337/243000 initial gzip bytes |
| `check:unused`, `check:security` | Pass |
| Both production dependency audits | Pass, zero vulnerabilities |
| `git diff --check` | Pass |
| Coding browser suite | 17 passed, including React success and 1220/1219/360px keyboard tooltips |
| Launch-pricing browser checks | Regular/discounted pricing and light/dark WCAG 2.2 AA passed at 390/1280px; Premium membership regression corrected to intercept the actual multiplexed entitlement route and rechecked separately |
| Actual Stripe sandbox API | Subscription session created with Managed Payments, exclusive EUR 4.99 Price, forever 55% coupon, EUR 2.25 total before location-dependent tax |
| Actual external checkout iframe | Current Endive `createEmbeddedCheckoutPage({fetchClientSecret})` verified in Chrome and headless Chromium after correcting the older call. Stripe displayed EUR 4.99 subtotal, EUR 2.74 discount, EUR 0.47 Czech VAT and EUR 2.72 due. No purchase was confirmed and no real learner entitlement was created; actual paid completion/webhook delivery remains an activation gate |
| Live payment/KYC, external webhook delivery, retry/email settings, logged-out cancellation email | Not verified; sales remain off and the owner deferred identity verification |

Final local checks: 249 light-mode responsive probes across 28 routes and widths 320–1440; 248 were clear on the first run, `/profile` at 430px had a transient response failure during rebuild, then its focused retry passed. Another 18 dark-mode probes cover the changed routes at 360/768/1440px, all clear. All 17 coding-workbench browser checks, the five pricing/AA checks, the Premium keyboard-tooltip/gold-diamond check, and 13 coding-page/navigation/route-accessibility checks passed. Client tooling typecheck passed. Vercel's readable production values were verified: matching public `pk_live_` key, prices, coupon, Managed Payments and disabled sales; private Secrets cannot be read back by design, and their creation/storage was verified through provider API and Vercel metadata.

GitHub protected `verify` and `sql` checks and production deployment are checked before release; their final evidence is recorded on PR #360. Physical-phone/Safari and real live purchase remain separate owner checks; no claims of these checks passing.

Final public HTML check passed after replacing the obsolete tax-inclusive contract with the owner-selected tax-exclusive expectation: 20 sitemap URLs, both Premium prices and VAT-extra wording/schema, 725 coding share pages, seven section pages, 87 daily pages and no Czech in 16 coding chunks. The private checkout page remains outside the sitemap.

## 12 October 2026 — OG and profile identity polish

- Profile name/email share a zero-gap column; friend nickname and optional country/crown share one row, with authoritative streak/accuracy directly below. Auth, data fetching, privacy choices, ordering and score calculation remain unchanged.
- Three actual Higgsfield Seedream 4.5 Unlimited background jobs completed; all reviewed, one accepted. Credits stayed 699→699. Exact navbar SVG lettering, fin and wave were composited deterministically. Main 1200×630 PNG and optional square/portrait files saved to the authorized Drive folder and verified by metadata readback. Full source/prompt/license/privacy/cost provenance is in the generated-media manifest.
- Passed locally: API and script/tooling typechecks; launch contracts; production-shaped build; nine existing profile/friends client tests; public HTML checks; security contracts; both production dependency audits (zero vulnerabilities); diff whitespace check. Two initial client test timeouts on the heavily loaded host passed on a one-worker retry; no assertion or product behavior was weakened.
- Direct authenticated local browser fixtures passed ten light/dark cases at 360/390/768/1220/1440: name/email gap 0px, nickname/flag overlap in the same row, stats 2px beneath it, no horizontal overflow, long-name and no-flag/no-answer rows retained. Only fake local users and intercepted API responses were used; no real account data or production entitlement was changed.
- Focused responsive sweeps cover signed-out /profile and home at 360/390/768/1280/1440 in light and 360/768/1440 in dark. These complement the authenticated fixture above; the signed-out Profile redirect is not claimed as an authenticated profile test.
- Protected CI and final Production deployment must pass before release; exact final evidence is recorded on the associated PR. Live Stripe sales remain disabled pending the existing activation checklist, including the owner's deferred identity verification.


## Learning, Challenge and grading release — 13–14 October 2026 (PR #371)

Implements compact coding outcomes with actual 25/15/0 XP; conditional authored
complexity, the public Big O guide/free DSA intro, ten restored Learn levels,
new-tab linked coding and accepted Skill Check answer review. Challenge uses
90 seconds per question, sealed selected topics, automatic positive-only scores
and mandatory independently chosen leaderboard names. Server-generated camelCase
names share one atomic immutable decimal ordinal. The React learner now runs in
QuickJS/WASM with private serialized capabilities; trusted suites and results
remain outside the learner engine. Twelve physical API handlers remain.

| Gate | Actual evidence before final protected release |
|---|---|
| API/script/client types and launch | PASS locally, including complete/nested authored targets, unknown estimates, direct Big O level-two completion and private-grant health readiness |
| Fresh SQL chain | PASS — 60 SQL checks; required SQL job passed on `f520045d` in run 38486027732 |
| Full coding/server/client step | PASS on `f520045d`: 770 authored / 725 issued tasks, server ownership/grading/reward/path/billing/fallback/garden/live-monitor checks, 104 client files / 996 tests |
| React compatibility and authority | PASS — 501 reference/junior/senior implementations locally after class/lifecycle support; private Promise/kernel and learner-authority tests passed locally and in the required full step |
| Public build and policy | PASS locally and on `f520045d`: production build, public HTML, unused code, security policies; existing chunk-size advisories retained |
| Initial bundle | `f520045d` initially failed at 243267/243000 gzip bytes. Removed unused retired English UI values, preserving archived Czech keys and all current copy; measured build and final `fec381a3` CI PASS at 242937/243000 |
| Responsive | PASS — 264 light probes (33 routes, 320–1440px), 63 focused dark probes (9 routes, 360–1440px), zero issues or unprobed routes |
| Active result UI | PASS — eight light/dark mobile/desktop Challenge/Big O cases; opaque feedback, full-width horizontally scrolling code, fresh 90-second clock, positive-only completion, 200% text reflow and keyboard scrolling; four Skill Check cases verify stable widths and complete answer/explanation review |
| Coding browser result | PASS — actual built editor completion and 1220/1219/360px command/tooltips, plus Start-labelled signed-in run fixture; API answered locally |
| Real preview HTTP/VM | PASS on deployed `f520045d`: health/guide/free-intro HTTP 200; real React and JavaScript correct submissions passed and wrong ones failed, with zero anonymous account XP/progress |
| Real Challenge write | PASS through the same preview with production storage: one positive guest record, camelCase numbered name, sealed JavaScript topic metadata; identical retry ID/name; zero-score API result had no record. SQL read confirmed one score/allocation and no zero scores. Exact guarded cleanup removed the fixture score/allocation and preserved eleven account handles; counter stayed 13 |
| Production schema/name checks | 061–065 applied in order. Eleven case-insensitive unique account handles and unique ordinals, ten unchanged seed identities converted, custom identities preserved; counter/allocation RLS and private RPC grants checked. Advisors returned INFO-only private-table notices, no warnings/errors |
| Production dependency audits | Root and client: zero vulnerabilities; no dependency changes in the follow-up |
| Diff whitespace | PASS |
| Protected merge and production code | PASS — final `fec381a3` required `verify` and `sql`, including Storybook/performance, in [run 38494594258](https://github.com/lukaskourilcz/react-express-app/actions/runs/38494594258). Merge `1ed1d5c2` is production READY as `dpl_5r8fBKN8fzT91h2qN4Zn3X5uQRP6` on devshark.app |

The old production health code used anonymous SELECT on `user_stats`, which
061 correctly revoked. That caused a false HTTP 503 after schema deployment.
The fix reads readiness through private server access; its grant-denying
regression and deployed preview return 200. The production merge now returns
200 with healthy database/service-role dependencies. No anonymous grants were
widened to mask the issue.

The final production smoke also passed correct and wrong React/JavaScript
submissions with zero guest account XP/progress. A positive guest Challenge
allocated ordinal `13`, retained sealed JavaScript topics and replayed the same
score/name; a zero result returned no record and SQL found no zero-score rows.
Exact guarded cleanup removed only that QA score/allocation, preserved all
eleven account handles and left the next number at decimal string `14`.
The spent ordinal is not recycled. The prior 30-minute CI attempt was cancelled
in the final Storybook step; the 45-minute cap retains every gate and the final
run completed. #366–#370 closed with production evidence. The separately
confirmed native instrumentation gap in #373 was subsequently fixed in PR #374;
#373 and the completed grading-authority scope of #191 are now closed.

## Native grading authority follow-up — 14 October 2026 (#373)

A private local `maxGap` candidate replaced the appended `__countReads` helper,
made one linear warm-up call, then compared every pair. The actual old path
grader accepted it. No malicious production submission was performed.

Authored harnesses now keep counters, wrap state and original function
references in a private lexical closure. Only immutable helpers needed by
trusted calls or the stated learner API leave it; exposed fixture objects are
recursively sealed with captured intrinsics. Submitted source is not parsed or
filtered. This protects the observed input-access contract; it does not turn
finite operation-budget tests into a proof of arbitrary algorithmic complexity.

Local API/script types, launch contracts, all 47 native/reused code references
and nineteen authority/valid-alternative checks pass. Checks reject helper
replacement across five shuffles, same-named declarations, Proxy/prototype
replacement, recursion/queue counter shadowing and fixture mutation (including a shadowed
freezer), while accepting independent min/max, recursive-sum and queue code.
The existing grading integrity suite passes after making queue-expiry evidence
deterministic with a held slot: a TypeScript diagnostic may legitimately finish
before its wait cap, so compiler speed no longer substitutes for an expiry
test. Real burst admission, retry/no-verdict behavior, actual expiration bounds
and pool recovery remain checked. Final required verify/SQL passed on
`611e74bc` in [run 38499204299](https://github.com/lukaskourilcz/react-express-app/actions/runs/38499204299).
Merge `cf128185` deployed READY as `dpl_CiBJNbTuZfUccoxc2AYyypiXVUNF`.
Production health, guide/free intro and actual correct/wrong React/JavaScript
grading passed. No authenticated native activity was submitted in production.
No new migration or API handler is introduced.

## Final learning browser and starter compatibility — 14 October 2026 (#375)

WebKit exposed a four-pixel main-scrollbar width change between long and short
Skill Check questions, despite a stable gutter. The main scroll lane now stays
present. Focused Big O table arrow keys scroll inside its region in all three
engines. Chromium's answer-width test now waits for the answers to be visible
before measuring; the two-pixel width requirement remains unchanged.

A correct native queue implementation failed with its authored starter example
because the provided buffer factory was initialized afterwards. Immutable helper
APIs now exist before learner source, while instrumentation installs once after
declarations. Private counters/original references and sealed fixtures remain
protected. All 47 native/reused references and every native authored scratch-pad
example pass; 22 authority/setup checks pass, including repeated setup and
replacement refusal. All 46 English starter action comments match Submit.

Local API/script types, launch and full grading/Learn integrity pass. Chromium,
Firefox and WebKit each pass twelve light/dark cases at 360/1440px; the Big O
cases include keyboard and 200% text reflow. The focused nine-route light and dark
sweeps each pass all 63 probes at 360–1440px. Both production dependency audits
report zero vulnerabilities. Initial bundle remains within the unchanged
243000-byte cap at 242948 gzip bytes. Final required verify/SQL passed on
`2fb7ced1` in [run 38508356988](https://github.com/lukaskourilcz/react-express-app/actions/runs/38508356988).
Merge `006fae90` is production READY as `dpl_6y3kLFYECJaqWFVGr6FsVwGLN73z`;
health, guide/free intro and actual correct/wrong React/JavaScript grading passed.
These checks do not claim an authenticated native activity or physical device.

No physical Safari/Firefox/Windows/phone, timed managed-backup restore, actual
external alert delivery, sustained expected-load acceptance or paid Stripe
completion is inferred from these checks. Billing and merchandise remain off;
marketing PR #365 stays draft under its separate production/publication gate.
Question overrides remain hidden. #176's full editorial wave is still open;
`docs/audit/inventory-2026-10-14.json` records current coverage without turning
execution evidence into editorial approval. Private preview links, cookies,
sessions and proofs are absent from commits and evidence comments.


## Coding attempt versions — 14 October 2026 (#380)

New ordinary/linked/puzzle/design sessions and native code sessions carry their
server-only authored/grader versions inside encrypted tokens. Legacy or stale
unaccepted work is refused before grading/progress/evidence/XP writes. Latest-brief
loading preserves typed code and the validated linked Learn parent. Native accepted
network retries return the stored matching result without repeated grading/XP.

Local API/script/client/tooling types, launch, path, coding ownership/version and
full grading/Learn integrity checks pass. The stale-editor client checks pass
(37 tests across two files). The final browser matrix passes light/dark at 360/1440, keyboard activation,
44px refresh targets and 200% text at 1440. The first extended check found
a 32px target; both refresh controls were corrected and the matrix rerun. The
three-route light/dark reflow sweep passed 18 probes each at 360–1440. Both
production dependency audits report zero vulnerabilities. Build/public/unused/
security policies pass; initial production-shaped bundle is 242982/243000 bytes
with the unchanged budget. Twelve physical API handlers remain. Required release
CI, preview and production verification for this change are pending; no live
account, score/name allocation or malicious production probe was used.


## D04 content and automatic native retry — 14 October 2026 (#383)

The D04 queue proxy counts indexed definitions and deletions through captured
operations. Exact 32-value append/read/clear costs 96 operations. Proper direct
property definitions pass; excessive definitions/deletions fail. Stack/queue
identity and falsey/undefined witnesses reject the demonstrated old shortcuts.
Twelve individually read records add exact bindings (48/263), with item-specific
scores and same-session self-review. 215 native records and 705 coding tasks
remain; no full-catalogue/independent/human review is claimed.

Local selected worker verdicts pass 21/21 (7 valid, 3 starters, 11 wrong), as do
33 authority checks, all 47 native/reused references and 46 starter examples.
Cost question contexts are executed. API/script types, launch, version authority,
build/public/unused/security and both production dependency audits pass. The
changed automatic native-retry flow passes real-handler version checks and the
client retains its source (38 tests across the two stale-editor files). Both
bracket reference and alternative report unknown complexity against authored
O(n), so neither is penalized and no estimated-complexity line is shown. Initial
bundle 242995/243000, unchanged budget. Required release CI and deployment
verification are pending; visual checks for the final combined build are recorded
when complete. Twelve API handlers, no migration/dependency or live user writes.

## Logging-path content batch b024 — 15 October 2026

Five individually read and manually scored coding records raise coverage to
150/725, with575remaining and263/263native. Final-hash QuickJS verdicts agree
36/36 (20valid,5starters,11wrong), compared with25/36before. Twenty authored
complexity-target checks retain25XP; copy sweep has zero artifacts. Focused
cumulative coding, API/script types, launch, build, native bindings, both
production dependency audits (zero vulnerabilities) and diff checks pass.
The first new native clone probe compared different realms' prototypes and
failed; the final probe compares ordinary clones from the same realm while
retaining the own-key/independence assertions. No checker policy changed.
The content relies on local runtime fix #403; checked release/deployment and
authenticated acceptance are pending. No owner progress or balances were used.

## Tracing-path content batch b025 — 15 October 2026

Five individual model reviews raise coding coverage to155/725,570remaining;
native remains263/263. Final-hash QuickJS results agree35/35 (20valid,
5starters,10wrong) versus25/35before. Twenty authored-target/base25XP
checks and copy sweep pass. Focused cumulative coding, API/script types, launch,
build, native bindings, both zero-vulnerability production dependency audits
and diff checks pass. Callback/source ownership and local promises are tested
without live accounts/network or balance changes. Release/independent and
authenticated acceptance remain separate.

## PR #402 exact production — 15 October 2026

15 October: PR #402 passed required run38685241521 on exact95674b5e180ee5ca511fb6a4d8836d1e353d96b0 (verify30m37s; SQL42s), merged at8ea7ce7919140c4cad99f4082ee9264d5f20991f. READY production dpl_FYPZbZ64Crs8u8frbYcXG5KodXSH matches that merge, owns devshark.app and has no alias error. Eleven general guest checks pass at zero XP/null progress, with no Challenge/name/owner-state fixture. Shipped coding coverage is135/725; native remains263/263. This is not authenticated native/Premium or independent/human acceptance.

## Edge/input content batch b026 — 15 October 2026

Five individual model reviews raise coding coverage to160/725,565remaining;
native remains263/263. Final-hash QuickJS results agree35/35 (20valid,
5starters,10wrong) versus25/35before. Twenty target/base25XP and copy checks
pass. Focused cumulative coding (including date probes in four non-UTC host
zones), API/script types, launch, build, native bindings, both zero-vulnerability
production dependency audits and diff checks pass. The final checks explicitly
observe post-call price order and1.005without premature rounding. Exact READY
PR #404 preview at3e8d209d passes11general guest checks; SQL41s passes, verify
is pending. B026 is local and not part of that frozen PR. No real profile,
billing transaction, progress, score or generated-name allocation is involved.

## Array mutation/copy content batch b027 — 15 October 2026

Five individual model reviews raise coding coverage to165/725,560remaining;
native remains263/263. Final-hash QuickJS results agree35/35 (20valid,
5starters,10wrong) versus25/35before. Twenty target/base25XP and copy checks
pass. Focused coding, API/script types, launch, build, native bindings, both
zero-vulnerability production dependency audits and diff checks pass. Initial
identical insertion boards were corrected to distinct explicit/literal argument
forms and the final35verdicts/20target checks rerun. Ownership and normalization
checks include10000-element arrays; finite tests do not prove arbitrary method
conformance or asymptotics. B026–b027are local; #404 remains frozen separately.

## Loop/fallback content batch b028 — 15 October 2026

Five individual model reviews raise coding coverage to170/725,555remaining;
native remains263/263. Final-hash QuickJS results agree35/35 (20valid,
5starters,10wrong) versus25/35before. Twenty target/base25XP and copy checks
pass, as do focused coding, API/script types, launch, build, native bindings,
both zero-vulnerability production dependency audits and diff checks. Correct
fixed-one-element slice retains25XP againstO(1); uncertain countdown analysis
remains unpenalized. Identity, strict-equality and10000-item cases are local
fixtures; no real user progress, balances, scores or names were created.
B026–b028are local and #404 remains frozen separately.

## Search/text/callback content batch b029 — 15 October 2026

Five individual model reviews raise coding coverage to175/725,550remaining;
native remains263/263. Final-hash QuickJS results agree35/35 (20valid,
5starters,10wrong) versus26/35before. Twenty target/base25XP and copy checks
pass, as do focused coding, API/script types, launch, build, native bindings,
both zero-vulnerability production dependency audits and diff checks. Text
copying costs are explicitly conservative/output-sensitive; finite execution
and supplied-source reading are separate from arbitrary program guarantees.
Original callback errors/counts and opaque references use isolated local data.
B026–b029are local, and #404 remains frozen separately.

## Array predicates/reduce content batch b030 — 15 October 2026

Five individual model reviews raise coding coverage to180/725,545remaining;
native remains263/263. Final-hash QuickJS results agree35/35 (20valid,
5starters,10wrong) versus25/35before. Twenty target/base25XP and copy checks
pass, as do focused coding, API/script types, launch, build, native bindings,
both zero-vulnerability production dependency audits and diff checks. Explicit
NaN membership-versus-index semantics, fresh100×100rows, fractional thresholds,
strict opaque ids and10000-item scans are covered. Only the fresh final export/
execution after a private edit-helper boundary repair is recorded as evidence.
B026–b030are local and #404 remains frozen separately; no live account changes.

## Reduce/destructuring content batch b031 — 15 October 2026

Five individual model reviews raise coding coverage to185/725,540remaining;
native remains263/263. Final-hash QuickJS results agree35/35 (20valid,
5starters,10wrong) versus25/35before. Twenty target/base25XP and copy
checks pass, as do focused coding, API/script types, launch, build, native
bindings, both zero-vulnerability production dependency audits and diff checks.
Safe normalized own keys, exact callbacks/error identity, tuple labels and
10000-item arrays use local fixtures. B026–b031are local and #404 remains
frozen separately. No progress, account/name or score fixture was created.

## PR #404 exact production — 15 October 2026

15 October: PR #404 passed required run38688593761 on exact3e8d209deab49e8c62f973fd47a8f38cdcb7b710 (verify30m53s; SQL41s), merged at9a85c3683f46cf1a3a4fcb13bdda74a3946efc94. READY production dpl_XG32jkhw1h5fYCWtWyEeBdy6BXBY matches that merge, owns devshark.app and has no alias error. Eleven general guest checks and four direct actual-Submit clone contracts pass at zero XP/null progress, with no Challenge/name/owner-state fixture. The clone probes cover own-key aliases/descriptors, self-cycles, arrays and captured defineProperty despite a learner replacement. Shipped coding coverage is155/725; native remains263/263. This is not authenticated native/Premium or independent/human acceptance.

## Rest/closure/callback content batch b032 — 15 October 2026

Five individual model reviews raise coverage to 190/725 coding, 535 remaining;
native remains 263/263. Combined current-hash QuickJS results agree 35/35
(20 valid, five starters, ten wrongs) versus 24/35 exact baseline labels. The
old handler starter already failed to boot; its scratch example is now safely
commented and it fails grading normally. Seven tally candidates were rerun after
the final call-bound probe refinement. Twenty target/base 25 XP checks and copy
checks pass, as do focused coding, API/script types, launch, build, native
bindings, both zero-vulnerability production dependency audits and diff checks.
PR #404 is merged and exact-production verified (11 general + 4 direct clone
checks); #403 is closed. B026–b032 remain local and add 35 coding reviews.
No live account, stored balance, score or generated name was used.

## PR #405 UTC parity fixture — 15 October 2026

Required run 38692289923 passed SQL in 40 seconds but verify stopped at the
UTC task-parity fixture: its local-getter example did not pad years to four
digits, unlike the expanded b026 task contract. The example now pads only the
year; timezone policy, task checks and expected outcomes are unchanged. Full
local grading integrity and Learn integrity against the stand-in database pass
after the fix. Required exact-head CI will rerun; the failed run is not a pass.

The local cohort build passes all 264 fixture-backed responsive route/viewport
probes, 320–1440 px, with zero issues/unprobed routes. Its exact initial preview
at 533776fa also passes eleven general guest checks at zero XP/null progress.
New b033 content remains uncommitted and is outside this 35-task PR.

## Dense reducers/truthiness content batch b033 — 15 October 2026

Five individual model reviews raise coverage to 195/725 coding, 530 remaining;
native remains 263/263. Combined current-hash QuickJS results agree 35/35
(20 valid, five starters, ten wrongs) versus 25/35 before. Fourteen compact/
nested-key cases were rechecked after final wording/skeleton edits. Twenty
target/base 25 XP checks, copy sweep, focused coding, API/script types, launch,
build, native bindings, both zero-vulnerability production dependency audits
and diff checks pass. The local fixture-backed responsive sweep separately
passes all 264 probes; its build stayed fixed while b033's later build waited.
PR #405 remains frozen at the separate UTC-fixture repair; b033 is local.
No real account, stored progress/balance, score or generated name was used.

## Map and grouping content batch b034 — 15 October 2026

Five individually scored model reviews raise coverage to 200/725 coding,
525 remaining; native remains 263/263. All 35 current-hash QuickJS verdicts
agree versus 25/35 before. Twenty target/base-25-XP checks and zero-artifact
copy checks pass, as do focused coding, API/script types, launch, build, native
bindings, both production dependency audits (zero vulnerabilities) and diff
checks. Original references, Map ordering/SameValueZero, frozen records,
nullish defaults and fresh groups use bounded local fixtures. PR #405 remains
frozen separately; no production progress, score or name fixture was created.

## Rotation, encoding and matrix batch b035 — 15 October 2026

Five individual model reviews raise coverage to 205/725 coding, 520 remaining;
native remains 263/263. All 34 selected current-hash QuickJS verdicts agree
(20 valid, five starters, nine wrongs), versus 26/34 selected baseline. The
unobservable already-sorted-sort negative was removed from both selected sets;
original baseline is retained privately. New surrogate tests compare numeric
code units and use escaped record literals. Twenty target/base-25-XP checks,
copy sweep, focused coding, API/script types, launch, build, native bindings,
both production dependency audits (zero vulnerabilities) and diff checks pass.
PR #405's updated exact preview at 58686aaa passed eleven guest checks, all
zero XP/null progress. Required verify is still pending. No user-state fixture.

## Safe balances and stateful content batch b036 — 15 October 2026

Five individual model reviews raise coverage to 210/725 coding, 515 remaining;
native remains 263/263. All 30 current-hash QuickJS verdicts agree versus 25/30
before, with 20 valid, five starters and five selected wrongs. Twenty authored-
target/base-25-XP checks, copy sweep, focused coding, API/script types, launch,
build, native bindings, both production dependency audits (zero vulnerabilities)
and diff checks pass. Safe own-name dictionaries, CSV logical-record grammar,
opaque history references, identity-preserving chain methods and bounded grid/
operation sequences use local fixtures. No runtime/schema/UI policy change,
no live user-state writes and no independent/human acceptance claim.

## Cache, arity and scoring batch b037 — 15 October 2026

Five individual model reviews raise coverage to 215/725 coding, 510 remaining;
native remains 263/263. All 30 current-hash QuickJS verdicts agree versus 27/30
before. Twenty authored-target/base-25-XP checks, copy sweep, focused coding,
API/script types, launch, build, native bindings, both production dependency
audits (zero vulnerabilities) and diff checks pass. NaN cache keys, exact
opaque/error identity, all 1024 binary-word pairs, default/rest arity, high
limiter bounds and incomplete bowling bonuses use local fixtures. No grader
engine/schema/UI-policy change or live user-state write; same-session model
and finite execution evidence only. PR #405 remains frozen separately.

## PR #405 exact production — 15 October 2026

Required run 38693420570 passes at exact 58686aaa (verify 30m50s; SQL 41s).
PR #405 merged at fe214b686ffeff1c951dab07ae64a25919fc791a. READY production
dpl_CJbygg7tdYp3P4tuAa25ePVbtPj5 matches, owns devshark.app and has no alias
error. Eleven general guest checks pass at zero XP/null progress. Shipped
coverage is 190/725 coding and 263/263 native. No authenticated native/Premium,
independent/human or full editorial-coverage claim.

## Event and timer content batch b038 — 15 October 2026

Five individual model reviews raise coverage to 220/725 coding, 505 remaining;
native remains 263/263. All 30 final-hash QuickJS verdicts agree versus 26/30
before. Twenty target/base-25-XP checks, copy sweep, focused coding (including
reversed hidden order and native Run), API/script types, launch, build, native
bindings, both production dependency audits (zero vulnerabilities) and diff
checks pass. Initial gate failures were a new 1000-tick native wait-limit case
and a pre-existing cleanup fixture tracking another hidden check's interval.
The final 100-tick test fits the wait limit; scoped allocation/firing observation
removes cross-check cancellation hooks. Both failures are retained privately.
Snapshot delivery, prototype-safe names, callback errors/arity and bounded
1000-listener/10000-call cases use local fixtures. No live user-state writes.

## Sorting and callback content batch b039 — 15 October 2026

Five individual model reviews raise coverage to 225/725 coding, 500 remaining;
native remains 263/263. All 30 current-hash QuickJS verdicts agree versus 25/30
before. Twenty target/base-25-XP checks, copy sweep, focused coding including
reversed hidden/native Run, API/script types, launch, build, native bindings,
both production dependency audits (zero vulnerabilities) and diff checks pass.
Opaque undefined sorting, own safe settings keys, exact callback values/errors,
10000-item/key and 5000-line boundaries, 100 native-compatible timer callbacks
and capture-time reminder values use local fixtures. No live user-state writes,
no engine/schema/UI-policy change and no independent/human acceptance claim.
The owner requested completing and shipping current work; further audit batches
remain in #176/#391. B033–b039 form the next 35-review release cohort.


## PR #406 exact production and audit resumption — 15 October 2026

PR #406 passed required run 38700013792 at exact ad6a0a5822b465dbd477f724e1db9845cb8fb420 (verify 31m39s; SQL 37s), merged at dca959f9839d43ad73ff7a8137b61e08cffa5fde. READY production dpl_5FuxpnzTardVzaqJPPsm8EBd1iW1 matches that merge, owns devshark.app and has no alias error. All eleven general guest checks and four changed-cohort actual Submit checks pass at zero XP/null progress; updated briefs, valid solutions and selected wrongs were verified. Shipped coverage is 225/725 coding and 263/263 native. No authenticated native/Premium, independent/human or complete editorial-coverage claim.

The owner requested continuing after shipment. The next five-item batch resumes the remaining 500 coding reviews; historical stop-current-cohort notes describe the earlier instruction only. Existing owner holds remain unchanged.


## Stateful text and timing content batch b040 — 15 October 2026

Read template filling, streamed line buffering, bounded scores, debounce and
throttle individually. Senior template replacement now uses replace/String,
including Symbol primitives. Score boards use the requested findIndex/splice.
Throttle stores one accepted timestamp before invoking its callback, so a thrown
callback consumes the window without leaving it permanently blocked. Exact
boundary semantics follow the stated Date.now clock model. Correct line-reader
and debounce boards are retained under explicit supported callback domains.

All 30 final-hash worker verdicts agree (20 valid, five starters, five wrongs),
versus 25/30 baseline. Distinct valid alternatives, twenty target/base-25-XP
checks, copy sweep, focused coding including reversed hidden/native Run,
API/script types, launch, build, 263 native bindings, both zero-vulnerability
production dependency audits and diff checks pass. Cases include Symbol/BigInt
literal substitution, a three-million-unit expansion, 10000 total UTF-16 units
and reader calls, repeated reusable flushes, a 1000-entry board, 10000 pending
call replacements, zero-delay deferral, exact opaque argument identity, callback
reentry/errors and a 10000-call burst. Revision 2 replaces the initial clock
stubs after whole-integrity exposed a valid Date-constructor false rejection.
Current normal-clock probes also accept captured Date.now/Date aliases.
Structural factory-versus-method estimate scope remains explicitly tracked in
#391; twenty no-false-penalty checks are not a scope-correctness claim.

Coverage is 230/725 coding, 495 remaining, and 263/263 native. PR #406 ships
225 coding reviews; b040 adds five staged reviews after the owner's explicit
request to continue. Same-session model self-review and finite execution only;
no independent/human, authenticated production or full-catalogue claim.


## Parsing and graph content batch b041 — 15 October 2026

Read dotted version sorting, heading trees, flood fill, JSON log lines and role
inheritance individually. Heading boards now ignore trimmed-empty titles before
changing the parent stack and preserve internal Unicode line-separator text.
The format is explicitly a simplified heading/fence exercise. Roles’ junior and
senior now follow the requested recursive includes/some predicate. Numeric
version limits make Number conversion exact; recursion/ownership and raw JSON
whitespace rules are explicit. Correct sort and fill algorithms remain intact.

All 30 final-hash worker verdicts agree (20 valid, five starters, five wrongs),
versus 25/30 baseline. Twenty authored-target/base-25-XP checks, copy sweep,
focused coding including reversed hidden/native Run, API/script types, launch,
build, 263 native bindings, both zero-vulnerability production dependency
audits and diff checks pass. All 235 coding records match current full hashes.
Cases cover 1000 versions/twenty parts, 5000 headings and independent children,
100 frozen/shared-row cells and empty colour values, literal NBSP/BOM JSON
framing, duplicate/prototype-like JSON data, 5000 bad lines/exact 100000-unit
input and 100-level cyclic roles with duplicate edges/1000 roots. Cost targets
state their parsing, comparison-sort and average constant-time Set models;
finite checks are not universal engine guarantees or measured asymptotics.

Coverage is 235/725 coding, 490 remaining, and 263/263 native. Ten coding
reviews are staged after PR #406’s verified 225-review release. Same-session
model self-review only; no live learner state, schema, grader engine, UI or
entitlement policy change. Continue sequential five-item commits under #176/#391.


## Grid and tree content batch b042 — 15 October 2026

Read Game of Life, folder rendering, deep equality, cinema ranking and sudoku
individually. Folder dictionaries are now null-prototype objects for every
literal name; the unfinished starter no longer calls join on undefined. Deep
equality compares every numeric position, treating holes as undefined, while
ignoring unrelated array metadata; it is symmetric and checks array length.
Sudoku rejects malformed shapes/cells and uses twenty-seven independent Sets.
Supplied Life/seat variants now follow their authored map/offset/while/sort
objectives, with exact finite input and complexity models.

All 30 final-hash worker verdicts agree (20 valid, five starters, five wrongs),
versus 24/30 baseline: five old false passes plus the folder starter error.
Twenty target/base-25-XP checks, copy sweep, focused coding including reversed
hidden/native Run, API/script types, launch, build, 263 native bindings, both
zero-vulnerability production dependency audits and diff checks pass. All 240
coding records match their current hashes; archived Czech is unchanged.
Cases cover every 3x3 Life state (512, independently enumerated), 100x100 grids,
1000 filenames/twenty segments/prototype-like names, sparse-array symmetry,
10000 entries/depth 100, exact ragged/empty-row and half-seat ties, invalid
sudoku values/shapes and a locally valid but unsatisfiable partial board.
An initial authoring compile caught an escaped-template property-boundary
replacement; it was repaired before recording any review or passing gate.

Coverage is 240/725 coding, 485 remaining, and 263/263 native. Fifteen coding
reviews are staged after verified PR #406 (225 deployed). Same-session model
self-review and finite execution only; no full-catalogue, independent/human or
authenticated production acceptance claim. No live learner state, schema,
grader engine, UI or entitlement-policy change.


## 15 October correction — throttle clock compatibility, b040 revision 2

The whole grading-integrity suite caught a false rejection introduced by the
b040 Date.now-only clock stubs: its existing correct new Date().getTime()
implementation failed. The task now accepts equivalent Date timestamp reads
and captured aliases. Functional cases leave the coherent clock untouched and
check exact original arguments, undefined returns, reentry, consumed original
errors with later recovery, and increasing accepted payloads in a 10000-call
burst. Exact >= boundary and drop-stamp rules are source-reviewed, not inferred
from a fake clock or a precise wall-clock count. The supplied algorithms and
runtime engine are unchanged. A permanent captured-Date.now integrity proof
joins the existing Date-constructor proof.

The previous record is preserved under coding/history; only throttle advances
to revision 2, with no increase in unique coverage. All 32 current-hash b040
verdicts agree (22 valid, five starters, five wrongs), including the two new
clock aliases. Twenty original plus two alias target/base-25-XP checks pass.
The complete updated grading/Learn integrity, focused coding (reversed hidden
and native Run), API/script types, launch, build, 263 native bindings, both
zero-vulnerability dependency audits and diff checks pass. The initial failure
and superseded 30-case proof remain historical evidence, not final acceptance.

The 15-review cohort b040–b042 now has 92/92 final-hash selected verdicts and
62 no-false-penalty checks. Responsive validation passes 264 fixture-backed
probes, 320–1440 px. All 1004 emitted HTML/JS/CSS files are byte-identical
before/after this server-only fixture correction, so the sweep covers the
unchanged client build. Preview/required CI and production acceptance for this
cohort remain pending. Coverage is 240/725 coding, 485 remaining, with 225
coding and 263 native records deployed. Same-session model and finite checks;
no authenticated Premium, independent/human or complete-catalogue claim.


## Native promise content batch b043 — 15 October 2026

Read fulfillment mapping, fallback recovery, Promise.all totals, timer firing
order and allSettled error messages individually. Supplied then/catch variants
now follow the stated objective. Timer jobs capture original names and count,
so later caller edits cannot change or prevent completion. Contracts preserve
opaque fulfilled/fallback/error identity, adopt a promised fallback outcome,
consume initial promise-array membership and keep input-order Number folds.
Error messages include empty/duplicate text and are read after every settlement.

All 31 final-hash worker verdicts agree (20 valid, five starters, six wrongs),
versus 25/31 baseline. Twenty authored-target/base-25-XP checks, copy sweep,
focused coding including reversed hidden/native Run, API/script types, launch,
build, 263 native bindings, both zero-vulnerability production dependency
audits and diff checks pass. All 245 coding records match current full hashes.
Cases include exact opaque rejection/fulfillment/fallback references, literal
function/Symbol fallback values, promised fallback rejection, signed zero,
frozen native promises, fail-fast rejection beside a never-settling input,
input-order floating-point addition, post-call membership/name edits, deferred
microtask-versus-timer behavior, 1000 prices/zero-delay jobs/repeated errors and
current messages after a slower producer finishes. No global clock/timer hooks.
Finite watchdogs turn incorrect noncompletion into a case failure rather than
claiming exact physical timing. Targets exclude producer work and waiting.

Coverage is 245/725 coding, 480 remaining, and 263/263 native. Twenty coding
reviews are staged above verified #406: fifteen are frozen in #407 at f8fba18d,
with eleven exact-preview guest checks and required CI in progress; b043 adds
five on a separate continuation branch. No claim of authenticated changed-
Premium acceptance, independent/human reading or complete-catalogue coverage.
No runtime-engine, schema, UI, entitlement or reward-policy change.

## PR #407 exact production — 15 October 2026

PR #407 passed required run 38710148788 at exact f8fba18d8e7351c7cc8b5db5542aaa0d675bdc78 (verify 29m14s; SQL 50s), merged at f19169f107c3325fd22d635954937a99e0e2fe6d. READY production dpl_3rJe7gAv39RThwTcoEUGEbqQbJLt matches that merge, owns devshark.app and has no alias error. All eleven general guest checks pass with zero XP/null progress. These checks do not exercise the fifteen changed Premium tasks as an authenticated learner. Shipped coverage is 240/725 coding and 263/263 native; no independent/human or complete-catalogue acceptance claim.

The release covers b040–b042 and the current b040 throttle revision, with no duplicate review count. Five later b043 reviews are committed separately; they are not part of this production proof.

## 15 October — pre-initialization Promise.all restriction (#408)

The actual QuickJS grader accepted a top-level captured/bound native Promise.all
alias despite the task's prohibition. Its hidden check patched the function only
after learner initialization and immediately restored it. The new shared runtime
policy replaces the original native implementation before initialization in the
fresh Submit realm and disposable Run worker. Coding derives the rule from its
canonical task ID; reused Learn code carries it server-side. The Run controller's
aggregation helper stays outside learner scope. No host Promise is patched.
The obsolete hidden monkeypatch is removed; the next five-item content audit
will separately review the clone task's sparse-input/snapshot contracts.

Twelve selected programs are checked in both actual Submit (visible and hidden
partitions) and isolated Run: direct calls, initialized aliases, constructor and
reflection access, inheritance, dynamic Function and replacement/deletion attempts
are rejected; two manual aggregation forms pass. Two actual reused Learn grades
accept the manual form and reject the saved native alias. Other tasks and the
Node host retain native Promise.all. The real Chromium workbench rejects the
saved alias and then passes the reference on a second fresh worker.

API/script types, focused canonical coding (reversed hidden order and native
Run), complete updated grading/Learn integrity, launch, production build, all
263 native bindings, both production dependency audits (zero vulnerabilities)
and diff checks pass. The final additional reused-Learn assertions pass in the
focused suite and script typecheck. Twelve physical API handlers remain.

The first local browser attempt lacked a preview server; the second used a build
without CI's placeholder authentication configuration and failed the signed-in
run test while the other 22 checks passed. Neither attempt is a complete pass.
The final fixture-configured build uses CI's documented placeholder Auth URL/key,
with requests intercepted locally; it creates no real account/progress/name.
Final CI-fixture browser suite passes 23/23 checks; responsive validation passes all 264 probes (320–1440 px), with zero issues and zero unprobed routes. Authenticated
production Premium acceptance and physical devices remain unverified. This is
local evidence until the new PR's required checks, merge and exact release.

## Five-item continuation b044 — 15 October 2026

Five Promise tasks now cover exact timeout values/reasons, a stable fallback,
zero-delay scheduling, ordered prefix rendering, callback-throw rejection,
sparse/dense aggregation snapshots and first-then-second await semantics.
Clone Promise.all uses the runtime restriction committed separately under #408;
its reference boards now fill holes and use captured membership. The clone's
filled-skeleton fixture was updated too: the initial canonical test caught its
old algorithm and then an omitted inline scaffold comment. Final checks below
use the corrected fixture, not those failed attempts. A partial authoring pass
stopped before completing every source file and is excluded from final evidence.

Final five-item worker evidence is 31/31 selected verdicts (20 valid forms,
five starters, six wrongs), versus 25/31 labels matched by the original baseline.
All twenty target/base-25-XP checks pass; unknown complexity is unpenalized.
Per-item model scores, original-hash comparisons and separate final reading are
recorded in review-2026-10-15-b044.jsonl. All 250 current coding hashes match;
475/725 coding still require review, and native coverage remains 263/263.

Curation/index generation, final canonical coding (including reverse hidden
order, native Run and the filled skeleton), API/script types, launch, build,
263 native bindings, both production dependency audits (zero vulnerabilities),
copy sweep (zero findings) and diff checks pass. Existing IDs/history and archived
Czech are unchanged. PR #409 is frozen separately with b043/runtime #408; b044 is
not yet released. No live-account, authenticated Premium, independent/human or
complete-catalogue acceptance claim. Stateful factory complexity scope remains
open under #391.

## Five-item continuation b045 — 15 October 2026

Five cache/request/await tasks now define own-key cache semantics and safe
literal __proto__ storage, exact opaque values/reasons, correct request/json
arity and receiver, HTTP status versus parsing errors, dependency ordering and
fresh POST options/headers. All boards align with the authored async/await
lessons. The null JSON mock uses HTTP 200; a separate 204-like parsing failure
is forwarded. Bounds exercised include a 1000-unit cache key, a frozen sparse
1000-slot posts array and a 10000-unit serialized body. No real network is used.

Final evidence is 30/30 selected current-hash worker verdicts (20 valid forms,
five starters, five wrongs), versus the original baseline's 25/30 labels. All
twenty authored-target/base-25-XP checks pass, with unknown estimates unpenalized.
Individual scores and final reading are in review-2026-10-15-b045.jsonl. All 255
current coding hashes match; 470 coding items remain, and native is 263/263.
Curation/index generation, canonical coding including reverse hidden/native Run,
API/script types, launch, build, native bindings, both production dependency
audits (zero vulnerabilities), copy sweep (zero findings) and diff checks pass.

B044–b045 are not yet released; frozen PR #409 separately contains b043 and
runtime #408, with exact READY preview and eleven general guest checks. Required
CI/production remain pending. No live-account, authenticated Premium,
independent/human or complete-catalogue acceptance claim. Owner holds remain.

## Factory workload scope correction (#410) — 15 October 2026

Before correction, actual probes showed O(1) for two limiter boards, one curry
board and all three latest-only boards, comparing cheap construction with a
whole-sequence/per-gathering goal or deferred work. All nine actual boards now
return null time/unknown assessment with the authored target preserved and base
25 XP. The banner's existing null-time rule hides the entire complexity row.

Bounded AST value reachability follows direct closures, local bindings and
assignments, conditional returns, methods/accessors, callable containers and
executed named helpers. A 500-link alias case stays unknown without copying a
growing Set at every step. Dynamic value flow is still a manual-review limit;
this is not general interprocedural/lifetime analysis or a benchmark. Eager map
analysis remains O(n), a reliably quadratic eager solution still earns 15 XP,
and an uncalled local factory does not replace its caller's eager workload.

Final focused complexity contracts, API/script types, complete updated
grading/Learn integrity, launch, build, native 263 bindings, both production
dependency audits (zero vulnerabilities) and diff checks pass. All 1004 emitted
HTML/JS/CSS files are byte-identical before/after this server-only correction.
It adds no unique content review. B044–b045 separately pass all 80 probes on their ten actual task routes
at 320–1440 px, with zero issues and zero unprobed routes.
No schema/RLS, activation, access, reward ordering, handler-count or dependency
change. Existing twelve handlers and owner holds remain. Required PR checks,
merge and exact production are pending; #410 remains open.

## PR #409 exact production — 15 October 2026

PR #409 passed required run 38717316234 at exact 57dff6387d0a3f6b521afe1c9483bcfe3148d604 (verify 30m05s; SQL 41s), merged at da47f1957a6a012b70a085e59e42f8ef5ab51168. READY production dpl_BAbKFtd8CPMbsnunkdDXyS7WtQ3J matches that merge, owns devshark.app and has no alias error. All eleven general guest checks pass with zero XP/null progress. Three actual served Run-worker contracts block a captured native Promise.all alias, accept manual aggregation under the restriction and retain native aggregation for another task. Those worker checks make no server submission. Shipped coverage is 245/725 coding and 263/263 native. This does not establish authenticated server-side Premium, physical-device, independent/human or complete-catalogue acceptance.

The runtime #408 implementation is complete; its separate issue can close with this evidence. B044–b045 and scope correction #410 remain in the follow-up branch. The ten-task responsive sweep passes 80/80 probes, zero issues/unprobed, and the 410 server-only change keeps all 1004 emitted UI files byte-identical.

## Scope correction: containers filled later — 15 October 2026

A further regression reproduced O(1) when a factory first created an empty
object and then assigned its callable member. Bounded possible-alias/container
tracking now covers property/element writes and common container mutators too.
Fourteen generic deferred source shapes, a 500-link alias chain and all nine
actual limiter/curry/latest-only boards report unknown/25 XP; eager linear and
reliably quadratic checks retain their 25/15 XP behavior. Dynamic flow still
needs manual review and no universal interprocedural-analysis claim is made.

Final focused contracts, API/script types, complete grading/Learn integrity,
launch/build, native 263, both production dependency audits (zero vulnerabilities)
and diff checks pass. All forty b044–b045 target/base-25-XP checks pass again
against the final inspector. All 1004 emitted UI files remain byte-identical;
the existing 80-probe ten-task matrix therefore still applies. No new unique
review or live user-data action. #410 awaits checked release.

## Five-item continuation b046 — 15 October 2026

Five async/graph tasks now define finally cleanup/exception precedence,
initial batch membership and fail-fast current-batch rejection, latest-only
observation timing and synchronous reentry, own-key-safe ancestor-Set JSON
copying, and sequential retry budgets including zero. Correct spinner boards
are retained; conflicting method variants are aligned. The latest-only target
is per run, with factory analysis withheld under #410. Expanded graph/output
size counts repeated shared subtrees, not only unique objects.

Final evidence is 30/30 selected current-hash worker verdicts (20 valid forms,
five starters, five wrongs), versus the original baseline's 25/30 labels. All
twenty authored-target/base-25-XP checks pass. Cases include 1000 concurrent
batch workers, 1000 overlapping wrapper calls, depth-100 frozen cyclic data,
1000 shared records, lone surrogates and 1000 sequential failed attempts.
No timer/clock is stubbed and no elapsed duration is used to infer Big O.

Individual scores/final reading are in review-2026-10-15-b046.jsonl. All 260
coding hashes match; 465 coding tasks remain and native stays 263/263.
Curation/index generation, canonical coding with reversed hidden/native Run,
API/script types, launch/build, native bindings, both production dependency
audits (zero vulnerabilities), copy sweep (zero findings) and diff checks pass.
B046 is not released. Frozen #411 contains only b044–b045 and scope #410;
#409/runtime #408 are exact-production verified. No live-account, authenticated
Premium, independent/human or complete-catalogue acceptance claim.

## B046 batch-start fixture revision 2 — 15 October 2026

The input-mutation fixture assumed the first worker registered before the
wrapper returned. A valid async implementation captures items immediately and
awaits one microtask before its first batch; the task does not forbid this.
Adding that form reproduced a false failure (30/31 selected verdicts matched).
The producer gate is now created before the wrapper is invoked, preserving the
mutation check without that extra timing assumption. No prompt policy changed.

Final evidence is 31/31 current-hash verdicts across the five items (21 valid
forms, five starters, five wrongs), including seven for the revised batch item.
Twenty existing target/base-25-XP checks plus the new form's check pass. The new
form also passes every current visible/hidden check in isolated native Run and
is a permanent canonical coding variant. Final curation/index generation,
focused coding (reverse hidden/native Run), API/script types, launch/build,
native 263, both production dependency audits (zero vulnerabilities) and diff
checks pass. The original record/source commit are retained in history; one
current record is revision 2, with zero added unique coverage. All 260 coding
hashes match and 465 still require review. This remains unreleased.

## PR #411 exact production and session checkpoint — 15 October 2026

PR #411 passed required run 38722800635 at exact head 60caa1e873ac97fe8c094449be91080d5638a450 (verify 25m03s; SQL 39s), and merged at ad67b83113b06408fe68c2cba16b0160e1a3927f on 15 October 2026 at 11:18:23 UTC. READY production dpl_9aEaAboGu1kQn4xrPZW3TdJGKB4u matches that merge, owns devshark.app and has no alias error. All eleven general guest checks and four actual factory Submit checks pass on that production: valid free running-average/cancel-timer factories return null-time/unknown with authored targets preserved, and wrong implementations fail. All submissions grant zero XP and return null progress. Shipped coverage is 255/725 coding reviews and 263/263 native reviews. This does not establish authenticated Premium, physical-device, independent/human or full-catalogue acceptance.

The owner requested ending this session and continuing the audit later. Current individual model review coverage is **260/725 coding** and **263/263 native**; **465 coding tasks remain** (66 JavaScript, 146 TypeScript, 183 React, 70 algorithms). Five completed b046 reviews remain in branch `codex/content-audit-b046-onward`: initial five-item commit e7888215, fixture revision 2 at 244245da, then a main merge and release-checkpoint documentation. Final b046 evidence is **31/31** selected current-hash verdicts (21 valid, five starters, five wrongs), **21** authored-target/base-25-XP checks, canonical native Run/reversed hidden order, and a permanent valid deferred-start variant. Current review hashes match all 260 records. All prescribed local types, grading/content gates, launch/build and both production dependency audits pass (zero vulnerabilities). B046 has not been merged or production-verified; its PR must pass mandatory checks before merge and exact production verification. The prior ten b044–b045 reviews have 61/61 selected verdicts, forty target checks and 80/80 responsive probes. Those visual results do not claim a separate B046 responsive matrix. Runtime #408 and factory-scope #410 are production-verified and complete.

No b047 content changes or reviews were started. Suggested next five IDs, to re-read against the then-current catalogue: `js-run-tasks-in-order`, `js-mh-thread-from-list`, `js-mh-batch-loader`, `js-mh-shared-request`, `js-lru-cache`. Resume only when the owner requests it, reconcile inventory/hashes first, and continue one commit per five reviewed items. Bank/override/copy/longest-option reconciliation, hidden system-design review, authenticated/independent acceptance and all recorded owner holds remain separate. Preserve historical hides and held draft #365.

The completed B046 cohort is prepared as a separate PR. Its mandatory CI, merge, and exact production verification remain pending at session end. Do not infer completed release from local checks. No schema/auth/RLS, entitlements, dependency or handler changes; twelve physical API handlers remain. No owner account state, leaderboard identity or positive score was used as a fixture.

## PR #412 verified release and resumed audit — 15 October 2026

PR #412 passed required run 38727343919 at exact head 76c80b0af9715f29e414a512f5ea72b768ad89bd (verify 29m44s; SQL 56s), then merged at 137dbb786b567bd434cd64901306ec2c29a83617 on 15 October 2026 at 12:25:38 UTC. Preview dpl_D55uMQsJ9RWbRTF85sWUbULJZhNH and production dpl_7fTpF5BV7kKcwEhZ3KP4xCjEEZMW are READY at their exact head/merge; production owns devshark.app with no alias error. Eleven general guest checks pass on each, including actual correct/wrong React and JavaScript Submit, zero XP/null progress. B046 local evidence remains 31/31 selected current-hash verdicts, 21 target/base-25-XP checks and its permanent valid deferred-start variant. Shipped model-review coverage is 260/725 coding and 263/263 native. These guest checks do not establish authenticated execution of the five Premium tasks, independent/human review, physical-device or full-catalogue acceptance.

The owner subsequently requested continuing the audit and remaining issues. Work resumes from current main, preserving held draft #365 and recorded owner decisions.

## Five-item continuation B047 — 15 October 2026

Five individual English reviews cover sequential task snapshots, typed-ID comment
forests, independent timed loader batches, per-entry shared-request identity and
the fixed five-entry LRU simulation. Newly explicit domains distinguish data
contracts from prior failures. Keep IDs/history and correct alternatives; do not
require synchronous first-task startup or producer-Promise identity.

The original baseline matched 25/30 verdicts: all five meaningful wrongs passed.
Final selected evidence is 30/30 (20 valid, five starters, five wrongs), with all
twenty authored-target/base-25-XP checks passing. The two valid alternative
scheduling/rethrowing forms are permanent canonical variants. Focused canonical
coding passes isolated native Run and reversed hidden tests. All 265 current
individual coding hashes match; 460 remain. Native remains 263/263. These are
same-session model reviews, not authenticated Premium or independent acceptance.

API/script types, complete grading/Learn integrity, launch/build, native bindings,
curation/index generation, both production dependency audits (zero vulnerabilities)
and diff checks pass. The five changed task routes pass 40/40 fixture-backed
responsive probes at 320–1440 px in the default theme. The copy sweep has one
reviewed false positive: “the first pass” describes the comment-tree algorithm,
not reviewer workflow; no audit note or option-position clue is introduced.
Twelve physical API handlers remain; no schema/RLS, dependency, reward or access
policy changed. PR #412 is exact-production verified; these five B047 reviews
still await their own checked release. The owner has resumed the audit.

## Five-item continuation B048 — 15 October 2026

Five TypeScript reviews cover inferred UTF-16 length totals, generic callback
arity/results, round-robin absence versus empty names, one-pass extrema with
earliest signed-zero ties, and identity-preserving generic tuple reversal.
Correct alternatives remain accepted. The queue brief states the copied-shift
approach's quadratic single-size upper bound and more precise O(w + t*w), while
allowing faster indexing; it does not mislabel repeated shifts linear.

The baseline matched 25/30 verdicts, accepting five meaningful wrongs. Final
selected evidence is 30/30 (20 valid, five starters, five wrongs), and twenty
authored-target/base-25-XP checks pass. Sixteen runtime and five hidden type
assertions cover previously missing units, identity, ordering and generic output
relationships. Canonical focused coding passes actual TypeScript checking,
isolated native Run, reversed hidden checks and all model boards. All 270 current
coding review hashes match; 455 remain. Native stays 263/263. API/script types,
launch/build, native bindings, curation/index generation, both production audits
(zero vulnerabilities), copy sweep (zero findings) and diff checks pass. B047
also passes its dark-theme matrix, bringing that five-task cohort to 80/80
responsive probes at 320–1440 px. No authenticated Premium, independent/human or
complete-catalogue claim. B048 also passes 80/80 fixture-backed light/dark responsive probes at 320–1440 px, zero issues/unprobed. Both new cohorts still await checked release.

## Production override and retention reconciliation — 15 October 2026

Read-only production checks confirm 485 deleted overrides, no active edits/custom
questions, the same deleted identities as 14 October (lexically sorted IDs joined
with newline, MD5 7271a4b58a6e2b174fe541351d7cbdc4), and 1820 effective eligible
questions after 194 eligible hides. Every effective question has a current
review binding. The active retention schedule calls a function including practice
purging; no checked excess TRUNCATE/REFERENCES/TRIGGER/MAINTAIN grant remains for
anon/authenticated on the eleven tables in #236. The purge was not invoked.
Evidence is docs/audit/question-overrides-2026-10-15.json; no database, learner
state, historical hide or marketing setting changed. Copy/longest-option
reconciliation and owner decisions remain open.

## Five-item continuation B049 — 15 October 2026

Five readonly/formatting reviews cover index-based route legs, truly fresh padded
arrays, stable standard-lowercase UTF-16 sorting, shallow header/rest identity and
exact nested order formatting. Correct alternatives remain accepted. The readonly
hint no longer claims runtime method removal, ASCII ordering is scoped correctly,
and lowercase-key equality is distinguished from Unicode case folding.

The baseline matched 25/30, accepting five meaningful wrongs. Final evidence is
30/30 selected current-hash verdicts (20 valid, five starters, five wrongs) and
twenty target/base-25-XP checks. Nineteen runtime/four type assertions cover
previously missing empty values, fresh mutable results, opaque row references,
Unicode ordering, sparse item counts and maximum bounded inputs. Canonical
coding passes actual TypeScript checking, reversed hidden checks and isolated
native Run. All 275 current coding review hashes match; 450 remain. Native remains
263/263. API/script types, launch/build, native bindings, curation/index, both
production dependency audits (zero vulnerabilities), copy sweep (zero findings)
and diff checks pass. The five changed routes pass 80/80 fixture-backed light/dark
responsive probes at 320–1440 px with zero issues/unprobed. Same-session model
review only; authenticated Premium/independent acceptance remains separate.

PR #413 remains frozen at 9c8f7265631ee2d025edc8a38d89b5f47587c0aa while B049 is
committed separately. That exact READY preview passes eleven general guest checks
and twelve actual changed-task Submit verdicts (reference, valid alternative and
wrong for four free tasks), all zero XP/null progress. Six tasks return 402 and
remain explicitly blocked for dedicated Premium acceptance. Required CI and
production for #413 are pending; B049 is not part of that frozen PR.

## Five-item continuation B050 — 15 October 2026

Five individual object/default reviews cover guarded own expense keys, exact
pinned-name consolidation, shallow todo metadata preservation, two-level user
copies and accurate unconstrained generic nullish fallback. The todo senior's
valid already-done no-op reuse remains allowed. Generic T may itself be nullable;
no NonNullable constraint or unsupported always-present promise is introduced.

The baseline matched 25/30 verdicts, accepting five meaningful wrongs. Final
evidence is 30/30 selected current-hash verdicts (20 valid, five starters, five
wrongs) and twenty target/base-25-XP checks. Eighteen runtime/seven type assertions
exercise inherited/extra keys, exact opaque/Symbol/prototype-like metadata,
shallow identity, duplicate IDs, nullable/undefined/union generic instantiations
and maximum bounded inputs. Canonical coding passes actual TypeScript checking,
reversed hidden cases and isolated native Run. All 280 current coding hashes
match; 445 remain. Native stays 263/263. API/script types, launch/build, native
bindings, registry/index generation, both production dependency audits (zero
vulnerabilities), copy sweep (zero findings) and diff checks pass. Final complete
grading/Learn integrity also passes on the B049–B050 tree. The five changed routes
pass 80/80 fixture-backed light/dark responsive probes at 320–1440 px with zero
issues/unprobed. These are same-session model reviews, not authenticated Premium
or independent/full-catalogue acceptance. Exactly twelve handlers remain; no
schema/RLS, dependency, entitlement, account-data or reward-policy change.

## PR #413 exact production — 15 October 2026

PR #413 passed required run 38737325851 at exact head 9c8f7265631ee2d025edc8a38d89b5f47587c0aa (verify 28m15s; SQL 49s), then merged at 0b754f3192b1514a4c5d5b51d2d9cb1cd65f49da on 15 October 2026 at 13:17:21 UTC. READY production dpl_FUWzWDu9seJZ9XMi3vmUr6984omJ matches that merge, owns devshark.app and has no alias error. Both exact preview and production pass eleven general guest checks plus twelve actual changed-task Submit verdicts: reference, valid alternative and meaningful wrong for four available TypeScript tasks. Six tasks return 402 and remain explicitly unverified through the dedicated Premium path. All guest submissions grant zero XP and return null progress. Local cohort evidence remains 60/60 final-hash selected verdicts, forty authored-target/base-25-XP checks and 160 light/dark responsive probes. Shipped model-review coverage is 270/725 coding and 263/263 native. No authenticated Premium, independent/human, physical-device or full-catalogue acceptance claim.

PR #414 now targets main at fixed c01f700c8c34e612235141cdca265e20fe5f4e63. Its exact READY preview passes eleven general guest checks and six changed-task Submit verdicts at zero XP/null progress; eight tasks return402. Its SQL job passes and verify remains pending. B051 is developed separately from both frozen PR heads.

## Five-item continuation B051 — 15 October 2026

Five individual reviews cover closed Light transitions, typed priority ranks,
doubling schedules, API field defaults and insertion-ordered Set toggles. Correct
cycle shortcuts, stable linear buckets, frozen schedules and filter/copy variants
remain accepted. Readonly terminology now describes static views accurately. The
Set scratch demo waits until the function returns a Set, so an untouched starter
fails checks without an accidental top-level spread error.

The baseline matched 26/30 expected labels: three wrongs were falsely accepted
and one starter returned error rather than failed; reverse-cycle and shared-output
wrongs were already rejected. Final evidence is 30/30 (20 valid, five starters,
five wrongs), with twenty authored-target/base-25-XP checks. Sixteen runtime/six
type assertions cover bounds, stable references, output lifetime, exact strings,
undefined defaults and Set order. All 285 current review hashes match; 440 coding
tasks remain and native stays 263/263. Canonical TypeScript checks, isolated native
Run, reversed hidden order, API/script types, launch/build, registry/index, native
bindings, both production dependency audits (zero vulnerabilities), copy sweep
(zero findings) and diff checks pass. The five changed routes pass 80/80 light/dark
fixture-backed responsive probes at 320–1440 px, zero issues/unprobed.

A development parameter-pattern default produced a real compiler error and was
replaced by body destructuring before final approval; no failing board was
approved. These are same-session model reviews with finite executable evidence.
B049–B050 stay frozen in #414; B051 is separate and not yet released. No schema,
RLS, dependencies, entitlements, real-account state or reward rules changed; twelve
physical handlers remain. Direct production has_table_privilege checks additionally
confirm zero excess grants over all 88 combinations, including MAINTAIN; this is
stronger than relying only on information_schema table_privileges.

## PR #414 exact production — 15 October 2026

PR #414 passed required run 38740773379 at exact head c01f700c8c34e612235141cdca265e20fe5f4e63 (verify 30m43s; SQL 42s), then merged at 1240d724b94b44282df486a278325e5b57b455d3 on 15 October 2026 at 13:49:00 UTC. READY production dpl_76YkFQ5v4AxdEaizSWA3DaiqZywJ matches that merge, owns devshark.app and has no alias error. Both exact preview and production pass eleven general guest checks plus six actual changed-task Submit verdicts: reference, valid alternative and meaningful wrong for two available TypeScript tasks. Eight tasks return 402 and remain explicitly unverified through the dedicated Premium path. All guest submissions grant zero XP and return null progress. Local cohort evidence remains 60/60 final-hash selected verdicts, forty authored-target/base-25-XP checks and160 light/dark responsive probes. Shipped model-review coverage is 280/725 coding and263/263 native. No authenticated Premium, independent/human, physical-device or full-catalogue acceptance claim.

## Five-item continuation B052 — 15 October 2026

Individually read and repaired note tags, airport route names, path length,
basket pricing and visited grid squares. Note updates preserve own enumerable
string/Symbol metadata, opaque references and exact no-op identity. Route tokens
retain empty/space/Unicode cases. All nontrivial path comparisons now accept a
stated absolute/relative tolerance while rejecting non-finite results; the
actual exp/log alternative previously failed strict equality and now passes.
Basket errors name the first missing product in input order. Grid equality is
by bounded integer coordinate value, including signed zero, without mutation.
Targets state their input sizes and average Map/Set or bounded Number models.

All 30 selected final-hash verdicts agree (20 valid, five starters, five wrongs),
versus 24/30 baseline: five false passes and one correct rounding variant rejected.
Twenty authored-target/base-25-XP checks pass; unknown complexity stays hidden
and unpenalized. Seventeen added runtime and four added static assertions cover
frozen/null-prototype data, metadata/aliasing, 1000-element limits, empty tokens,
first missing errors and floating results; original Note static checks remain.
Canonical focused coding passes actual TypeScript checks, native Run and reversed
hidden cases. All 290 current review hashes match, 435 coding reviews remain.
Native remains 263/263. API/script types, launch, build, registry/index generation,
full grading/Learn integrity on the B051–B052 tree, native bindings, both production
dependency audits (zero vulnerabilities), copy sweep (zero findings) and diff pass.
All 80 fixture-backed light/dark probes across these five routes at 320–1440px
pass with zero issues/unprobed. Same-session model self-review and finite
execution; no independent/human, physical-device or authenticated Premium claim.

B051–B052 add ten reviews above production-verified #414 (280 deployed). They
await their own required PR checks, merge and exact-production acceptance. No
schema/RLS, handler, dependency, UI or entitlement/reward-policy change; no real
account state is a test fixture. Nine existing issues remain open for actual
residuals/owner holds; none is closed merely because its implementation subset
has passed. Marketing draft #365 stays held.

## Five-item continuation B053 — 15 October 2026

Individually audited UTC fillDays, mixedTotal, parent paths, reply errors and firstError. Preserved exact inputs, empty segments/messages, UTF-16 lengths, ordered Number folds and independent output tuples. Changed the incorrect junior path join to append/reverse/join and replaced potentially quadratic instructional boards with linear collection. Date bounds include output day count; the original fixed-UTC alternative remains accepted.

All 30 final-hash selected verdicts agree (20 valid, five starters, five wrong), versus 25/30 baseline. Twenty authored-target/base-25-XP checks pass after correcting a target phrase the guidance parser did not recognize. The earlier failed target and transient stale registry are not final acceptance. Seventeen added runtime/four added static assertions retain existing date tuple checks. Canonical focused coding includes actual TypeScript, native Run, reversed hidden cases and this calendar task in UTC plus four other time zones. API/script types, launch, build, registry/index generation, 263 native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings) and diff pass. All 295 current coding hashes match; 430 remain.

All 80 fixture-backed light/dark responsive probes over five task routes at 320–1440px pass, zero issues/unprobed. B051–B052 remain frozen in PR #415 at cd003932eeaab7c8c42957cfe45278ba2864e0a5; B053 is separate, with 15 later reviews above the 280 deployed in #414. No schema/RLS, handler, dependency, UI or reward-policy change. Same-session model/finite execution, not independent/human, authenticated Premium or full-catalogue acceptance. All owner holds, including draft #365, remain unchanged.

## Five-item continuation B054 — 15 October 2026

Individually audited Celsius conversion, file predicates, unknown-value classification, parsed User guards and fixed Accent validation. Cases preserve frozen input records and file identity, check negative-zero conversion and exact text, classify nonfinite primitive numbers/boxed values without coercion, and retain the stated structural guard behavior for inherited data. Corrected an explanation that overstated restrictions on unknown. isUser checks declared types; it does not silently add business-validation rules. These are isolated teaching tasks, not account-validator changes.

All 30 final-hash selected verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. Twenty authored-target/base-25-XP checks pass. Sixteen new runtime/four new static assertions preserve existing predicate checks. An initial fixture tried to assign a function's readonly name; that fixture was corrected before acceptance. Canonical focused coding includes actual TypeScript, native Run and reversed hidden checks. All 300 coding hashes match; 425 remain. Native 263/263. API/script types, launch, build, registry/index, full grading/Learn integrity on B053–B054, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings) and diff pass. All 80 fixture-backed light/dark probes at 320–1440px pass with zero issues/unprobed. Exactly 12 physical API handlers; no schema/RLS, dependency, UI or entitlement/reward-policy change.

B053–B054 add ten later reviews beyond frozen PR #415. Together 20 reviews are staged above the 280 deployed in #414. Their required checks, merge and exact-production acceptance remain separate. Same-session model self-review and finite execution only; no independent/human, physical-device, authenticated Premium or full-catalogue claim. All owner holds, including marketing draft #365, remain unchanged.

## Five-item continuation B055 — 15 October 2026

Individually audited discount savings, shape areas, primitive-string guards, original-offset edits and playlist durations. Discount checks distinguish rounded savings from a rounded remainder. Edit validation rejects nonintegral/nonfinite indices before overlaps and builds output with chunks rather than repeated growing-string copies. The TypeScript explanation now acknowledges inferred predicates since 5.5; the actual 5.9.3 checker accepts the selected inferred guard. A permanent known-right fixture protects it. The older last-invalid-edit mutation fixture was updated to match the new integer-validation prefix; it still fails as intended.

All 30 final-hash selected verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. Twenty authored-target/base-25-XP checks pass. Seventeen new runtime/three new static assertions preserve existing exhaustive/readonly result checks. Canonical focused coding passes actual TypeScript, native Run, reversed hidden checks and both applicable known-answer verdicts. All 305 coding review hashes match; 420 remain. API/script types, launch, build, registry/index generation, 263 native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark responsive probes at 320–1440px pass. Initial stale known-answer applicability failed the canonical gate and was fixed before this acceptance. No schema/RLS, handler, dependency, UI or real billing/account-state change.

PR #415 has passed mandatory verify/SQL at cd003932 and merged; exact production verification is pending. PR #416 targets main after its parent merge and remains fixed at 808dcb1d, with exact preview general/changed-task checks passed. B055 is separate from both fixed heads. Model self-review/finite checks only; no independent/human, physical-device, authenticated Premium or full-catalogue claim. All activation/publication holds remain.

## PR #415 exact production — 15 October 2026

PR #415 passed required run 38747201800 at exact head cd003932eeaab7c8c42957cfe45278ba2864e0a5 (verify 27m34s; SQL 44s), then merged at 40344faaac1cd8bdf997964b721b63673a02f2fd on 15 October 2026 at 14:28:11 UTC. READY production dpl_J6oZAGKoGaaNcB3T6hqjK5XEjjHm matches that merge, owns devshark.app and has no alias error. Both exact preview and production pass eleven general guest checks plus three actual changed-task Submit verdicts: reference, valid alternative and meaningful wrong for the available Set-toggle task. Nine changed tasks return 402 and remain explicitly unverified through dedicated Premium acceptance. All guest submissions grant zero XP and return null progress. Local cohort evidence remains 60/60 selected final-hash verdicts, forty authored-target/base-25-XP checks and 160 fixture-backed light/dark responsive probes. Shipped model-review coverage is 290/725 coding and 263/263 native. No authenticated Premium, independent/human, physical-device or full-catalogue acceptance claim.

## Five-item continuation B056 — 15 October 2026

Individually audited enum counts, ranked record entries, everyNth, chunk and zip. Exact references, input preservation, independent mutable containers and dense-array bounds are explicit. Ranked ties follow Object.entries ownership/enumeration; inherited/symbol/hidden properties are ignored. everyNth now calls its positional stride step, leaving n unambiguous as the input-size variable. Correct filter/group/map alternatives remain accepted despite the stepping-loop teaching boards.

All 30 current-hash selected verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. The six everyNth checks were re-run after a final grammar correction and are the final-hash evidence used in the ledger. Twenty authored-target/base-25-XP checks pass; unknown remains hidden/unpenalized. Sixteen added runtime/five added static assertions cover frozen opaque values, caller order, fresh groups/pairs, integer key ties, signed zero and 1000-element boundaries. Canonical focused coding passes actual TypeScript, native Run and reversed hidden checks. All 310 coding review hashes match; 415 remain. Native 263/263. API/script types, launch, build, registry/index generation, final B055–B056 grading/Learn integrity, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark probes at 320–1440px pass. Exactly 12 physical handlers; archived Czech untouched.

#415 is merged and exact-production verified at 40344faa (290 coding plus 263 native reviews). #416 has ten fixed later reviews at 808dcb1d with SQL and exact-preview guest checks passed; verify/merge/exact production remain pending. B055–B056 add ten separately. Individual same-session model self-review and finite execution only; no independent/human, physical-device, authenticated Premium or whole-catalogue claim. No schema/RLS, dependency, UI, account-state or entitlement/reward-policy change. All owner activation/publication holds remain.

## PR #416 exact production — 15 October 2026

PR #416 passed required run 38750173289 at exact head 808dcb1def07618d95e9cbcab87168df7d1e81b4 (verify 25m24s; SQL 43s), then merged at 9827c3b293b6b04dcb882048fa4c16dbf170210d on 15 October 2026 at 14:44:44 UTC. READY production dpl_6ap6UQNPJa92x8FfCFE4kT91EPk5 matches that merge, owns devshark.app and has no alias error. Both exact preview and production pass eleven general guest checks plus six actual changed-task Submit verdicts: reference, valid alternative and meaningful wrong for the file-filter and parsed-object-guard tasks. Eight changed tasks return 402 and remain explicitly unverified through dedicated Premium acceptance. All guest submissions grant zero XP and return null progress. Local cohort evidence remains 60/60 selected final-hash verdicts, forty authored-target/base-25-XP checks and 160 fixture-backed light/dark responsive probes. Shipped model-review coverage is 300/725 coding and 263/263 native. No authenticated Premium, independent/human, physical-device or full-catalogue acceptance claim.

## Five-item continuation B057 — 15 October 2026

Individually audited first-value selection, adjacent runs, constrained length comparison, active records and newest versions. Generic selectors preserve exact opaque values and winner references; containers are independent and mutable. groupRuns calls its callback once per item with one argument, preserves stateful key order and propagates thrown values. The length selector uses strict b.length>a.length consistently, with explicit unordered-NaN fallback. Newest-version boards use Map presence and first-ID/earliest-tie semantics rather than a quadratic scan or implicit sentinel.

All 30 final-hash selected verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. Twenty authored-target/base-25-XP checks pass. Eighteen added runtime/four added static assertions cover frozen/sparse native arrays, callback arity/throw order, exact references, inherited stable data, nonfinite comparisons, prototype-like IDs and 1000-element bounds. Canonical focused coding passes actual TypeScript, native Run and reversed hidden checks. All 315 coding review hashes match; 410 remain. Native 263/263. API/script types, launch, build, registry/index, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark responsive probes at 320–1440px pass. Final full grading/Learn recheck for the next two-batch cohort is still pending; the prior B055–B056 tree passed it.

#416 is merged and exact-production verified at 9827c3b2 (300 coding plus 263 native reviews). #417 now targets main at fixed 86a5b1eb with ten later reviews; its required checks/preview/production are separate. B057 adds five in this continuation. Same-session individual model self-review and finite execution; no independent/human, physical-device, authenticated Premium or whole-catalogue claim. No schema/RLS, handler, dependency, UI, account-state or entitlement/reward-policy change. All activation/publication holds remain.

## PR #417 exact production — 15 October 2026

PR #417 passed required run 38753165919 at exact head 86a5b1ebadcc67d42d27f18213d21d35dcd24e43 (verify 24m58s; SQL 43s), then merged at 901fc0533ab5e09e8f44f76a56ccb2e852f85510 on 15 October 2026 at 15:16:50 UTC. READY production dpl_CDHb5FE8ZG6pfRrJzpGVAnWhsDKY matches that merge, owns devshark.app and has no alias error. Both exact preview and production pass eleven general guest checks; all ten changed tasks return 402, with zero changed-task Submit verdicts, and remain explicitly unverified through dedicated Premium acceptance. All actual general guest submissions grant zero XP and return null progress. Local cohort evidence remains 60/60 selected final-hash verdicts, forty authored-target/base-25-XP checks and 160 fixture-backed light/dark responsive probes. Shipped model-review coverage is 310/725 coding and 263/263 native. No authenticated Premium, independent/human, physical-device or full-catalogue acceptance claim.

## Five-item continuation B058 — 15 October 2026

Individually audited cheapest offers, replacement by ID, cursor pages, grouping by a key and a typed reducer. Replacement now updates every matching ID consistently across the boards. Grouping uses Partial<Record<K,T[]>> because absent keys have no group; dictionaries safely handle prototype-like string keys, numeric coercion and Symbols. Existing public type expectations were corrected and an unsafe missing-group access now fails. The reducer uses a linear loop and calls its step with exactly accumulator and item; returned opaque references and deliberate accumulator mutation remain valid. Inputs, stable ties, fresh mutable containers and callback/throw order are explicit.

All 30 final-hash selected verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. The six cursor-page verdicts were rerun after normalizing the authored target wording and provide its final-hash evidence. Twenty authored-target/base-25-XP checks pass; unknown estimates remain hidden and unpenalized. Nineteen added runtime/five added static assertions preserve existing cursor checks. The final grouping alternative uses a canonical-key Map and a null-prototype output, after the older plain-object alternative was found incompatible with absent inherited names. Canonical focused coding passes actual TypeScript, native Run and reversed hidden checks. All 320 coding review hashes match; 405 remain. Native 263/263. API/script types, launch, build, registry/index, final B057–B058 grading/Learn integrity, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark responsive probes at 320–1440px pass. Twelve physical handlers; archived Czech untouched.

PR #417 is merged and exact-production verified at 901fc053 (310 coding plus 263 native reviews), with eleven general guest checks and all ten changed tasks explicitly blocked by Premium gating. B057–B058 add ten source reviews separately; required checks, merge and exact-production acceptance remain pending. Same-session individual model self-review and finite execution only; no independent/human, physical-device, authenticated Premium or whole-catalogue claim. No schema/RLS, dependency, UI, real-account state or entitlement/reward-policy change. All owner activation/publication holds remain.

## Five-item continuation B059 — 15 October 2026

Individually audited named sorting, one-field Product updates, column sorting, pluck and setting fallbacks. Sorting explicitly uses case-sensitive UTF-16 code-unit order and stable exact record references. All sortByName boards now use the same comparator; readonly guidance describes the type interface accurately. Product spread preserves own enumerable Symbol/literal __proto__ metadata without invoking target setters. Pluck preserves opaque values and optional undefined positions. Settings lookup never writes defaults into saved data; null remains outside Partial<Settings> rather than invalidating the correct junior undefined branch.

All 30 final-hash selected verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. Twenty authored-target/base-25-XP checks pass; unknown estimates remain hidden/unpenalized. Sixteen added runtime/five static assertions preserve existing checks. A malformed expected Unicode literal in an initial fixture was corrected before final execution and approval. Canonical actual TypeScript, native Run, reversed hidden checks, API/script types, launch, build, registry/index, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings) and diff pass. All 325 coding hashes match; 400 remain. Native 263/263. All 80 fixture-backed light/dark probes at 320–1440px pass with zero issues/unprobed. Exactly twelve physical handlers; archived Czech untouched.

PR #418 remains frozen at df419127 with ten B057–B058 reviews. Its exact READY preview passes eleven general guest checks; all ten changed tasks return 402, with zero changed-task Submit verdicts. Required SQL passed, verify/merge/exact production remain pending. B059 is separate from that head. Same-session individual model self-review and finite execution, without independent/human, physical-device, authenticated Premium or whole-catalogue claims. No schema/RLS, dependency, UI, real-account state or entitlement/reward-policy change. Nine open issues retain actual residuals and owner holds; held draft #365 is unchanged.

## Five-item continuation B060 and unsupported cost models — 15 October 2026

Individually audited multi-key projection, text-table formatting, missing Post fields, new Todo creation and Weekday narrowing. Projection keeps opaque references and independent rows. Table formatters are own entries, called once per cell in row-major order with one argument, with explicit UTF-16 padding/empty-column rules. Missing-field reads preserve the draft. Todo creation now assigns its calculated ID after spread; Omit is explained as a type view rather than a runtime sanitizer. Weekday static checks cover all five weekdays and both narrowing branches; old runtime checks already covered all seven days.

All 30 final-hash selected verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. Fifteen added runtime/five static assertions preserve existing cases. Twenty authored-target/base-25-XP checks pass, including an inferred weekday predicate on the actual TypeScript 5.9.3 checker. All 330 current coding review hashes match; 395 remain. Native 263/263. Canonical actual TypeScript, native Run, reversed hidden checks, API/script types, launch/build, registry/index, final B059–B060 grading/Learn integrity, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark probes at 320–1440px pass with zero issues/unprobed. After adding six permanent actual-task complexity regressions, script types and launch passed again.

Issue #419 records an additional discovered display bug: independent item/key scans were labelled O(n^2) despite their authored O(n*m) model. Separate commit fa1eb91f makes unsupported authored cost models return unknown/time=null while preserving the desired target and base 25 XP. Five model regressions and six actual task-board regressions cover independent/output-sensitive dimensions and unsupported variable notation. Existing reliable constant/linear/log/sort/quadratic estimates and 15 XP above-target contracts remain passing. A source inventory finds twenty currently authored unsupported target notations; this is conservative suppression, not new multivariate analysis. No schema/RLS, dependency, UI, real-account or entitlement/reward-policy change; twelve physical handlers remain.

PR #418 remains frozen at df419127: exact preview passed eleven general guest checks and blocked all ten changed tasks with 402. B059–B060 and #419 are separate later work. Mandatory PR checks, guarded merge and exact production for this cohort remain pending. Same-session model self-review and finite execution only, without independent/human, authenticated Premium, physical-device or complete-catalogue claims. All owner holds, including marketing draft #365, remain.

## Five-item continuation B061 — 15 October 2026

Individually audited Profile completeness, typed form rules, ordered patches, single settings patches and Article previews. Completeness follows literal nonempty-string semantics without trimming/contact validation. Form rules now include own enumerable Symbol keys, safe prototype-like error names, exact plain one-argument callback calls and throw/stop behavior. Patch helpers share an explicit ignore-undefined/own-only policy so required output fields remain complete; ordered zero-patch calls return the original, and supplied patches preserve shallow source metadata. Article previews contain exactly id/title with independent objects, regardless of construction-key order.

All 30 final-hash selected verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. Twenty authored-target/base-25-XP checks pass. Twenty new runtime assertions (two public policy examples/eighteen hidden) and five static assertions preserve existing cases. A no-op fixture initially did not inspect the undefined-patched result; direct visible regressions now do. Canonical known-right title-first previews also exposed an overstrict key-order assertion; the new exact-key checks sort names before comparison. Both initial failures were corrected and the five uncommitted records rebound before final acceptance. Canonical actual TypeScript, native Run, reversed hidden checks and the applicable known-right fixture pass. All 335 coding hashes match; 390 remain. Native 263/263. API/script types, launch/build, registry/index, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark probes at 320–1440px pass, zero issues/unprobed. Twelve physical handlers; archived Czech untouched.

PR #418 passed required verify 31m00s/SQL 46s at df419127, then merged at c9052e7c on 15 October 16:02:59 UTC; exact-production acceptance is separate and pending. PR #420 targets main at fixed f1c7c67e with ten B059–B060 reviews and #419. Its exact preview passes eleven general/three changed-task guest checks, plus six actual unsupported-target Submit verdicts on two free algorithms. Nine changed tasks remain 402/Premium-blocked. B061 adds five separately. Final full grading/Learn recheck for the next paired cohort remains pending; the B059–B060 tree passed it. Same-session model/finite evidence only; no independent/human, authenticated Premium, physical-device or complete-catalogue claim. No schema/RLS, dependency, UI, real-account or entitlement/reward-policy change. All activation/publication holds remain.

## PR #418 exact production — 15 October 2026

PR #418 passed required run 38761067124 at exact head df419127d9416404423c90d11945dc5c92bda8fe (verify 31m00s; SQL 46s), then merged at c9052e7c418b59711903802c2cbb54689bfee28d on 15 October 2026 at 16:02:59 UTC. READY production dpl_9yEqw1w1bH2x8oKbwGDjCc4XreiW matches that merge, owns devshark.app and has no alias error. Both exact preview and production pass eleven general guest checks; all ten changed tasks return 402, with zero changed-task Submit verdicts, and remain explicitly unverified through dedicated Premium acceptance. All actual general guest submissions grant zero XP and return null progress. Local cohort evidence remains 60/60 selected final-hash verdicts, forty authored-target/base-25-XP checks and 160 fixture-backed light/dark responsive probes. Shipped model-review coverage is 320/725 coding and 263/263 native. No authenticated Premium, independent/human, physical-device or full-catalogue acceptance claim.

## Five-item continuation B062 — 15 October 2026

Individually audited typed click filtering, ReturnType receipt totals, one-field password removal, TSV imports and player totals. Clicks preserve original event identity without invented coordinate validation. Receipt folds use safe bounded integer cents and leave records untouched. Password removal retains every other shallow own field. TSV boards precompute header positions, use safe row keys and call parsers once as plain functions. Player totals now use Partial<Record<string,number>> with safe observed keys and a numeric-zero ordered fold; required missing-player type assertions were corrected.

All 30 final-hash selected verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. Twenty authored-target/base-25-XP checks pass. Eighteen new runtime/six static assertions preserve existing checks; two public score-lookup expectations were corrected. A constructor dot-property static assertion encountered TypeScript's inherited Object Function typing; a general string-index optional lookup replaced it before final approval, while independent runtime prototype-key checks remain. The final Map alternative adopts Partial after its old required-Record baseline. Canonical actual TypeScript, native Run, reversed hidden checks, API/script types, launch/build, registry/index, final B061–B062 grading/Learn integrity, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark probes at 320–1440px pass, zero issues/unprobed. All 340 coding review hashes match; 385 remain. Native 263/263. Twelve physical handlers; archived Czech untouched.

PR #418 is exact-production verified at c9052e7c (320 coding and 263 native reviews). B059–B060 and #419 remain frozen in PR #420 at f1c7c67e, with SQL and exact preview passed; verify/guarded merge/exact production are pending. Its guest preview has eleven general checks, three changed-task Submit verdicts and six unsupported-model Submit verdicts on two free algorithms, all zero XP/null progress; nine changed tasks are Premium-blocked. B061–B062 add ten separately. Same-session individual model self-review and finite execution only, without independent/human, authenticated Premium, physical-device or full-catalogue acceptance. No schema/RLS, dependency, UI, real-account or entitlement/reward-policy change. All owner holds, including draft #365, remain.

## PR #420 exact production and #419 — 15 October 2026

PR #420 passed required run 38764081249 at exact head f1c7c67ecd5454c8ceeea3f0aba7c95fc5a381c5 (verify 31m36s; SQL 42s), then merged at a9df63081c796839d8c89d0ff74280bcbcb83ee5 on 15 October 2026 at 16:25:44 UTC. READY production dpl_FnUi3cPgPXvve5v6GCzrwK2RBC1C matches that merge, owns devshark.app and has no alias error. Both exact preview and production pass eleven general guest checks plus three actual changed-task Submit verdicts for missing Post fields; nine changed tasks return 402 and remain explicitly unverified through dedicated Premium acceptance. Six additional actual Submit verdicts on free jewels/GCD tasks preserve unsupported authored targets with unknown/time=null for reference, valid alternative and wrong programs, resolving the display bug in #419. All guest submissions grant zero XP and return null progress. Local cohort evidence remains 60/60 selected final-hash verdicts, forty authored-target/base-25-XP checks, five unsupported-model/six actual-board regressions and 160 fixture-backed light/dark responsive probes. Shipped model-review coverage is 330/725 coding and 263/263 native. No authenticated Premium, independent/human, physical-device or full-catalogue acceptance claim.

## Five-item continuation B063 — 15 October 2026

Individually audited simplified header blocks, Contact headings, pass-mark filtering, query strings and release-note grammar. Header lookups now use safe Partial dictionaries and stop before evaluating body entries. Record explanations distinguish fresh-literal excess checks from compatible wider variables. Own entry ordering excludes inherited students/parameters. Query encoding follows encodeURIComponent, including Unicode and lone-surrogate errors. Manual release-note parsers now agree with the original regex on colon-containing scopes while rejecting nested parentheses; exact summary whitespace remains valid.

All 30 final-hash selected verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. Twenty authored-target/base-25-XP checks pass. Eighteen new runtime/seven static assertions preserve existing checks; two required header-lookup expectations were corrected. The initial narrower no-colon scope draft was revised before approval, preserving valid original-senior behavior. The final regex alternative restores that full grammar; baseline/simple-fixture evidence is not universal proof. Canonical actual TypeScript, native Run, reversed hidden checks, API/script types, launch/build, registry/index, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark probes at 320–1440px pass with zero issues/unprobed. All 345 coding hashes match; 380 remain. Native 263/263. Twelve physical handlers; archived Czech untouched. Final full grading/Learn recheck for the next paired cohort remains pending; the B061–B062 tree passed it.

PR #420 is merged and exact-production verified at a9df6308 (330 coding and 263 native reviews). Issue #419 is complete after guarded production evidence, including six actual unsupported-target Submit verdicts on free algorithms; its automatic closure at merge was reopened until that verification passed. PR #421 targets main at unchanged 9d7424c2 with ten B061–B062 reviews, required checks/exact preview/merge/production separate. B063 adds five here. Same-session individual model and finite evidence only, without independent/human, dedicated Premium, physical-device or full-catalogue acceptance. No schema/RLS, dependency, UI, real-account or entitlement/reward-policy change. All owner holds, including draft #365, remain.

## Five-item continuation B064 — 15 October 2026

Individually audited warehouse allocation, frozen copies, edge blank-line trimming, free-day intersections and page ranges. Stock dictionaries now represent absent SKUs with Partial and copy own entries safely; preflight, repeated demand, warehouse priority and independent results are explicit. The senior allocator precomputes demand instead of rescanning it. Frozen copies preserve every own data descriptor, including Symbols, hidden names and literal __proto__, while freezing only the new outer record. Blank-line trimming uses exact JavaScript trim semantics and always returns a fresh mutable array. Intersection and range inputs are strictly ordered and unchanged; independent intersection dimensions retain O(n + m) with an unknown displayed estimate under #419.

All 30 final-hash selected verdicts agree (20 valid, five starters, five wrongs), versus 25/30 selected baseline. Twenty authored-target/base-25-XP checks pass. Nineteen new runtime/five static assertions preserve existing checks. One public stock lookup expectation was corrected for optional keys; its known-bad East-alias fixture was updated to the new copy expression and remains applicable/rejected. Initial static fixture variable collisions were corrected before approval; final negative diagnostics were inspected. The first frozen sorted-array sort probe did not distinguish a mutation violation in QuickJS; #422 records the separately reproduced native/engine mismatch. A real input-consuming program was replayed against the original snapshot and rejected by final mutable-input preservation checks. The original sort probe is not claimed as mutation evidence.

Canonical actual TypeScript, native Run, reversed hidden checks, API/script types, launch/build, registry/index, final B063–B064 grading/Learn integrity, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark probes at 320–1440px pass with zero issues/unprobed. All 350 coding review hashes match; 375 remain. Native 263/263. Twelve physical handlers; archived Czech untouched. PR #421 passed mandatory checks and merged at e9b8a734; exact production acceptance is separate. B063–B064 add ten later source reviews. Same-session individual model self-review and finite execution only; no independent/human, dedicated Premium, physical-device or whole-catalogue acceptance claim. No schema/RLS, dependency, UI, real-account or entitlement/reward-policy change. All owner holds remain.

## PR #421 exact production — 15 October 2026

PR #421 passed required run 38767971106 at exact head 9d7424c29d62cae54119db80612d1d0350a2b2ee (verify 31m03s; SQL 41s), then merged at e9b8a7347842e86a9612776503b8ad5ac68d3262 on 15 October 2026 at 16:53:23 UTC. READY production dpl_LmgwNLYhePSmxLXYgPhVMuQouZym matches that merge, owns devshark.app and has no alias error before/after probes. Exact preview and production each pass eleven general guest checks; all ten changed tasks return 402, with zero changed-task Submit verdicts. Dedicated authorized Premium acceptance remains outstanding. General guest submissions grant zero XP and return null progress. Local cohort evidence is 60/60 selected final-hash verdicts, forty authored-target/base-25-XP checks and 160 fixture-backed light/dark probes. Shipped model-review coverage is 340/725 coding and 263/263 native. No independent/human, physical-device, authenticated Premium or whole-catalogue acceptance claim.

## Five-item continuation B065 — 15 October 2026

Individually audited primitive filtering, first/last index spans, playlist interleaving, a memoized run and template-literal tags. Pure helpers accept readonly inputs, keep opaque references and return independent mutable results. The playlist starter now carries its stated generic signature; explicit union element types are valid. Memoization uses a local Map on all boards and distinguishes membership from undefined values, including NaN/signed-zero keys, exact plain one-argument callback calls and exception order. Tag inputs are explicitly finite bounded integers so the runtime strings fit the advertised template shape; this task is separate from profile nickname allocation. Span scanning also accepts a correct binary-bound alternative.

All30 final-hash selected verdicts agree (20 valid,five starters,five wrongs), versus25/30 baseline. Eighteen new runtime/eight static assertions preserve old checks. Initial new runtime fixtures incorrectly included TypeScript syntax; they were converted to JavaScript before final approval. The authored memoization target wording was normalized for the existing parser. Twenty final authored-target/base25-XP checks pass; unsupported/uncertain estimates stay hidden and unpenalized. Static negatives were inspected and fail for their intended boolean/number, never and template-suffix errors. Canonical actual TypeScript, native Run, reversed hidden checks, API/script types, launch/build, registry/index, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and80 fixture-backed light/dark probes at320–1440px pass with zero issues/unprobed. All355 coding review hashes match;370 remain. Native263/263. Twelve physical handlers; archived Czech untouched.

PR #421 is exact-production verified at e9b8a734 with340 coding reviews. Ten B063–B064 reviews are frozen in PR #423 at520dc8a1: exact READY preview passes eleven general guest checks, while all ten changed tasks return402, with zero changed-task Submit verdicts; required verify/merge/production remain separate. B065 adds five later reviews. #419 is complete; #422 retains its narrow sort-parity evidence and remaining acceptance. Full grading/Learn integrity passed the B063–B064 tree; the next paired cohort will be rechecked separately. Same-session individual model self-review/finite execution only; no independent/human, dedicated Premium, physical-device or full-catalogue acceptance claim. No schema/RLS, dependency, UI, real-account or reward-policy change. All owner holds remain.

## Five-item continuation B066 — 15 October 2026

Individually audited all five cumulative Generic collection helpers levels: groupBy, countBy, uniqueBy, partition and sortBy. Shared dense/frozen-input rules preserve opaque values, arbitrary Map/Set keys and fresh mutable outputs. Group/count/unique/partition callbacks execute once per item, in input order, as plain one-argument calls; exceptions stop processing. The senior partition now uses one reduce pass instead of two filter passes. Its Exclude result explicitly relies on an honest two-sided type guard. The junior sorter captures each selector before calling it, preserving a plain receiver; homogeneous finite-number or UTF-16 string keys keep comparisons consistent. A fixed five-selector bound supports the stated comparison-sort model, without claiming an actual measured engine complexity.

All30 selected final-hash verdicts agree (20 valid,five starters,five wrongs), versus25/30 baseline. Sixteen distinct new runtime assertions execute46 times across cumulative levels; five new stage static assertions execute15 times. Old cases and negatives remain. Twenty authored-target/base25-XP checks pass, including independent grouping/counting/deduplication and indexed stable-sort alternatives; uncertain complexity stays hidden/unpenalized. Canonical actual TypeScript, native Run, reversed hidden and applicable no-less-than comparator mutation fixtures pass. All360 coding hashes match;365 remain. Native263/263. API/script types, launch/build, registry/index, final B065–B066 grading/Learn integrity, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and80 fixture-backed light/dark probes at320–1440px pass with zero issues/unprobed. Twelve physical handlers; archived Czech untouched.

PR #421 remains exact-production verified at e9b8a734 with340 coding reviews. Ten later B063–B064 reviews remain frozen in PR #423 at520dc8a1, whose exact preview passes eleven general guest checks and blocks all ten changed tasks with402; required verify/merge/production are separate. B065–B066 add ten more source reviews. #419 is complete. #422 now includes bare SDK/NG reproduction, a thirteen-case native/worker matrix and primary upstream writeback code; no runtime/dependency change has been made. Same-session model self-review and finite execution only, without independent/human, dedicated Premium, physical-device or complete-catalogue acceptance. No schema/RLS, UI, real-account or reward-policy change; all owner holds remain.

## Five-item continuation B067 — 15 October 2026

Individually audited all five cumulative Unions and narrowing levels: area, perimeter/assertNever, decimal parsing, isShape and totalArea. Formulas preserve typed input and do not round individual outputs. Decimal conversion now checks finiteness after a matching string is converted, with a visible overflow example and updated hint/explanation. Shape guards preserve unknown data and retain the original non-null-object semantics, including inherited fields and decorated arrays/boxed objects; they do not silently sanitize dimensions. Aggregation accepts readonly input and rounds the full-precision accumulated sum once at the end. Numeric/data domains and diagnostic serialization boundaries are explicit.

All 30 selected final-hash verdicts agree (20 valid, five starters, five wrongs), versus 25/30 corrected baseline. An initially untyped reduce accumulator in the independent final-stage alternative inferred unknown; its explicit type was corrected before the accepted baseline/final runs, with raw initial evidence retained. A final wording reread added the post-conversion finite rule to the hint/explanation and reran all six stage-three cases at that final hash. Fifteen distinct added hidden plus one visible runtime assertion execute 48 times cumulatively; five added stage static assertions execute 15 times. All old checks/negatives remain. Twenty authored-target/base-25-XP checks pass; unknown estimates remain hidden/unpenalized. All 365 coding review hashes match; 360 remain. Native 263/263.

Canonical actual TypeScript, native Run, reversed hidden tests, API/script types, launch/build, registry/index, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark probes at 320–1440px pass, zero issues/unprobed. Full grading/Learn integrity passed B065–B066 and will be rerun for the next paired tree. Twelve physical handlers; archived Czech untouched. No schema/RLS, dependency/runtime, UI, real-account or reward-policy change. Same-session model self-review/finite execution only, without independent/human, dedicated Premium, physical-device or complete-catalogue acceptance.

PR #423 passed required run 38773819510 at unchanged 520dc8a1 (verify 30m08s; SQL 1m02s), then merged at 93230392 on 15 October at 17:33:34 UTC. Its exact preview passed eleven general guest checks, with all ten changed tasks returning 402 and zero changed-task Submit verdicts. Exact production remains pending. PR #424 is frozen at 6310f6ff with ten later B065–B066 reviews; its checks/preview/merge/production remain separate. B067 adds five here. #419 is complete; #422 remains a documented upstream writeback parity gap. All owner holds remain, including draft #365.

## PR #423 exact production — 15 October 2026

PR #423 passed required run 38773819510 at exact head 520dc8a16a0c5a86fe94b523bce4e7ceb1133007 (verify 30m08s; SQL 1m02s), then merged at 932303922e62eef7ce9b9f05d656f5a414df8bc7 on 15 October 2026 at 17:33:34 UTC. READY production dpl_3kv8bKDqAVgveSet6pHPA2N2YSuB matches that merge, owns devshark.app and has no alias error before/after probes. Exact preview and production each pass eleven general guest checks; all ten changed tasks return 402, with zero changed-task Submit verdicts. Dedicated authorized Premium acceptance remains outstanding. General guest submissions grant zero XP and return null progress. Local cohort evidence remains 60/60 selected final-hash verdicts, forty authored-target/base-25-XP checks and 160 fixture-backed light/dark probes. Shipped model-review coverage is 350/725 coding and 263/263 native. No independent/human, physical-device, authenticated Premium or whole-catalogue acceptance claim.

## Five-item continuation B068 — 15 October 2026

Individually audited jewel membership, Two sum, anagram grouping, note-character coverage and first unique characters. String tasks explicitly use Unicode iterator elements, without normalization/grapheme claims; anagram keys use well-formed strings. Junior anagrams/unique-character boards now preserve supplementary characters. Senior grouping computes each key once and appends to owned groups without repeatedly copying them; jewels/note/unique boards avoid unnecessary full-source arrays for their stated auxiliary-space goals. Two sum now has one visible deterministic policy: smallest completed right index, then smallest left index. All boards retain the first value index, with junior using the linear Map scan. Two visible examples expose both duplicate and pair-selection ties.

All 30 selected final-hash verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. Fifteen new hidden/two visible runtime assertions preserve existing cases. No TypeScript assertions apply to these JavaScript tasks. A final wording reread removes the claim that only a second source scan can select a unique character; all six cases were rerun at its final hash. Twenty authored-target/base-25-XP checks pass; independent unsupported dimensions remain unknown/hidden and unpenalized. Reference, junior, senior and independently written frequency/first-index/ordered-Map alternatives pass; the old indexed UTF-16 junior, source mutation and duplicate-index adversaries fail. All 370 coding hashes match; 355 remain. Native 263/263.

Canonical coding/native Run/reversed-hidden checks, API/script types, launch/build, registry/index, final B067–B068 grading/Learn integrity, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark probes at 320–1440px pass with zero issues/unprobed. The stale source comment claiming the entire Algorithms catalogue has no tier gate now points to shared/tiers.ts/server issuance; no access policy changed. Twelve physical handlers; archived Czech untouched. No dependency/runtime, schema/RLS, UI, real-account or reward-policy change. Same-session model self-review/finite execution only; no independent/human, dedicated Premium, physical-device or complete-catalogue acceptance.

PR #423 is exact-production verified at 93230392 with 350 coding reviews; its eleven general guest checks pass and all ten changed tasks remain Premium-blocked. Ten later B065–B066 reviews are frozen in PR #424 at 6310f6ff: exact READY preview passes eleven general plus six actual changed-task Submit verdicts on free playlist/grouping tasks, all zero guest XP/null progress, while eight tasks return 402; verify/merge/production are separate and pending. B067–B068 add ten further source reviews here. #419 is complete; #422 remains an upstream sort-writeback follow-up. All owner holds, including draft #365, remain.

## Reproducible sort parity follow-up #422 — 15 October 2026

Added docs/audit/wip/tools/check-sort-parity.ts as a read-only native/actual-worker differential report. Its thirteen constructed cases reproduce six known differences: sorted frozen, equal frozen, frozen leading-value/trailing-hole, sorted readonly index, sorted accessor writeback and a sorted Proxy returning false from set. Seven other cases agree. The report intentionally exits 1 on a difference; it is an optional investigation tool, not a falsely passing required CI gate. Native Node is v24.19.0 and installed QuickJS/SDK is 0.32.0. Private bare SDK and current NG-variant probes also reproduce the original case. Current primary upstream C sources skip writeback when a sorted value retains its index, consistent with the probes, without proving the exact binary source revision. No runtime shim, dependency update or app behavior change is included. #422 remains open for a validated fix and broader regression/release acceptance; no universal language-parity or security-exploit claim.

## PR #424 exact production — 15 October 2026

PR #424 passed required run 38776931495 at exact head 6310f6ffac17248bc74c268cf0262f6fd6693ee7 (verify 25m44s; SQL 42s), then merged at b149805003cf9d7b6c69f9976a235d406fd0c4a4 on 15 October 2026 at 17:52:36 UTC. READY production dpl_E6BdPKHwxGwvqu1JWSgoNYDV64c4 matches that merge, owns devshark.app and has no alias error before/after probes. Exact preview and production each pass eleven general guest checks plus six actual changed-task Submit verdicts on free playlist interleaving and generic grouping: reference/valid alternative pass and meaningful wrong fails. Eight other changed tasks return 402 and await dedicated authorized Premium acceptance. All guest submissions grant zero XP and return null progress. Local cohort evidence is 60/60 selected final-hash verdicts, forty authored-target/base-25-XP checks and 160 fixture-backed light/dark probes. Shipped model-review coverage is 360/725 coding and 263/263 native. No independent/human, physical-device, authenticated Premium or whole-catalogue acceptance claim.

## Five-item continuation B069 — 15 October 2026

Individually audited majority values, happy numbers, Top K frequencies, longest integer runs and ASCII palindromes. Majority voting now uses SameValueZero consistently with Map counting, including NaN, opaque identities and the documented null/undefined outcomes. Happy-number inputs are positive safe Numbers; the authored goal now describes the whole digit-scale process with a bounded tail, and a visible large input rejects 32-bit truncation. Frequency ties retain first-seen keys with fresh results. Longest-run inputs are exact bounded integers and preserve input; the final wording fixes whole numbers versus negative examples. Palindromes classify original ASCII content before lowercasing, with a visible Kelvin-sign example; cleaned-copy alternatives remain valid O(n)-time/O(n)-space choices while pointers use O(1) space.

All 30 selected final-hash verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. Fifteen new hidden/three visible runtime assertions preserve existing cases; no TypeScript assertions apply. All six longest-run cases were rerun after the final integer-wording edit. Twenty authored-target/base-25-XP checks pass, including the amortized Set traversal and a linear endpoint-Map alternative; uncertain estimates remain hidden/unpenalized. Supplemental native checks cover 3906 short interval inputs, 4681 vote sequences, 10000 happy-number inputs and 9331 short ASCII-filter texts on authored alternatives; they are distinct from worker evidence and not arbitrary-program proof. All 375 coding hashes match; 350 remain. Native 263/263.

Canonical coding/native Run/reversed-hidden checks, API/script types, launch/build, registry/index, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark probes at 320–1440px pass, zero issues/unprobed. The final full grading/Learn suite for the next paired cohort remains pending; B067–B068 passed it. Twelve physical handlers; archived Czech untouched. Same-session model self-review and finite execution only, without independent/human, dedicated Premium, physical-device or complete-catalogue acceptance. No runtime/dependency, schema/RLS, UI, real-account or reward-policy change. PR #424 is exact-production verified at b1498050 with 360 coding reviews. PR #425 remains frozen at 9750304b with ten later reviews; its preview passes eleven general/nine changed-task guest checks and blocks seven tasks with 402. B069 adds five separately. All owner holds and open #422 remain.

## Range-copy estimate follow-up #426 — 15 October 2026

The B070 reward check caught a valid O(n) Roman token decoder receiving O(n^2)/15 base XP because slice(index,index+2) was charged as a whole-input copy. A separate free average program reproduces the bug on exact production b1498050: bounded-pair and genuinely quadratic versions both pass correctness and return above-target/O(n^2); actual guest XP remains0 with null progress. This is baseline evidence, not a deployed fix.

The structural estimator now withholds unmodelled range widths instead of choosing a whole-input/fixed width without proof. Known literal bounds are normalized by truncation; mixed-sign slice ranges and nonfinite/unsafe bounds remain unknown. slice/substring/substr retain their different negative-index rules. Twenty-three new permanent assertions cover nine uncertain ranges, seven fixed normalized windows, six genuine whole-copy/suffix quadratic controls and the actual Roman task. Existing factory/unsupported-model/scalar/linear/quadratic contracts and base25/15 rewards pass. All twenty B070 solution-board/alternative reports retain base25 after the change; the Roman alternative becomes unknown/time=null with its O(n) authored target intact. API/script types and diff pass. Task runtime correctness, grading authority, dependencies, schema/RLS and twelve handlers are unchanged. Full paired-tree gates, CI, guarded merge and exact-production acceptance remain pending; #426 stays open. This is conservative suppression of unsupported width inference, not general affine/data-flow analysis.

## Five-item continuation B070 and range-copy correction — 15 October 2026

Individually audited raw UTF-16 common prefixes, canonical Roman numerals, whitespace word reversal, opaque array chunks and stable sorted merging. Prefix boards now track a length and slice once instead of accumulating or repeatedly shrinking/rechecking strings. Roman singletons/subtractive pairs and the complete canonical 1..3999 range are checked with an independent positional formatter. Word-reversal guidance now describes JavaScript whitespace and the empty split placeholder accurately. Chunk sizes are explicitly noncoercing integer Numbers and outputs have independent outer/inner ownership. Merge ties take the left side first, including zero signs; its hint now says at most one remainder.

All 30 selected final-hash verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. Fifteen hidden/one visible new runtime assertion preserve old cases; no TypeScript assertions apply. A final minor Roman wording correction reran all six cases at that hash. Supplemental native checks cover 585 prefix lists, 4000 numeral inputs, 7381 whitespace strings, 135 chunk combinations and 1225 sorted-list pairs on authored alternatives, distinct from actual worker evidence. The independent Roman token decoder exposed #426: correctness passed but the old range model assigned quadratic/15 XP. Separate aa8d773e fixes the inference boundary conservatively; twenty final authored-target/base-25-XP checks now pass. Twenty-three permanent range scenarios retain unknown/base25 for unsupported widths, fixed literal bounds and genuine quadratic/base15 controls. Free-average production-before evidence remains baseline only; the fix is not yet deployed.

All 380 coding review hashes match; 345 remain. Native 263/263. Canonical coding/native Run/reversed-hidden checks, API/script types, launch/build, registry/index, final B069–B070 grading/Learn integrity, native bindings, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark probes at 320–1440px pass with zero issues/unprobed. Twelve physical handlers; archived Czech untouched. No runtime/dependency, schema/RLS, UI, real-account or entitlement-policy change. The complexity inference affects the existing server-authoritative reward calculation without changing grading correctness or base reward rules.

PR #424 is exact-production verified at b1498050 with 360 coding reviews. PR #425 passed its mandatory checks at unchanged 9750304b and merged at 974c427f on 15 October at 18:26:00 UTC; its preview passed eleven general/nine changed-task guest checks, with seven changed tasks Premium-blocked. Exact production for #425 remains separate and pending. B069–B070 add ten further source reviews plus the #426 inference correction. Same-session model self-review/finite execution only, without independent/human, dedicated Premium, physical-device or full-catalogue acceptance. #422 and all owner holds, including draft #365, remain open/preserved.

## PR #425 exact production — 15 October 2026

PR #425 passed required run 38780544748 at exact head 9750304b3e26bbe4591de522646658ac37709cc6 (verify 30m46s; SQL 38s), then merged at 974c427fc765bf8cbe204448d697f51e5a373c84 on 15 October 2026 at 18:26:00 UTC. READY production dpl_7FH6gHTRd7TZLp5JAjAHLaz2f3DF matches that merge; live devshark.app alias checks before and after probes point to it, without alias error. Exact preview and production each pass eleven general guest checks plus nine actual changed-task Submit verdicts on free union-area, jewels and TwoSum tasks: reference/valid alternative pass and meaningful wrong fails. Seven other changed tasks return 402 and await dedicated authorized Premium acceptance. All guest submissions grant zero XP and return null progress. Local cohort evidence is 60/60 selected final-hash verdicts, forty authored-target/base-25-XP checks and 160 fixture-backed light/dark probes. Shipped model-review coverage is 370/725 coding and 263/263 native. The optional #422 report records six native/worker differences in thirteen cases and does not fix them. No independent/human, physical-device, authenticated Premium or whole-catalogue acceptance claim.

## B071 five-item audit — 15 October 2026

Individually reviewed second distinct maximum, in-place rotation, fixed-denomination change, missing range member and one chronological trade. Define finite/bounded numeric domains, input ownership and exact result policies. Keep correct extrema/sum/trade/coin boards; replace both copying rotation boards with constant-storage swaps/cycles and correct the empty-before-modulo explanation. Negative rotation has a visible example; opaque values retain identity. Greedy complexity distinguishes six kinds from the number of individual coins and accepts faster division.

All30 selected final-hash worker verdicts agree (20valid, five starters, five wrongs), versus26/30 baseline: the reused coin object already failed the original runner, while four other wrong programs are newly rejected by explicit policies. Fifteen hidden/one visible runtime assertion preserve old cases; no TypeScript assertions apply. Independent hidden oracles cover1000 coin amounts by dynamic programming,325 missing-number gap/size pairs,1365 short price sequences and120 rotation size/step pairs. An additional3906 native alternative extrema checks pass; their first fixture incorrectly distinguished the allowed signs of zero, corrected without source/candidate changes. Twenty authored-target/base25 checks pass; unsupported multivariate/uncertain estimates remain hidden/unpenalized.

All385 coding review hashes match;340 remain. Native263/263. Canonical/native Run/reversed-hidden/applicable fixture checks, API/script types, full grading/Learn integrity, launch/build, registry/index, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and80 fixture-backed light/dark probes at320–1440px pass with zero issues/unprobed. Twelve physical handlers; archived Czech untouched. No sandbox-engine/dependency, schema/RLS, UI, real-account or entitlement/reward-policy change. This is same-session model self-review and finite execution, without independent/human, dedicated Premium, physical-device or whole-catalogue acceptance.

Exact-production PR#425 has370 coding/263 native reviews and separate acceptance above. Ten later B069–B070 reviews plus #426 are frozen in #427 at847d6ff1; exact preview passes eleven general/nine changed-task/two range regression-control guest checks, with seven changed tasks returning402. Guarded release acceptance is still pending. This B071 adds five source reviews separately. #422 and all owner holds, including draft#365, remain open/preserved.

## B072 five-item audit — 15 October 2026

Individually reviewed unique three-sum triples, longest distinct-character windows, fixed-window sums, prefix-frequency stretch counts and first broken builds. Define bounded exact integers and ownership. All substring boards now stream JavaScript iterator values, including lone surrogates, with O(k) auxiliary storage; a visible Unicode example and the skeleton use the same units. Rewrite the quadratic junior window sum and eliminate the senior temporary slice. Use low+floor((high-low)/2) in every binary-search board and the hint, with explicit valid-query/empty/error rules through MAX_SAFE_INTEGER. Keep correct three-sum/prefix-frequency boards and clarify output-space exclusion.

All30 selected final-hash worker verdicts agree (20valid, five starters, five wrongs), versus25/30 baseline. Fifteen new hidden/one visible assertions preserve old cases. Independent finite oracles cover781 short three-sum lists,1365 Unicode sequences,2005 window/size combinations,1820 prefix/target combinations and2144 monotone size/threshold combinations. The original32-bit search negative initially hit timeout in an unguarded large callback; applying the already-promised query-range/budget guard makes rejection prompt, then all six candidates reran at that final task hash. Twenty authored-target/base25 checks pass; uncertain estimates stay hidden/unpenalized. No TypeScript cases apply.

All390 coding hashes match;335 remain. Native263/263. Canonical/native Run/reversed-hidden/applicable fixtures, API/script types, full final B071–B072 grading/Learn integrity, launch/build, registry/index, both production dependency audits (zero vulnerabilities), diff and80 fixture-backed light/dark probes at320–1440px pass with zero issues/unprobed. Copy sweep initially matched the original literal abcabcbb twice; the existing exact item/field/literal allowlist now documents that input, with zero outstanding findings and no broader suppression. Twelve physical handlers; archived Czech untouched. No sandbox-engine/dependency, schema/RLS, UI, real-account or entitlement/reward-policy change.

Verified production remains #425 at370coding/263native; #427 separately freezes ten later B069–B070 reviews and the #426 correction. B071–B072 add another ten source reviews. Same-session model self-review/finite execution only, without independent/human, dedicated Premium, physical-device or whole-catalogue acceptance. #422 and owner holds, including draft#365, remain preserved.

## Production advisor reconciliation — 15 October 2026

Read-only production Supabase advisors reported32 informational no-policy RLS tables and no security WARN/ERROR in that response. Performance diagnostics reported39 Auth-policy initPlan warnings,17 unused-index INFO findings and one fixed Auth-connection INFO. Direct pg_policies metadata contradicts the39 warnings: all39 named policies, and all43 public Auth policies inspected (45uid calls), already use uncorrelated scalar SELECT subqueries. Cast placement varies; all current expressions were checked. Do not reapply an optimization, grant browser access to server-owned tables or drop indexes from these diagnostics alone. No schema, policy, grant, index, Auth or user-data change occurred. This is metadata reconciliation, not actor isolation, measured query plans, sustained load, restore, physical-device or full security acceptance. Exact rows/counts and provider remediation links are in docs/audit/database-advisors-2026-10-15.json; #190's operational residuals remain open.

## PR#427 exact production and #426 — 15October2026

PR #427 passed required run 38786408152 at exact head 847d6ff12fd363249e57da6c7c37f9de8003fbdc (verify30m50s; SQL46s), then merged at c56b6cc6381d7e6353efee2514b3582db70c5298 on15October2026 at19:04:21UTC. READY production dpl_7WrAxdJDhrHHdFrttyuFVormCG5k matches that merge; live devshark.app alias checks before and after probes point to it, without alias error. Exact preview and production each pass eleven general guest checks plus nine actual changed-task Submit verdicts on free ASCII palindrome, chunk and merge tasks: reference/valid alternative pass and meaningful wrong fails. Seven other changed tasks return402 and await dedicated authorized Premium acceptance. Both deployments also pass two actual free-average Submit regressions for #426: the bounded dynamic range is unknown/time=null with retained O(n) goal, while the correct full quadratic control remains above-target/O(n²). Both pass correctness and award guest0XP/null progress. Permanent server reward contracts assert base25 for unknown and15 for reliable above-target; no authenticated payout is claimed. Local cohort evidence is60/60 selected final-hash verdicts, forty authored-target/base25 checks,23 permanent range scenarios and160 fixture-backed light/dark probes. Shipped model-review coverage is380/725 coding and263/263 native. No independent/human, physical-device, authenticated Premium or whole-catalogue acceptance claim.

## B073 five-item audit — 15 October 2026

Individually reviewed half-open meeting capacity, maximum container area, exact linked-list middle, stable numeric-zero compaction and rotated numeric search. Keep correct scheduling/search boards. Replace the quadratic junior area scan, two-pass junior list traversal and copying junior zero buffer with the authored linear/constant-storage approaches. Clarify fractional/empty meetings and allocated capacity, geometric width/ties, frozen/null-prototype nodes with opaque payloads, NaN/infinity/zero equality and bounded index-read accounting. Four visible examples distinguish newly explicit boundaries.

All 30 selected final-hash worker verdicts agree (20 valid, five starters, five wrongs), versus 25/30 baseline. Fifteen hidden/four visible assertions preserve old cases; no TypeScript assertions apply. Independent oracles cover 1555 meeting lists including empty intervals, 1365 height lists, 33 small chain lengths plus a 2000-node Symbol chain, 781 numeric compactions and 1770 rotated target combinations. Four present/missing queries in a frozen 65536-item fractional array each stay within 200 reads. The block-copy zero alternative advances a cursor monotonically and copies disjoint total-length blocks. Twenty authored-target/base25 checks pass; uncertain estimates remain hidden/unpenalized. A final search wording/read-policy correction reran all six task candidates at its final hash; otherwise-correct harmless beyond-end reads are not forbidden.

All 395 coding hashes match; 330 remain. Native 263/263. Canonical/native Run/reversed-hidden/applicable fixtures, API/script types, full grading/Learn integrity, launch/build, registry/index, both production dependency audits (zero vulnerabilities), copy sweep (zero findings), diff and 80 fixture-backed light/dark probes at 320–1440px pass with zero issues/unprobed. Twelve physical handlers; archived Czech untouched. No application sandbox-engine/dependency, schema/RLS, UI, real-account or entitlement/reward-policy change.

PR #427 is exact-production verified at c56b6cc6 with 380 coding/263 native reviews, including the #426 unknown-bounded/genuine-quadratic control; #426 is closed with evidence. Ten later reviews are frozen in #428 at bf88c1e0; its exact preview passes eleven general/three changed-task guest Submit checks with nine changed tasks returning 402. This B073 adds five more source reviews. Same-session model self-review and finite execution only; no independent/human, dedicated Premium, physical-device or whole-catalogue acceptance. #422 remains an unresolved engine issue; a private upstream build investigation is not a shipped fix. Preserve all owner holds, including draft #365.

## PR#428 exact production — 15October2026

PR #428 passed required run38790894296 at exact head bf88c1e0e59cb628075924c229f5418ae02331fb (verify27m10s; SQL57s), then merged at dcee58e3d25f2d22ee1a501218b2dd960d411fe4 on15October2026 at19:46:37UTC. READY production dpl_48gWCzxissSMHVEetrEnUKXXjL57 matches that merge; live devshark.app alias checks before and after probes point to it, without alias error. Exact preview and production each pass eleven general guest checks plus three actual changed-task Submit verdicts on free missing-number recovery: reference/valid alternative pass and meaningful wrong fails. Nine changed tasks return402 and await dedicated authorized Premium acceptance. Guest Submits award0XP/null progress; no authenticated payout is claimed. Local cohort evidence is60/60 selected final-hash verdicts, forty authored-target/base25 checks and160 fixture-backed light/dark probes. Shipped model-review coverage is390/725 coding and263/263 native. B073 adds five source reviews separately; #422 implementation is not part of this deployment. No independent/human, physical-device, authenticated Premium or whole-catalogue acceptance claim.

## #422 runtime implementation — 15October2026

Pinned shared wasm fixes the37 constructed Node24/worker sort cases and compiled React guest regression. Separate-source local rebuild is byte-identical; types, launch, full grading/Learn, build, native bindings, unused/security and zero-vulnerability dependency audits pass. Full coding run had one9352ms React negative-budget failure; its focused unchanged-task rerun passes. Required Linux rebuild/full CI and exact preview/production acceptance are pending. The bounded runtime evidence was in `docs/audit/quickjs-sort-2026-10-15.md` (deleted on 22 October 2026, kept in Git history); #422 stays open.

## B074 five-item audit — 15October2026

Individually reviewed mixed-bracket validation, removal from a list, numeric median, half-open meeting conflicts and balanced-string enumeration. Keep correct bracket/list/median boards and the junior buffer generator. Filter empty intervals before sorting in every conflict board; update its prompt, hint, approach and skeleton. Replace generator reference prefix strings and senior queued strings with a shared mutable buffer and call/explicit frames. State the output-sensitive O(n * C_n) target and O(n) extra space, excluding output; n is pairs and C_n the answer count. Preserve IDs, levels, history and access.

All30 final-hash selected worker verdicts agree (20valid, five starters, five meaningful wrongs), versus25/30 baseline. Fifteen hidden/three visible runtime assertions preserve old cases. Independent finite evidence covers1555 bracket strings,10000-level nesting,300 node-removal positions and three5000-node Symbol chains,1365 fractional median inputs,1555 interval lists,5461 candidate binary strings through six bracket pairs and validity/strict ordering/count of all58786 answers at11. A separate Catalan recurrence confirms58786. Repeated calls/mutated prior arrays check result independence. Readonly nested input, exact original node/payload/link identity, input zero signs and equivalent result zero signs are distinguished. Twenty authored-target/base25 checks pass; unknown recursive estimates stay hidden/unpenalized. No TypeScript cases apply.

All400 current coding review hashes match;325 remain (61JavaScript,46TypeScript,183React,35algorithms). Native263/263. Canonical/native Run/reversed-hidden/applicable fixtures, API/script types, launch/build, full grading/Learn integrity, registry/index, copy sweep0findings, both production dependency audits0vulnerabilities, clean diff and80 fixture-backed light/dark probes at320–1440px pass. An initial unescaped apostrophe in the revised hint stopped an exploratory bundle; it was fixed before authoritative fresh export/grader/candidates and release checks. Twelve physical handlers; archived Czech unchanged. B074 adds content changes only; the pinned runtime is separately committed in ancestor45a4fbd5.

Verified production remains390coding/263native through #428. B073 and runtime #422 are frozen separately in PR#429 at45a4fbd5: Linux source rebuild and exact preview regression/control pass; required full verify/guarded merge/production-after are pending. This B074 adds five more source reviews. Same-session model self-review and finite execution only; no independent/human, dedicated Premium, physical-device or whole-catalogue acceptance. Preserve owner holds, including draft#365.

## B075 five-item audit — 15October2026

Individually reviewed closed interval unions, exact maximum three-position products, greedy threshold matching, strict search-tree validation and stable multi-key record sorting. Retain correct sorting/greedy/range boards. Replace only the junior tree value array with a streaming previous-value traversal to meet O(h) storage on shallow trees. Correct the false suggestion that explicit negative/zero/positive comparators inherently mishandle equality. Define closed point intervals, independent mutable output pairs, bounded exact integer products, fractional/noncoercing snack thresholds, n/m/h and a supported recursive height, stable raw UTF-16 names and original-record identity.

All30 final-hash selected worker verdicts agree (20valid, five starters, five wrongs), versus25/30 baseline. Fifteen hidden/four visible assertions preserve old cases. Independent finite evidence includes1555 interval lists via overlap/touch connected components,1344 cubic product oracles,1600 exhaustive assignment pairs,1291 tree shape/value assignments via all-descendant comparisons and1555 stable record sorts via identity-based selection. Boundaries cover2000-item inputs, a128-height readonly chain, a2000-node balanced tree,1e15 products, zero signs, fractional sizes, empty/point ranges, original Symbol payloads and unpaired surrogate order. The initial new interval fixture had an extra parenthesis; it was corrected before the fresh authoritative30-case run. The20 authored-target/base25 checks were bundled again from the final tree and pass; uncertain complexity stays hidden/unpenalized. No TypeScript assertions apply.

All405 current coding review hashes match;320 remain (61JavaScript,46TypeScript,183React,30algorithms). Native263/263. Canonical/native Run/reversed-hidden/applicable fixtures, API/script types, launch/build, full grading/Learn integrity, registry/index, copy sweep0findings, both zero-vulnerability production dependency audits, clean diff and80 fixture-backed light/dark probes at320–1440px pass. Twelve physical handlers; archived Czech unchanged. This five-item commit adds content changes only; the pinned runtime is separately frozen in ancestor45a4fbd5/PR#429.

Verified production remains390coding/263native through #428. #429 has successful required Linux source rebuild and exact preview JavaScript/React regression/control; the full CI test step now passes, with remaining release checks pending. B074–B075 add ten source reviews separately. Same-session model self-review and finite execution only; no independent/human, dedicated Premium, physical-device or whole-catalogue acceptance claim. Preserve owner holds, including draft#365.

## PR#429 exact production and #422 completion — 15October2026

PR#429 passed required run38802106010 at exact head45a4fbd5b6109bd374b17f3d2236a92f77b9c337 (verify28m26s; SQL40s), including Linux byte-identical pinned-source runtime rebuild, full coding catalogue, grading/Learn authority and browser/release gates. It merged at53b3967b9bc5b69733bb33818fd27286a366eb84 on15October2026 at20:56:56UTC. READY production dpl_2W9Cz1xU2JPDc3LvDRMSiCLURjso matches that merge; live devshark.app alias checks before and after probes point to it, without alias error. Exact preview and production each pass eleven general guest checks and four actual JavaScript-average/React-heading regression/control Submits for #422. Ordinary controls pass before/after; the two previously rejected correct frozen-sort guards now pass after the fix. Guest0XP/null progress; no authenticated payout claim. All five B073 changed tasks return402 and await dedicated authorized Premium acceptance. Local/CI evidence includes37 actual-worker/native sort cases, compiled React guest regression and pinned artifact/ABI hashes. The broad local9352ms React-negative timing failure and successful focused rerun remain recorded; fresh required full CI passed. B073 also has30/30 final-hash selected verdicts, twenty authored-target/base25 checks and80 fixture-backed light/dark probes. Verified production coverage is395/725 coding and263/263 native; ten later B074–B075 reviews are frozen separately in #430. This completes the bounded #422 engine/release acceptance, without universal JavaScript conformance, independent/human, real-device, dedicated Premium or whole-catalogue acceptance claims.

## B076 five-item audit and #431 implementation — 15October2026

Individually reviewed Euclid GCD, memoized Fibonacci, unbounded optimal coin counts, nested-array flattening and fixed-width binary generation. Define safe numeric/recursion/output domains and input-size variables. Keep correct GCD/Fibonacci/binary boards. Replace deepFlatten child/growing-output copies with indexed shared accumulation or array/index frames; preserve opaque identities, undefined, numeric signs, null-prototype arrays and repeated shared occurrences. Replace reference/senior coin recursion with ascending array/Map states and retain the junior bottom-up algorithm with empty/zero guards. The actual old reference overflows its stack on coins[1],amount10000; the repaired boards pass that bound without increasing engine budgets.

#431 uses the existing server-derived runtime policy to make only native Array.prototype.flat/flatMap unavailable before learner initialization in this exercise. Run/Submit/reused Learn, captured/reflected aliases, constructor access, attempted restoration, caught errors followed by a valid manual walk, custom method names, other fresh task realms and unchanged host methods are covered. No source-text ban, global host mutation, new handler, dependency or sandbox-engine change. The implementation remains unreleased pending the next PR/production evidence; keep #431 open.

All31 selected final-hash worker verdicts agree (20valid, five starters, six meaningful wrongs), versus25/31 baseline. Fifteen hidden/five visible assertions preserve old cases. Final Fibonacci cache-domain/zero/copy clarification reran all six candidates at its final hash; populated high-index caches remain valid inputs, cache presence honors zero/NaN/infinity, base keys retain their stored data and opaque unrelated entries survive. Existing deliberately noncanonical seed behavior is explicit. Twenty current authored-target/base25 checks pass; unknown estimates stay hidden/unpenalized. Independent finite evidence includes2601 divisor-enumeration pairs, seven BigInt extremes,79 exact unseeded recurrence indices,672 exhaustive coin-count cases,1555 constructed nested shapes,20000-slot width/64depth and all8191 binary strings through length12. No TypeScript cases apply.

All410 current coding hashes match;315 remain (61JavaScript,46TypeScript,183React,25algorithms). Native263/263. Canonical/native Run/reversed-hidden/applicable fixtures, API/script types, launch/build, full grading/Learn integrity including the new policy, registry/index, copy sweep0findings, unused/security checks, both zero-vulnerability production dependency audits, clean diff and80 fixture-backed light/dark probes at320–1440px pass. Twelve physical handlers; archived Czech unchanged.

Verified production has395coding/263native through #429 at53b3967b, with #422 closed after actual JavaScript/React before/after controls and required full Linux/browser gates. Ten later B074–B075 reviews are frozen in #430 at36024249; exact preview passes eleven general/three median Submit checks and records nine Premium402 refusals. This B076 adds five more source reviews and #431 implementation. Same-session model self-review/finite execution only; no independent/human, dedicated Premium, real-device or whole-catalogue acceptance. Preserve all owner holds, including draft#365.

## PR#430 exact production — 15October2026

PR#430 passed required run38805821640 at exact head36024249c2697688db42bfb653fbf5f0bc144596 (verify32m44s; SQL40s), then merged atf6ffef2e0cd0aeb139a1cc66a5b216e3d4a26efa on15October2026 at21:29:57UTC. READY production dpl_9ojjGRJp9Dax7NkreFguw3ymmYWR matches that merge; live devshark.app alias checks before and after probes point to it, without alias error. Exact preview and production each pass eleven general guest checks and three actual changed-task median Submits: reference/valid alternative pass and meaningful cents-rounding wrong fails,0XP/null progress. Nine changed tasks return402 and await dedicated authorized Premium acceptance. Local cohort evidence is60/60 selected final-hash verdicts, forty authored-target/base25 checks, full grading/Learn/release gates and160 fixture-backed light/dark probes. B074–B075 bring shipped model-review coverage to405/725 coding and263/263 native. Five later B076 reviews and #431 native-flatten enforcement are committed at4284c682, separately from this release. #422 remains completed through predecessor#429. Same-session model self-review/finite execution only; no independent/human, authenticated Premium, real-device or whole-catalogue acceptance claim.

## B077 five-item audit — 15October2026 UTC

Read tree mirroring, manual deep cloning, trapped rain, root-to-leaf sums and nested numeric aggregation individually. Preserve correct boards where their stated bounds hold. Copy every mirror topology node but retain opaque payload identities. Fix reference/junior clone output to keep an own __proto__ data key without changing prototypes; index array slots without invoking ignored source iterators, and repair the unfinished starter scratch pad. Replace the rain junior's two auxiliary arrays with two pointers. Define exact bounded integer path/water arithmetic, Number subtotal grouping, own-property selection, immutable source ownership and honest auxiliary-space bounds.

B077 passes31/31 selected final-hash worker expectations:20valid, five starters and six wrongs, versus24/31 baseline (six old false passes plus the crashing clone starter). Fifteen hidden/five visible assertions preserve existing checks. Independent finite evidence covers65 tree shapes,1555 clone patterns,1365 water lists,1291 shape/value path trees with16783 target comparisons,1555 aggregation patterns,128-node trees,64 container depth,20000 copied values,50000 walls and safe totals above32bits. Seven clone candidates reran after the last iterator/prose refinement at its final hash. Twenty authored-target/base25 checks pass; unknown complexity stays hidden/unpenalized.

#432 adds the canonical per-task native JSON.parse/structuredClone restriction before learner initialization in Run, Submit and reused Learn. JSON.stringify debugging, actual returned-object/log formatting, valid manual copying/custom names, other tasks and host natives remain available. Focused final contracts additionally reject constructor access and accept caught blocked calls followed by manual copying. The existing unrestricted structuredClone integrity fixture is decoupled from the manual-copy task, whose opaque functions/Symbols native cloning correctly rejects; seven explicit native capability cases preserve object/array independence, primitive/numeric values and DataCloneError. Existing Map/Set/cycle/own-key runtime contracts remain.

All415 coding review hashes match current content;310 remain, with263/263 native records. Canonical/native Run/reversed-hidden/applicable fixtures, API/script types, complete grading/Learn integrity, launch, production build, registry/index, unused/security, copy sweep, both production dependency audits (zero vulnerabilities), diff and80 fixture-backed light/dark responsive probes at320–1440px pass. The initial launch run ended before a React guest's start marker; a separate complete rerun passed with unchanged code/deadlines. The first integrity run found the stale native-clone/task coupling above; the corrected complete suite passes. Preserve these initial failures as observations, not final acceptance. Twelve physical handlers; archived Czech untouched. No dependency, engine, schema/RLS, entitlement or reward-policy change.

PR#433 has passed required run38811893210 (verify30m58s, SQL41s) at frozen4661ccc6 and merged ata1722c8ccdae8515535983e5bd8fb2500d96e09b. Exact READY preview passes eleven general/six actual changed-task guest Submits, with three Premium tasks blocked. Its production acceptance is still pending. Previously verified production#430 has405 coding/263 native reviews; this B077/#432 adds five source reviews separately. NEEDED reconciles completed table-grant work and labels historical longest-answer statistics as observations requiring a fresh bank audit. Same-session model self-review/finite execution only; no independent/human, authenticated Premium, real-device or whole-catalogue acceptance. Preserve all owner holds and draft#365.

## PR#433 exact production — 15October2026 UTC

PR#433 passed required run38811893210 at frozen4661ccc6b553bf3ea6f8faee63a033f83f0f9f0a (verify30m58s; SQL41s), then merged ata1722c8ccdae8515535983e5bd8fb2500d96e09b on15October2026 at22:15:10UTC. READY production dpl_7QiJR2qZ96CtS5vJeAe3zLsKn9qC matches that merge, owns devshark.app before/after probes and has no alias error. Exact preview and production each pass eleven general guest checks and six changed-task Submits: GCD/Fibonacci references and independent alternatives pass, narrowing/truthiness wrongs fail,0XP/null progress. Three changed tasks return402 and await dedicated authorized Premium acceptance. Each deployment also passes three actual served Run-worker controls: captured native flat blocked under the task policy, manual flattening accepted, native flattening preserved in another realm. Those disposable browser-worker controls do not constitute an authenticated Premium task submission. Canonical server policy authority and reused Learn are covered by the complete successful required integrity run. #431 implementation/release is complete; dedicated Premium acceptance remains under#190. B076 brings shipped current coding review coverage to410/725, with263/263 native. Five B077/#432 reviews are separately frozen in#434 at50ac98ca; B078 remains separate until its checks/commit. Same-session model self-review/finite execution only; no independent/human, real-device or whole-catalogue acceptance claim.

## B078 five-item audit — 15October2026 UTC

Read weighted routing, increasing subsequences, unweighted crawl paths, preorder tree serialization and level-order values individually. Define bounded readonly numeric/graph/tree domains, special/empty string names, exact safe integer costs, complete valid serialization grammar and opaque tree payload identity. Replace copied-route/shift BFS boards with head-index node queues and predecessor Maps; read only own adjacency entries, and reconstruct once with push/reverse. Correct the tied-route visible check to accept both valid shortest routes. Use a scan senior weighted route board matching the authored V²+E bound. Keep correct lower-bound LIS boards. Replace recursive child-string concatenation with token accumulation and the reference level-order queue shift with a head index. Preserve correct junior/senior frontier boards and all previous unique-route/300-depth cases.

All30 final-hash selected verdicts agree (20valid, five starters and five wrongs), versus24/30 baseline: five wrong solutions passed, while the valid reverse-neighbour BFS alternative was falsely rejected. Fifteen hidden/four new visible assertions and the corrected tied-route assertion retain prior cases. Independent finite oracles cover27 weighted maps/243 endpoint queries and512 directed graphs/4608 queries using Floyd distances plus actual route validity;1365 increasing-sequence lists by all-subsequence enumeration;65 tree shapes with independently authored preorder/depth/path order;200 stations/10000 tracks,2000 graph nodes/10000 adjacency slots,20000 scores/tree nodes and512-depth trees. Actual worker cases cover readonly/null-prototype inputs, large exact costs/values, source zero signs, Unicode-safe primitive string names, opaque function/Symbol/BigInt/cyclic payloads and fresh mutable results. Two initial added fixture issues (a weight outside the stated bound and literal __proto__ syntax) were corrected before fresh30-case acceptance. No relaxation of learner grading was used to hide them.

Twenty authored-target/base25 checks pass; unknown estimates remain hidden/unpenalized. Final copy spacing, the accurate sequence title and queue-focus/hint correction reran all30 candidates and20cost checks and rebound all five unpublished reviews to current hashes. Canonical/native Run/reversed-hidden/applicable contracts, API/script types, complete grading/Learn integrity, final launch/build, registry/index,420 current coding bindings,263 native bindings, copy sweep, both zero-vulnerability production dependency audits, diff and80 final-build fixture-backed light/dark responsive probes at320–1440px pass. Earlier responsive observations are retained separately from the final-copy sweep. No runtime-engine/dependency, schema/RLS, entitlement, reward or API-handler change; archived Czech untouched. These are same-session model self-reviews/finite execution, not independent/human or full-catalogue acceptance.

PR#433 is exact-production verified ata1722c8c:410coding/263native, eleven general/six changed-task Submits and three served Run-worker controls on both exact preview/production, with three Premium tasks blocked. #431 is closed with bounded evidence; dedicated authenticated acceptance remains under#190. B077/#432 is separately frozen in#434 at50ac98ca: its exact preview passes eleven general checks and five served-worker clone-policy/format/debug controls; all five changed tasks require Premium, so zero changed-task guest Submits are claimed. Required#434 checks/release remain pending. B078 adds five source reviews:420/725 current,305 remaining (JS61,TS46,React183,algorithms15), with ten source reviews staged above verified production. Preserve all owner holds and draft#365.

## B079 five-item audit — 15October2026 UTC

Read all five cumulative Two pointers and windows stages individually, including inherited specifications, examples, references, starters, hints, approaches and every supported board/fixture. The last two rows were checked against already-read exact inherited material. Keep correct pair, prefix-compaction and numeric/binary window boards. Explicitly bound exact integer pair/window arithmetic, preserve readonly inputs, define non-NaN compaction equality/first exact representatives and allow valid tail trimming. Flips are conceptual and oversized nonnegative budgets are valid.

Fix inconsistent Unicode units in all three subsequence boards. Original actual-worker probes give reference/senior false,false and junior true,true for complete-emoji and half-surrogate queries. The brief now chooses string-iterator code points, including lone surrogates, separate combining marks and no normalization. Reference/senior store wanted code points; junior advances codePointAt by one/two UTF-16 units. State O(n) time/O(m) auxiliary storage, with n=total UTF-16 input length and m=small code-point count; a streaming O(1) alternative is accepted. Correct the mixed-unit hint/approach and carry the fixed function into later stages.

All30 final-hash selected worker verdicts agree (20valid, five starters, five wrongs), versus25/30 baseline with all five wrongs passing. Fifteen new authored hidden/five visible assertions propagate through the cumulative helper as45/15 effective assertions across the five rows, preserving every original case. Independent finite oracles cover1536 pair-target combinations,781 sorted compaction lists,1600 string pairs by two-dimensional code-point DP,27300 positive-window queries by quadratic enumeration and4608 budgets across511 binary lists. Boundaries cover20000-element/UTF-16-unit inputs, exact sums/targets beyond32bits, infinities/fractions, first zero signs, readonly/frozen inputs, result freshness, complete/lone surrogate cases and2^40flip budgets. Correct independent alternatives include monotone shared cursors, run compaction, streamed matching and nonshrinking best-width windows; the alternative proofs are recorded item by item. Type suites are inapplicable to these JavaScript tasks.

Twenty authored-target/base25 checks pass with uncertain estimates hidden/unpenalized. Canonical/native Run/reversed-hidden and earlier-stage regression checks, API/script types, full grading/Learn integrity, launch/build, registry/index,425 current coding bindings,263 native bindings, copy sweep, both zero-vulnerability dependency audits, diff and80 fixture-backed light/dark responsive probes at320–1440px pass. The production-shaped placeholder bundle measures242979gzip bytes against the unchanged243000limit. No runtime-engine/dependency, schema/RLS, entitlement, reward or handler-count change; archived Czech and unrelated stacks stages remain untouched.

Source coverage is425/725 coding,300remaining (JS61,TS46,React183,algorithms10), native263/263. Verified production#433 remains410coding/263native and completes#431. Five B077/#432 reviews are frozen in#434 at50ac98ca with exact preview11general/5served-worker controls; all five changed tasks require Premium and required CI/release remain pending. B078–B079 add ten separate source reviews. Reviews are same-session model self-review/finite execution, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance. The owner's new16October request is tracked in#435: keep the entire identity/photo settings block in the Profile card only, and implement it after the content audit. No UI placement change was made early. Preserve all prior owner holds and draft#365.

## PR#434 exact production — 15October2026 UTC

PR#434 passed required run38816057695 at frozen50ac98ca5b521ee30b2ea5621279a782c928e0e1 (verify31m06s; SQL38s), then merged at7f4d3ac8c21e9ea68c0227dc4fea6e2f79e68b17 on15October2026 at22:54:27UTC. READY production dpl_CGUHKnhrbQj9i85WHXiH4ENx5uCf matches that merge, owns devshark.app before/after probes and has no alias error. Exact preview and production each pass eleven general guest checks. All five changed tasks return402; no authenticated Premium Submit acceptance is claimed. Each deployment passes five actual served Run-worker controls: captured structuredClone and bound JSON.parse blocked under the task policy, manual copying with JSON.stringify debug/result formatting accepted, and both native helpers preserved without that policy. Disposable browser-worker controls do not constitute an authenticated task submission. Canonical server policy authority and reused Learn are covered by the complete successful required integrity run. #432 implementation/release is complete; dedicated Premium acceptance remains under#190. B077 brings shipped current coding review coverage to415/725, with263/263 native. Ten B078–B079 source reviews are separately frozen in#436 at6bfe79183bfcd60658922b930655c9e192de00fb: exact preview eleven general checks and three actual pairWithSum Submits pass; nine tasks require Premium. Same-session model self-review/finite execution only; no independent/human, real-device or whole-catalogue acceptance claim. #435 remains sequenced after the audit.

## B080 five-item audit — 15October2026 UTC

Read all five cumulative Stacks and queues stages individually, including inherited specifications, examples, references, starters, hints, approaches and every supported board/fixture. Keep the three correct path, postfix-evaluation and next-greater boards; explicitly bound inputs, exact safe-integer arithmetic, numeric comparison, ownership and fresh mutable output arrays. Path normalization preserves literal spaces, dots, percent/backslash/Unicode/lone-surrogate names and remains separate from filesystem behavior. Postfix operands/intermediate integers stay safe, with division truncated toward zero. Fractions/infinities are valid in next-greater and sliding maxima, NaN is excluded, output zero signs compare equal and source signs stay unchanged.

Rewrite all three nested decoders to collect chunks, join a body once and repeat it once. Define exact ASCII-count grammar, literal text and empty groups, input/output lengths up to20000 UTF-16 units and depth<=64. State O(n+L) time/storage including input reading, and explicitly explain the fixed depth cap; unbounded depth adds a copying factor. Keep the already-correct front-index sliding-max reference; only junior/senior shift-based boards need repair. Correct the hint/approach to use queue[front] with active suffix bounds and O(n) backing storage; O(k)-space deques remain valid. References now lead to used pop/push methods rather than shift. The initial documentation-contract rejection of the length property link is recorded; no grading contract was weakened to bypass it.

All30 final-hash selected worker verdicts agree (20valid, five starters, five wrongs), versus25/30 baseline with all five wrongs passing. Fifteen new authored hidden/five visible assertions propagate as45/15 effective assertions through cumulative stages, preserving original cases. Independent finite checks cover1555 literal-path combinations by string-suffix parent rewriting, generated postfix trees against BigInt arithmetic,1555 next-greater arrays by quadratic scanning,1555 known encoded/decoded group combinations, and1555 small sliding-max arrays across valid/oversized windows by direct maxima. Boundaries include20000-unit paths/arrays/parser inputs/expanded output,64-deep empty1000x groups,19999-token expression stacks, max-safe integers and2^40windows, exact Unicode/fractions/infinities, readonly/frozen sources and mutable fresh results. Alternatives use token-prefix compaction, bounded BigInt evaluation, reverse value stacks, a length-annotated AST with empty-subtree pruning and block prefix/suffix maxima. Type suites are inapplicable to these JavaScript tasks. Initial authoring-tool path/escaping errors were repaired before acceptance and are not counted as learner verdicts.

Twenty authored-target/base25 checks pass, with uncertain estimates hidden/unpenalized. Canonical/native Run/reversed-hidden and earlier-stage regression checks, API/script types, full grading/Learn integrity, launch/build, registry/index,430 current coding bindings,263 native bindings, copy sweep, both zero-vulnerability production dependency audits and80 final-build fixture-backed light/dark responsive probes at320–1440px pass. The copy sweep's literal accaccacc is an exact item/field/string exemption for decoded example data, not a broad hexadecimal exemption. Earlier probes begun while the build was finishing are retained separately and excluded from final acceptance. Production-shaped initial requests measure242979gzip bytes under the unchanged243000budget. No runtime-engine/dependency, schema/RLS, entitlement, reward or physical-handler change; archived Czech and reviewed pointer stages are untouched.

Source coverage is430/725 coding,295remaining (JS61,TS46,React183,algorithms5); native263/263. Verified production#434 remains415coding and completes#432. Ten B078–B079 reviews are separately frozen in#436 at6bfe7918; exact preview passes11general/3actual pairWithSum Submits with9Premium tasks blocked; required CI/release pending. Same-session model self-review/finite execution only, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance. Keep#435 sequenced after the audit, owner holds and draft#365 unchanged.

## PR#436 exact production — 15October2026 UTC

PR#436 passed required run38819522261 at frozen6bfe79183bfcd60658922b930655c9e192de00fb (verify31m33s; SQL35s), then merged at83b398ee75d5ddb5126ed7cb7882e4c5375cf87d on15October2026 at23:21:00UTC. READY production dpl_AHuTwRNMxDpmdjrXqcWd1QwfAwWW matches that merge, owns devshark.app before/after probes and has no alias error. Exact preview and production each pass eleven general guest checks and three actual pairWithSum Submits: reference/independent alternative pass,32-bit narrowing wrong fails,0XP/null progress. Nine changed tasks return402 and await dedicated authorized Premium acceptance under#190. B078–B079 bring shipped current coding review coverage to425/725, with263/263 native. B080 is separately committed at55689e58; B081 is in final local gates and is not claimed deployed. Same-session model self-review/finite execution only, not independent/human, real-device or whole-catalogue acceptance. Keep#435 sequenced after the audit, owner holds and draft#365 unchanged.

## B081 five-item audit — 15October2026 UTC

Read the last five algorithm tasks individually, including every field, supported board and visible/hidden fixture. Fix the smallest-window boards/skeleton/approach to use consistent code points, including lone surrogates, with code-point window length and explicit UTF16 input-size bounds. State actual O(n+m) materialized storage, allowing streaming alternatives. Contact merging consumes each email adjacency once; reference/junior traverse iteratively and senior uses compressed ranked union with first-encounter names/order separate from root choice. Define N contacts/E occurrences, bounded literal strings and readonly/null-prototype inputs; include email-less contacts in the O(N+ElogE) model.

Keep valid promise workers and bounded junior batches without inventing a work-conserving requirement. Standardize bare zero-argument callback invocation, opaque result/rejection identity and no cancellation guarantee. Make both unfinished async starters return promises so their scratch pads no longer crash. Retry junior becomes an iterative async loop; distinguish scheduling/call overhead from exponential waits and preserve exact falsy/undefined/Symbol/object outcomes. Define all callback/budget/input bounds. Rewrite dictionary segmentation into a viable-cut DAG and one push/pop output path, avoiding retained suffix-sentence copies. Include substring/hash work and string-sort comparisons in the applicable O(D+n³+L+nRlogR) time/O(D+n²+L) space model, with actual n,D,R,L definitions and explicit output bounds; exact UTF16 words, tabs, duplicates and separator policy are specified.

All30 final-hash selected worker verdicts agree (20valid, five starters, five wrongs), versus23/30 baseline: five wrongs passed and two async starters errored. Fifteen new hidden/five visible assertions preserve original cases. Independent finite oracles cover1573 covering-window pairs by direct substring counts,512 contact books by pairwise transitive closure and1984 segmentation cases by cut-mask enumeration. Bounds include50000/20000UTF16 strings,2000-contact chains/stars/empty-email books,10000 duplicate email occurrences,2000 promise tasks at serial/intermediate/2^40 limits,200-unit segmentation/2000-word dictionaries and original4181 answers. Identity, exact call counts/concurrency, readonly/frozen sources, fresh mutable results, Unicode/default ordering, literal spaces/tabs, negative/zero retry budgets and opaque successes/failures are checked. Independent alternatives include formed-kind counters, ranked DSU, shared workers, trie cut discovery with iterative enumeration and a while-loop retry. Type suites do not apply to these JavaScript tasks.

Initial exact timing fixtures passed the virtual Submit worker but were rejected by native Run, whose timers are real; a20-combination fixture also exceeded native per-case duration. Authored checks now use bounded real-scheduler tolerances, five failed budgets and no-overlap/identity/interval checks; original timing cases remain. Twelve separate private exact virtual-clock probes across four valid boards still pass, including20 budget/outcome timelines and exact7ms-callback start/completion times. No timer-global mutation, changed deadline or runtime-engine change was used. The initial stale helper binding was recompiled and all435 current hash bindings pass. Target wording was corrected to identify time work explicitly; no guidance extractor or grading test was weakened.

Twenty authored-target/base25 checks, canonical/native Run/reversed-hidden/earlier-stage contracts, API/script types, full grading/Learn integrity, launch/build, registry/index,435 coding/263 native bindings, copy sweep, both zero-vulnerability production dependency audits, diff and80 final-build fixture-backed light/dark probes at320–1440px pass. The final production-shaped initial download remains242979gzip bytes under the unchanged243000budget. Twelve physical handlers; archived Czech unchanged. No schema/RLS, entitlement/reward, dependency/engine or UI placement change.

Source435/725 coding,290remaining (JS61,TS46,React183,algorithms0); all70algorithm and263native rows now have current individual model bindings. Verified production#436 is425coding/263native at83b398ee / READY dpl_AHuTwRNMxDpmdjrXqcWd1QwfAwWW, with required CI and exact preview/production11general plus3pairWithSum Submits; nine Premium tasks remain blocked under#190. B08055689e58 and these five B081 reviews are ten source records above that release. These are same-session model self-reviews/finite execution, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance. Do not enable global reviewed-coding eligibility before the remaining290 and associated bank reconciliation are complete. Keep#435 explicitly after the audit, all owner holds and draft#365 unchanged.

## B082 five-item audit — 15October2026 UTC

Read five JavaScript tasks individually: fixed-order debt settlement, greedy paragraph justification, literal route matching, nested settings diffs and the single-number Expression engine checkpoint. Every field, supported solution, visible/hidden fixture and relevant checkpoint generator/reference/hint flow was read. Keep correct settlement reference/senior and change junior shifts to indices. Bound exact integer cents/counts/names and ownership; define UTF16 name ordering, one initial sort and fresh mutable payments. Keep justification semantics while all boards collect chunks, senior caches packing length and junior pads once; state literal UTF16 width, exact whitespace splitting, no normalization and O(n+L) copy/output work.

Fix route reference/junior __proto__ parameter capture with null-prototype data records, and senior root normalization with the same one-pop rule. Actual original-worker probes show reference/junior root-pass/own-key-fail, senior root-fail/own-key-pass. Specify literal path/segment bounds, internal empty segments, duplicate/rest rules, stable specificity and a string-length-aware complexity model. Keep correct settings traversal/flattening with own-property guards; bound plain-record trees and nonempty dot-free keys, strict leaf/array equality including NaN and zero signs, readonly inputs and path-copy/sort costs. Empty objects and object/leaf replacement retain their previous behavior.

Keep the sole Number(trim) checkpoint board and define bounded ASCII decimal literals, leading zeros, official trim whitespace, exact safe Number values and O(n) copy-model guidance. Add optional checkpoint focus/reference metadata through the existing builder so this one step links Number documentation and uses strings/functions rather than inherited split/reduce/addition metadata. Other checkpoint metadata stays unchanged. Its existing tier projection already labels it Easy; no difficulty/access/reward change. No junior/senior board is invented. Czech source arguments and archived files are unchanged and not newly approved.

All28 final-hash selected worker verdicts agree:18valid, five starters, five wrongs, versus23/28 baseline with all five wrongs passing. This supported-board mix has18 authored-target/base25 checks, not20. Fifteen new hidden/five visible assertions retain originals; the visible checkpoint requirement propagates to later unreviewed calculator stages, while its hidden cases stay scoped to this checkpoint. Independent finite oracles cover381 balanced books by cumulative flow-interval overlap,364 word sequences across9widths by independent greedy grouping/round-robin gaps,1089 route-pair/path cases,100 settings-value pairs by separately flattened leaves and1025 bounded numeric-string queries. Boundaries cover2000people/1e12cents,20000-unit text/widths,Unicode/combining/lone-surrogate literal behavior,1000routes/1000-unit paths,64-level settings/19997arrayitems within the input cap,25trim-whitespace forms,MAX_SAFE_INTEGER and20000-unit numeric padding. Own prototype-like keys, symbol/non-enumerable metadata, readonly/frozen inputs, fresh mutable outputs and exact equality are covered. Early authored fixture encoding/own-prototype literals and a count bound were corrected before acceptance; no learner grading rule was weakened.

Canonical/native Run/reversed-hidden and checkpoint/earlier-stage contracts, API/script types, full grading/Learn integrity, launch/build, registry/index,440coding/263native bindings, copy sweep, both zero-vulnerability production dependency audits, diff and80 final-build light/dark fixture-backed probes at320–1440px pass. The initial download is242972gzip bytes under the unchanged243000budget. Manual digit accumulation also receives O(n)/base25; complex authored models remain unknown and unpenalized. No runtime/dependency, schema/RLS, entitlement/reward, physical-handler count or UI placement change in B082.

Source440/725coding,285remaining (JS56,TS46,React183); all70algorithms/263native remain bound. Verified production#436 stays425coding/263native. Ten B080–B081 reviews are frozen in#437 atdcc7aa7e; exact READY preview passes11general and3actual simplifyPath Submits at0XP/nullprogress, with9Premium tasks blocked. Required run38823946963/release remain pending. Larger follow-up#438 records actual accepted native eval/Function use despite the later parser prohibition: local7-case baseline5matches/two prohibited-helper false passes at hashd0faa8c88fb98632. Implement that canonical runtime/Run-controller correction with the next calculator audit, after this five-item commit. It is not fixed or counted as reviewed by B082. Preserve #435 after the whole content audit, owner holds and draft#365. Same-session model self-review/finite execution only, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance.

## PR #437 exact production — 16 October 2026 UTC

PR #437 passed required run 38823946963 at frozen dcc7aa7e20bd2b8bb38dd6f431138a53ba88d548 (verify 31m35s; SQL 39s), then merged at ab0bc48124d54478924500d8dc62b4072e20b815 on 16 October 2026 at 00:08:28 UTC. READY production dpl_BuT91F3gFqWmT41jzwdJJT9nB22A matches that merge, owns devshark.app before and after probes and has no alias error. Exact READY preview dpl_55t8Bv75df2N99psQKdEfmEc8X2W and production each pass eleven general guest checks and three actual simplifyPath Submits: reference and independent alternative pass; name-trimming wrong fails; all receive 0 XP/null progress. Nine changed tasks return 402 and await dedicated authorized Premium acceptance under #190. B080–B081 bring shipped current coding review coverage to 435/725; native remains 263/263. B082 is separately committed at 70502b0d, bringing source coverage to 440/725 with 285 remaining. B083/#438 is in progress and not yet approved or deployed. Same-session model self-review and finite execution only; no independent/human, real-device or whole-catalogue acceptance claim. Preserve #435 after the whole content audit, owner holds and draft #365.

## B083 five-item audit and parser compiler policy — 16 October 2026 UTC

Read five JavaScript Expression engine tasks individually: safe sums, decimal addition/subtraction, multiplication/division precedence, valid parentheses and the complete unary/validating parser. Define raw20000UTF16-unit bounds, ASCII decimal grammar, ECMAScript intertoken whitespace, leading zeros, ordinary Number rounding and O(n) time/storage with actual raw n. Later parser grammar is bounded to64parenthesis levels/64consecutive unary signs and requires complete consumption, null for malformed/empty/trailing input, any zero divisor or a nonfinite final result. Intermediate overflow is not independently banned: a huge literal reciprocal may validly become0. Keep the existing safe-sum boards and valid earlier checkpoint semantics. Reference uses sticky numeric matches rather than repeated suffix copies; junior copies each numeric span once and now checks final finiteness. Preserve senior precedence climbing, original tests and archived Czech arguments.

Own focus/hints/method steps now match each milestone/checkpoint. Clearing an absent checkpoint approach prevents new later instructions leaking backward; all440 prior review hashes remain unchanged. No unsupported junior/senior boards are invented. Fifteen hidden/five visible assertions cover1764 safe triples,864 decimal left-fold cases, bounded precedence combinations with an independent arithmetic-tree oracle, generated parenthesized ASTs, MAX_SAFE_INTEGER, ordinary0.1+0.2 rounding, FEFF/NBSP,19999/20000-unit inputs,64nesting/unary signs, malformed lexical/token partitions, nested zero divisions and huge finite-final/overflow behavior. All27 selected final-hash worker verdicts agree (16valid,5starters,6wrong), versus21/27 baseline where all six wrongs passed. Sixteen supported-board authored-target/base25XP checks pass; uncertain estimates remain hidden and unpenalized.

#438 fixes the existing no-eval/no-Function requirement in the complete parser and its later dependents. Canonical task IDs select the existing runtime policy; no source-word or custom-method blacklist. Target-realm denial wrappers revoke eval and ordinary/async/generator/async-generator Function-family constructors before learner initialization. Constructor descriptors and getter-only global properties prevent restoration, including the observed QuickJS value-only defineProperty replacement of locked data properties. Native Run captures its trusted compiler privately and compiles authored call closures over learner declarations rather than direct eval; console compilation remains lazy for page CSP. Existing strict/probe/line-number/async/formatting behavior is retained. Earlier stages, unrelated tasks and host constructors remain available. Actual Run/Submit/reused Learn controls cover twelve alias/constructor routes with positive unrestricted controls, restoration attempts, three manual boards, caught denials, custom similarly named functions, syntax, trailing-comment/semicolon callbacks and cross-realm isolation. A rebuilt worker is used; an earlier stale worker result is excluded.

All14 served-worker controls pass against the final local build: five native compiler routes blocked, three manual boards accepted, five unrestricted counterparts accepted and value-only global restoration blocked. These disposable browser workers create no server submission or progress. The first local public-workbench attempt had no API fixture and timed out waiting for a worker; it is excluded. Final local evidence explicitly loads the built served asset. Preview/production must separately discover the actual worker from the deployed public workbench.

API/script types, all calculator canonical/native Run/reversed-hidden/checkpoint/earlier-stage contracts, full grading/Learn integrity,104client files/1002tests, coding authorization,206Chromium harness assertions, launch, security/unused, registry/index,445coding/263native bindings, copy sweep, build and80final-build light/dark fixture-backed probes at320–1440px pass. Both production dependency audits report zero vulnerabilities. The production-shaped placeholder initial download is242996gzip bytes under the unchanged243000budget. SQL and broader required CI/release acceptance are pending the PR; local evidence does not claim them. Exactly twelve physical TypeScript handlers; no engine/dependency, schema/RLS, entitlement/reward or UI placement change.

Source445/725coding,280remaining (JS51,TS46,React183); native263/263. Verified production#437 is435coding at ab0bc481 / READY dpl_BuT91F3gFqWmT41jzwdJJT9nB22A, with required CI and exact preview/production11general plus3simplifyPath Submits;9Premium tasks remain blocked under#190. B08270502b0d and B083 add ten separately staged source reviews. #438 stays open until guarded release; #435 remains explicitly after the whole content audit. Preserve owner holds/draft#365. These are same-session model self-review/finite execution, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance. Do not activate complete coding eligibility before the remaining280 and bank reconciliation are complete.

## B084 five-item audit — 16 October 2026 UTC

Read five JavaScript tasks individually: valid identifier operands, validating identifier lookup, valid programs, rejecting invalid programs and the initial shallow array-copy Query checkpoint. Define case-sensitive64-character names,<=2000 own variable data fields, arbitrary prototypes/frozen records, own non-enumerable values, ignored inherited/symbol fields and only referenced property lookup. Raw expression/total program text is bounded to20000UTF16 units with<=2000program lines and earlier parser grammar/depth/numeric rules. Finite Number variable values include MIN_VALUE/MAX_VALUE and exponent-printed values; substitution uses plain digits/parentheses or direct token lookup. Outputs retain fresh mutable ownership; each program call starts fresh and assignments evaluate their right side before storing. Query's<=20000dense records stay opaque and retain exact identities/order/duplicates in a fresh mutable array.

Actual original-worker probes show the senior variable lookup rejecting an own non-enumerable variable while reference/junior pass; the valid-program checkpoint loses __proto__, while all three milestone boards pass that own-key probe. Senior now reads referenced own fields rather than copying Object.entries, junior collects source chunks and scans identifier spans once, valid-program checkpoint uses a null-prototype environment, and senior program avoids copying the entire environment before every line. Keep correct remaining boards, original assertions and archived Czech arguments. Scoped advanced/checkpoint focus and method guidance match the actual step; all445 prior English task hashes remain unchanged. O(n)/O(n) targets count actual raw source/line count or copied array positions, with bounded Number decimal width and normal property-lookup model.

Fifteen new hidden/five visible assertions cover500 direct-arithmetic identifier cases,150 independently checked Map-oracle programs,1365 opaque-reference array arrangements, readonly/prototype-like/non-enumerable/symbol ownership, ordinary rounding/extreme Number values,64nesting,20000-unit source/2000-field and2000-line stress, malformed/unknown/zero-dividing/nonfinite programs, output descriptors/freshness/mutability and20000shared records with opaque20000-unit data. All24 selected final-hash worker verdicts agree (14valid,5starters,5meaningfulwrongs), versus19/24 baseline where every wrong passed. Fourteen supported-board authored-target/base25checks pass; unknown estimates stay hidden/unpenalized. An initial boundary fixture accidentally assigned __proto__ through the inherited setter; it was corrected to an own data descriptor before final acceptance. The first post-edit grader bundle was stale and is excluded; final evidence uses a rebuilt current grader. A missing Localized compatibility field in new method metadata was corrected using the existing text helper and empty unserved translation; API/script types then pass.

All calculator/query canonical/native Run/reversed-hidden/checkpoint/earlier-stage contracts, full grading/Learn integrity, API/script types, launch, registry/index,450coding/263native bindings, copy sweep, final build, both zero-vulnerability production dependency audits, diff and80light/dark fixture-backed probes at320–1440px pass. All final build files are byte-identical after the metadata type-wrapper correction, preserving the completed responsive evidence. Production-shaped placeholder initial download242991gzip bytes passes the unchanged243000budget. B083's104client files/1002tests/206Chromium harness assertions remain dated evidence for the unchanged UI/runtime; they were not newly rerun as B084 tests. Twelve physical handlers; no runtime/engine/dependency, schema/RLS, entitlement/reward or UI placement change.

Source450/725coding,275remaining (JS46,TS46,React183); native263/263. Verified production#437 remains435coding. Ten B082–B083 source records are frozen in#439 at9db2a0b5 with required run38830360155 in progress/SQLpassed, exact READY preview11general/3actual single-number checkpoint Submits and14served-worker controls. Seven Premium tasks and two later free evolving-stage locks require separate dedicated acceptance under#190; no lock is bypassed. The original QA helper's null-session400attempts are excluded; final helper reports existing stage gates while preserving frozen authored solution data. B084 adds five separate source reviews. #438 stays open until guarded production acceptance; #435 remains after the whole audit. Preserve owner holds/draft#365. Same-session model self-review/finite execution only, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance.

## B085 five-item audit — 16 October 2026 UTC

Read five Query pipeline tasks individually: strict filtering, stable sorting checkpoint, sorting/pagination milestone, own-field projection checkpoint and projection/deduplication milestone. Define bounded own enumerable condition keys, ordinary row lookup, strict NaN/zero/object-reference equality, readonly dense arrays/records and opaque unrelated fields. Cache reference filter conditions once. Preserve the existing numeric/literal UTF16 sort model with homogeneous finite Numbers or bounded strings, no locale/NFC, stable ties in both directions and optional orderBy distinguished from an empty supplied field name. Keep filter->sort->page->project->distinct ordering, safe-integer bounds/defaults/zero limit and exact row/value identities. Later briefs refer to inherited rules rather than repeating their whole domain. Authored targets account for input row/condition work and sorting: O(n*m) or O(n*m+n*log(n)), O(n+m) storage, n=rows.length+1,m=conditions+1, bounded key/comparison/serialized widths. Complex multiinput estimates remain unknown, hidden and unpenalized.

Actual original-worker probes show reference/sole sorting checkpoint failing empty orderBy while junior/senior pass. Projection reference passes own non-enumerable/prototype-like fields, junior loses __proto__ and senior loses non-enumerable selected data. All reference query variants now test orderBy against undefined; junior projects into null-prototype data records and tracks seen identities in a Set; senior reads requested own fields directly. Preserve correct reference key/value-pair identity encoding and existing strict-equality/phase semantics. Projection includes own non-enumerable/undefined data, omits inherited/missing fields, preserves selected references and creates fresh mutable records; distinct compares bounded JSON-primitive own enumerable string-field sets with first-result identity. Prototypes/symbol/non-enumerable metadata do not affect distinct identity. No source Czech argument or archived file changes; all450previous English task hashes remain current.

Fifteen new hidden/five visible assertions cover4096 explicit two-field predicate matrix comparisons,364ternary arrays in both directions against independent counting-bucket order,1152small page-oracle configurations,128direct-field-set equality inputs, selection masks/duplicates/empty projections, NaN/signed-zero/object/missing-undefined behavior, composed/decomposed/lone-surrogate literal ordering,2^32/MAX_SAFE_INTEGER bounds, combined filtering/sort/page order, readonly/opaque/prototype/non-enumerable/undefined/descriptors/freshness/mutability and20000record sorting/filtering/projection/unique/repeated boundaries. All26 final-hash worker verdicts agree (16valid,5starters,5meaningfulwrongs), versus21/26baseline with every wrong accepted. The independent implementation uses explicit stable merge sorting, filtering/manual pages, own-data projection and Set identities. Sixteen supported-board authored-target/base25checks pass. The final recheck follows shortened cumulative prompts and added combined-phase/empty-selection assertions; no stale-hash execution is counted.

All calculator/query canonical/native Run/reversed-hidden/checkpoint/earlier-stage contracts, full grading/Learn integrity, API/script types, launch, registry/index,455coding/263native bindings, copy sweep, build, both zero-vulnerability production dependency audits, diff and80final-build light/dark fixture-backed probes at320–1440px pass. Initial download242976gzip bytes passes the unchanged243000budget. Earlier B083 client/harness acceptance remains dated evidence for the unchanged UI/runtime rather than a new B085full-client claim. Exactly twelve physical API handlers; no runtime-engine/dependency, schema/RLS, entitlement/reward or Profile placement change.

Source455/725coding,270remaining (JS41,TS46,React183); native263/263. Verified production#437 remains435coding. Ten B082–B083 records are frozen in#439 at9db2a0b5 with exact READY preview11general/3Number-checkpoint Submits and14served-worker controls;7Premium/2evolving-stage locks remain blocked under#190. Its required CI/guarded release stays separately tracked, and #438 remains open until production acceptance. B084659ebea0 and B085 add ten separate source reviews. Preserve #435 after the whole audit, owner holds and draft#365. Reviews are same-session model self-review/finite execution, not independent/human, physical-device, authenticated Premium or whole-catalogue acceptance.

## PR #439 exact production and #438 completion — 16 October 2026 UTC

PR #439 passed required run38830360155 at frozen9db2a0b5048a90526e8c197ad14426f22cd59dcc (verify31m49s; SQL39s), then merged at62a706a53b42f7048c4ea4865155001fa2b2ecb6 on16October2026 at01:08:51UTC. READY production dpl_2so9KGwiUxRWyWDCtMxQKyfFXTMw matches that merge, owns devshark.app before/after probes and has no alias error. Exact READY preview dpl_8XFHNm823ymyMDSNHJC3DEUUAMxU and production each pass eleven general guest checks, three actual single-number calculator checkpoint Submits (reference/independent accumulator pass;32-bit narrowing wrong fails;0XP/null progress), and fourteen actual served Run-worker controls for #438: five native compiler routes plus value-only restoration blocked, three manual boards/five unrestricted counterparts accepted. Disposable workers create no server submission/progress. Seven other tasks require Premium and two later free evolving stages issue no session before prerequisites; these remain separate dedicated acceptance under#190. The original cohort helper assumed all200responses had a session; its null-session400attempts are excluded. Final helper recognizes existing stage locks and retains frozen authored solutions. Local/required CI cover actual parser Run/Submit/reused Learn and target-realm isolation; no authenticated Premium production Submit is claimed. This completes #438. B082–B083 bring deployed coding review coverage to445/725; native263/263. B084659ebea0/B0854f3f7342 are ten newer source records frozen in#440 ate257fe3c5a40136f307afedbdd017c577b1bb8d4:455source/270remaining. B086 is private preparation, not accepted coverage. Same-session model self-review/finite execution only, not independent/human, physical-device or whole-catalogue acceptance. Keep #435 explicitly after the whole audit, owner holds and draft#365 unchanged.

## B086 five-item audit — 16 October 2026 UTC

Read five JavaScript tasks individually: finite-only grouping checkpoint, finite-filtering grouping milestone, inner-join checkpoint, left-join milestone and the one-listener Event bus checkpoint. Define ordinary bounded data-property lookup, immutable dense records, first-seen key/position order, exact source/key/payload identities, fresh mutable outputs and explicit input/output bounds. Keys retain strict=== semantics: each NaN starts a separate group and never joins, zero signs match and object/function/symbol keys match by identity. Amount sums use ordinary Number rounding/possible overflow; the checkpoint requires finite amounts, while the milestone counts every row and ignores invalid amounts. Grouping is O(n)/O(n); nested joins retain an honest O(n*m+L)/O(n+m+L)target with indexed alternatives permitted, n/m including1 and L the bounded pair output. Event delivery is O(1)per method excluding callback work, with O(k)lifetime storage; it forwards opaque values synchronously without inspecting/cloning them and keeps independent state. Multiple listeners/reentrancy/errors remain later work at this first checkpoint.

Actual original-worker probes show the finite grouping checkpoint and senior group/join boards violating the NaN rule, with five passing nested/reference/junior controls. Group reference/junior now use indexed lookup plus ordered groups rather than repeated group searches. The finite checkpoint/senior grouping use fresh private Symbol slots for NaN; output keys remain original. Senior join skips NaN right keys and guards NaN left lookup, producing a null-right pair only in left mode. Keep correct nested joins and the one-listener Map board. Scoped focus/hints/method steps fit each stage, and later prompts refer to inherited domain rules instead of repeating them. Every original assertion/Czech source argument is retained; all455 prior English hashes still match. All10calculator and10query tasks now have current individual source bindings, alongside70algorithms/263native; this is not a complete-catalogue claim.

Fifteen new hidden/five visible assertions cover128eight-row mixed-key grouping sequences against an independent linear===oracle,64five-by-five join inputs (both modes for the milestone),32event sequences over10string/symbol names, NaN/zero/identity/case/invalid-amount/overflow boundaries, ordinary inherited/missing/empty/prototype-like field lookup, readonly/opaque/descriptors/freshness/mutability,20000repeated/2000unique grouping records,20000Cartesian pairs/1000unique joins, empty sides and20000event registrations/emits. Opaque event payloads include falsy/undefined/NaN/signed-zero/function/symbol/cyclic/getter objects. All24 final-hash worker verdicts agree (14valid,5starters,5meaningfulwrongs), versus19/24 original catalogue baseline. Semantic wrongs were isolated from inherited group-search costs and rebaselined before source/fixture export; the initial raw baseline is retained separately. Fourteen supported-board target/base25checks pass; uncertain estimates remain hidden/unpenalized. The final fresh recheck includes shortened milestone prompts and combined ownership/stress assertions.

All calculator/query/events canonical/native Run/reversed-hidden/checkpoint/earlier-stage contracts, full grading/Learn integrity, API/script types, launch, registry/index,460coding/263native bindings, copy sweep, build, both zero-vulnerability production dependency audits, diff and80final-build light/dark fixture-backed probes at320–1440px pass. Initial download242981gzip bytes passes the unchanged243000budget. No runtime-engine/dependency, schema/RLS, entitlement/reward, handler-count or Profile placement change. Prior B083 full client/harness acceptance remains dated evidence for the unchanged UI/runtime, not a new B086client run. Exactly twelve physical API handlers.

Source460/725coding,265remaining (JS36,TS46,React183); native263/263. Verified production#439 is445coding at62a706a5 / READY dpl_2so9KGwiUxRWyWDCtMxQKyfFXTMw and completes#438: required verify31m49s/SQL39s, exact preview/production11general/3actual Number-checkpoint Submits/14served-worker controls and before/after alias/SHA/READY/no-error guards. Ten B084–B085 records are frozen in#440 ate257fe3c with exact READY preview11general and3initial Query-checkpoint Submits;7Premium/2stage locks remain dedicated acceptance under#190. Required run38833627674/guarded release are pending for#440; these five B086 reviews are separate source work. Preserve #435 explicitly after the whole audit, owner holds and draft#365. Same-session model self-review/finite execution only, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance.

## PR #440 exact production — 16 October 2026 UTC

PR #440 passed required run38833627674 at frozene257fe3c5a40136f307afedbdd017c577b1bb8d4 (verify31m56s; SQL43s), then merged at4e941628055eda96e3eaf8b8d522c7a79f17d346 on16October2026 at01:45:09UTC. READY production dpl_BKpvT45mtMXrqDET27ubAnENVA5t matches that merge, owns devshark.app before/after probes and has no alias error. Exact READY preview dpl_8Sbw5tXqAvN3WHPWPuZQXx5vmiRg and production each pass eleven general guest checks and three actual initial Query-checkpoint Submits: reference/independent identity-preserving array copy pass, per-record cloning wrong fails,0XP/null progress. Seven other changed tasks require Premium and two later free evolving stages issue no session before prerequisites; these remain dedicated acceptance under#190, with no lock bypass or authenticated Premium claim. B084–B085 bring deployed coding review coverage to455/725, native263/263. B086e787b3a2 is a separate five-item source commit:460current/265remaining (JS36,TS46,React183). B087 is in progress and not yet approved. #438 remains closed with its own #439production acceptance; #435 stays explicitly after the whole content audit. Same-session model self-review/finite execution only, not independent/human, physical-device or whole-catalogue acceptance. Preserve owner holds and draft#365.

## B087 five-item audit — 16 October 2026 UTC

Read five JavaScript Event bus tasks individually: ordered multiple listeners, unsubscribe checkpoint, once milestone, direct-error checkpoint and snapshot/error milestone. Clarify exact bounded string/symbol keys, opaque payload identity, one synchronous callback argument, independent repeated registrations, idempotent off, once consumed before callback invocation, direct error identity, fresh mutable error arrays and per-call nested error ownership. Subscription changes are excluded until the snapshot stage; its own per-emit snapshots preserve queued ordinary listeners despite off, defer new registrations and skip already-fired once entries. Callback this-value is not graded. Targets are O(n) time/O(n) additional space per emit, n=1+that event's subscriptions, excluding callback work and persistent state; registration/off are amortized O(1), persistent state O(k) for at most20000 lifetime registrations, with bounded nested depth/invocations.

Replace array removal in the generic reference with ordered unique Set entries and direct deletion. Junior once boards use stable entry objects in a Set; only the snapshot milestone copies the Set, while the error checkpoint deliberately retains live traversal so it still fails the next stage's mutation cases. Keep correct senior Set/pending-wrapper boards and unsubscribe checkpoint. Instrumented source-copy controls with64once registrations/deliveries count2016 trailing array shifts in three original reference boards or2080 removal-loop visits in two junior boards; two original senior controls already avoid array removal. All seven final boards make64 Set deletions for64deliveries. These finite work counters are not measured timing, a speedup claim or an automated whole-program complexity proof.

Fifteen hidden/five visible assertions add64command traces over nine exact names,256unsubscribe masks,64on/once/off models, nested once delivery, mutation/snapshot ordering, nested direct error ownership, opaque/falsy/undefined/NaN/signed-zero/function/symbol/cyclic/getter/array payloads, Unicode canonical distinctions, repeated callback independence and fresh mutable empty/nonempty results. Boundaries include20000duplicate registrations and2000once deliveries/throws. Fix the new oracle before acceptance to invoke bus methods normally and unsubscribe as standalone functions; it imposes no detached-method binding rule. Correct the event enumeration step to cover all nine names. Preserve all original assertions and all460 prior English hashes.

Final current-hash recheck passes26/26 verdicts:16valid boards/alternatives,5starters and5meaningful semantic wrongs, versus21/26 original catalogue baseline. Baseline wrongs were isolated onto an independent efficient Set bus before authored fixture/source changes; initial raw results are retained separately. Sixteen supported target/base25 reward checks pass; unknown factory estimates remain hidden and unpenalized. Own hints/method steps explain each stage without disclosing later rules. Original Czech source arguments remain unchanged.

All calculator/query/events canonical/native Run, reversed-hidden, earlier/checkpoint contracts, full grading/Learn integrity, API/script types, launch, registry/index,465coding/263native bindings, copy sweep, build, both zero-vulnerability production dependency audits, diff and80final-build light/dark fixture-backed probes at320–1440px pass. Initial download242981gzip bytes meets the unchanged243000budget. B083full-client/harness acceptance remains dated evidence for unchanged UI/runtime, not a new B087run. Exactly twelve physical API handlers; no engine/dependency/schema/RLS/entitlement/reward/Profile placement change.

Source465/725coding,260remaining (JS31,TS46,React183); native263/263. Verified production#440 has455coding at4e941628 / READY dpl_BKpvT45mtMXrqDET27ubAnENVA5t after required verify31m56s/SQL43s and exact preview/production11general/3actual Query-checkpoint Submits with before/after alias/SHA/READY guards. Seven Premium/two prerequisite locks remain dedicated acceptance under#190. Ten B086–B087 source records are separate pending release. #438 remains closed with #439production evidence; #435 explicitly follows the whole content audit. Preserve owner holds and draft#365. Same-session model self-review/finite execution only, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance.

## B088 five-item audit — 16 October 2026 UTC

Read five JavaScript tasks individually: FIFO-buffer checkpoint, callback-pause/reentrant buffer milestone, bounded-replay checkpoint, clear-history milestone and independent graph-key checkpoint. Preserve original cases, exact bounded event/payload identity, prior subscription/snapshot/error rules and all465 earlier reviewed English hashes. Add15hidden/5visible assertions. Correct a private LIFO candidate closing brace and rerun the original baseline before authored changes; final baseline is19/24. Correct the new graph oracle to define an own __proto__ property instead of invoking its inherited setter; exclude that initial failed oracle. Final current-hash acceptance is24/24:14valid boards/independent alternatives,5starters and5meaningful semantic wrongs. Fourteen supported authored-target/base25 reward checks pass; unknown factory estimates stay hidden/unpenalized.

Buffer reference uses a cleared head cursor, junior linked head/tail nodes and senior two stacks. Consume each pair before callbacks, resolve subscriptions when draining, finish the current event snapshot before honoring pause and preserve FIFO across nested resume or newly queued emits. Each call owns its direct errors; thrown arrays remain one value. Checkpoint deliberately excludes callback buffer mutation until the milestone and still fails it. Define at most20000lifetime emissions/registrations and inherited base nesting bounds. Target O(n)amortized resume with n=1+drained pairs+captured subscription entries, excluding callbacks/separately charged nested calls; queue storage O(H)lifetime enqueues rather than claiming only pending length, subscriptionsO(k), transient delivery/errorO(c). Queue-operation amortization, not elapsed-time/asymptotic measurements, justifies cursor/linked/two-stack approaches. Replace Array.shift reading with Array.push. Tests cover32modeled8-event/24queued traces with on/once/off/exact errors, opaque/falsy/cyclic/getter values, nested pause/resume/once/error traces and20000FIFO deliveries. LIFO and queued-object-clone wrongs passed originals and now fail.

Replay boards use lazy per-event rings rather than repeated array copies/front shifts. Capacity is any non-negative safe integer, including0,2^32 andMAX_SAFE_INTEGER; allocate only actual retained emissions. Keep original values, separate histories, retain before live callbacks, replay oldest first and return idempotent off. The checkpoint has no clear and retains its prior after-replay registration under the nonmutating callback protocol. The milestone registers live before replay; clear deletes one history lookup without touching listeners or a captured ongoing replay. A live callback clear removes the just-retained value. Replay callbacks do not throw/emit/change subscriptions; the milestone allows clear. Targets O(n)emit/replay with n=1+live entries or1+retained replay count, excluding callback work; retention/clear amortizedO(1), historyO(H)lifetime emissions, subscriptionsO(k). Tests model7events across6capacities, no-replay/live/off and opaque error/payload ownership, clear during replay/live and20000emissions at0/1024/2^32. Capacity narrowing and retained-object-clone wrongs passed originals and now fail. Update the existing known-wrong no-replay mutation to the new ring guard, preserving its original behavior check; all five selected known answers retain verdicts.

Keep the correct independent graph Object.keys board. Scope only this checkpoint focus/reading to objects/functions/Object.keys instead of recursion. Define own enumerable string IDs, exact numeric-index-first/creation order, ignored inherited/nonenumerable/symbol metadata without getter reads, frozen records/empty dependency arrays, mutable fresh outputs,≤20000ownproperties and≤64unitnames. O(n)uses all own properties+1. Tests cover explicit index boundaries4294967294/4294967295, own prototype-like/empty/Unicode IDs, readonly/opaque metadata,32creation-order models and20000reverse-insertednumericIDs. Reflect.ownKeys/filter alternative passes; for-in inherited-task wrong passed originals and now fails. Dependency traversal stays the next milestone.

All40calculator/query/events/graph stages pass canonical/native Run/reversed-hidden contracts:96earlier solutions fail their next level,20checkpoint boards fail their milestone and5known answers retain verdicts. Full grading/Learn integrity, API/script types, launch, registry/index,470coding/263native bindings, copy sweep, build, both zero-vulnerability production dependency audits, diff and80final-build light/dark fixture-backed probes at320–1440px pass. Initial download242998gzip bytes meets the unchanged243000budget. Earlier B083full-client/harness acceptance is dated evidence for unchanged UI/runtime, not newly rerun here. Exactly twelve physical API handlers; no runtime-engine/dependency/schema/RLS/entitlement/reward/Profile placement change. Original Czech arguments/files remain unchanged.

Source470/725coding,255remaining (JS26,TS46,React183); native263/263. Verified production#440 has455coding at4e941628/READY dpl_BKpvT45mtMXrqDET27ubAnENVA5t. Ten B086–B087 records are frozen in#441 at0625791d481c1d877c9e184ffd8ff277b1fd114c with exact READY preview dpl_4cYQH1TExw44pS5wTZ4yQurdDEMo:11general checks/3actual first Event-bus checkpoint Submits, reference/alternative accepted and payload-copy wrong rejected,0XP/nullprogress;7Premium/2stage locks remain dedicated acceptance under#190. Required run38839698452/guarded release remain pending for#441. Five B088source reviews are separate. #438remains closed; #435explicitly follows the whole audit. Preserve owner holds/draft#365/complete-coding eligibility gate and bank reconciliation. Same-session model self-review/finite execution only, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance.

## B089 five-item audit — 16 October 2026 UTC

Read five JavaScript graph-planning tasks individually: ordered DFS, missing-reference checkpoint, cycle validation, valid-layer checkpoint and validated-layer milestone. Preserve every original case and all470 prior individually reviewed English hashes. Fifteen hidden/five visible assertions raise final acceptance from21/26original-catalogue expectations to26/26current-hash verdicts:16valid boards/independent iterative alternatives,5starters and5meaningful wrongs. Sixteen supported authored-target/base25 checks pass; uncertain multi-input complexity stays hidden/unpenalized. Original unmodified source was baselined before authoring new fixtures.

Define declared tasks as own enumerable string keys, preserving exact numeric/prototype-like/empty/Unicode IDs and Object.keys root order. Visit dense readonly dependency arrays left to right and append in deterministic DFS postorder, once per task; arbitrary topological order is insufficient. Ignore inherited/hidden/symbol metadata without getter reads, allow frozen graphs/arrays and require fresh mutable results. Bounds are20000ownproperties/totaledges,512dependencypositions per task and64distinct nodes on an active walk before termination/repeat/missing. n=allownproperties+1,m=dependencypositions+1; default DFS targetsO(n+m)time/space. Keep correct three board strategies; validation uses propertyIsEnumerable rather than accepting hidden own metadata as tasks. This membership policy clarifies the inherited enumeration boundary and is explicitly authored, not a claim that prior own-key wording alone excluded every hidden property. Prevalidation does not access hidden metadata getters. Active-path state distinguishes cycles from completed shared/duplicate dependencies; inspect every component and never return partial validation output. The acyclic checkpoint intentionally still lacks cycle rejection.

Layer options are omitted/undefined/false ortrue, without newly grading arbitrary truthiness. Collect every ready task in root-key order using only earlier completed layers, then mark the whole layer. Require independent fresh mutable outer/inner arrays. The checkpoint supplies valid true-mode graphs and retains validated default DFS, deliberately failing the next invalid-layer milestone. Full layered mode rejects any cycle/undeclared reference anywhere with null. Retain correct ready scans and senior postorder-depth grouping. Honest conservative layered targetsO(n*(n+m))time/O(n+m)space permit rescanning; faster depth/index alternatives remain valid and default keepsO(n+m). Own hint/method ladders explain each stage without leaking later requirements. Original Czech arguments/files stay unchanged.

Fixtures cover64four-node DAG masks with varied dependency/root order, all512three-node directed adjacency matrices for default validation and independently modeled simultaneous-ready layer validation, disconnected/self/duplicate/shared cases, exact numeric-index boundaries and composed/decomposed IDs, inherited/hidden/absent references with unread getters, readonly/opaque metadata and mutable fresh outputs across repeated calls. Boundaries include20000reverse-insertednumeric roots,64-deep chains and20000edges through shared500-dependency arrays. Meaningful original-passing wrongs reverse dependency order, accept inherited references, normalizeUnicode IDs, freeze layers or reuse cached output arrays; all now fail. Separate iterative frames/declared-key Set/predecessor depths pass against node-index DFS and simultaneous-ready oracles. These finite checks are not proofs over arbitrary learner programs or measured asymptotic time.

All40calculator/query/events/graph stages pass canonical/native Run/reversed-hidden contracts,96earlier-stage and20checkpoint failures at the next requirement, and5known-answer verdicts. Full grading/Learn integrity, API/script types, launch, registry/index,475coding/263native current bindings, copy sweep, build, both zero-vulnerability production dependency audits, diff and80final-build light/dark fixture-backed probes at320–1440px pass. Initial download242998gzip bytes meets unchanged243000budget. B083full-client/harness acceptance remains dated for unchanged UI/runtime, not newly rerun here. Exactly twelve physical API handlers; no runtime-engine/dependency/schema/RLS/entitlement/reward/Profile placement change.

Source475/725coding,250remaining (JS21,TS46,React183); native263/263. Verified#440has455coding at4e941628 / READY dpl_BKpvT45mtMXrqDET27ubAnENVA5t. Ten B086–B087records are frozen in#441 at0625791d with exact READY preview dpl_4cYQH1TExw44pS5wTZ4yQurdDEMo:11general/3actual first Event-bus checkpoint Submits;7Premium/2stage locks remain dedicated acceptance under#190. Required run38839698452/guarded release remain pending. Ten B088–B089reviews are separate newer source work. #438remains completed; #435explicitly follows the whole content audit. Preserve owner holds/draft#365/bank reconciliation/complete-coding eligibility gate. Same-session model self-review/finite execution only, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance.

## PR #441 browser readiness correction — 16 October 2026 UTC

Initial required run38839698452 at0625791d failed the first en/light public-guide disclosure check: summary.focus/Enter was followed by a details element without open. SQL and all earlier content/grading checks passed; the other six public cases passed. The later Storybook report overwrote the retained browser failure trace in the quality artifact, so no trace-based diagnosis is claimed. Three local repetitions of the unchanged seven-test suite pass21/21. A controlled delayed-entry reproduction opens the prerendered fallback by keyboard and observes React replacement reset its disclosure, matching the startup race implied by the identical static/live article selectors. The live-client test now waits for the existing ss-public-fallback to leave before finding/focusing the article; no arbitrary sleep/retry or product/runtime change. The separate JavaScript-disabled case still checks static disclosure behavior. Required CI must pass again at the corrected head, followed by its own exact preview/guarded production checks; the failed run is not release acceptance. Coding source remains465/725 for this PR, with B088–B089/B090 separate source work; preserve#435after-audit sequencing and all owner holds.

## B090 five-item audit — 16 October 2026 UTC

Read five JavaScript tasks individually: supplied-duration critical-path checkpoint, validated/defaulted critical path, valid-changes impact checkpoint, validated impacted nodes and the first debugging item-trim checkpoint. Preserve every original assertion and all475 earlier individually reviewed English hashes. Fifteen hidden/five visible assertions pass24/24current-hash verdicts (14valid boards/alternatives,5starters,5meaningful wrongs), versus19/24original catalogue baseline. Fourteen supported authored-target/base25checks pass; uncertain complexity remains hidden/unpenalized.

Keep correct critical-path boards. Define own supplied duration values including nonenumerable data, ignored inherited/unused/symbol metadata without getter reads, frozen records, bounded graph, ordinary Number rounding/no integer narrowing, finite chain sums, equivalent zero signs and fresh mutable result/path. Resolve equal dependency totals by first dependency-array position and equal global totals by first node in plan order, including zero totals. Longest means duration, not node count. Checkpoint requires all own finite nonnegative durations; milestone defaults missing own values to1 and rejects invalid used values/graphs while ignoring unused invalid metadata. HonestO(n*d+m)time/space allows existing copied paths, d=maxchainnodes+1; independent predecessor links may be faster. Tests enumerate512DAG/duration combinations and exact paths, hidden-own/default/invalid-used/opaque metadata/ties/freshness,20000flat nodes/64chain/20000edges. Original-passing wrongs truncate fractions or ignore own hidden durations; both now fail. No defect is invented in the already correct canonical critical-path boards.

Keep correct forward Set impact scans; validate changed IDs against declared own enumerable tasks rather than hidden metadata. Define exact IDs, duplicate/frozen≤20000changed arrays, fresh results in plan order and propagation to dependents without unaffected ancestors. Validate graph even when changes are empty. Senior reverse traversal now uses a head cursor instead of repeated queue shifts and appends dependents individually instead of spreading an outdegree up to19999arguments. TargetO(n+m+k)time/space includes input/queued edges, k=changed.length+1. Tests cover1024DAG/changed-subset combinations against a separate index-closure model, exact Unicode/metadata/freshness/readonly state, hidden/inherited/absent changed IDs, invalidgraph/emptychanges,20000changed roots/19999dependent fanout/64chain. Unknown-ID validation remains outside the checkpoint until its milestone. Original-passing normalization/hidden-task wrongs now fail. Queue claims are code-structure/bounded-worker evidence, not measured timings.

Keep the debugging starter/sole correct item.trim repair and console-first Run/scratch/hint/method lesson. Define primitive≤20000unit exactly-two-comma lines, ECMAScript edge whitespace only on item, exact interiors/case/Unicode and unchanged raw numeric-field strings including empty fields. Outputs are fresh mutable ordinary three-field records; numeric conversion/other helpers are later work. TargetO(n)time/space, n=rawlength+1. Visible Unicode item-only assertion stays compatible with later numeric upgrades; raw-string hidden assertions attach only to this checkpoint's separate DEBUG solution registry. Tests cover25ECMAScript whitespace forms×9items, U180E/zero-width nonwhitespace, raw values, ordinary-record/fresh/mutable output and20000unit boundaries. Independent indexed whitespace scanning passes; ASCII-only trimming passed originals and now fails. Original Czech material is unchanged.

All50calculator/query/events/graph/debug stages pass canonical/native Run/reversed-hidden contracts,120earlier-stage and25checkpoint failures at the next requirement, and5known-answer verdicts. Full grading/Learn integrity, API/script types, launch, registry/index,480coding/263native bindings, copy sweep, build, both zero-vulnerability production dependency audits, diff and80final-build light/dark fixture-backed probes at320–1440px pass. Bundle242998gzip bytes meets unchanged243000budget. Earlier B083full-client/harness evidence remains dated for unchanged UI/runtime. Exactly twelve physical API handlers; no engine/dependency/schema/RLS/entitlement/reward/Profile placement change.

PR#441initial required run38839698452 at0625791d failed its first public-guide keyboard assertion, not its content/SQL checks. Controlled delayed-entry reproduction shows React replacing an already focused/open static fallback; three unchanged local repetitions pass21/21. Test-only correction9da171bb waits for the existing fallback to leave before live keyboard assertions, preserving no-JavaScript/static coverage; corrected suite also passes21/21. Missing retained CI trace is explicitly not claimed as diagnostic evidence. New required run38842822782 remains pending at9da171bb10a8b4433b42ddff9071bb8e9c7b4b20. Its exact READY preview dpl_GE4LCnrBqyV27Hvvui6ytFtwzauB passes11general/3actual first Event-bus checkpoint Submits;7Premium/2stage locks remain dedicated acceptance under#190. Old failed run is excluded from release acceptance. B088–B089freeze69a2398649ca834fd7d269844ffe21a47e208ca0 includes that parent test/docs correction only; authored exports are equivalent tofe744923. Its exact READY preview dpl_AvMpsfFHyj8uFU2517KCww4zwTLp passes11general/3actual independent-key graph checkpoint Submits (reference/Reflect alternative pass,for-in wrong fails,0XP/nullprogress) with7Premium/2stage locks. Its PR/release awaits#441; never recompile either frozen helper from newer B090content.

Source480/725coding,245remain (JS16,TS46,React183), native263/263. All10calculator/10query/10events/10graph/70algorithm source bindings are current. Verified production#440still has455coding;25newer source records comprise10in#441,10frozenB088–B089 and5B090separate. #438remains completed; #435explicitly follows the whole audit. Preserve owner holds/draft#365/bank reconciliation/complete-coding eligibility gate. Same-session model self-review/finite execution only, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance.

## B091 five-item audit — 16 October 2026 UTC

Read five JavaScript debugging tasks individually: numeric parsing, unique-item total checkpoint, repeated-item totals, percentage-only checkpoint and inclusive/rounded discount milestone. Preserve every original assertion, console-first Run/scratch/log/method teaching and all480 prior individually reviewed English hashes. Fifteen hidden/five visible assertions pass26/26current-hash verdicts (16valid supported boards/alternatives,5starters,5meaningful wrongs), versus21/26original-catalogue baseline. Sixteen authored-target/base25checks pass; uncertain multi-function estimates stay hidden/unpenalized.

Keep correct three Number parsing boards. Define primitive≤20000unit exactly-two-comma valid lines, exact ECMAScript-trimmed item names/interiors/case/Unicode, nonblank finite whole-field Number conversion including signs/exponents/binary/hex forms, equivalent zero signs and fresh mutable ordinary three-field records. Explicitly upgrade the earlier raw numeric-string checkpoint rule. O(n)time/space uses rawlength+1. Tests cover360explicit whitespace/item/numeric-pair cases, typeof/record/freshness/mutability and20000unit item/numeric fields. Independent comma-index/slice/Number alternative passes; prefix-only parseFloat passed originals and now fails.

Fix prototype-like item totals with null-prototype state in reference/junior/senior fixed accumulators and the unique-item checkpoint. Preserve the untouched buggy STARTER_SUMMARIZE, so the reviewed initial checkpoint and later debugging work remain stable. Keep published unique checkpoint assignment distinct from later addition; private Map/fromEntries alternatives may support more. Define exact names, readonly≤2000lines/≤20000totalcharacters, ordinary Number products/input-order accumulation without rounding, finite products/totals, zero groups, safe fresh mutable own enumerable data records and native numeric-index/creation order. O(n)time/space includes line count+totalUTF16units. Tests cover32unique/64repeated-key rotations with independent Map expectations, __proto__/constructor/toString/Unicode/empty/numeric names, signed/large/small/falsy Number totals, fresh/readonly/prototype data and2000records/20000unit keys. Four actual original checkpoint/reference/junior/senior controls lose or corrupt own prototype-like totals; all final controls pass. Original-passing normalized-name/zero-group-dropping wrongs now fail.

Define discount arithmetic explicitly: finite total/threshold0..1e9, integerpercent0..100, removed=total*(percent/100), discounted=total-removed. Checkpoint retains strict> and no rounding; milestone uses>= and Math.round(discounted*100)/100 only on that branch, returning below-threshold total unchanged even past two decimals. O(1)time/space is per applyDiscount; earlier helpers retain their own sizes. Change senior multiplication grouping to the stated subtraction order: actual original0.05/30%/threshold0 controls return0.04reference/junior but0.03senior. This is a newly explicit binary Number operation-order rule, not a claim that all algebraic variants were unambiguously excluded by old wording. All three final boards return0.04. Seven final prototype/rounding controls pass. Each discount stage adds264selected threshold/percent cases, explicit strict/raw or binary-half-cent/unchanged-below boundaries and10000finite arithmetic inputs. Variable-based alternatives use the stated primitives; prematurely rounding the checkpoint or below-threshold result passed originals and now fail. Strict/unrounded hidden checks are scoped to the checkpoint; its compatible visible example remains valid after the next upgrade. Original Czech material unchanged.

All50calculator/query/events/graph/debug stages pass canonical/native Run/reversed-hidden contracts,120earlier-stage and25checkpoint next-requirement failures and5known-answer verdicts. Full grading/Learn integrity, API/script types, launch, registry/index,485coding/263native current bindings, copy sweep, build, both zero-vulnerability production dependency audits, diff and80final-build light/dark fixture-backed probes at320–1440px pass. Bundle242998gzip bytes meets unchanged243000budget. B083full-client/harness evidence stays dated for unchanged UI/runtime; the separate corrected public-guide browser suite passes21/21. Exactly twelve physical API handlers; no engine/dependency/schema/RLS/entitlement/reward/Profile placement change.

Verified production#440still has455coding/263native at4e941628 / READY dpl_BKpvT45mtMXrqDET27ubAnENVA5t. #441current9da171bb10a8b4433b42ddff9071bb8e9c7b4b20 has exact READY preview dpl_GE4LCnrBqyV27Hvvui6ytFtwzauB acceptance (11general/3actual first Event-bus checkpoint Submits,7Premium/2stage locks); required38842822782/guarded release remain pending after excluded initial38839698452browser-readiness failure. No trace-based diagnosis is claimed: controlled delayed-entry reproduction and test-only fallback-readiness correction are documented separately. #442freezes ten B088–B089reviews at69a2398649ca834fd7d269844ffe21a47e208ca0, content-equivalent tofe744923 plus parent test/docs correction. Its exact READY preview dpl_AvMpsfFHyj8uFU2517KCww4zwTLp passes11general/3actual first graph-key checkpoint Submits with7Premium/2stage locks; required checks/release pending. Until#441merges its diff also contains that dependency; merge/production order stays#441then#442. Ten B090–B091source records are separate newer work. Never rebuild frozen deployment helpers from newer content.

Source485/725coding,240remain (JS11,TS46,React183), native263/263. All10calculator/query/events/graph and70algorithm source bindings are current. Thirty newer source records above production455 are10in#441,10in#442and10B090–B091separate. #438remains completed;#435explicitly follows the whole content audit. Preserve owner holds/draft#365/bank reconciliation/complete-coding eligibility gate. Same-session model self-review/finite execution only, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance.

## PR#441 corrected exact production — 16 October 2026 UTC

PR#441 passed corrected required run38842822782 at9da171bb10a8b4433b42ddff9071bb8e9c7b4b20 (verify28m40s,SQL42s), then merged at20dbee96b989fec83d949b3978fa940b4ffaea29 on16October2026 at03:24:40UTC. READY production dpl_5S7x7Lvxc7gwucBjvJvYR8Shcgkk matches that merge, owns devshark.app before/after probes and has no alias error. Exact corrected READY preview dpl_GE4LCnrBqyV27Hvvui6ytFtwzauB and production each pass11general guest checks and3actual initial Event-bus checkpoint Submits: reference/independent original-value alternative pass,payload-copy wrong fails,0XP/nullprogress. Seven other tasks require Premium/two later free evolving stages issue no session before prerequisites; dedicated acceptance remains under#190 without bypass/authenticated Premium claims. Initial required38839698452 at0625791d failed a public-guide startup keyboard assertion and is excluded. The test-only readiness fix waits for the existing static fallback to leave before live focus; unchanged/corrected local suites each pass21/21, with controlled delayed-entry reproduction separately documented and no retained-CI-trace diagnosis claimed. Exported authored bytes are identical across the test-only correction. B086–B087 bring deployed coding to465/725, native263/263. Current source485/725 leaves240 (JS11,TS46,React183), with ten B088–B089reviews in#442at69a23986 and ten B090–B091in#443atb50e7b0c, each separate from this production release. B092is in progress/unapproved. #438remains closed;#435explicitly follows whole-audit completion. Preserve owner holds/draft#365/bank reconciliation/complete-coding eligibility gate. Same-session model self-review/finite execution only, not independent/human, physical-device or whole-catalogue acceptance.

## B092 five-item audit — 16 October 2026 UTC

Five individually read tasks: trace return checkpoint, sorted report, safe-report checkpoint, validated safe report and line diff. Preserve correct supplied boards, console-first teaching, every original assertion and all485 prior coding bindings. Fifteen hidden/five visible assertions yield26/26current-hash verdicts (16valid,5starters,5semantic wrongs), versus21/26original baseline; initial no-log candidate baseline is excluded and replaced by the meaningful return-copy case. Sixteen authored-target/base25checks pass; unknown complexity stays hidden/unpenalized.

Trace returns opaque original values with Object.is identity. Thirteen direct shared-VM console controls include twelve supported boards/alternatives plus a cached-logger positive control, which also passes35visible/3hidden identity checks. Console emission remains explicitly Run/manual inspection; Submit checks returned values/identity without monkeypatching a cached logger. Reports specify exact UTF16 default sorting, safe fresh mutable records, zero groups, dense≤2000lines/≤20000units and Number totals guaranteed0..1e9 by the input domain. Negative fields are not independently rejected. Sorted-report cost O(n+u*w*log(u)) includes all raw line counts/characters, distinct names and maximum name width. The checkpoint consumes valid lines; the final report preserves each exact raw invalid occurrence and checks empty→field count→finite whole-number conversion. Empty item names, signed/exponent/prefix Number syntax and ECMAScript whitespace are explicit. Tests cover64report/64safe-checkpoint models,32classified invalid vectors, duplicate errors, prototype/Unicode/zero names, ownership and2000record/20000unit bounds.

Line diff uses literal string equality, fresh mutable independent pairs and the stated remove-first LCS tie. Its O(n*m)time/space uses both line lengths+1;≤200lines per side,≤128UTF16units per line, including empty/whitespace/newline/NFC/NFD distinctions. Tests compare961binary-array pairs with an independent exhaustive-subsequence oracle,32literal ownership models and a200line/199kept boundary. Original-passing case-folding, frozen output, duplicate-error removal and normalized-line wrongs now fail. Archived Czech remains unchanged.

All51selected coding tasks pass canonical/native Run/reversed-hidden contracts,120earlier-stage/25checkpoint next-requirement failures and5known-answer verdicts. Full grading/Learn integrity, API/script types, launch, registry/index,490coding/263native current bindings, copy sweep, build, both zero-vulnerability production dependency audits, diff and80final-build light/dark fixture-backed probes at320–1440px pass. Bundle242998gzip meets unchanged243000budget. B083full-client/harness evidence stays dated for unchanged UI/runtime. Exactly12physical handlers; no engine/dependency/schema/RLS/entitlement/reward/UI change.

Verified production#441has465coding after corrected required CI/exact preview/guarded release (20dbee96, READY dpl_5S7x7Lvxc7gwucBjvJvYR8Shcgkk). Frozen#442at69a23986 and#443atb50e7b0c each have exact READY preview acceptance:11general/3actual checkpoint Submits,7Premium/2prerequisite locks. Their required checks and guarded production releases remain pending in order#442then#443. B092adds five separate newer source records. Source490/725 leaves235(JS6,TS46,React183), native263/263;25source records are above verified production. #435Profile placement and#444guide startup state handoff explicitly follow the whole content audit. Preserve owner holds/draft#365/bank reconciliation/complete-coding eligibility gate. Same-session model self-review/finite execution only; no independent/human, authenticated Premium, physical-device or whole-catalogue acceptance claim.

## PR#442 guarded production acceptance — 16 October 2026 UTC

PR#442 passed required Product quality38844984996 at frozen69a2398649ca834fd7d269844ffe21a47e208ca0 (verify31m06s,SQL39s), all protected-main verify/sql app15368 and rollup/head/mergeability guards, then merged at96fc35836b120de630f9c09220ed335eeedc7ce0 on16October2026 at03:53:10UTC. READY production dpl_Ctr2VJVLpYtK6avvf3DsstimytsP matches that merge, owns devshark.app before/after probes and has no alias error. Exact READY preview dpl_AvMpsfFHyj8uFU2517KCww4zwTLp and production each pass11general guest checks and3actual first graph-key checkpoint Submits: reference/independent Reflect own-key alternative pass, inherited-key for-in wrong fails,0XP/nullprogress. Seven other tasks require Premium/two later free stages issue no session without prerequisites; dedicated acceptance remains under#190without bypass/authenticated Premium claims. Frozen helpers retain the exact source bytes and were not rebuilt from newer content. B088–B089 bring verified deployment to475/725coding,263/263native. #441was production-accepted first;#443exact preview and required38845281869now passed, guarded release next. B092five records separate; B093in progress excluded. Preserve owner holds/draft#365/bank reconciliation/complete-coding eligibility gate;#435/#444follow whole audit. Same-session model self-review/finite execution only, not independent/human, physical-device or whole-catalogue acceptance.

## B093 five-item audit — 16 October 2026 UTC

Five individually read JavaScript tasks: link draft, planner hours, stockroom stock, workshop seats and word-grid search. Preserve correct boards except the link senior prefix check and the misleading stage-one object-helper name. New contracts/15hidden/5visible assertions are scoped to these five issued identities; later typed/API/UI prompts, boards and tests stay unchanged. All490prior coding and263native bindings remain current. Final30/30current-hash verdicts (20valid,5starters,5semantic wrongs) agree versus25/30original baseline. Twenty authored-target/base25checks pass; unknown complexity stays hidden/unpenalized.

Link normalization explicitly trims/lowercases before UTF16 bounds, accepts literal https://prefix plus any nonempty remaining text, checks ASCII slug alphabet/length including hyphens anywhere, inherits ordinary data fields, ignores extras without reading them and returns fresh mutable two-field records. Raw strings≤20000units;O(n)time/space counts both raw lengths+1. Correct JavaScript senior regex to startsWith/length; six direct old/new controls show its original rejection of an interior line break and all final boards agreeing. Tests cover1040whitespace/slug/url combinations, Kelvin casing, Unicode rejection, prefix/max200UTF16url/max20slug, arbitrary interior spaces/newlines, frozen/inherited/null-prototype/ignored getter/type/freshness and padded/maxsize controls. Independent slice/character-scan alternative passes; additional real URL parsing passed originals and now fails.

Each distinct app validator preserves exact case/Unicode/interior whitespace after ECMAScript trim, requires primitive name1..80UTF16units and Number integer0..1000inclusive (signed zero equivalent), excludes coercion, accepts inherited ordinary data fields and fresh mutable two-field outputs. Rawname≤20000units;O(n)time/space counts raw name+1. Each gets1600whitespace/name/amount combinations, ownership/readonly/inherited/ignored-extra/type controls and raw20000/max80surrogate bounds. Independent finite/trunc/fromEntries alternatives pass; original-passing ASCII-only trim (planner), collapsed interior whitespace (stockroom) and normalization (workshops) now fail. Rename only seniorPlain’s shape predicate, not later typed boards. Add stage-one methods and MDN trim/integer readings without changing archived Czech.

Word search retains correct three boards/skeleton and deterministic row-major starts/up-right-down-left nonrepeating orthogonal paths. Define readonly dense≤8x8equal-length primitive rows, word≤8UTF16units, literal code-unit equality without normalization/case folding, null for impossible nonempty input and fresh mutable outer/coordinate pairs including empty success. Equivalent implementation styles are accepted. ConservativeO(r*c*4^L*L)time/O(r*c+L^2)space includes senior path copying/scanning; marked-state implementations improve these bounds. Independent iterative path-stack oracle verifies1008binary2x2grid/word cases;11Unicode/empty/newline/case/freshness models and8x8/eight-character boundaries pass. Independent flat typed visited-array alternative passes; NFC-normalizing wrong passed originals and now fails.

Five selected canonical/native Run/reversed-hidden checks and three known-answer verdicts, full grading/Learn integrity, API/script types, launch, registry/index,495coding/263native current bindings, copy sweep, production build, both zero-vulnerability production dependency audits, diff and80final-build light/dark fixture-backed probes at320–1440px pass. Bundle242998gzip meets unchanged243000budget. An attempted nonexistent check:bundle-budget command is excluded; the actual check:bundle passed after registry/index regeneration. B083full-client/harness evidence stays dated for unchanged UI/runtime. Exactly12physical handlers; no engine/dependency/schema/RLS/entitlement/reward/UI change.

Verified production#442has475coding at96fc3583/READY dpl_Ctr2VJVLpYtK6avvf3DsstimytsP after required38844984996/exact preview/guarded production acceptance. #443required38845281869and exact READY preview passed; protected exact-head merge47381ae4is production-probing, not yet accepted. Its retained premerge REST snapshot returned UNKNOWN rather than independently asserted MERGEABLE; the additional local assertion failed and was read after the separate GitHub exact-head protected merge had been dispatched. GitHub accepted the merge; all other retained required/head/base/open/non-draft/no-closing-issues/rollup evidence independently passes, and the merged tree exactly matches frozenb50e7b0c. No independent MERGEABLE claim. Further mutations await completed guard assertions. B092–B093add ten separate records. Source495/725leaves230(JS1,TS46,React183), native263/263;20records above verified production. #435Profile placement and#444guide startup handoff follow whole audit. Preserve owner holds/draft#365/bank reconciliation/complete-coding eligibility gate. Same-session model self-review/finite execution only; no independent/human, authenticated Premium, physical-device or whole-catalogue acceptance claim.

## PR#443 protected merge and production acceptance — 16 October 2026 UTC

PR#443 passed required Product quality38845281869 at frozenb50e7b0c41675b1e52cfda7013d77f95628c9511 (verify32m53s,SQL41s). Retained premerge evidence verifies exact head,open/non-draft/main,no closing issues,all successful rollup checks and required verify/sql app15368. REST mergeable was UNKNOWN, so the additional local MERGEABLE assertion was not satisfied and its result was read after a separate merge call had been dispatched; do not claim independently asserted MERGEABLE. GitHub accepted the protected, non-admin exact-head merge at47381ae45a355141998879dc2e60aa520c3a3c22 on16October2026 at04:00:06UTC, and its complete tree is identical to the frozen head. Future mutations await completed guard assertions.

READY production dpl_74g2JM93iW64t7Up7v2MT2rcATrT matches that merge, owns devshark.app before/after probes and has no alias error. Exact READY preview dpl_14rmAQYD7LX6L1Tt7CJFr89nk3zh and production each pass11general guest checks and3actual first debug item-trim checkpoint Submits: reference/independent indexed-whitespace scanner pass,ASCII-only trim wrong fails,0XP/nullprogress. Seven other tasks require Premium/two later free stages issue no session without prerequisites; dedicated acceptance remains under#190without bypass/authenticated Premium claims. Frozen helpers were not rebuilt from newer content. B090–B091bring verified production to485/725coding,263/263native, after#442production acceptance. Current source495leaves230(JS1,TS46,React183);ten B092–B093records are frozen in#445atde16f09580efc71b89490f1bf9b6153de5e72d0b, required/preview/guarded release pending. #438remains completed;#435/#444follow whole content audit. Preserve owner holds/draft#365/bank reconciliation/complete-coding eligibility gating. Same-session model self-review/finite execution only, not independent/human, physical-device or whole-catalogue acceptance.

## B094 five-item audit — 16 October 2026 UTC

Five individually read tasks: the last JavaScript arrangement task, TypeScript target-sum pair/binary search and successful/full first Result mapping. Preserve every original assertion, all495prior coding and263native current bindings. Fifteen hidden/five visible additions and four first-Result positive/rejecting compiler probes yield28/28current-hash verdicts (18valid,5starters,5semantic wrongs), versus23/28original baseline. Eighteen authored-target/base25checks pass; unknown complexity stays hidden/unpenalized.

Repair arrangement junior to Array.from with explicit selection depth and senior to remove letter.length UTF16units. Correct reference Map recursion remains. Define exact well-formed Unicode code points≤10,≤10000distinct outputs, no normalization/casefold/trim, default UTF16 string sorting, fresh mutable output including empty success and equivalent duplicate-avoiding algorithms. ConservativeO(n^2*p*log(p))time/O(n^2+n*p)space includes recursive copies/intermediate sorting, n=pointcount+1,p=outputs+2. Tests compare112forward/reversed tiny multisets with independent insertion-permutation oracle,9Unicode/literal/ownership models,5040distinct outputs and10repeated emoji. Six old/new Unicode controls show original junior/senior corruption and final agreement. Normalization wrong passed originals and now fails. The source literal aaaaaaaaab is a nine-a/one-b permutation example, not a Git revision: add only its exact item/question/token allowance to the copy sweep; one positive/three negative controls preserve all other artifact detection.

Repair TypeScript pair junior’s quadratic scan and senior’s repeated binary searches to the requested inward-pointer technique. Match reviewed JavaScript counterpart: readonly≤10000exact integer values±1e6,target±2e6, smallest-first match, distinct indices/duplicates, signedzero equivalence and fresh mutable output. TargetO(n)time/O(1)auxiliary,n=length+1. Tests cover3780independently brute-forced sorted multiset/target cases, frozen/ownership/boundary tuples and10000element misses/match. Six bounded128element read controls distinguish original junior/senior from reference/all final boards; finite operation observations only, not timing/arbitrary-program proof. An initial larger-value fixture was corrected into the authored domain before final export. In-place-sort wrong passed originals and now fails.

Keep correct binary-search boards; specify dense readonly≤20000finite Numbers±1e9, fractions and exact===without rounding/tolerance. Any matching duplicate index is accepted, preserving equivalent implementations. TargetO(log(n))time/O(log(n))space includes recursive senior frames,n=length+2. Independent membership/index-validity checks cover3960small cases, adjacent representable values/zero/frozen controls and20000element boundaries. Half-open alternative passes; target-rounding wrong passed originals and now fails. Existing pair/binary compiler probes retained.

Keep correct first Result boards, including junior’s equivalent fresh failure wrapper and the existing documented SAME_AS_MILESTONE first-checkpoint exception. Success maps opaque original argument/return synchronously once into a fresh mutable success record, preserving arrays/cycles/Promise identity without clone/await/inspection. Full milestone preserves exact error text without invoking fn; original or equivalent new failure record allowed. RuntimeO(1)time/space excludes callback/payload costs, distinct from compiler work. Four new generic assignment/rejecting probes supplement the original two and are inherited by the success checkpoint. Hidden cases cover14opaque values, mutable wrapper ownership,8error strings including20000units and1000calls. Array-copy/error-trimming wrongs passed originals and now fail. First-stage prose/visible/type requirements propagate to later unreviewed Result stages without claiming their individual acceptance. Archived Czech unchanged.

All13selected arrangement/pair/binary/Result stages pass canonical/native Run/reversed-hidden contracts,24earlier-stage/3checkpoint next-requirement failures,7signature boundaries and1known answer. Full grading/Learn integrity, API/script types, launch, registry/index,500coding/263native bindings, copy sweep, build, both zero-vulnerability production dependency audits, diff and80final-build light/dark fixture-backed probes at320–1440px pass. Bundle242998gzip meets unchanged243000budget. B083full-client/harness evidence remains dated for unchanged UI/runtime. Exactly12physical handlers; no engine/dependency/schema/RLS/entitlement/reward/UI change.

Verified production#443has485coding/263native at47381ae4/READY dpl_74g2JM93iW64t7Up7v2MT2rcATrT, with required38845281869/exact preview and production11general/3actual debug-checkpoint Submits and alias/SHA guards. Its extra REST MERGEABLE assertion was not satisfied(UNKNOWN); protected exact-head GitHub merge and exact merged-tree equivalence are documented without a false independent-MERGEABLE claim. Frozen#445atde16f095has exact READY preview dpl_FjN1JzkpAn67jStTG2yztJ2ZpZua acceptance:11general/12actual changed-task Submits across four JavaScript fullstack validators, six Premium locks under#190without bypass; required38848823998/guarded production release pending. B094adds five separate records. Source500/725leaves225(JS0,TS42,React183);all316JavaScript/70algorithm source records and263native bindings are current. Fifteen records above production. #435/#444follow whole audit. Preserve owner holds/draft#365/bank reconciliation/complete-coding eligibility gate. Same-session model self-review/finite execution only, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance.

## B095 five-item audit — 16 October 2026 UTC

Five individually read TypeScript Result tasks: nonthrowing flatMap checkpoint, catching map/flatMap milestone, collect checkpoint, collect/traverse milestone and all-success partition checkpoint. Keep every correct supplied board, all original assertions, existing SAME_AS_MILESTONE first/partition checkpoint exceptions and500prior coding/263native bindings. Fifteen hidden/five visible assertions and11positive/rejecting compiler probes yield27/27current-hash verdicts (14valid,5starters,5semantic wrongs,3erased-generic wrongs), versus19/27original baseline. Fourteen authored-target/base25checks pass; unknown complexity stays hidden/unpenalized.

FlatMap forwards the exact callback Result after one synchronous callback with original opaque input, without nesting/clone/await/inspection. Input failure skips fn and preserves exact error text; original/equivalent failure wrapper both allowed. O(1)runtime own-work target excludes callback/payload costs. Cases cover26frozen/reused opaque callback records,5input-error strings, nested Results/Promise payloads and1000repeated calls. The checkpoint still omits catches, so it fails its next milestone; only the existing documented checkpoint exceptions remain. Callback-result copying passed original serialization cases and now fails.

Catching milestone preserves exact Error.message or String(nonError), including empty/whitespace/Unicode text, and returns independent mutable newly caught failures. Only synchronous callback throws are caught; Promise payloads stay opaque. Error messages are strings and other thrown values have nonthrowing ordinary conversion≤20000units; conversion/callback/payload costs are explicitly outside the O(1)control/wrapper target. Twenty-four Error/primitive/BigInt/Symbol/custom-object throw controls plus a conversion-count case, caught-wrapper mutation and prior identity models pass. Trimming thrown messages passed originals and now fails. Correct junior input-failure clones remain accepted; no new failure-wrapper identity requirement is invented.

Collect uses readonly/frozen dense≤10000valid Results, shallow original payload references with duplicates/order, fresh mutable all-success/empty wrapper and array, exact first failure error, no input mutation. O(n)time/space uses input length+1,excluding payload size. Tests cover1365independent small prefix/error models, cyclic/frozen/duplicate/empty/mutable ownership and10000entry/20000unit opaque boundaries; the front-failure array is10000,not10001. Copying collected arrays passed originals and now fails.

Traverse retains those collection contracts, calls fn once per visited original value in order and stops at the first failed Result/throw with no later callbacks. Callbacks keep input membership/tags stable. O(n)own-work/output target excludes callback/payload/error-conversion costs. Tests combine collection models with64callback/stop/throw models, repeated frozen Result/payload/Promise values, fresh arrays and10000entry/count boundaries with failure at997and20000unit error. Deduplicating mapped values passed originals and now fails. Partition checkpoint deliberately grades only all-success/empty≤10000inputs, preserving opaque values/order/duplicates into a fresh outer record and two distinct mutable arrays. Tests cover364small models, mutable empty errors/values independence and10000repeated opaque payloads; frozen empty errors passed originals and now fail. Mixed partition remains a later individual review.

Add optional additionalTypeTests to the existing Checkpoint metadata/step helper and append these to inherited signatures, avoiding replacement or copied predecessor fixtures. Eleven authored probes cover exact generic flatMap/collect/traverse/partition relationships. Three erased-generic controls compile with zero source errors and pass every runtime assertion, yet each fails exactly one new expected-rejection probe; they are real type-boundary failures, not syntax failures. Every supported reference/alternative passes all probes. Changes propagate cumulative prerequisites to later unreviewed Result stages without claiming their acceptance; all500earlier hashes remain unchanged.

All10Result stages pass canonical/native Run/reversed-hidden checks,24earlier-stage/3checkpoint next-requirement failures,5signature boundaries and1known answer. Full grading/Learn integrity, API/script types, launch, registry/index,505coding/263native current bindings, copy sweep, build, both zero-vulnerability production dependency audits, diff and80final-build light/dark fixture-backed probes at320–1440px pass. Bundle242998gzip meets unchanged243000budget. B083full-client/harness evidence stays dated for unchanged UI/runtime. Exactly12physical handlers; archived Czech unchanged; no engine/dependency/schema/RLS/entitlement/reward/UI change.

Verified production#443has485coding/263native at47381ae4/READY dpl_74g2JM93iW64t7Up7v2MT2rcATrT. Frozen#445atde16f095has exact READY preview dpl_FjN1JzkpAn67jStTG2yztJ2ZpZua acceptance:11general/12actual changed-task Submits across four fullstack JavaScript validators, six Premium locks under#190without bypass. Required38848823998/guarded release pending. B094–B095add ten separate source records. Source505/725leaves220(JS0,TS37,React183);all316JavaScript/70algorithms/263native source bindings current. Twenty records above verified production. #435/#444follow whole audit. Preserve owner holds/draft#365/bank reconciliation/complete-coding eligibility gate. Same-session model self-review/finite execution only, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance.

## PR#445 guarded production acceptance — 16 October 2026 UTC

PR#445 passed required Product quality38848823998 at frozende16f09580efc71b89490f1bf9b6153de5e72d0b (verify33m01s,SQL37s), plus fresh protected-main verify/sql app15368,all rollup/exact-head/open/non-draft/main/no-closing-issues/MERGEABLE and exact READY preview guards. All guard assertions completed successfully before dispatching the non-admin exact-head merge. Merged at75aa79fb8deed5ea3df444cd513ee5ff03a423ec on16October2026 at04:41:56UTC.

READY production dpl_AyQc9y61KMZzceue6Ta8MgVTGvEo matches that merge, owns devshark.app before/after probes and has no alias error. Exact READY preview dpl_FjN1JzkpAn67jStTG2yztJ2ZpZua and production each pass11general guest checks and12actual changed-task Submits across all four JavaScript fullstack validators: reference/independent alternative accepted,semantic wrong rejected,0XP/nullprogress. Six other changed tasks require dedicated authorized Premium acceptance under#190without bypass. The initial protected-production host probe received Vercel authentication HTML instead of task JSON and is excluded entirely, including its three superficial HTTP200lines. A later private-host preflight verified the expected final hostname,application JSON and accepted access cookie; the unchanged frozen helper retry passed completely. Public devshark.app preflight also returned application JSON with no auth cookie. No protection/Trusted Sources configuration changed and no particular transient-auth root cause is claimed. Frozen helpers were not rebuilt from newer content.

B092–B093bring verified production to495/725coding,263/263native. Ten B094–B095reviews are frozen#446atdf78e289b6c4c8072f9ca54d2df3dcf3be8679b9 with exact READY preview dpl_DB2hQQss3kobcZvk8LHQrRVXrJGo acceptance:11general/3actual initial Result-map checkpoint Submits, nine Premium/prerequisite locks. Required38851254912/guarded release pending. Five B096local records await their final responsive/commit gate and are separate from this release. #435Profile placement/#444guide startup handoff follow the whole audit. Preserve owner holds/draft#365/bank reconciliation/complete-coding eligibility gate. Same-session model self-review/finite execution only, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance.

## B096 five-item audit — 16 October 2026 UTC

B096 individually reviews mixed partition, recovery checkpoint, recovery/lazy sequence milestone and primitive/full typed-store factories. Correct supplied boards, every original assertion,505prior coding/263native bindings and documented checkpoint exceptions remain. Fifteen hidden/five visible assertions and five compiler probes yield29/29current-hash verdicts (16valid,5starters,5semantic wrongs,3erased-type wrongs), versus21/29original baseline. Sixteen authored-target/base25checks pass; unknown complexity remains hidden/unpenalized.

Partition preserves exact duplicate errors/success references into fresh mutable independent arrays. Three tests carry all previous collection/traversal contracts and add1365mixed models, raw Unicode/empty errors, ownership and10000records with5000repeated20000unit errors. Recovery forwards original successes and exact callback Results, invokes once with exact error text, retains earlier Error.message/String conversion and mutable newly caught failures. Cases include13opaque payloads/104failure-return combinations,24throws/one conversion count, caught-wrapper ownership and1000calls. Sequence adds64lazy order/stop/throw models, duplicated frozen Result/Promise payloads, fresh empty state and10000steps with failure at997. O(n)partition/sequence targets andO(1)recovery own-work targets explicitly exclude callbacks, opaque payloads and throwable conversion where relevant.

Store checkpoint defines exact finite Number/string state, signed zero, Unicode/whitespace and detached methods; the full milestone accepts opaque undefined/NaN/infinities/BigInt/symbol/function/cycle/frozen/Promise values without clone/inspection/coercion/freeze/await. Independent state bindings may intentionally share caller-owned payloads. O(1)factory/get/set own-work/storage excludes payload storage. Tests cover13primitive states/replacements,32stores/64detached updates,1000long-string replacements,16opaque states/replacements, uninspected getter payloads, caller-visible shared mutation and10000opaque replacements. Error deduplication, recovery copies, sequence deduplication, text normalization and JSON state clones passed originals and now fail. Three erased recovery/sequence/getter controls compile without source errors and pass all runtime assertions, then each fails exactly one new required type rejection.

All20Result/store stages pass canonical/native Run/reversed-hidden checks,48earlier-stage/7checkpoint next-requirement failures,10signature boundaries and1known answer. Full grading/Learn integrity, API/script types, launch, registry/index,510coding/263native bindings, copy sweep, build, both zero-vulnerability production dependency audits, diff and80final-build light/dark fixture-backed320–1440px probes pass. The initial80probes completed before delayed checker teardown, which eventually exited0; no forced interruption was performed. The checker now explicitly closes its DevTools WebSocket before shutting down Chrome. A fresh80probe run with that test-only cleanup change exited0; no assertion was removed and no specific delayed-handle root cause is claimed. Bundle242998gzip meets unchanged243000budget. B083full-client/harness evidence stays dated for unchanged product UI/runtime; exactly12physical API handlers and archived Czech remain unchanged. No engine/dependency/schema/RLS/entitlement/reward/product-UI change.

Verified production#445has495coding/263native at75aa79fb/READY dpl_AyQc9y61KMZzceue6Ta8MgVTGvEo after required38848823998,completed premerge guards and exact preview/production11general/12actual fullstack validator Submits/six Premium locks. Initial protected-host auth HTML is excluded; unchanged frozen-helper retry and public canonical JSON preflight pass without protection changes. Frozen#446atdf78e289has exact READY preview dpl_DB2hQQss3kobcZvk8LHQrRVXrJGo acceptance(11general/3actual Result-map Submits,nine Premium/prerequisite locks);required38851254912/guarded release pending. FiveB096records separate. Source510/725leaves215(TS32,React183);all316JavaScript/70algorithms/10Result stages/263native source bindings current. Fifteen accepted source records above production. #435/#444follow whole audit; preserve owner holds/draft#365/bank reconciliation/complete-coding eligibility gating. Same-session model self-review/finite execution only, not independent/human, authenticated Premium, physical-device or whole-catalogue acceptance.

## B097 five-item audit — 16 October 2026 UTC

B097 individually reviews typed update checkpoint, subscriptions, undo checkpoint, undo/redo milestone and cached selected-value checkpoint. Correct supplied boards and every original assertion remain. Fifteen hidden/five visible assertions and nine own compiler probes yield27/27current-hash verdicts(14valid,5starters,5semantic wrongs,3erased-type wrongs),versus19/27original baseline. An initial wrong-array candidate had a source type error and is excluded; corrected cast compiles and genuinely passes originals before failing new identity coverage. Three erased updater/undo/selected-getter controls compile with zero source errors and pass every runtime assertion,then fail exactly one own expected type rejection each. Fourteen supported authored-target/base25checks pass; unknown estimates remain hidden/unpenalized. Standard Target:O(...)time wording was corrected after an initial parser check; the final current hashes were re-exported and regraded.

The updater receives exact current opaque T synchronously once and stores its exact return,including detached calls and10000updates. Subscriptions are independent per registration,even for the same callback; idempotent off/snapshot additions/removals,NaN/signed zero,ignored returns and256live subscriptions are covered. Undo/redo retains original references with no fixed history cap,does not create history on traversal and preserves redo across Object.is-equal set/update. Independent16x96operation models,mutable/frozen history ownership and1000change/undo/redo boundaries validate notifications. Selected get accepts a minimal get/subscribe source,caches exact opaque U from one initial read and one selection per notification,never recomputes on get,and supports Promise U,real no-op/history notifications and10000changes/10001selector calls. All previous B096opaque-state assertions are carried through every selected stage. Callbacks are nonthrowing/nonreentrant and have no this dependence as specified; no speculative callback-error policy is introduced.

Authored own-work targets are O(1)update and cached selection,O(n)subscription/undo with n=live registrations+1(amortized array append/pop for undo),and O(h+n)full history with h=all retained entries including redo+1 before operation. The common history bound explicitly includes deleting the senior timeline suffix; faster supported stacks are retained. Callback/source work and opaque payload contents are excluded where stated. Double updaters,function deduplication,copied restored arrays,32entry history cap and per-get selector recomputation passed originals and now fail.

Five selected stages pass canonical/native Run/reversed-hidden coverage,24earlier-stage/four checkpoint next-requirement failures and five signature boundaries. Full grading/Learn integrity,API/script types,launch,registry/index,515coding/263native current bindings,copy sweep,build,both zero-vulnerability production dependency audits,diff and80final-build fixture-backed320–1440px light/dark probes pass;both responsive processes exit0. Bundle242998gzip meets unchanged243000budget. B083full-client/harness evidence remains dated for unchanged UI/runtime. Exactly12physical API handlers;archived Czech unchanged. No engine/dependency/schema/RLS/entitlement/reward/UI change.

Source515/725leaves210(TS27,React183);all316JavaScript/70algorithms/10Result stages/263native source bindings current. Production remains verified495via#445 until#446post-deploy probes finish. PR#446atdf78e289 passed required38851254912(verify30m26s,SQL43s),all completed exact-head/MERGEABLE/protected checks and exact READY preview,and merged at21da48a04c735b1ee359749d36b9bcf8f0576a2c;production acceptance pending. Ten B096–B097records separate. Preserve #435/#444after whole audit,owner holds,draft#365,effective-bank/longest-answer reconciliation and complete-coding eligibility gating. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## PR#446 guarded production acceptance — 16 October 2026 UTC

PR #446 passed required Product quality run 38851254912 at frozen df78e289b6c4c8072f9ca54d2df3dcf3be8679b9 (verify30m26s, SQL43s). Fresh protected-main verify/sql checks from app15368, all rollup/exact-head/open/non-draft/main/no-closing-issues/MERGEABLE assertions and the exact READY preview guard completed successfully before the non-admin exact-head merge. Merged at21da48a04c735b1ee359749d36b9bcf8f0576a2c on16October2026 at05:12:27UTC.

READY production dpl_9wTv71DLkJyTwTqMS2i4orzBL5es matches that merge, owns devshark.app before and after probes and has no alias error. Exact READY preview dpl_DB2hQQss3kobcZvk8LHQrRVXrJGo and canonical production each pass11general guest checks and three actual initial Result-map checkpoint Submits: reference and independent alternative pass, array-copy wrong fails,0XP/nullprogress. Nine other changed tasks retain Premium/prerequisite locks under#190 without bypass. Frozen helpers were compiled from the exact cohort before later task edits; no production account, XP, score, progress or generated-name fixture was written.

B094–B095bring verified production to505/725coding,263/263native. Ten B096–B097records are separately frozen in#447at439c46e6b05ce18638375784e840c9e5bbff1147; source515/725leaves210(TS27,React183). B098private/current checks are excluded until individual records and all final gates finish. Preserve #435/#444after whole audit,owner holds,draft#365,effective-bank/longest-answer reconciliation and complete-coding eligibility gating. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## B098 five-item audit — 16 October 2026 UTC

B098 individually reviews the full derived-store lifecycle,successful/throwing transactions,and string-only/full primitive schema validation. Fifteen hidden/five visible assertions and11own compiler probes yield31/31current-hash verdicts(16valid,5starters,5semantic wrongs,5erased-type wrongs),versus21/31original baseline. Five erased return controls compile with zero source errors and pass all runtime cases,then miss1/1/1/2/1expected rejections respectively. Sixteen supported authored-target/base25checks pass; unknown estimates stay hidden/unpenalized. All515prior coding hashes remain current.

Fix reference/junior/senior derived callbacks to return before selection if already disposed. An earlier source listener may dispose the derived store within the current notification snapshot; its already queued callback must not change the cached binding or invoke the selector. dispose disconnects once,retains exact caller-owned U without freezing/cloning it,clears independent registrations and makes late subscriptions inert. Tests cover real/minimal external sources,detached disposal,NaN/signed-zero equality,duplicate/snapshot registrations and queued callbacks. Separate current-hash controls reject all seven previous published modules across full selection and both transaction stages; the17comparison verdicts all match. Correct transaction implementations remain,with the misleading private-copy comment corrected to a local binding.

Transactions use minimal get/set sources,read once,stage exact opaque references through synchronous pure readonly/frozen stable<=10000steps and set exactly once on success including empty/no-op input. They expose no intermediate state or extra undo entries. Any thrown value aborts before set/notifications/history/redo changes and later callbacks. Eleven opaque initial states,Promise/intermediate identities,write counts,one-history/redo no-ops,10throw kinds at three positions and10000step success/late-failure boundaries are covered. O(n)own transaction time/O(1)space,n=steps.length+1,excludes callbacks/source/payloads; derived O(n)own time/space uses live registrations+1 and leaves prior history bounds separate.

Primitive schemas retain all correct boards,including senior noncoercing Number.isFinite. String-only checkpoint retains the supplied union but its runtime domain only uses string. Full primitive stage supports exact finite Numbers including signed zero/fractions/MIN_VALUE/MAX_VALUE and primitive booleans/strings; boxed objects,NaN/infinities and nonmatching opaque data fail. Each result is a fresh mutable exact error/empty string[]; input getters/conversion methods are not touched. Three hidden checks per stage cover27input categories,all3schema cross-products at full stage,ownership and1000long-string/extreme-number/frozen-object rounds. O(1)own time/space excludes input contents. Boxed acceptance,empty transaction write omission,null/undefined rethrow and queued disposal regressions passed originals and now fail. Official TypeScript/MDN sources were reread.

All20store/schema stages pass canonical/native Run/reversed-hidden checks,48earlier-stage/nine checkpoint next-requirement failures,10signature boundaries and one known answer. Full grading/Learn integrity,API/script types,launch,registry/index,520coding/263native current bindings,copy sweep,build,both zero-vulnerability production dependency audits,diff and80final-build fixture-backed320–1440px light/dark probes pass;both responsive processes exit0. Bundle242998gzip meets unchanged243000budget. B083full-client/harness evidence stays dated for unchanged product UI/runtime. Exactly12physical handlers and archived Czech remain unchanged. No engine/dependency/schema/RLS/entitlement/reward/UI change.

PR#446is production-accepted at21da48a0/READY dpl_9wTv71DLkJyTwTqMS2i4orzBL5es after required38851254912,completed premerge guards and exact preview/production11general/three actual initial Result-map Submits/nine locks. Source520/725leaves205(TS22,React183);production505coding/263native. Ten B096–B097frozen#447at439c46e6have exact READY preview dpl_9HmjkG8gSE2fLamK3D57U4f6B5zS acceptance(11general/three actual primitive-store Submits/nine locks),required38855075757/guarded release pending;fiveB098separate. Parent issues176/190/208/391were refreshed at515source/505production/210remaining before B098final approval,with stale#432release checkbox corrected from actual closed/production evidence. No other open issue is complete: preserve owner holds and #435/#444after whole audit,draft#365,effective-bank/longest-answer reconciliation and complete-coding eligibility gating. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## B099 five-item audit — 16 October 2026 UTC

B099 individually reviews flat/recursive object schemas,array checkpoint,full optional/array schemas and record-adapter checkpoint. Fifteen hidden/five visible assertions and seven own compiler probes yield25/25current-hash verdicts(14valid,5starters,5semantic wrongs,one erased-type wrong),versus19/25original baseline. Fourteen authored-target/base25checks preserve the explicit output-size/multivariable models:unsupported structural estimates remain unknown/unpenalized. The erased record return compiles with zero source errors and passes every runtime assertion,then fails one own expected type rejection. All520prior coding hashes remain current.

Retain correct own-property/primitive/object validators. Define ordinary valid acyclic data schemas,own enumerable schema fields in standard Object.keys order,candidate own data or undefined,ignored extras without inspection,frozen/null-prototype maps/values,literal exact paths,fresh mutable errors and shared-schema occurrences. Fields<=1000,keys<=64UTF16units,depth<=32,visited schema/value pairs<=20000;payload contents/unvisited extras excluded. Flat targets O(n+p)time/space with n=declared fields+1,p=total returned error-text length;recursive/record common bounds O(n*d+p)include visited pairs,depth,rendered paths and repeated error-array copying. Correct direct-accumulation boards may improve the bound.

The reference/checkpoint and senior array validators used flatMap,which skips absent indexed properties and conflicted with validating every index. Materialize standard ordinary sparse-array iteration with Array.from before flattening;the junior indexed loop remains correct. Arrays<=10000may be sparse/frozen,holes validate as undefined without being filled. Optional accepts undefined/missing fields/holes without adding a path segment;null is validated normally. Record checkpoint traverses only Object.keys of valid non-null non-array records,ignoring inherited/nonenumerable/symbol keys,retaining numeric-before-insertion string order and replacing only leading$. Wrong-container record rejection comes in the next milestone and is not required here.

Three cumulative hidden assertions per stage carry all earlier primitive/ownership checks and add729independent flat-schema/value models,prototype sentinel keys/inherited getter avoidance/extra unread getters,1000fields/500errors,16nested depths/seven invalid root kinds,shared schema occurrences and32deep64unit paths. Arrays add3schemas x64sparse/dense models,nested exact index paths,10000entries/9999ordered errors and fresh empty output ownership. Optional adds21primitive/value combinations,nested optional paths,10000optional holes and32layers. Record addsmixed numeric/string order/ignored key kinds,nested null-map/frozen errors and1000entries. Inherited-field acceptance,hole skipping,key sorting and erased record output passed originals and now fail. Twelve separate comparison verdicts pass,including rejection of four previous published reference/senior modules. Official ECMAScript/MDN/TypeScript sources were reread.

All10schema stages pass canonical/native Run/reversed-hidden checks,24earlier-stage/five checkpoint next-requirement failures,five signature boundaries and one known answer. Initial canonical execution against a partially applied patch is excluded;the template-escaping assertion was corrected,remaining source repair applied,exporter/grader recompiled and the complete fresh suites passed. Full grading/Learn integrity,API/script types,launch,registry/index,525coding/263native current bindings,copy sweep,build,both zero-vulnerability production dependency audits,diff and80final-build fixture-backed320–1440px light/dark probes pass;both responsive processes exit0. Bundle242998gzip meets unchanged243000budget. B098initial80probes eventually exit0 after delayed teardown;separately restarted40light/48dark diagnostic probes also exit0 with zero issues. The extra dark duplicate route is counted explicitly;no new cleanup fix or specific delayed-handle cause is claimed. A late diagnostic attachment found its target process already gone;no debugger was started and no forced interruption occurred. B083full-client/harness evidence stays dated for unchanged product UI/runtime. Exactly12physical handlers and archived Czech unchanged. No engine/dependency/schema/RLS/entitlement/reward/UI change.

Source525/725leaves200(TS17,React183);verified production505coding/263native via#446. Ten B096–B097frozen#447at439c46e6have exact READY preview dpl_9HmjkG8gSE2fLamK3D57U4f6B5zS acceptance(11general/three actual primitive-store Submits,seven Premium/two prerequisite locks),required38855075757/guarded release pending. Ten B098–B099separate. Preserve #435/#444after whole audit,owner holds,draft#365,effective-bank/longest-answer reconciliation and complete-coding eligibility gating. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## B100 five-item audit — 16 October 2026 UTC

B100 individually reviews full record validation,union checkpoint,union/tuple milestone and both typed link-API stages. Fifteen hidden/five visible assertions and11own compiler probes yield33/33final current-hash verdicts(18valid,5starters,5semantic wrongs,5erased-type wrongs),versus23/33original baseline. Five erased returns compile with zero source errors and pass all runtime cases,then miss1/1/1/2/3expected rejections respectively. Eighteen authored-target/base25checks pass;unsupported output-size/multivariable estimates remain unknown/unpenalized. All525prior coding hashes stay current. The first32/33final attempt exposed union probes attached to unrelated metadata;the probes were moved to the exact TS checkpoint and the unrelated entry restored. That run is excluded. Final English spacing was reread;exporter/grader were recompiled,current hashes regraded and selected canonical/types rerun successfully.

Retain all correct record/union/tuple boards,including senior stable sorting of branch error lists. Full records reject invalid containers once,validate all falsy own enumerable values and preserve ignored key kinds/order/fresh output ownership. Union chooses earliest minimum error count,not text length,without changing caller schema order;full scanning after a successful ordinary branch remains allowed. Tuples check exact array length before each position,interpret sparse holes as undefined,preserve optional semantics and prefix only leading$. Three cumulative hidden cases per stage retain all prior schema checks and add3schemas x7falsy values,11invalid record categories/empty Date/fresh invalid outputs,125union branch/value models,1000branch boundaries,256sparse tuple models and1000required holes. Authored O(n*d+p)record/union and O(n*d+p+b log b)full union/tuple common bounds explicitly define pair counts,depth,error text and branch/schema count,and include the supported senior sort. Fresh mutable outputs,readonly/frozen schemas and prior bounded valid-data domain remain.

Repair the senior typed link normalizer from regex dot-prefix matching to the stated literal startsWith/length rule:an internal line break after https://is valid in this exercise. Correct reference/junior API and strict anchored routing remain. Native Node/official MDN checks confirm the existing non-multiline route regex already rejects a trailing newline;no speculative route rewrite is made. API contracts define unique valid readonly/frozen seeds<=10000,primitive copied fields,safe visits,independent API state,fresh mutable copies,exact method/path matching,no route trim/decode/query normalization,insertion order,normalized conflicts,delete/recreate reset and<=10000requests/live links. O(n+s)common construction/request time/space includes junior linear lookups and returned lists,with link-count/raw-text variables defined. Three hidden assertions per API carry1040earlier trim/slug/url vectors plus shape/ownership/long UTF16 checks and add16x96independent create/list/error or visit/delete models,seed/reply/instance isolation,10000frozen records,nine malformed/five wrong-method forms and1000visits from1000000. Ten separate comparison verdicts pass,including rejection of both original senior typed modules. Correct independent accumulating validators/indexed APIs pass;falsy skipping,last union tie,tuple hole skipping,sorted listing,trimmed routes and erased outputs passed originals and now fail.

Thirteen selected schema/JS+TS link stages pass canonical/native Run/reversed-hidden checks,27earlier-stage/five checkpoint next-requirement failures,seven signature boundaries,six known answers and three calendar-invariance tasks in four extra zones. Full grading/Learn integrity,API/script types,launch,registry/index,530coding/263native bindings,copy sweep,build,both zero-vulnerability production dependency audits,diff and80final-build fixture-backed320–1440px light/dark probes pass;both responsive processes exit0. Bundle242998gzip meets unchanged243000budget. B083full-client/harness evidence stays dated for unchanged product UI/runtime. Exactly12physical handlers and archived Czech unchanged. No engine/dependency/schema/RLS/entitlement/reward/product-UI change. Typed normalizer fixes propagate to two unreviewed React link stages without claiming them individually reviewed.

Source530/725leaves195(TS12,React183);verified production505coding/263native via#446. #447at439c46e6passed required38855075757(verify27m45s,SQL41s),all completed exact-head/MERGEABLE/protected-main and exact READY preview guards before mergef78c8f4cab922ea71499758cce9f54a912a50c5d at05:51:36UTC;post-deploy acceptance pending. Ten B098–B099frozen#448ate7a09402have exact READY preview dpl_6KASECd2XSSCUuX1TKwc9G6CBBAh acceptance(11general/four actual primitive-schema Submits,seven Premium/two prerequisite locks),required38856861035/parent acceptance/guarded release pending. FiveB100separate. Preserve #435/#444after whole audit,owner holds,draft#365,effective-bank/longest-answer reconciliation and complete-coding eligibility gating. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## PR#447 guarded production acceptance — 16 October 2026 UTC

PR #447 passed required Product quality run38855075757 at frozen439c46e6b05ce18638375784e840c9e5bbff1147(verify27m45s,SQL41s). Fresh exact-head/open/non-draft/main/no-closing-issues/MERGEABLE/all-rollup/protected verify+sql app15368 and exact READY preview assertions completed successfully before non-admin exact-head mergef78c8f4cab922ea71499758cce9f54a912a50c5d on16October2026 at05:51:36UTC.

READY production dpl_73JEQQa9SiRroi9r272fQMJKJQ7n matches that merge,owns devshark.app before/after probes and has no alias error. Exact READY preview dpl_9HmjkG8gSE2fLamK3D57U4f6B5zS and canonical production each pass11general guest checks and three actual primitive-store checkpoint Submits:reference/independent alternative pass,string normalization wrong fails,0XP/nullprogress. Seven other tasks retain Premium locks and two prerequisite locks under#190 without bypass. Frozen helpers were compiled from this exact cohort before later edits. No account,progress,score or generated-name fixture was written.

B096–B097bring verified production to515/725coding,263/263native. Ten B098–B099records are separately frozen#448ate7a09402a12233d8c6b4b263a48592cef8594bfd,whose exact READY preview dpl_6KASECd2XSSCUuX1TKwc9G6CBBAh passes11general/four actual primitive-schema Submits(reference/alternative pass,boxed-string/erased-return wrongs fail,0XP/nullprogress),seven Premium/two prerequisite locks. Required38856861035/guarded release pending. FiveB100records are separately committedc17e44b6;current source530/725leaves195(TS12,React183). B101private preparation is excluded. Preserve #435/#444after whole audit,owner holds,draft#365,effective-bank/longest-answer reconciliation and complete-coding eligibility gating. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## B101 five-item audit — 16 October 2026 UTC

B101 individually reviews planner typed port/update/create-list/full mutation stages and the stockroom typed port. Correct supplied boards and all original assertions remain. Fifteen hidden/five selected visible assertions and12selected own compiler probes yield31/31current-hash verdicts(16valid,5starters,5semantic wrongs,5erased-type wrongs),versus21/31original baseline. Five erased Item.version/update-return/Reply.body controls compile without source errors and pass all runtime checks,then miss1/1/1/2/1expected rejections respectively. Sixteen supported authored-target/base25checks pass;unknown estimates stay hidden/unpenalized. All530prior coding hashes remain current.

Port checks preserve exact ECMAScript trim/UTF16/case/Unicode/interior whitespace,noncoercing integer amounts and signed zero as zero,ordinary inherited data/frozen inputs/unread extra getters and fresh mutable results. Item.id/version must remain number fields despite no update/API at the checkpoint. Three hidden cases per port carry all B093validator checks and add72name/amount combinations,inherited decomposed-name ownership and1000exact20000unit raw-bound inputs. Shared port metadata also adds a visible Unicode case/three compiler probes to the unreviewed workshops checkpoint;that propagation is explicitly not an individual approval.

Planner updates accept valid normalized Items/safe integer identity+version,matching primitive integer patches and original hours bounds. Every success,including equal hours,creates a fresh mutable record and increments once while preserving exact id/name and both inputs. Three cumulative hidden cases add384version/amount combinations,frozen inherited no-op patches/unread extra getters/owned outputs and1000updates. Typed APIs own copied state from unique valid readonly/frozen seeds<=10000,compute max-ever IDs from all seeds regardless of order,preserve insertion order and never expose mutable state. Exact methods/paths<=256/no trim/decode/query handling,raw names<=20000,<=10000requests/live items and initial IDs/versions<=1000000bound safe arithmetic. PATCH establishes existence404before version409before amount400,including both-invalid input;failures preserve state/counter,no-op success increments once,DELETE retains max-ever identity and survivor order.

Each API adds16x96independent sequence models,with canonical sorted-key JSON comparison so correct differently ordered records are accepted. Ownership/unsorted seed counter cases,10000reverse-ID frozen seeds,10conflict payloads/seven invalid amounts/unknown-ID precedence,11malformed suffixes and1000no-op updates/deletion/recreation exercise state transitions. Reference/senior10000argument max calls were actually executed successfully rather than rewritten speculatively. O(n)normalization/update bounds define name size;O(n+s)API construction/request common bounds define item and raw name/path sizes and allow faster Map operations. NFC conversion,skipped no-op version,last-seed maximum,amount-first stale conflicts and erased types passed originals and now fail. No runtime board repair is necessary. Official TypeScript/MDN integer/Fetch references were reread.

All12typed planner/stockroom/workshop stages pass canonical/native Run/reversed-hidden checks,18earlier-stage/three checkpoint next-requirement failures,nine signature boundaries and21known answers. Full grading/Learn integrity,API/script types,launch,registry/index,535coding/263native bindings,copy sweep,build,both zero-vulnerability production dependency audits,diff and80final-build fixture-backed320–1440px light/dark probes pass;both responsive processes exit0. Bundle242998gzip meets unchanged243000budget. B083full-client/harness evidence stays dated for unchanged product UI/runtime. Exactly12physical handlers and archived Czech unchanged. No engine/dependency/schema/RLS/entitlement/reward/product-UI change.

Verified production#447is515coding/263native atf78c8f4c/READY dpl_73JEQQa9SiRroi9r272fQMJKJQ7n after required38855075757(verify27m45s,SQL41s),completed premerge guards and exact preview/production11general/three actual primitive-store Submits/seven Premium+two prerequisite locks. Source535/725leaves190(TS7,React183). Ten B098–B099frozen#448ate7a09402exact preview accepted(11general/four actual primitive-schema Submits/seven Premium+two prerequisite locks),required38856861035/guarded release pending;tenB100–B101separate. Parent issues176/190/208/391were refreshed at530committed source/515production/195remaining before B101final approval. Preserve #435/#444after whole audit,owner holds,draft#365,effective-bank/longest-answer reconciliation and complete-coding eligibility gating. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## PR#448 guarded production acceptance —16October2026UTC

PR #448 passed Product quality run38856861035 at frozen e7a09402a12233d8c6b4b263a48592cef8594bfd (verify29m04s,SQL42s). All fresh exact-head/open/non-draft/main/no-closing-issues/MERGEABLE/all-rollup/protected verify+sql app15368 assertions and exact READY preview completed successfully before guarded non-admin merge b55b4a07542d5e02590c59ccc3ac75be6c6509e3 on16October2026 at06:14:26UTC.

Exact READY production dpl_FoYgUoLHZTULgpJ6t9EqXs9vhjds matches the merge,has no alias error and owns devshark.app before/after probes. Exact READY preview dpl_6KASECd2XSSCUuX1TKwc9G6CBBAh and canonical production each pass11general guest checks and four actual primitive-schema checkpoint Submits:reference/independent alternative pass,boxed-string/erased-return wrongs fail,0XP/nullprogress. Seven other tasks retain Premium locks and two prerequisite locks under#190. Initial overlapping production/next-preview cohort runs hit429 and are excluded;sequential unchanged frozen-helper retries complete with expected verdicts/locks. No throttling/access policy was changed and no account,progress,score or generated-name fixture was written.

Verified production is525/725coding,263/263native. TenB100–B101records are frozen in#449 at7d9fdd43f10eabfc357aea401f6e02913b731c37;its exact READY preview dpl_5P7h3jieXxyPmAXF8yJNpZaftNZM passes11general checks,but all ten cohort tasks remain legitimately locked(eight Premium,two prerequisite);zero actual cohort Submits are claimed. Required38859620668/guarded release pending. FiveB102source records are locally recorded at540/725(185remaining:TS2,React183),awaiting their final QA/commit;fifteen records are above verified production. Preserve#435/#444after whole audit,owner holds,draft#365,effective-bank/longest-answer reconciliation and complete-coding eligibility gating. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## B102 five-item audit —16October2026UTC

B102 individually reviews stockroom typed update/create-list/full mutations and workshop typed port/update. All correct supplied boards and original assertions remain. Fifteen hidden/five visible additions and11own compiler probes yield33/33current-hash verdicts(18valid,5starters,5semantic wrongs,5erased-type wrongs),versus23/33authoritative original baseline. Five erased return/body/name controls compile without source errors and pass runtime,then miss1/1/2/2/1required type rejections. Eighteen authored-target/base25checks pass;unknown estimates remain hidden/unpenalized. All535prior coding hashes remain current.

Stock/booking updates preserve exact normalized names and IDs,require primitive matching integer versions/noncoerced amounts0..1000,and return fresh mutable Items with one version increment even for equal amounts. Ordinary inherited/frozen patches and ignored extra getters are in scope. Three hidden cases per update include384version/amount models,inherited no-op ownership and1000updates. O(n)normalization/update common bounds define raw/existing UTF16 name size and80unit valid names.

Stock APIs own independent state copied from dense readonly/frozen valid unique seeds<=10000,derive max-ever IDs from the entire seed regardless of order,preserve insertion order and consume no ID on failed POST. Exact method/path<=256,raw names<=20000,initial IDs/versions<=1000000and<=10000requests/live items keep arithmetic safe. All wrappers/items/lists/errors are fresh mutable copies. PATCH checks404existence before409version before400amount,including both-invalid input;failures preserve state/counters,no-op success increments,DELETE preserves survivor order/max-ever identity. Common O(n+s)construction/request time/space defines item counts and raw path/name size;faster Maps are allowed. Each API receives16x96independent state-model steps,canonical key-order-independent comparisons,unsorted99/1seed,10000reverse-ID frozen seeds,10conflict/seven invalid amounts,11malformed suffixes and1000no-op updates/deletion/recreation.

Workshop port explicitly keeps primitive Draft.name,ECMAScript trim with tabs/NBSP,exact Unicode/case/interior whitespace,noncoercing seats and signed-zero-as-zero,unknown narrowing,numeric Item identity/version,inherited data/frozen ownership/unread extras and fresh mutable results. No update/API is required at that checkpoint. Three cumulative hidden cases cover72name/amount models,inherited decomposed names and1000raw20000unit names;three name probes supplement previously propagated numeric probes without recounting them as new defects. Whole board comparisons against read planner equivalents after explicit field/endpoint substitution confirm every variant. Original private stock mutation candidates retained a wrong prefix offset;that invalid private baseline is excluded,the offset corrected and all authoritative baselines rerun. No published runtime board needed repair.

All12typed fullstack stages pass canonical/native Run/reversed-hidden coverage,18earlier-stage/three checkpoint failures,nine signature boundaries and21known answers. Full grading/Learn integrity,API/script types,launch,registry/index,540coding/263native bindings,copy sweep,build,two zero-vulnerability production dependency audits,diff and80fresh final-build fixture-backed320–1440px light/dark probes pass,both tracked responsive processes exit0. Bundle242998gzip meets unchanged243000budget. B083full-client/harness evidence stays dated for unchanged product UI/runtime;exactly12physical handlers and archived Czech unchanged.

The original dark responsive run completed all40measurements but retained one referenced Unix stderr pipe. Node inspector and lsof identified the peer as Chrome crashpad/Google updater descendants inheriting browser stderr,distinct from esbuild's pipes. A later inspection attempt found the original process already exited;no forced destruction or helper termination occurred. The original run remains diagnostic only. QA cleanup now destroys our spawned browser stdout/stderr as well as closing its DevTools socket/killing only that browser. A controlled surviving-descendant regression rejects the old kill-only behavior and accepts cleanup while the descendant stays alive;its explicitly created fixture is then removed. An initial scratch mutation missed esbuild's renamed local and is excluded. Both complete80probe runs were repeated after the real fix with tracked successful exits. No production browser/runtime/access policy changed.

Verified production#448is525coding/263native after required38856861035(verify29m04s,SQL42s),all completed premerge guards and exact preview/production11general/four actual schema Submits/seven Premium+two prerequisite locks at mergeb55b4a07/READY dpl_FoYgUoLHZTULgpJ6t9EqXs9vhjds. Initial overlapping served probes hit429 and are excluded;unchanged sequential retries complete,without changing rate limits. TenB100–B101records remain frozen#449at7d9fdd43,exact READY preview11general/eight Premium+two prerequisite locks,zero cohort Submits;required38859620668/guarded release pending. Current source540/725leaves185(TS2,React183);fifteen records exceed verified production. Preserve#435/#444after whole audit,owner holds,draft#365,effective-bank/longest-answer reconciliation and complete-coding eligibility gating. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## PR#449guarded production acceptance —16October2026UTC

PR#449passed Product quality38859620668at frozen7d9fdd43f10eabfc357aea401f6e02913b731c37(verify32m45s,SQL41s). Fresh exact-head/open/non-draft/main/MERGEABLE/no-closing-issues/all-rollup/protected verify+sql app15368/exact completed-success checks and exact READY preview completed before guarded non-admin merged3365a14bd2af477e22f3bcdc8fc45537bb89cee on16October2026at06:44:40UTC. An initial guard script incorrectly required strict:true;the existing strict:false profile matches prior accepted protection and remains unchanged. That failed assertion triggered no merge. The corrected fresh full assertions completed successfully before the later merge.

READY production dpl_BUrvDb9gp68LLdnabGTwcF8yUejr matches that merge,has no alias error and owns devshark.app before/after probes. Exact READY preview dpl_5P7h3jieXxyPmAXF8yJNpZaftNZM and canonical production each pass11general guest checks. All ten cohort tasks retain legitimate locks(eight Premium,two prerequisite);zero actual cohort Submits are claimed. Initial overlapping preview-cohort429run is excluded;unchanged sequential retry completes with all ten expected locks. No rate/access/protection policy was changed or account,progress,score/generated-name fixture created. Frozen helpers were compiled from the exact cohort before later edits.

B100–B101bring verified production to535/725coding and263/263native. FiveB102records are committed79b0d711;fiveB103records are locally recorded at545source,with final QA/commit pending(180remaining,all React). Ten newer records exceed verified production. Keep complete-coding eligibility gated,effective-bank/longest-answer reconciliation,owner holds,draft#365and dedicated authorized acceptance under#190. #435Profile-only identity/photo settings and#444guide startup handoff follow the whole audit. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## B103five-item audit —16October2026UTC

B103individually reviews the final two TypeScript booking APIs and first three React JSX/props/list lessons. All156TypeScript,316JavaScript and70algorithm source reviews are now current;React3/183leaves180remaining. Final35/35current-hash verdicts(20valid,5starters,10semantic/type controls)match expectations versus25/35original baseline. Twenty base25/unknown-safe checks pass:two authored O(n+s)API targets and three React null targets;unknown complexity stays hidden/unpenalized. Fifteen hidden/five visible additions and four own compiler probes supplement originals. Two erased-body controls compile without source errors and pass36/44runtime assertions respectively,then miss1/2required type rejections. All540prior coding hashes remain current.

Booking create/list and mutation stages preserve all three correct boards and original cases. Exact field/endpoint substitution against individually read planner modules confirms complete code correspondence. The independent API uses the correct15unit workshop item prefix. Explicit readonly/frozen unique valid seeds<=10000,initial identity/version<=1000000,<=10000requests/live records,raw names<=20000,exact paths<=256,independent copied state/max-ever IDs,insertion order,owned mutable replies and unknown bodies define the contract. Common O(n+s)construction/request time/space defines items/raw path-name input and allows faster Maps. Each API adds16x96independent key-order-neutral state-model steps,unsorted99/1seed and10000reverse-ID frozen copies. Mutations add404before409before400precedence,10conflict/seven invalid seats,11bad suffixes,1000no-op version increments and delete/recreate identity checks. Last-seed counters,amount-first stale conflicts and erased body types passed originals and now fail. Correct anchored regex/max operations remain.

Original React samples only observed fixed default output. JSX text dependency becomes observable with optional supplied heading/description defaults in the starter. Greeting/Price gain named exports for direct prop checks,while optional people/products inputs default to original arrays;all nine published boards,starters,skeletons/hints/methods are made consistent. No-props output remains unchanged. Allow equivalent loops/array methods rather than rejecting correct junior loops. Exact plain strings including empty/whitespace/Unicode/markup-like content,immediate prop changes,independent mounts,empty/reordered/read-only lists and100item boundaries are explicit. Price requires Number.toFixed(2),one space and currency,with2.675=>2.67and finite±1000000bounds rather than a different money-rounding promise. Three hidden tests per lesson cover nine heading/name values,12amount/currency pairs,omitted defaults and repeated replacement/empty/restored states. Direct and nondefault visible examples guide learners. Static data,unsafe HTML,trimmed names and Math.round substitutions pass originals and fail the relevant new checks.

Final self-review removes unnecessary child-tag restrictions:exact literal text already detects parsed markup. A first successful35-case matrix is excluded from final-hash evidence;the exporter/grader are freshly compiled and all35cases rerun,including independent valid createElement/span/loop/reduce/bold-name alternatives that prove equivalent inner markup is accepted. Baseline alternatives preceded those harmless wrappers;semantic controls stay unchanged. No source AST policing,state/effects,memoization or grading/runtime-policy change is introduced. React guidance uses installed19.2.8,JSDOM30.0.1andRTL16.3.3;stable concepts were reread in official React/MDN sources. The stale react-hidden comment is corrected to the already-existing trusted-page/serialized QuickJS learner/fresh production microVM boundary;no executable isolation behavior changes. Audit-only grade-task output now splits existing React case names into visible/hidden arrays;retained35-case metadata is recounted from exact raw outcomes,without changing verdicts or hashes. A fresh valid/wrong control confirms3visible/3hidden and unchanged passed/failed outcomes.

All12typed fullstack stages plus three React lessons pass canonical/native Run/reversed-hidden checks,18earlier-stage/three checkpoint failures,nine signature boundaries,21known answers and four incomplete React skeleton placements. Full grading/Learn integrity,React promise/authority suites,API/script types,launch,registry/index,545coding/263native bindings,copy sweep,build,both zero-vulnerability production dependency audits,diff and80final-build fixture-backed320–1440px light/dark probes pass;both tracked responsive processes exit0 with the B102inherited-pipe regression. Bundle242998gzip meets unchanged243000budget. B083full-client/harness evidence stays dated for unchanged product UI/runtime. Exactly12physical handlers;archived Czech unchanged.

Verified production#449is535coding/263native at merged3365a14/READY dpl_BUrvDb9gp68LLdnabGTwcF8yUejr after required38859620668(verify32m45s,SQL41s),completed fresh premerge assertions and exact preview/production11general checks/eight Premium+two prerequisite locks. Zero actual cohort Submits are claimed;dedicated authorized coverage remains under#190. The initial mistaken strict:true assertion triggered no merge;existing strict:false protection was verified unchanged and all corrected fresh guards completed before merge. Source545/725leaves180React tasks;ten B102–B103records await their own guarded release. Parent issues176/190/208/391were refreshed at540committed/525production/185remaining before B103final approval. Preserve#435/#444after whole audit,owner holds,draft#365,effective-bank/longest-answer reconciliation and complete-coding eligibility gating. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## B104five-item audit —16October2026UTC

B104individually reviews keyed books,in-stock products,guest edits,stop insertion/reordering and task toggles. Thirty-five current-hash outcomes match expectations(20valid,5starters,10semantic controls),versus25/35original baseline. Fifteen hidden/five visible additions supplement all original assertions;twenty safe base25checks confirm all five React targets are null/unknown,so no complexity text/penalty is invented. All545prior coding hashes remain current. Individually scored relevance is9/9/10/10/9with quality floor4,not a blanket content endorsement.

Book/stock starters and all six supplied boards accept optional current data with original defaults. Exact plain strings,read-only/frozen dense lists<=100,2000unit fields,unique ids,empty/reordered/renamed data and accurate count paragraphs are explicit. Stock flags remain boolean and duplicate names across ids are valid. Actual surviving LI node identity follows ids through reorder,rename,insertion/removal/filtering;removed rows need not retain nodes if later reintroduced. Independent loop/span and reduce/bold-name alternatives prove equivalent inner markup remains accepted. Static sample arrays and index-key controls pass originals and fail the changed-data/identity cases. Loop equivalents are allowed where the old filter/map wording contradicted valid junior implementations. No effects or derived state are added.

Guest trim/blank semantics already present in all supplied logic are stated explicitly. Blank input leaves both list/input unchanged;valid text appends a distinct guest and clears input. Duplicate names remain independent rows,only the selected id is removed,and adding after clearing the list works. All three published inputs gain the accessible name Guest name;tests use role/name and accept equivalent visible labels,not just aria-label. This accessible name is a newly explicit requirement,not an old grader finding. Literal text/Unicode/internal spaces are preserved. Three hidden cases exercise whitespace/literal markup,duplicate deletion/empty/readd and24independent modeled add/remove steps with simultaneous mounts. A reducer alternative passes;name-based removal and raw-whitespace controls passed originals and now fail. No global never-reuse id claim is imposed on the correct current-max strategy.

Stop insertion labels use total current length+1at first/middle/last positions. Stable unique row ids preserve surviving nodes through insertion/neighbour swaps;edges are no-ops and prior state/seeds stay untouched. Three hidden cases include repeated positions,24modeled mixed actions with DOM identity,edge repetition and independent mounts. Correct slice/loop/flatMap boards are retained;equivalent immutable methods are explicitly permitted. Index-based labels/one-insertion-only controls passed originals and fail new cases. Task toggles keep exact labelled checkboxes/order/counts and stable LI nodes,work in both directions repeatedly,and preserve independent/fresh mounts. Six repeated first-task clicks,36modeled toggles and concurrent/fresh mounts reject once-per-task/set-true-only controls that passed originals. Correct map/loop boards and the independent reducer/Array.from variant pass. Tests prove outcomes;they do not claim universal inspection of hidden object identity or source method syntax.

Every original/final field and all15published modules were read individually. Official React list/props/immutable-array/state-identity/input/reducer documentation was reread against the installed runtime. A first35/35matrix preceded final prompt punctuation cleanup;all35variants were freshly rerun after that cleanup. A later single method-comma space fix changes only Guest's hash,so its seven variants are freshly regraded and combined with28unchanged current-hash rows. The ledger/JSONL use that exact35row union;registry/index,550bindings,launch/build/bundle are rerun afterwards. No already-passed unrelated suites are claimed rerun at the final punctuation edit. All execution/hint/source readings remain same-session model self-review.

Eight selected React lessons pass canonical/native Run/reversed-hidden checks and14incomplete skeleton placements;expected duplicate-key warnings belong only to incomplete skeleton controls. Full grading/Learn integrity,API/script types,launch,registry/index,550coding/263native bindings,copy sweep,build,two zero-vulnerability production dependency audits,diff and80final-build fixture-backed320–1440px light/dark probes pass;both tracked responsive processes exit0with inherited-pipe cleanup controls. Bundle242998gzip meets unchanged243000budget. B103React authority and B083full-client/harness evidence remain dated for unchanged runtime/product UI. Exactly12physical handlers and archived Czech unchanged. No engine,dependency,schema,RLS,reward,access-policy or product-UI change.

Verified production remains535coding/263native via#449atd3365a14/READY dpl_BUrvDb9gp68LLdnabGTwcF8yUejr. TenB102–B103records are frozen#450atcc4585060efb6a27ae6f3336374bb13b5f200d83;its exact READY preview dpl_Hw6EKp1cVvBhEkHFXrpGkSMz11JG passes11general checks and12actual React Submits over the three B103lessons(each reference/alternative passes,two semantic controls fail,all0XP/nullprogress),six Premium/one prerequisite lock. Required38863823341/guarded release pending. FiveB104records are separate. Source550/725leaves175React tasks;fifteen accepted records exceed verified production. Parent issues176/190/208/391were refreshed at545committed/535production/180remaining before B104final approval. Preserve#435/#444after whole audit,owner holds,draft#365,effective-bank/longest-answer reconciliation and complete-coding eligibility gating. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## PR#450guarded production acceptance —16October2026UTC

PR#450passed Product quality38863823341at frozencc4585060efb6a27ae6f3336374bb13b5f200d83(verify33m04s,SQL47s). Fresh exact-head/open/non-draft/main+accepted base d3365a14/MERGEABLE/no-closing-issues/all-rollup/protected verify+sql app15368/exact completed-success assertions and exact READY preview completed successfully before guarded non-admin merge0757265e22b9ee0bc3cf00d3d0f328cd95c0045e on16October2026at07:28:41UTC. Existing strict:false protection remains unchanged;no bypass/force/admin merge is used.

READY production dpl_B8r8BWbu7nc776DNJHcuuMVC79wL matches the merge,has no alias error and owns devshark.app before/after probes. Exact READY preview dpl_Hw6EKp1cVvBhEkHFXrpGkSMz11JG and canonical production each pass11general guest checks plus12actual React Submits across all three B103lessons:each reference/independent alternative passes,two semantic controls fail,all0XP/nullprogress. Six other tasks retain Premium locks and one prerequisite lock under#190. Frozen helpers were compiled from the exact cohort before later edits. No production account,progress,score/generated-name fixture or protection/rate/access setting was written.

B102–B103bring verified production to545/725coding and263/263native. FiveB104records are committed40909eef;fiveB105records are locally recorded at555source with final responsive/commit acceptance separate(170remaining,all React). Ten newer records exceed verified production and are not included in this release. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds,draft#365and dedicated authorized acceptance under#190. #435Profile-only identity/photo settings and#444guide startup handoff follow the whole audit. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## B105five-item audit —16October2026UTC

B105individually reviews newest-first forms,memoized totals,stable pick callbacks,Undo stacks and ticket queues. Final35current-hash outcomes match expectations(20valid,5starters,10semantic controls),versus25/35original baseline. Fifteen hidden/five visible additions retain every original assertion. Twenty base25checks confirm all five React targets remain null/unknown with no complexity text or penalty. All550prior coding hashes remain current. Relevance9/8/8/9/9and quality floor4are individually justified;the two tiny memo examples have practical-utility1rather than invented production-performance claims.

Todo forms retain three correct submit/list strategies,add accessible Todo text naming and state JavaScript trim/blank no-op/distinct duplicates/literal text/2000unit inputs/unique stable keys/independent mounts explicitly. A visible duplicate/nonalphabetic example and three hidden cases cover form association/whitespace/literal duplicates,six changed/duplicate/long values with surviving LI nodes and24modeled submissions. Descending sort accidentally matched original First/Second/Thirdsamples;deduplication also passed unique samples. Both now fail,while an independent reducer alternative passes. The final skeleton labels its input consistently.

Memo work becomes observable through optional calculate(default named summarizeOrders)and a pure helper export. Each published board's original filtering/sum logic is extracted without changing defaults. Query trim/case-insensitive substring semantics,2000unit inputs,readonly order records,raw-query callback input and authoritative returned matching/total are explicit. The supplied function may return up to100ordinary uniquely identified records. Both query and calculate are dependencies;normal Nudge/parent renders skip unchanged work and either changed input recomputes. Exact call-count observations exclude Strict Mode,Suspense/hot reload and cache eviction;cache is not persistent state,and real performance should be measured before optimizing. Search orders naming,starter/full skeleton/hints/method match the contract. Three hidden cases exercise nine helper/default queries,actual skipped calls/function replacement/default restoration and independent lifetimes. Observer counters instrument deterministic calculators without making returned data depend on counts. An independent reduce/reducer alternative passes;unconditional recalculation and missing function dependency passed originals and now fail.

Stable pick starter supplies its existing memo child and optional Button prop. Published Apps retain defaults and pass label/shared onPick with stable keys. Stable state updater wording permits the independent reducer dispatch strategy. Runtime captures test actual shared function identity across normal parent/selection renders,actual skipped rendering by a memoized injected child and state/callback lifetimes for simultaneous mounts. No source AST rule or blanket rule to memoize every callback is introduced. Fresh self-review drops an unnecessary different-function-object requirement across mounts;within-mount stability and independent state remain. Correct three boards and the independent reducer/array alternative pass. Always-new/picked-dependent callbacks passed originals and now fail.

Undo retains correct three reducers and explicitly numbers Step by new current depth,including partial/full Undo followed by Push;empty Undo is disabled/no-op. A visible repush and three hidden cases add partial/full reset,36modeled LIFO transitions beyond depth3and independent/remounted state. Per-mount monotonic step labels and a depth3cap passed originals and fail now. Ticket numbering intentionally differs:it belongs to the mounted App's lifetime,continues after empty and resets only for a fresh mount. Visible drain/refill plus three hidden cases cover Ticket4/5after draining1..3,36modeled FIFO transitions and independent/fresh sessions. Empty-reset/three-issue-cap controls passed originals and now fail. Independent concat/slice/filter reducers pass;no private action representation is policed. These counters do not modify global shark handles.

All original/final material and15complete published modules were read individually. Existing serialized function/component props support the new observations,including host memo component props,without any runtime/authority change. Current official React useMemo/useCallback/memo/input/array/reducer/state guidance was reread against installed19.2.8. The first scratch record delimiter stopped inside a useMemo callback and export compilation failed before verdicts/review records;only owned B105edits were restored from B104HEAD,the delimiter corrected and exports/grader rebuilt. That patch error is excluded and is not a defect in published learner code. The first35successful verdicts precede final Todo skeleton label/updater wording/permissiveness fixes;all14variants for those two changed tasks are freshly regraded and combined with21unchanged current-hash rows. Ledger/JSONL bind that exact35row union before registry/index/build.

Thirteen selected React lessons pass canonical/native Run/reversed-hidden checks and23incomplete skeleton placements. Full grading/Learn integrity,React promise/authority suites,API/script types,launch,registry/index,555coding/263native bindings,copy sweep,build,two zero-vulnerability production dependency audits,diff and80final-build fixture-backed320–1440px light/dark probes pass;both tracked responsive processes exit0with inherited-pipe controls. Bundle242998gzip meets unchanged243000budget. B083full-client/harness evidence remains dated for unchanged product UI/runtime. Exactly12physical handlers;archived Czech unchanged. No engine,dependency,schema,RLS,reward,access-policy or product-UI change.

Verified production#450is545coding/263native at0757265e/READY dpl_B8r8BWbu7nc776DNJHcuuMVC79wLafter required38863823341(verify33m04s,SQL47s),all completed fresh exact-head/accepted-base/MERGEABLE/protected assertions and exact preview/production11general plus12actual B103React Submits(six correct pass,six semantic controls fail,0XP/nullprogress),six Premium/one prerequisite lock. Ten B104–B105records are separate and await their own guarded release. Source555/725leaves170React tasks. Parent issues176/190/208/391were last refreshed at545committed/535production/180remaining before B105final approval. Preserve#435/#444after whole audit,owner holds,draft#365,effective-bank/longest-answer reconciliation and complete-coding eligibility gating. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## B106five-item audit —16October2026UTC

B106individually reviews pagination hooks,stable-key reordering,person lists,conditional paragraphs and native color selection. All37current-hash outcomes match expectations(20valid,5starters,12semantic controls),versus25/37original baseline. Fifteen hidden/five visible additions retain original assertions. Twenty base25checks confirm null/unknown React targets with no complexity text/penalty. All555prior coding hashes and263native records remain current. Individually justified relevance9each and qualityfloor4;no independent/human review claim.

Pagination now exports the named generic hook and documents readonly dense arrays<=1000opaque values,positive size1..100,one-based bounds/empty page1of1/reference identity and functional repeated navigation. Optional App data/size defaults preserve seven cities/3. Changed inputs preserve valid page or persist a nearest-valid stored clamp so later growth cannot resurrect invalid state. All three boards add converging guarded same-component render adjustment;junior also fixes zero empty-page count and batched captured-state updates. Nine interface-only old-hook comparisons separately verify all3pass originals/fail new empty/input checks without compile errors,while only old junior loses an isolated batched step. Three hidden cases exercise always-enabled direct hook controls,batching,opaque frozen values,1000items,size100,dynamic bounds and independent mounts. Four semantic controls pass originals and fail now;independent reducer alternative passes.

Stable reorder retains all correct boards including actually executed senior toSpliced. Existing one-LI identity evidence is not recounted as a new gap. New checks cover current-position disabled flags,36modeled moves/all surviving nodes and independent mounts. Two-move cap/static-id flags pass originals and fail now. Splice,toSpliced and equivalent immutable moves are explicitly allowed. Data lists preserve all three display strategies while adding optional readonly people/default data and exact name-space-age text. The original never checked ages. Exact literal/duplicate/empty/zero/150-age/frozen values,100records and actual id-bound LI identities under reorder/name/age changes are exercised. Missing ages/index keys pass originals and fail now;reduce/span alternative passes.

Show/hide retains all correct wording choices and discrete-click strategies;paragraph must actually leave the DOM initially/off,but paragraph node identity and exact text are not constrained. Twenty-fourtoggles,parent renders and independent/fresh mounts expose a two-click cap/shared lifetime state that passed original even-click examples. Color selection retains all correct state strategies,adds accessible Color naming and checks exact native option/value/status agreement through24choices including Green/returnRed,normal parent renders and independent mounts. AlwaysBlue/native-stuckRed passed original Blue-text-only cases and fail now. Visible-label reducer alternative passes,so aria-label spelling is not required.

All original/final prompts,starters,skeletons,hints,methods,suites and15complete published modules were read individually,plus the two existing complete hint QA answers for Data/Color. First canonical run caught those old fills using fixed people/missing new label;both are repaired while retaining every skeleton line,and the subsequent canonical suite passes. Private audit exporter now inventories filledSkeleton separately so existing QA answers remain visible in future readings. This changes no served solution/grading authority. Original failed canonical run is excluded from pass claims. Current React/WAI/MDN primary guidance is recorded per item;runtime supports named hook/probe props without engine changes.

Eighteen selected React lessons pass canonical/native Run/reversed-hidden checks and32incomplete skeleton placements. Full grading/Learn integrity,React promise/authority,API/script types,launch,registry/index,560coding/263native bindings,copy sweep,build,two zero-vulnerability production dependency audits,diff and80final-build320–1440px light/dark probes pass with both tracked processes exiting0. Bundle242998/243000gzip remains unchanged. Exactly12physical handlers;archived Czech unchanged. No dependency,engine,schema,RLS,reward or access-policy change. B083full-client/harness evidence remains dated for unchanged product UI/runtime.

Source560/725leaves165React tasks. Verified production545via#450;ten B104–B105records in#451and these five B106records have separate release acceptance. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds,draft#365and dedicated authenticated/physical acceptance. #435Profile-only leaderboard identity/photo settings and#444guide startup handoff follow the whole audit. Same-session model self-review/finite execution only.

## PR#451guarded production acceptance —16October2026UTC

PR#451passed Product quality38868736091at frozen9876fca852923370fbb85178075d4632fa1ba69a(verify28m18s,SQL38s). All fresh exact-head/open/non-draft/main+accepted-base0757265e/MERGEABLE/no-closing/all-rollup/protected verify+sql app15368/exact completed-success assertions completed successfully and were read before guarded non-admin merge4955ffec07f7fe56b928290030a9e87ce7d5d261on16October2026at08:22:18UTC. Existing strict:false stays unchanged;no bypass/admin/force merge.

Exact READY preview dpl_4rnL7CFfs2vjc2y9Ea9ZoCbFrg1b and READY production dpl_DvcqmJYoomdCaXFvrJMDE1uuKZiM each pass11general checks plus16actual Submits across four free cohort lessons:each reference/independent alternative passes and two semantic controls fail,all0XP/nullprogress. Six other tasks retain Premium locks under#190. Production matches the merge,has no alias error and owns devshark.app before and after both fully completed probes. Frozen cohort helpers were built from the accepted head before B106edits. No account,progress,score/name fixture or protection/access/rate setting was written.

Verified production is555/725coding and263/263native. Five newer B106records are committed069d27f1at560source;165React remain. B107is still unreviewed work in progress and excluded. Complete-coding eligibility remains gated;effective-bank/longest-answer reconciliation,dedicated authenticated/physical acceptance,owner holds and draft#365remain. #435Profile-only leaderboard identity/photo settings and#444startup guide handoff follow the whole audit. Same-session model self-review/finite execution only,not independent/human or whole-catalogue acceptance.

## B107five-item audit —16October2026UTC

B107individually reviews Counter,accessible disclosure,Tabs,ON/OFF button and pressed formatting controls. The final35current-hash outcomes(21unchanged+14fresh Counter/Tabs)all match:20valid,5starters,10semantic controls,versus25/35original baselines. Fifteen hidden/five visible additions retain all original assertions. Twenty base25checks confirm all five targets stay null/unknown with no complexity text or penalty. All560prior coding and263native hashes remain current. Individually justified relevance9each and qualityfloor4;no human/independent acceptance claim.

Counter retains all three correct separate-click strategies and adds every intermediate count through36,parent renders,concurrent/fresh state and a self-contained five-click visible example. A cap at3and a reducer skipping2passed originals and fail now. The original already rejected a proposed shared-module control;that rejected draft is excluded and one actual skip-two baseline result replaces it,with34other baseline verdicts retained. Existing exact0/1/3hidden coverage is not recounted as new. No batched public-hook interface,exact button wording or wrapper is imposed. Disclosure retains all correct native-button/useId strategies and original close/type/two-instance-id tests. New24toggle/stable-target/focus/parent/eight-instance/fresh checks expose open-dependent ids and a two-action cap. The general WAI pattern makes aria-controls optional,but this exercise explicitly requires it. Native Enter/Space remains inherited,without duplicate key handlers or a physical-device claim.

Tabs now explicitly teaches a horizontal automatically activated Account-named tablist,three native buttons,one selected/roving-tab-stop item,one exact-text focusable panel and stable unique useId-prefixed relationships. ArrowLeft/Right wrap;Home/End select and focus first/last with preventDefault. Other keys remain native. Clicking/focusing selects and normal parent/independent/fresh lifetimes are defined. Inactive panels need not exist. All three boards and existing filled-hint answer are updated;the junior keeps loop lookup and senior keeps extracted Tab. An independent index/reducer/section alternative passes. Original reference and senior are old-contract controls:both passed originals and fail these newly explicit accessibility requirements. Senior previously moved selection without focus and used duplicate static ids across mounts. Home/End are optional in general WAI guidance but explicit here. Actual focus and default prevention are observed rather than inferred from selected flags;trusted focus-triggered updates use act.

ON/OFF retains correct logic and exact requested action labels. Permanent OFF ON and a two-click cap passed old substring checks;exact whole-label and32click/parent/concurrent/fresh checks now reject them. Senior no longer adds unnecessary aria-pressed to a changing label,consistent with WAI button alternatives;learner absence of that attribute is not enforced. Bold/Italic retains all correct boards and original individual/both-on/three-Bold-click cases. Twenty-eightmodeled mixed actions,Italic release,parent/independent/fresh checks expose a three-click cap and never-released Italic. Exact original toolbar/labels/preview inline-style vocabulary is explicit;CSS class names are unconstrained and a class-free reducer alternative passes. This scope does not claim every possible toolbar navigation convention.

Every original/final field,15whole published modules and the Tabs complete hint answer were individually read. Actual source membership includes Easy-a/Easy-b files despite their grouped React export. An initial scratch path assumption failed before any source write. An incomplete new-test-import attempt was stopped and entirely excluded. Native Run then caught a new Counter visible assertion accidentally relying on a hidden helper;the assertion is self-contained now,and failed canonical evidence is excluded. Final reread also wraps trusted tab focus updates in act. Fresh14Counter/Tabs verdicts replace their earlier rows before hash binding;the other21unchanged current-hash rows all pass. Original baseline visible/hidden metadata is recounted from raw case labels without changing verdicts. Launch checking found a stale assertion that the real disclosure guest runs only3hidden cases. It now asserts all6exact original/new case names;the first failed launch run is excluded and full launch reruns. No learner/runtime authority change is introduced.

Twenty-three selected React lessons pass canonical/native Run/reversed-hidden checks and38incomplete skeleton placements at final source. Full grading/Learn integrity,React promise/authority,API/script types,launch,registry/index,565coding/263native bindings,copy sweep,build,two zero-vulnerability production dependency audits,diff and80final-build320–1440px light/dark probes pass with both tracked processes exiting0. Bundle242998/243000gzip remains unchanged. Exactly12physical handlers;archived Czech unchanged. No dependency,engine,schema,RLS,reward/access policy or product UI change. B083full-client/harness evidence stays dated.

Verified production#451is555coding/263native at merge4955ffec07f7fe56b928290030a9e87ce7d5d261,READY dpl_DvcqmJYoomdCaXFvrJMDE1uuKZiM,after required38868736091(verify28m18s,SQL38s),completed/read fresh exact-head/accepted-base/MERGEABLE/protected guards and exact preview/production each11general checks+16actual Submits(four free lessons:reference/alternative pass,two controls fail each,all0XP/nullprogress). Six Premium locks remain under#190. TenB106–B107records await separate guarded release at565source;160React remain. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds,draft#365and dedicated authenticated/physical acceptance. #435Profile-only identity/photo settings and#444startup-guide handoff follow whole audit. Same-session model self-review/finite execution only.

## B108 five-item audit — 16 October 2026 UTC

B108 individually reviews Star rating, Add a todo, Remove a todo, Read more and Create and append. Final 35 current-hash outcomes match expectations: 20 valid solutions, five starters and ten semantic controls, versus 25/35 original baseline matches. Evidence combines 28 unchanged final rows with seven fresh Add variants after repairing the native-input test oracle. Fifteen hidden and five visible additions preserve original assertions. Twenty base-25-XP checks confirm null/unknown React complexity targets with no complexity text or penalty. All 565 prior coding and 263 native hashes remain current. Relevance is individually justified at 9 each, quality floor 4; this is same-session model self-review and finite execution.

Star rating now checks exact filled-prefix positions, rather than only the count of changed buttons. All values, repeated higher/lower commitments and hover restoration are exercised without changing the committed Rating paragraph on hover. Native buttons have stable meaningful Rate 1 star through Rate 5 stars names. Existing symbol/class/attribute appearance approaches remain accepted; a separate class/reducer alternative passes. Reversed suffix and fifth-hover-to-three controls passed originals and fail now. All three boards, skeleton and complete hint answer gain the names; senior removes a misleading preview aria-pressed flag. Native button activation remains; no complete radio-group keyboard or arbitrary malicious CSS proof is claimed.

Add retains the correct three append/trim/no-op strategies, adds New todo naming and makes duplicate/order/literal text/blank behavior explicit. Earlier LI nodes survive appends. New tests cover trimmed duplicates, empty/whitespace inputs, Unicode/markup/2000-unit values, 24 modeled additions and parent/independent/fresh lifetimes. The separate full hint answer gains the trim guard and name. Prepend and raw/blank controls passed originals and fail now. A native text input removes newlines before React receives its value; the final oracle observes that actual value before Add rather than wrongly requiring CR/LF preservation. WHATWG guidance was checked. The initial scratch whitespace escape error and then the incorrect newline oracle are excluded, and all seven Add outcomes are freshly graded at the final hash. Correct learner code was not altered to satisfy impossible input behavior.

Remove retains the reference filter, junior new-array loop and senior extracted-row callback. It now names each button with its todo, specifies surviving id-bound LI identity and accepts empty UL or existing All done state. A visible middle deletion and all six complete removal orders verify the exact target, remaining text/order/nodes, parent renders and independent/fresh resets. Always-remove-last and positional-key controls passed original count-only assertions and fail now; an independent reducer/concat strategy passes. No arbitrary data API or filter-source-spelling rule is imposed.

Read more retains all correct boards and already-existing exact 60/61/default checks. Plain-string UTF16 length/slice semantics, literal three dots, empty/markup/emoji/long inputs and no trimming are explicit. Twenty toggles and changed long/short props preserve the mounted open flag while rendering current text; independent/fresh reviews start folded. Two-toggle cap and cached-first-text controls passed originals and fail now; a reducer alternative passes. This is built-in string indexing, not a grapheme/word-aware truncation claim. No complete hint answer exists for this id.

Create/append now validates the endpoint, POST, JSON Content-Type and chosen nonempty title/completed:false body. Controlled fixtures defer six sequential writes, verify disabled pending/no optimistic rows/no second request, preserve exact returned literal titles and repeated server ids, retain existing LI nodes and test parent/independent/fresh state. HTTP, network and JSON failures preserve earlier rows, show the retry alert, clear it on retry and always re-enable Add. All three boards and skeleton/hints/method are updated. Reference gets local UUID keys, junior keeps valid append-only positional keys and senior keeps its helper/UUID while adding catch/error state. An independent reducer passes; ignoring HTTP status and substituting requested text passed originals and fail now. General API idempotency, cancellation and real remote writes are outside scope; all transport is trusted local fixtures.

Every original/final prompt, starter, skeleton, hint, method, suite and 15 whole published modules was read individually, plus three complete hint answers. Current React, WAI, Fetch, JSONPlaceholder, String length/slice and native input primary guidance is recorded per item against installed React 19.2.8. Final canonical/native Run/reversed-hidden checks cover 28 selected React lessons and 48 incomplete skeleton placements. Full grading/Learn integrity, React promise/authority, API/script types, launch, registry/index, 570 coding/263 native bindings, copy sweep, build, two zero-vulnerability production dependency audits, diff and 80 final-build 320–1440 px light/dark probes pass; both tracked responsive processes exit 0. Bundle stays 242998/243000 gzip. Exactly 12 physical handlers; archived Czech unchanged. No dependency, engine, schema, RLS, reward/access policy or product UI change. B083 full-client/harness evidence stays dated.

Verified production remains 555 coding/263 native via accepted PR #451 at merge 4955ffec07f7fe56b928290030a9e87ce7d5d261, READY dpl_DvcqmJYoomdCaXFvrJMDE1uuKZiM. PR #452 freezes ten B106–B107 records at 2a87a9bc29b9566c4b1b63ea4b0fef2640446f29; its exact READY preview dpl_HXAPQ1ijCYe8zLKSbW8G3biVaGTF passes 11 general checks plus 12 actual Submits across three free lessons (reference/alternative pass, two controls fail each, all 0 XP/null progress), with seven Premium locks. Required run 38875515597 and guarded release remain separate. These five B108 records bring source to 570/725, with 155 React tasks remaining and 15 accepted records exceeding verified production. Preserve complete-coding eligibility gating, effective-bank/longest-answer reconciliation, owner holds, draft #365 and dedicated authenticated/physical acceptance. #435 Profile-only identity/photo settings and #444 guide startup handoff follow the whole audit.

## B109 five-item audit — 16 October 2026 UTC

B109 individually reviews Search a list, Breadcrumbs from a path, Filter fetched users, Sort a table by any column and Accordion. All 35 current-hash outcomes match expectations: 20 valid solutions, five starters and ten semantic controls, versus 25/35 original baseline matches. Fifteen hidden and five visible additions retain original assertions. Twenty base-25-XP checks confirm null/unknown complexity targets with no complexity text or penalty. All 570 prior coding and 263 native hashes remain current. Relevance is individually justified at 9 each, quality floor 4. This is same-session model self-review/finite execution, not independent/human acceptance.

Search keeps the three fixed names and correct filter/loop/optional-memo strategies. Reference/junior and the complete hint now match senior trimming and have Search names labels. The explicit contract preserves raw controlled query, trims/lowercases only for literal matching, restores the source on clearing, accepts empty UL or existing No matches and preserves surviving visible LI nodes. Visible an/clear and three hidden cases exercise middle substrings, punctuation, whitespace, long/no-match queries, 20 query changes and parent/independent/fresh state. Prefix-only and destructive-source controls passed originals and fail now; a reducer/visible-label alternative passes. No performance claim for memoizing three names or blanket index-key rule is introduced.

Breadcrumbs normalize initial start in the starter and three boards by removing empty slash parts and joining under root. A first Go up from a trailing slash now removes a real displayed segment. Scope is initial-only root-relative ASCII segments, up to 100 segments/2000 units, without URL decoding/query/fragment/dot resolution. Existing plain final text and optional senior span/aria-current remain valid under WAI guidance. Visible trailing ascent and three hidden cases cover repeated/slash-only paths, repeated labels, 40-segment ascent/root clamp, changed start props and independent lifetimes. Unnormalized empty-parent-step and a two-action cap passed originals and fail now. Existing deeper/trailing/root/two-step checks are not recounted as new. Independent reducer/normalizer passes.

Fetched users now handles status and JSON/network failures while leaving a named Filter users input available during loading. Each ordinary mounted instance makes one GET; the prompt explicitly distinguishes development Strict Mode setup/cleanup cycles. Current raw query filters actual response data locally using trimmed lowercase literal matching, including input typed before a deferred response. Responses have unique ids and exact literal/duplicate/empty names; surviving rows keep identity. All three boards add response.ok/loading/error/catch/cleanup while retaining promise-chain reference, async/loop junior and custom-hook/memo senior; the optional shown-count status remains allowed. Skeleton and complete hint are aligned. Visible custom data/one-request and three hidden cases exercise authoritative data, request counts, pending query, literal/long names, all failure types, normal parent renders and independent/old-versus-fresh responses. Query-triggered refetch and substituted default users passed originals and fail now; reducer alternative passes. Readonly/frozen fixtures are not claimed to prove arbitrary learner-memory immutability across serialization. No real service or production data is involved.

Sorting retains all three correct boards exactly, including actual executed senior toSorted, and all ten original cases covering ties/numbers/text/column resets/three clicks/source order/cells. New visible TR identity and three hidden cases add 36 modeled mixed sorts with exact cells, tie order, aria-sort/header semantics and nodes, normal parent renders, independent tables and fresh original order. Positional row keys and a three-action cap passed originals and fail now. A decorated reducer alternative passes. No comparator spelling, extra generic input API or speed claim for a four-row memo is imposed.

Accordion retains single optional open id and the three correct state strategies. Native heading buttons now expose actual expanded state and stable unique useId relationships; reference/junior, skeleton and full hint gain them, while senior fixes static cross-instance panel ids using useId in each Item. Visible Support open/close and three hidden cases exercise 36 mixed actions, same-header collapse, exact body/target/focus, normal parent renders and independent/fresh state. Never-collapse and ignored-Support controls passed originals and fail now; reducer alternative passes. Tests use heading roles, allowing appropriate native or ARIA headings. Native Enter/Space/Tab is inherited; extra arrow keys or region landmarks are not required.

Every original/final field and 15 whole published modules was individually read, plus all three complete hint answers. Current React/WAI/Fetch/toSorted primary guidance is recorded per item against installed React 19.2.8. Canonical/native Run/reversed-hidden checks pass for 33 selected React lessons and 58 incomplete skeleton placements. Full grading/Learn integrity, React promise/authority, API/script types, launch, registry/index, 575 coding/263 native bindings, copy sweep, build, two zero-vulnerability production dependency audits, diff and 80 final-build 320–1440 px light/dark probes pass with both tracked responsive processes exiting 0. Bundle stays 242998/243000 gzip. Exactly 12 physical handlers; archived Czech unchanged. No dependency, engine, schema, RLS, reward/access policy or product UI change. B083 full-client/harness evidence stays dated.

Verified production remains 555 coding/263 native via accepted #451. PR #452 freezes ten B106–B107 records at 2a87a9bc29b9566c4b1b63ea4b0fef2640446f29. Its exact READY preview dpl_HXAPQ1ijCYe8zLKSbW8G3biVaGTF passes 11 general checks and 12 actual Submits across three free lessons (reference/alternative pass, two controls fail each, 0 XP/null progress), with seven Premium locks. Required run 38875515597 and guarded production acceptance are separate. Source is 575/725, with 150 React tasks remaining and 20 accepted records exceeding verified production: ten in #452 and ten B108–B109 awaiting another release. Preserve complete-coding eligibility gating, effective-bank/longest-answer reconciliation, owner holds/draft #365 and dedicated authenticated/physical acceptance. #435 Profile-only identity/photo settings and #444 guide startup handoff follow the whole audit.

## PR #452 guarded production acceptance — 16 October 2026 UTC

PR #452 passed Product quality 38875515597 at frozen 2a87a9bc29b9566c4b1b63ea4b0fef2640446f29 (verify 34m03s, SQL 41s). Fresh exact-head/open/non-draft/main+accepted-base4955ffec/MERGEABLE/no-closing/all-rollup/protected verify+sql app15368/exact completed-success guards completed and were read before non-admin merge d5c33f76423fb4734c67f85fe275b1e54ee33506 on 16 October 2026 at 09:21:27 UTC. Existing strict:false remains unchanged; no bypass/admin/force merge.

Exact READY preview dpl_HXAPQ1ijCYe8zLKSbW8G3biVaGTF and READY production dpl_4c2JkPJcbQihcusmUZXi1UoQM7F5 each pass 11 general checks plus 12 actual Submits across three free cohort lessons: each reference/independent alternative passes and two semantic controls fail, all 0 XP/null progress. Seven other tasks retain Premium locks under #190. Production matches the merge, has no alias error and owns devshark.app before and after both fully completed probes. Frozen helpers were captured from the exact accepted head before later edits. No account, progress, score/name fixture or protection/access/rate setting was written.

B106–B107 bring verified production to 565/725 coding and 263/263 native. Ten B108–B109 records are separately committed 479ded89/c7aed1fb at 575 source, leaving 150 React tasks. PR #453 initially contained pending parent #452; after parent acceptance its branch is synchronized with current main and its exact new head/preview/required CI must be revalidated before release. The structural merge alone is checked byte-identical to the prior c7aed1fb tree. Its old c7 preview remains historical, not new-head served acceptance. B110 is private preparation and excluded from review counts.

Preserve complete-coding eligibility gating, effective-bank/longest-answer reconciliation, owner holds/draft #365 and dedicated authenticated/physical acceptance. #435 Profile-only leaderboard identity/photo settings and #444 guide startup handoff follow the whole audit. Same-session model self-review/finite execution only, not independent/human or whole-catalogue acceptance.

## B110 five-item audit — 16 October 2026 UTC

B110 individually reviews City combobox, Effect on mount, GET one user, GET users list and Loading state. All35 current-hash outcomes match:20valid boards/independent alternatives,five starters and ten semantic wrong controls. Final evidence combines14unchanged Combo/Users-list rows with21fresh Effect/One-user/Loading rows after final wording/layout repairs. All ten controls pass original suites without compile errors and fail final checks;baseline25/35. Fifteen new hidden checks,five new visible examples (including the combobox example),and20unknown-safe base25XP checks pass. Target complexity stays null for these UI/effect exercises.

Combobox preserves the existing13prefix/wrapping/pick/Escape/ARIA checks and all three correct navigation strategies. All boards now derive input/label/list/option identities from per-App useId;reference/junior formerly shared all ids,and senior still shared its input/label. Starter supplies the base without duplicating its text state in the skeleton. Option mousedown prevents losing native input focus before selection. Explicit repeated keyboard/default prevention/closed-list behavior,last-selection persistence,stable surviving nodes,parent and independent/fresh lifetimes are checked through36modeled arrows plus changed prefixes/picks. Reducer alternative passes;static input-label and four-key-cap controls pass originals and fail now. Worker focus observations do not replace physical-device acceptance.

Effect retains all three correct state/effect implementations. The authored contract requires exactly one status element,committing Waiting… before the effect yields Ready!,with ordinary parent and independent/fresh state. A trusted parent layout-effect observer sees committed DOM before passive effects;it does not claim a browser paint. Six separate controls verify all three original boards and an independent alternative show Waiting first while static Ready/render-phase update shortcuts fail. The final independent div/span status layout also passes the frozen original grader. No paragraph-only or AST/hook-spelling requirement is added;development Strict Mode setup repetition is explicit.

The request lessons keep their distinct promise-chain,async-loop and custom-hook/nullable-state approaches. Existing alternate-authoritative-record/path cases are retained and not recounted as new. Explicit status/HTTP/JSON/network/cleanup contracts use separately deferred response headers/body fixtures: loading continues until JSON settles,errors never render failed response data,normal parent renders do not refetch,and independent/fresh results cannot be overwritten by removed instances. One-user allows combined/separate name-email paragraphs or the existing mailto link. Users-list always retains its UL and keeps loading display optional;Loading-state explicitly ends loading on empty success and all failures. Dense bounded records include duplicate/empty/literal names,100record lists and stable keyed parent rows. No retry UX,backend/account setup or target complexity is invented. Two complete hint answers and scaffolds align with error/cleanup contracts.

Initial canonical execution caught five stale Loading-state exact-reference QA edit templates after the reference repair;that failed run is excluded. All five intentions remain (three valid starter/heading-status layouts,two invalid absent/persistent-loading layouts),with error branches retained. Final prompt accepts a status element,including h2/h3. The private audit exporter now includes both filledSkeleton and existing materialized React/known-answer variants,reporting missing edits without serving or counting them as extra35matrix variants. All770 exported tasks have zero missing QA edits. Original/final English fields,15whole final boards,two complete hint modules and six existing QA variants were read individually. Current React/WAI/Fetch primary sources are recorded;installed React19.2.8is distinguished from current documentation19.3.

Full grading/Learn integrity,React promise/authority,API/script types,launch,registry/index,all580current coding and263native bindings,copy sweep,build,bundle,two zero-vulnerability production dependency audits,diff and80final-build320–1440px light/dark probes pass;both tracked responsive processes exit0. Final scoped canonical run covers14React lessons and28incomplete skeleton placements;earlier repaired canonical evidence covers38lessons/68placements before final prompt-only widening,without treating that earlier hash as final matrix evidence. All575previous coding hashes remain current. Bundle stays242998/243000gzip,12physical handlers,Czech unchanged. No dependency,engine,schema,RLS,reward/access-policy or product UI change. Full-client/harness B083 evidence remains dated.

Verified production is565coding/263native via accepted#452 at d5c33f76423fb4734c67f85fe275b1e54ee33506/READY dpl_4c2JkPJcbQihcusmUZXi1UoQM7F5. PR#453 holds ten B108–B109 reviews at exact530099a5cad4204aeb81acb70fc6b4793acc5c8a,READY dpl_FKKbUGdkYuWFmFJMR28xRUSeNZR1 with11general checks and4actual free Search-a-list Submits(reference/alternative pass,two wrong fail,0XP/nullprogress),nine Premium locks and full processes exit0. Required38880951646/guarded production acceptance remain pending;old pre-sync c7 served evidence is historical only. B110 adds five locally accepted records:580/725source,145React remain,15above verified production. Preserve complete-coding eligibility gate,effective-bank/longest-answer reconciliation,owner holds/draft#365 and dedicated authenticated/physical acceptance. #435 Profile-only leaderboard identity/photo block and#444guide handoff follow the whole audit. Same-session model self-review and finite worker/browser evidence only.

## B111 five-item audit — 16 October 2026 UTC

B111 individually reviews Document title, Refresh data, Dependent fetch, User by id and Delayed message. All 35 final current-hash outcomes match: 20 valid published/independent solutions, five starters and ten semantic wrong controls. Evidence combines 21 unchanged Title/Refresh/Delay rows with 14 fresh Dependent/User rows after refining two controls. Both refined controls also pass the frozen original grader without compile errors; baseline stays25/35. Fifteen hidden checks, four visible examples and20unknown-safe base25XP checks pass. Desired complexity stays absent for these UI/effect exercises.

Document title preserves all three published modules byte-for-byte, including optional senior title restoration. Its original hidden title0/1/3 assertions remain. Visible two-click UI/title and three hidden cases now require the rendered counter and title to agree throughout0..36, survive ordinary parent renders and reset on a fresh mount after an unrelated title. One global title owner is explicit; simultaneous title ownership is not invented. A reducer with decorated title passes; capped3 and permanently999UI controls pass original suites and fail now. The generic cleanup scaffold becomes a count-specific effect with no unnecessary resource cleanup.

Refresh preserves shared-request async reference/junior and extracted callback/ref senior structures. Request tokens guard success and errors, cleanup invalidates pending results, HTTP/JSON/network failures show a fixed alert, and Refresh remains available to recover. Old data/errors clear at each start and only the newest started request may commit. Random ids are optional1..20 and may repeat; reference floor+1 fixes the Math.ceil zero edge already avoided by junior/senior. Literal/empty response paragraph titles,17mount/refresh requests,normal parent counts,all failure/retry kinds,overlaps and removed/fresh lifetimes are observed. Original hidden two-custom-response/path assertions are retained and not recounted as new. A fixed-id reducer alternative passes; ignoring HTTP and stopping after one Refresh pass originals and fail final checks.

Dependent fetch preserves promise-chain reference, async string-id junior and extracted AbortController senior while adding named Author select, fresh-id-dependent requests, exact literal ordered lists with duplicate/empty names, fixed errors and active-result guards. Senior keeps abort transport plus the guard. Each request clears stale rows/errors; parent renders do not refetch. Sixteen changes,empty/100record bodies,headers-versus-JSON pending state,stable keyed parent rows,three failure/recovery types and out-of-order/removed-versus-fresh responses are checked. The original only counted3/4records,so a synthesized-title control genuinely passed it. The race-prone control is labelled to isolate request semantics from accessibility. The original full hint was read and first repaired,then canonical validation caught order/name drift from the new scaffold. That failed run is excluded;the final complete hint preserves the exact supplied skeleton lines and async behavior,removing unused optional loading state without relaxing validation.

User by id refetches every changed selection,including returning1after2. Remove the senior response cache only because it violated this exercise's refetch contract;this is not a general claim that caching is wrong. Promise-chain reference,async junior and extracted senior hook remain distinct and now handle fixed errors/cleanup/named User select/stale detail clearing. Actual repeated revisions,empty/literal names,full-body waiting,16changes,parent counts,all failure/recovery kinds and late/fresh results are observed. Existing alternate actual users/path cases remain. A cache mutant derived from the repaired senior preserves label,error and cleanup behavior while isolating skipped refetch;fresh original/final executions establish its verdict. Reducer alternative passes;cache and race controls pass originals and fail now.

Delayed message keeps all three correct published modules byte-for-byte. Existing900/1000timing and clearTimeout-on-unmount tests remain. Three additional controlled-clock cases observe999+1,persistent Done for5000morems,parent renders at400ms,staggered independent lifetimes and early-removed fresh timers. Text queries allow other headings/wrappers;the reducer/div alternative passes. A950ms timer and a nested later reset to Waiting pass the originals and fail final checks. The prompt distinguishes deterministic fake-clock boundaries from real browser scheduling,which may fire later. No paragraph-only/status-role or generic changing-delay API requirement is added.

Original/final English fields,15whole final boards,the complete old/final hint and inherited clock/fetch helpers were read per item;B111 has no existing QA variants. Sources use current React/MDN/JSONPlaceholder primary references against installed React19.2.8. Full grading/Learn integrity,React promise/authority,API/script types,launch,registry/index,585current coding/263native bindings,copy sweep,build,bundle,two zero-vulnerability production dependency audits,diff and80final-build320–1440px light/dark probes pass;both tracked responsive processes exit0. Scoped canonical covers five React lessons/ten incomplete skeleton placements. All580previous coding hashes remain current. Bundle242998/243000gzip,12physical handlers,Czech unchanged;no dependency,engine,schema,RLS,reward/access-policy or product UI change. Full-client/harness B083 evidence remains dated. This commit also corrects B110's prose count from four to five visible additions;no extra task is counted.

Verified production is 565 coding/263 native via accepted #452. PR #453 is merged at 32722deae161012f41e38e57a7dd81f48ccb32ad after required 38880951646 (verify34m27s, SQL43s) and completed/read fresh protected exact-head/base/MERGEABLE guards; its exact production acceptance is still pending. Ten B108–B109 plus ten B110–B111 source reviews exceed verified production. Source is585/725,140React remain. B112 private preparation is excluded. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365 and dedicated authenticated/physical acceptance. #435 moves the complete leaderboard identity/radio/photo block into Profile only after the whole audit;#444guide startup handoff also follows the audit. Same-session model self-review and finite worker/browser evidence only.

## PR #453 guarded production acceptance — 16 October 2026 UTC

PR #453 passed required Product quality38880951646 at frozen530099a5cad4204aeb81acb70fc6b4793acc5c8a (verify34m27s, SQL43s). Fresh exact-head/open/non-draft/main+accepted-base d5c33f76/MERGEABLE/no-closing/all-rollup/protected verify+sql app15368/exact completed-success guards completed and were read before non-admin merge32722deae161012f41e38e57a7dd81f48ccb32ad on16October2026 at10:07:19UTC. Existing strict:false stays unchanged; no admin/force/bypass merge.

Exact READY preview dpl_FKKbUGdkYuWFmFJMR28xRUSeNZR1 and READY production dpl_FiStqReVUirxPaxNpkf1xsacGqNE each pass11general checks and four actual Search-a-list Submits: reference/independent alternative pass,prefix-only/destructive-filter controls fail,all0XP/nullprogress. Nine other cohort tasks retain Premium locks under#190. Both full helper processes complete exit0. Production matches the merge,has no alias error,and owns devshark.app before/after both probes. Helpers were frozen from exact530before later source edits. No account,progress,score/name fixture or protection/access/rate setting was written.

The branch was synchronized after accepted parent#452 and required/served checks were freshly repeated at530;old c7 pre-sync preview/run is historical only. Its old run38878905009was superseded/cancelled by concurrency after the new head;the manual-cancel precheck failed before any cancellation command ran because that old run was already completed. No old-head evidence substitutes for current530acceptance.

B108–B109 bring verified production to575/725coding and263/263native reviews. Separate five-item B110 e3317bc1 and B111 f4ae1139 commits bring current source to585,with140React tasks remaining;ten B110–B111records await their own guarded release. Their70/70current-hash outcomes,40unknown-safe base25checks and160final-build responsive probes pass with tracked exits0. B112 private preparation is excluded.

Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365 and dedicated authenticated/physical acceptance. #435moves the entire leaderboard identity/radio/photo block into Profile only after the whole audit;#444guide startup state/focus also follows the audit. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## B112 five-item audit — 16 October 2026 UTC

B112 individually reviews A cancel is not an error, Countdown to launch, Only the latest search, Stop the download and Remove listeners with one abort. All35final current-hash outcomes match:20valid boards/independent alternatives,five starters and ten semantic wrong controls. Evidence combines28unchanged classification/countdown/download/listener rows with seven fresh Latest-search rows after its final junior cleanup repair. Every wrong control passes its frozen original suite without compile errors and fails final checks;baseline25/35. Fifteen hidden/five visible additions and20unknown-safe base25XP checks pass. Desired complexity remains absent for these UI/effect exercises.

The three classification boards remain byte-for-byte unchanged. Existing alternate AbortError-message/DOMException/error-message-only cases are retained,not recounted as new. New lowercase-error/endpoint example plus seven exact-case error names,parent counts,Cancel-after-settlement and independent/fresh controller cases reject case-insensitive error matching and wrong endpoint,which genuinely passed originals. Scope remains ordinary fetch rejections rather than a parsed-body/HTTP exercise. The countdowns three correct count-dependent/single-interval strategies also remain unchanged. Original persistence,clear-at-zero,unmount and fresh-state checks stay. A separately named visible-owned controlled step clock adds99+1boundaries,all100/200/300ms states,actual pending interval counts,parent deadline preservation and staggered/fresh lifetimes.90ms/190ms interval mutants pass originals and fail now. Real browser scheduling can be later;no real-time precision promise is made.

Latest-search preserves reference promise chain,junior callbacks and senior extracted parser/search input/liveUL. It now clears old rows/errors,encodes bounded raw queries,checks response.ok,awaits JSON,shows active-query failures,and invalidates results before aborting cleanup. Empty query cancels/clears without fetching. Exact literal0..100record bodies include duplicate/empty titles.16query changes,long/unicode/punctuation encoding,header/body pending states,parent request counts,all failure/recovery types and obsolete/fresh parsing are observed. The held processing fixture intentionally separates settled transport from downstream parsing;it is not evidence that native Response.json ignores abort. Rereading caught the new juniors missing active=false in its braced cleanup and list indentation. That draft34/35run is excluded for the changed task;all seven variants freshly pass the final hash. Unencoded and three-character-cap controls pass originals and fail now. Starter/scaffold error state and guidance align.

Stop-the-download preserves three ref/async/conditional/signal styles. Both success and failure now require current controller ownership;cleanup nulls ownership before aborting,each new Download supersedes the old one,and non-abort rejection consistently shows the seniors existing Failed state instead of Stopped. Starter/scaffold align. New cases cover16cycles,actual endpoint,parent counts,terminal no-op Stop,an already-fulfilled old request versus a newer pending download,overlap cancellation and independent/removed/fresh state. The original senior guarded only errors;its old unconditional success remains a meaningful control that passes original suites and fails the new race. Fetch fulfillment is completion;no download-body/HTTP rules are invented. All existing latest-signal/Stop-after-Done/controller-reuse checks remain.

The three listener boards remain unchanged. Existing shared-signal/unmount/registration/latest-state assertions stay. A bubbled-key example plus36mixed keys/mouse events,12parent updates,actual callback invocation counts after abort and independent/fresh signal cases reject sample-key filtering and window-target-only handling,which passed originals. A task-local trusted tracer forwards function or handleEvent listeners with the original options/this. It proves actual callback removal,not merely ignored React state after unmount;manual removeEventListener identity compatibility is not claimed because this exercise requires shared-signal abort cleanup. The worker DOM observation does not replace physical-keyboard/device acceptance.

Every original/final English field,15whole final modules,all inherited fetch/clock/listener helpers and final Latest junior were individually read;the nine classification/countdown/listener code fields are explicitly compared with originals. None of these five items has an existing complete hint or QA variant. Primary React/MDN references are recorded against installed React19.2.8. All585prior coding/263native hashes remain current;all770private exported tasks have no missing QA edits. Full grading/Learn integrity,React promise/authority,API/script types,launch,registry/index,590coding/263native bindings,copy sweep,build,bundle,two zero-vulnerability production dependency audits,diff and80final-build320–1440px light/dark probes pass;both tracked responsive processes exit0. Scoped canonical covers five React lessons/ten incomplete skeleton placements. Bundle242998/243000gzip,12physical handlers,Czech unchanged. No shared FAKE_CLOCK/FAKE_FETCH,dependency,engine,schema,RLS,reward/access-policy or product UI change;B083full-client/harness evidence stays dated.

Verified production is575coding/263native via accepted#453 at32722deae161012f41e38e57a7dd81f48ccb32ad/READY dpl_FiStqReVUirxPaxNpkf1xsacGqNE. PR#454 holds ten B110–B111reviews at exact6d6b124afd7eec3972969fb4c6e9bf0cdc12b944,based on accepted main32722dea. Its READY preview dpl_DCTK6HJwShV5APvXT6EmigBfR1Gg passes11general checks and eight actual Submits across GET-one-user/Delayed-message(reference/alternative pass,two semantic controls fail each,all0XP/nullprogress),eight Premium locks and both whole processes exit0. Required38886096048/guarded production acceptance remain pending. B112 adds five locally accepted records:590/725source,135React remain,15above verified production. B113private preparation is excluded. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365 and dedicated authenticated/physical acceptance. #435moves the entire leaderboard identity/radio/photo block into Profile only after the whole audit;#444guide handoff also follows the audit. Same-session model self-review/finite worker/browser evidence only.

## PR #454 guarded production acceptance — 16 October 2026 UTC

PR #454 passed required Product quality38886096048 at frozen6d6b124afd7eec3972969fb4c6e9bf0cdc12b944 (verify34m01s,SQL40s). Fresh exact-head/open/non-draft/main+accepted-base32722dea/MERGEABLE/no-closing/all-rollup/protected verify+sql app15368/exact completed-success guards completed and were read before non-admin merge46dea43740aa1da678323a647f4d456b04df80b3 on16October2026 at10:53:39UTC. The actual merge parents are confirmed as exactly accepted32722dea and reviewed6d6b124a. Existing strict:false stays unchanged;no admin/force/bypass merge.

Exact READY preview dpl_DCTK6HJwShV5APvXT6EmigBfR1Gg and READY production dpl_33pD2jQrCYKkkPEtPoQJ665AyxFS each pass11general checks and eight actual Submits across GET one user and Delayed message:each reference/independent alternative passes,two semantic controls fail,all0XP/nullprogress. Eight other tasks retain Premium locks under#190. Both whole helper processes complete exit0. Production matches the merge,has no alias error and owns devshark.app before/after both probes. Helpers were frozen from exact6d6before later edits;private protected preview hostname and0600permissions are verified. No account,progress,score/name fixture or protection/access/rate setting was written.

Earlier prose incorrectly named the first free cohort lesson Effect on mount. Complete raw logs show GET one user;the actual requests,assertions and counts always used GET one user plus Delayed message. PR/body,affected audit prose and four issue prefixes are corrected from those logs. No check is rerun or counted again merely to correct that label.

B110–B111 bring verified production to585/725coding and263/263native reviews. B112a975fb1c plus five locally accepted B113reviews bring current source to595,with130React tasks remaining;ten B112–B113records await their own guarded release. One staged B112URI-query review is revised before publication to explicitly require well-formed Unicode,with a paired-surrogate query,fresh7/7checks and unchanged source programs;it is not counted as a new item. B11335/35final-hash outcomes and96final-build probes pass. B114preparation is excluded.

Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365 and dedicated authenticated/physical acceptance. #435moves the entire leaderboard identity/radio/photo block into Profile only after the whole audit;#444guide startup state/focus follows the audit too. Same-session model self-review/finite execution only,not independent/human,authenticated Premium,physical-device or whole-catalogue acceptance.

## B113 five-item audit — 16 October 2026 UTC

B113 individually reviews One Stop for two requests, Give up on a slow request, Abort a request, Debounced search and Notices that dismiss themselves. All35current-hash outcomes match:20valid programs,five starters and ten semantic wrong controls. Final evidence combines21unchanged Pair/Timeout/Abort rows with14fresh Debounce/Notices rows after final copy cleanup. All ten wrong controls pass frozen original suites without compile errors and fail final checks;baseline25/35. Fifteen hidden/five visible additions and20unknown-safe base25XP checks pass. No UI/effect task receives an invented Desired complexity target.

The parallel pair keeps reference Promise.all tuple,junior named promises/indexed results and senior getJson helper styles. It now aborts superseded pairs,checks HTTP status,awaits both JSON bodies,guards status by current ownership,aborts unfinished work after failure,and invalidates before unmount abort. Existing shared-signal/partial-answer/Stop/new-controller cases remain. A zero-post example plus16load/body-order/count/literal-data,parent,failure/recovery,fulfilled-old-versus-new-pending and fresh lifecycle cases reject count-clamping and stale-success controls that passed originals. Promise.all already handles all input rejection paths;the lazy JSON fixture avoids fabricating unconsumed body rejections.

All three timeout boards remain byte-identical. Existing quick-answer clearing,non-abort failure,new-controller and late-answer tests stay. A separate controlled clock checks299+1,deadline through pending JSON,completion at299without later abort,network/JSON timer clearing,16sequential loads and parent renders. The authored checked domain is sequential operations with successful HTTP replies or ordinary Error/DOMException rejections;no unsupported overlapping App contract is imposed on the already-correct reusable helper. Real browser timers may run later.250msdeadline and wrong-user endpoint controls genuinely pass originals and fail now.

Abort-a-request explicitly keeps both valid presentations:exact returned count or exact literal title list. Preserve the existing valid list QA and invalid missing-signal control;repair only the valid return edit to retain its new error branch. Promise-chain reference,async junior and custom useJson senior gain HTTP validation,active guards,consistent fixed alerts and invalidation-before-abort cleanup. Full hint/scaffold remain aligned and canonical validation accepts the complete hint. New data fixtures test empty/100records,literal/duplicate/empty titles,full-body parsing,parent counts,three failure kinds and independent/removed/fresh requests. Discarded-body and wrong-list-endpoint controls pass the original pending-abort-only suite and fail final checks. No paragraph-only,retry or loading-text requirement is added.

Debounce retains the reference effect,junior ref/event-handler and exact senior hook/typing-marker strategies;only reference/junior inputs gain Search names. Raw case,spaces,literal/Unicode/long/empty values settle at the full499+1boundary,with an optional marker that is not stripped out of actual query text. Sixteen queries,reset deadlines,parent renders and independent/removed/fresh timers are checked.475msand normalization controls pass originals and fail now. A private-draft syntax error was parsed/corrected before catalogue editing. Notices retains all three published modules byte-for-byte. Duplicate dismissal,36modeled actions/stable surviving LI nodes,pending timer counts,exact staggered deadlines,parent callbacks and independent/fresh roots supplement its existing capacity/dismissal/eviction/cleanup tests. Five-add cap and text-based dismissal controls passed originals and fail new cases. A reducer with a differently named child remains valid. No shared runtime,toast system or source-pattern grading rule is added.

Primary encodeURIComponent documentation prompted one staged B112correction before publication:the URI-query domain now explicitly requires well-formed Unicode,with a paired-surrogate shark query in the17query model. Seven fresh current-hash cases pass;all seven source programs are byte-identical to the B112final programs. Existing B112record/fragment becomes revision2with its previous staged hash retained;no additional item is counted. The current ten-item matrix is70/70using28unchanged B112rows plus seven refreshed revision2rows,and the35B113rows. Old revision1execution remains historical. Its base25checks are refreshed too. The earlier protected-QA prose incorrectly named Effect on mount;raw preview/production logs always executed GET one user and Delayed message. Affected prose and issue prefixes are corrected without rerunning or double-counting those checks.

All original/final English fields,15whole final boards,the complete Abort hint,two fully materialized existing QA variants,and original/new timer/fetch helpers were read per item. Six Timeout/Notices boards and the Debounce senior remain exact. Current primary React/MDN references are recorded against installed React19.2.8. Prior590bindings passed before the explicit staged correction;final595coding/263native bindings include it,with unique identities retained. Final canonical covers six React lessons/twelve incomplete skeleton placements,including the B112revision. Full grading/Learn integrity,React promise/authority,API/script types,launch,registry/index,copy sweep,build,bundle,two zero-vulnerability production dependency audits and diff pass. Both tracked96final-build320–1440px light/dark probe processes exit0:five new task routes plus the corrected prior query route. Bundle242998/243000gzip,12physical handlers,Czech unchanged. No dependency,engine,schema,RLS,reward/access-policy or product UI change;B083full-client/harness evidence remains dated.

Verified production is585coding/263native via accepted#454 at46dea43740aa1da678323a647f4d456b04df80b3,READY dpl_33pD2jQrCYKkkPEtPoQJ665AyxFS after required38886096048(verify34m01s,SQL40s),completed/read fresh exact-head/accepted-base/MERGEABLE/protected guards and confirmed exact merge parents. Exact preview/production each pass11general checks+eight actual Submits across GET one user/Delayed message(reference/alternative pass,two wrong fail each,all0XP/nullprogress),eight Premium locks and whole processes exit0. Canonical alias/exactmerge/READY/no-error guards pass before/after probes. Ten B112–B113records await a separate guarded release. Source595/725,130React remain;B114preparation excluded. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365 and dedicated authenticated/physical acceptance. #435moves the complete leaderboard identity/radio/photo block to Profile only after the whole audit;#444guide handoff also follows it. Same-session model self-review/finite execution only.

## PR #455 guarded production acceptance — 16 October 2026 UTC

PR #455 passed required Product quality run 38892436017 at exact head b6730cf6ca8d1c98d0dea685c45fe1a830ea8b37 (verify 35m53s; SQL 39s). Fresh exact-head/open/non-draft/main/accepted-base46dea437/MERGEABLE/no-closing/all-rollup/protected verify+sql app15368/exact completed-success checks and run guards completed and were read before non-admin merge ba874bf72952ff69cb631f563564f11d3146888e on 16 October 2026 at 19:35:37 UTC. Exact merge parents are accepted46dea437 and reviewedb6730cf6. Existing strict:false stays unchanged; no force, admin or bypass.

Exact READY preview dpl_46s2WnSHGkihmoxt9pJ1y1JbckGX and READY production dpl_UaUSDVsNAwqkn6HvYJxhQ2WSYnTf each pass eleven general checks and four actual Stop-the-download Submits: reference and independent alternative pass, obsolete-success and wrong-endpoint controls fail, all 0 XP/null progress. Nine other cohort tasks retain Premium locks under #190. Both full helper processes complete exit0. Helpers and the ten-task candidate set were frozen from exactb6730cf6 before B114 source edits. Protected preview access uses an exact-host-validated private0600 file. Production is the exact merge, has no alias error and owns devshark.app before and after probes. No account/progress/score/name fixture or protection/access/rate setting was written.

B112–B113 bring verified production to595/725coding and263/263native reviews. The revised B112 Unicode record is included once, with seven refreshed outcomes replacing the original staged cases. Combined ten-item evidence remains70/70current-hash outcomes,40safe base25checks and176responsive probes. The working tree was synchronized to accepted main without source changes before the next batch.130React tasks remain at this release checkpoint; B114 is not counted until its own five individual reviews and local gates finish.

Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365 and dedicated authenticated/physical acceptance. #435 moves the entire leaderboard identity/radio/photo block into Profile only after the whole audit; #444 guide startup/focus follows the audit too. Same-session model editorial review and finite local/guest execution, not independent human, authenticated Premium, physical-device or whole-catalogue acceptance.

## B114 five-item audit — 16 October 2026 UTC

B114 individually reviews Wait for the export,A carousel that plays itself,Modal,Focus the search box and Send the latest draft.35/35current-hash QuickJS outcomes match:20valid programs,five incomplete starters and ten semantic wrong controls,all without compile errors. Original suites matched26/35: nine incorrect controls passed;190mscarousel was already rejected by its timer-allocation cleanup check and is retained as an existing-regression control. Two draft wrong controls gain correct cleanup before final grading;fresh frozen-original rechecks still accept both. Five visible/fifteen hidden additions and20unknown-safe base25XP checks pass;no UI/effect complexity target is invented.

Export keeps all three published modules exactly unchanged. Existing overlap/progress/disabled/terminal/cleanup/restart tests stay. A visible POST assertion plus16delayed JSON bodies with199+1deadlines,twelve distinct alternating terminal jobs,parents and late-body removal reject150mspolling and GET startup controls that passed originals. The successful HTTP/JSON/URL-safe-id domain is explicit. The existing valid option to disable Export only after receiving the id stays accepted;the stronger full hint still disables from the click. Both original QA variants and the complete full hint remain unchanged and valid. A task-local body-aware wire fixture is added;shared clock/fetch helpers stay unchanged.

Carousel keeps all three published programs byte-identical,including senior reducer/hook structure.24modelled Pause/manual/autoplay cycles,combined pointer/focus holds,within-section focus moves,exact deadlines,parent renders and independent/fresh timer lifetimes supplement existing strong checks. Manual navigation may not silently undo Pause. The190mscontrol is not misreported as a newly discovered false pass. The explicitly authored resume-after-both-holds-leave policy is retained;this bounded timer exercise is not certified as the complete APG carousel pattern,which requires an explicit restart after keyboard focus entry.

Modal preserves the reference and complete full hint. Junior/senior gain document-scoped Escape effects with cleanup while retaining backdrop target/ref styles and senior focus return. Twelve ordinary document keys,Escape,twelve repeated opens,nested descendant clicks,parent preservation,listener teardown and independent roots are exercised. Every-key close and nested-bubble-close controls pass originals and fail final checks. The objective is close mechanics,not full APG focus trapping/inert-background conformance. Focus-search keeps all three modules unchanged;long/raw/Unicode values,eighteen jumps with Name preservation,parents,two roots and removed/fresh refs reject global-first selectors and40character truncation that passed originals.

Latest-draft preserves the senior unchanged and the reference/junior event-update styles,adding owned timeout Sets and unmount clearing to the latter. The starter imports useEffect and the skeleton explains pending-timeout cleanup.299+1deadlines,overlapping clicks,sixteen raw/Unicode/2000unit values,clearing a previous result,parent renders and independent/removed/fresh timers supplement original latest-value cases.250msand trimming controls include correct cleanup and still pass original suites;new checks isolate their actual deadline/text defects. Empty draft clearing matches all original published boards and is now explicit.

All original/final English fields,15whole boards,two complete hints,two materialized QA programs and original helpers were read individually;11published program fields remain byte-identical. Primary React/MDN and applicable WAI guidance were consulted against installed React19.2.8;scope limits are recorded per item. A copy sweep's existing phrase the last answer refers to the export's latest server response,not a shuffled choice;an exact item/field/text exception is recorded without changing learner copy or weakening other matches. Initial private patch attempts stopped on a suite-interpolation assertion before task writes;those partial runs are excluded. An invalid600pxresponsive argument failed before measuring routes;only corrected default-matrix runs count.

Current600coding/263native hashes bind uniquely. Selected canonical validation accepts all five lessons,their complete hints/QA programs and ten incomplete skeleton placements. API/script typechecks,grading/Learn integrity,React promise/authority,launch,registry/index,native bindings,copy sweep,build,bundle,both zero-vulnerability production dependency audits and diff pass. Eight default widths320–1440px times five routes times light/dark give80final-build responsive probes:40per theme,zero issues/unprobed and tracked process exits0. These local layout probes use API stand-ins;authenticated Premium/physical-device acceptance stays under#190. Bundle242998/243000gzip;12physicalAPIhandlers,Czech unchanged. No dependency,engine,schema,RLS,entitlement or reward-policy change. B083full-client/harness evidence remains dated.

Verified production595coding/263native is accepted#455 atba874bf72952ff69cb631f563564f11d3146888e,READYdpl_UaUSDVsNAwqkn6HvYJxhQ2WSYnTf,required38892436017(verify35m53s,SQL39s),with completed/read premerge guards,exact merge parents and before/after canonical alias guards. Exact preview/production each pass11general checks plus four actual Stop-the-download Submits(reference/alternative pass,two wrong fail,all0XP/nullprogress),nine Premium locks and full process exits0. Five B114reviews await their own required CI/exact preview/guarded production release. Source600/725,125React remain. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365 and dedicated authenticated/independent acceptance. #435Profile-only leaderboard settings and#444guide focus follow the whole audit. Same-session model review/finite execution only.

## B115 five-item audit — 16 October 2026 UTC

B115 individually reviews Cancel the reminder,Give the focus back,Select all or some,Stopwatch and A menu button.35/35current-hash worker outcomes match:20valid programs,five incomplete starters and ten semantic wrong controls;all have no compile errors. All ten wrong controls pass frozen original suites without compilation errors,so the baseline matches25/35expected final outcomes. Five visible/fifteen hidden additions and20unknown-safe base25checks pass. No UI/effect complexity target is invented.

Reminder retains the senior exactly and reference/junior handler styles,adding only effect cleanup to the latter and supplying useEffect/cleanup guidance. Existing cancel/repeat/rearm tests remain.299+1boundaries,51modelled reset/cancel/time actions,completed-message preservation,parents and independent/removed/fresh timer ownership reject250msand shared-timer controls. Both controls already include correct cleanup,isolating their named defects. Focus-back retains all three modules unchanged;literal/space/empty/Unicode/2000unit names,24save/cancel/Escape cycles,real cancelable form submission,parents,two editors and fresh state reject trimming and global-first-button focus controls. Native single-line constraints are respected.

Select-all retains all three modules byte-identically,including array/explicit-loop/Set approaches. Existing mixed/full/empty/delete/count tests remain. A visible individual uncheck after bulk selection plus all16selectionmasks and all15nonempty deletion subsets check each checkbox/master DOM property/count/disabled state,remaining rows and surviving LI identity. Parents and independent/fresh inboxes are covered. Clear-all-on-uncheck and greater-than-id filtering controls passed originals and fail now. Exhaustiveness applies only to the fixed four-message model,not arbitrary programs.

Stopwatch keeps all three programs and the complete full hint unchanged,including the valid state-held junior interval id and saved-callback senior hook. Original999+1/duplicate-Start/freeze/reset checks stay. Fresh999+1resume,31/32second runs,twelve stop/resume/reset cycles,parents,resource counts and independent/removed/fresh intervals reject a three-second cap and shared interval id that passed originals. Both original ignore/restart-one-interval Start policies and flexible seconds labels remain accepted. The reducer/effect alternative displays seconds as a word. No ref-only grading restriction is imposed.

Menu retains its three strategies while correcting the scoped APG focus-leave behavior:menu onBlur closes only when relatedTarget exits,without preventing Tab or returning focus. Junior gains the Actions menu name;reference optional controls useId;senior latest callback updates in an effect instead of render. Existing strong wrapping/Home/End/Enter/Escape/outside/listener tests and the ArrowUp-always-last QA control remain. A real Tab key event/defaultPrevented check plus outside focus,48keyboard moves,eighteen exact choices through nested empty spans,parent focus,optional instance-owned ids and fresh state reject prevented-Tab and shallow outside-containment controls that passed originals. Empty nested spans preserve the authored labels. Native closed-button Enter/Space activation and optional typeahead/ArrowUp opening are not claimed as newly exercised. Shift+Tab shares the native Tab/default and blur code path;this is finite jsdom/worker evidence,not physical-keyboard certification.

All original/final English fields,15whole boards,the complete Stopwatch hint,the fully materialized Menu QA program and original helpers were read individually;ten published program fields remain exact. Primary React/MDN/WAI guidance is recorded against installed React19.2.8. Current605coding/263native bindings are unique and valid. Selected canonical validation accepts all five lessons,the full hint/QA program and ten incomplete skeleton placements. Supported-program suite case time peaks at2408msin the private matrix,under the existing6000mscanonical budget. API/script types,grading/Learn integrity,React promise/authority,launch,registry/index,native bindings,copy sweep,build,bundle,both zero-vulnerability production dependency audits and diff pass.80final-build layout probes at eight default320–1440pxwidths,40light/40dark,complete with zero issues/unprobed and tracked exits0. Layout uses server-derived API stand-ins;authenticated Premium/physical-device acceptance remains#190. Bundle242998/243000gzip,12physical handlers,Czech unchanged. No dependency,engine,schema,RLS,entitlement or reward-policy change;B083full-client/harness evidence remains dated.

Verified production remains595coding/263native via accepted#455 atba874bf72952ff69cb631f563564f11d3146888e. PR#456 holds B114 at exact9d07e2178ebb5b8c5c2be900604c07c1a1efed7e,based on acceptedba874bf7. Its exact READY previewdpl_GUoFo5bG2xTBNuTDBd677R6zGnWF passes11general checks and four actual Focus-the-search Submits:reference/independent alternative pass,global-selector/truncation controls fail,all0XP/nullprogress. Four other tasks retain Premium locks and both whole helper processes exit0. Helpers were frozen before B115edits. Required38958002386and guarded production acceptance remain pending at this checkpoint. B114–B115 are ten records above verified production;source605/725,120React remain. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365 and dedicated authenticated/independent acceptance. #435Profile-only leaderboard settings and#444guide focus follow the whole audit. Same-session model review/finite execution only.

## B116 five-item audit — 16 October 2026 UTC

B116 individually reviews Live paragraph,Controlled form,Characters left,Labelled field and Rename in place.35/35current-hash worker outcomes match:20valid programs,five incomplete starters and ten semantic wrong controls,with no current compile errors. The original suites match26/35: nine wrong controls pass originals;missing preventDefault was already rejected by the trusted original runner and remains an existing-regression control. Five visible/fifteen hidden additions and20unknown-safe base25checks pass. No UI/effect complexity target is invented.

Live paragraph retains the senior exactly and the reference/junior handler styles,adding programmatic labels to the latter and the complete skeleton filling. Exact raw single-line empty/space/Unicode/2000unit values,24updates,long-to-short-to-empty,parent and independent/removed/fresh instances reject prefix and paragraph-only trimming. The trusted original controlled-props check remains. Controlled form retains the senior and other state strategies,adding Name/Email labels. Twenty raw/long/empty-name submissions with conventional email values,subsequent unsent edits,real cancelable events,controlled props,parents and independent/fresh forms reject live-draft results. The reducer alternative uses a definition list;no paragraph or separator format is forced.

Characters left defines80UTF16units via text.length,paired emoji,newlines and raw whitespace. All three boards now guard direct empty/over-limit submission after preventDefault using their existing derived state. Direct invalid submits,24cycles over79/80/81units and40/41emoji,newlines,stable appended LI rows,parents and independent/fresh posts reject a disabled-button-only guard and code-point counts. The first private added suite had an unescaped newline literal,causing seven suite compilation errors. It was repaired without changing answer programs or semantics;seven fresh current-hash outcomes replace those obsolete rows,joining28unchanged valid rows. All ten added suite blocks pass actual JavaScript syntax validation after transformation. Old malformed-suite outcomes are excluded.

Labelled field keeps senior exact,adding stable useId associations and noValidate to reference/junior and corresponding starter/skeleton/hint guidance. Validation deliberately checks current native value.trim blankness,not email syntax;native sanitization is respected. Eighteen blank/Unicode-space/ordinary/malformed/long cycles,parent id stability,actual label.control and own-error descriptions in two roots,correction and fresh state reject static ids and untrimmed Unicode blanks. A span-error alternative passes;no exact id spelling/error tag requirement. Rename keeps reference/senior exact,adding only a useId prefix to junior labels. Current exact case-sensitive trimmed names,old-name reuse,new-name reservation,24raw/Unicode/long save-or-Escape cycles,stable LI rows,parents and independent labels/focus/fresh files reject case-folded and stale-original duplicate checks. Existing any-key-close QA still materializes and fails. This is plain browser string/list editing,not real filesystem validation.

All original/final English fields,15whole boards,the Live complete skeleton filling and Rename materialized QA program were read individually;five published program fields remain exact. React/MDN primary guidance is recorded against installed React19.2.8. Current610coding/263native bindings are unique and valid. Selected canonical validation accepts all five lessons,the complete filling/existing QA and ten incomplete skeleton placements. API/script types,grading/Learn integrity,React promise/authority,launch,registry/index,native bindings,copy sweep,build,bundle,both zero-vulnerability production dependency audits and diff pass. The first local build failed ENOSPC;128owned historical frozen audit bundles were losslessly gzipped with verified SHA256 before deleting their uncompressed copies,reclaiming657008886bytes and preserving evidence. The rebuilt production artifacts and bundle check pass.80final-build layout probes at eight default320–1440pxwidths,40light/40dark,complete with zero issues/unprobed and tracked exits0. Layout uses server-derived API stand-ins;authenticated Premium/physical-device acceptance remains#190. Bundle242998/243000gzip,12physical handlers,Czech unchanged. No dependency,engine,schema,RLS,entitlement or reward-policy change;B083full-client/harness evidence remains dated.

Verified production remains595coding/263native via accepted#455 atba874bf72952ff69cb631f563564f11d3146888e. PR#456 now has exactd0bfc3aeb0f855465408180b880ab2a56de5ee30,based on acceptedba874bf7. Its original9d07head failed required38958002386because the browser test hardcoded3/3after Focus-the-search gained a fourth visible case;coding-workbench had22passes/onefailure and later suites did not run. The test-only correction derives the complete expected count from the existing suiteCaseCount helper,retaining three Runs,stale-code,focus and build-error assertions. Focused real Chromium test passes1test in8.2s atd0. The five B114 task hashes/programs are unchanged. Fresh exact READY previewdpl_AVXVKer1ThHhfefBHFiREPawqQCc passes11general checks and four actual Focus-the-search Submits:reference/independent alternative pass,global-selector/truncation controls fail,all0XP/nullprogress. Four other tasks retain Premium locks and both whole helper processes exit0. Frozen helpers are exactd0. Required38963711485and guarded production acceptance remain pending at this checkpoint;old9d07preview is historical only. B114–B116 are fifteen records above verified production;source610/725,115React remain. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365 and dedicated authenticated/independent acceptance. #435Profile-only leaderboard settings and#444guide focus follow the whole audit. Same-session model review/finite execution only.

## B117 five-item audit — 16 October 2026 UTC

B117 individually reviews POST a new post,A sign-up form that says what is wrong,Select fetched user,Read the theme and Nearest provider wins.35/35current-hash worker outcomes match:20valid programs,five incomplete starters and ten semantic wrong controls,with no current compile errors. All ten wrong controls pass frozen original suites;baseline25/35matches expected final outcomes. Five visible/fifteen hidden additions and20unknown-safe base25checks pass. No UI/effect complexity target is invented.

POST reference/junior gain Title labels and senior sends the same raw title as the other boards. Sixteen nonblank raw/quoted/Unicode/2000unit requests check exact endpoint,POST,case-insensitive JSON header and parsed string body. Separate deferred response/body resolution,distinct server titles/varying ids,pending edits,parents,two forms and fresh state reject omitted headers and invented{id:101,title}results. Existing blank/failure policies remain outside the explicitly successful sequential scope;no arbitrary ordering policy is imposed. The independent alternative uses a definition list,while original JSON/paragraph presentation remains accepted. Signup keeps three distinct derived-validation strategies,adding stable instance-local field/error ids with useId and matching starter/skeleton/hint guidance. Seven/eight UTF16units,ASCII versus Arabic digits,exact untrimmed repeats,ten invalid combinations/three valid long-emoji-space cases,twelve simple email-pattern cases,twenty correction/dependency cycles,input identity,all first-invalid positions,actual label.control/error paragraphs and two/fresh forms reject seven-unit passwords and trimmed-repeat equality. Native email sanitization is respected;this is a local teaching form,not the app auth handler.

Select-fetched-user retains junior/senior exact and adds the missing detail name to the reference. Configurable responses cover empty,single2000unitname and24users with opaque ids/repeated display names,48selections,one-record name/email output outside buttons,button order/identity,parents and independently resolved/fresh instances. Always-second and all-emails-after-selection controls pass originals and fail new checks. Theme and nearest-size retain all six whole programs and the existing Toolbar. Explicit empty string differs from an absent provider;25theme and24size changes reach the same child element,with text/class agreement,nearest nested/sibling scopes,raw/long labels,provider removal and fresh defaults. Constant dark class,falsey fallbacks and first-value capture pass originals and fail final checks. The alternatives use valid module-level custom hooks. The theme alternative was refined before acceptance and seven baseline rows refreshed;all ten wrong controls retain original behavior. Signup email-boundary/copy refinements replace seven staged final rows,joining28unchanged outcomes;one review identity/revision per task is counted.

All original/final English fields,15whole boards,public partial skeletons,API notes and original hidden suites were read individually. No complete hint filling or pre-existing QA variant exists for these five. Eight published program fields remain exact. React/MDN/JSONPlaceholder primary guidance is recorded against installed React19.2.8;current React docs identify19.3. Current615coding/263native bindings are unique and valid. Selected canonical validation accepts the five lessons and rejects eight incomplete skeleton placements. Supported-program case time peaks at863msin the private matrix,below the existing6000mscanonical budget. API/script types,grading/Learn integrity,React promise/authority,launch,registry/index,native bindings,copy sweep,build,bundle,both zero-vulnerability production dependency audits and diff pass.80final-build layout probes at eight default320–1440pxwidths,40light/40dark,complete with zero issues/unprobed and tracked exits0. Layout uses server-derived API stand-ins;authenticated Premium/physical-device acceptance remains#190. Bundle242998/243000gzip,12physical handlers,Czech unchanged. No dependency,engine,schema,RLS,entitlement or reward-policy change;B083full-client/harness evidence remains dated.

Verified production remains595coding/263native via accepted#455 atba874bf72952ff69cb631f563564f11d3146888e. PR#456 holds B114 at exactd0bfc3aeb0f855465408180b880ab2a56de5ee30,based on acceptedba874bf7. Its current exact READY previewdpl_AVXVKer1ThHhfefBHFiREPawqQCc passes11general and four actual Focus-the-search Submits:reference/independent alternative pass,global-selector/truncation controls fail,all0XP/nullprogress. Four other tasks retain Premium locks and both whole helper processes exit0;helpers are frozen fromd0. Original38958002386failed the hardcoded3/3browser assertion after the suite correctly grew to4cases. The focused corrected browser test passes1test in8.2s;the existing suiteCaseCount helper now requires every declared case. Only that test file changed between9d07andd0;all five B114task hashes/programs stay exact. The correction is integrated into this content branch atb2183c69. Required38963711485and guarded production acceptance remain pending at this checkpoint;old9d07preview is historical only. B114–B117 are twenty records above verified production;source615/725,110React remain. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365 and dedicated authenticated/independent acceptance. #435Profile-only leaderboard settings and#444guide focus follow the whole audit. Same-session model review/finite execution only.

## PR #456 guarded production acceptance — 16 October 2026 UTC

PR #456 passed corrected required Product quality run38963711485at exact head d0bfc3aeb0f855465408180b880ab2a56de5ee30 (verify36m15s;SQL40s). Fresh exact-head/open/non-draft/main/accepted-baseba874bf7/MERGEABLE/no-closing/all-rollup/protected verify+sql app15368/exact completed-success checks/run guards completed and were read before non-admin merge788b7be8823af1228026cbe3cb536f929df7aaea on16October2026at21:15:36UTC. Exact merge parents are acceptedba874bf7and reviewedd0bfc3ae;strict:false stays unchanged,no force/admin/bypass.

Original run38958002386at9d07e217failed in coding-workbench:22passed/onefailed because a hardcoded3/3assertion received the correctly expanded4/4. Subsequent browser suites did not run in that failed attempt. The test-only correction derives the complete positive declared count using existing suiteCaseCount,retaining three Runs,stale-code,focus and intentional build-error assertions. Focused real Chromium passes1test in8.2s;only that test file differs9d07..d0,and all five B114task hashes/programs remain exact. Original9d07preview/failed CI are historical and excluded from corrected-head acceptance.

Exact READY corrected preview dpl_AVXVKer1ThHhfefBHFiREPawqQCc and READY production dpl_2A2xMEWYyHWYHtmp7ikYj7ZtrwfC each pass11general checks and four actual Focus-the-search Submits:reference/independent alternative pass,global-selector/truncation controls fail,all0XP/nullprogress. Four other B114tasks retain Premium locks under#190. Both whole helpers complete exit0. Helpers were frozen from exactd0before follow-up edits. Protected access uses exact-host-validated private0600files. Production is the exact merge,has no alias error and owns devshark.app before and after probes. No account/progress/score/name fixture or protection/access/rate setting was written.

B114 brings verified production to600/725coding and263/263native reviews. Its five individual records have35/35current-hash matrix outcomes,20safe base25checks,canonical/local gates and80final-build responsive probes;eleven published program fields remain exact. Current committed follow-up source B115–B117 has615reviews,110React remain,and fifteen already locally accepted records await their own guarded PR/release. Those three five-item commits have105/105current-hash outcomes,60safe base25checks and240responsive probes;corrected parent test expectations are integrated. This release proof changes no content hashes. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365and dedicated authenticated/physical acceptance. #435Profile-only leaderboard settings and#444guide focus follow the whole audit. Same-session model review/finite local and guest execution,not independent human,authenticated Premium,physical-device or whole-catalogue acceptance.

## B118 five-item audit — 16 October 2026 UTC

B118 individually reviews Share a count through context,Dispatch through context,A radio group through context,Theme context and A useToggle hook.35/35current-hash worker outcomes match:20valid programs,five incomplete starters and ten semantic wrong controls,with no compile errors. All ten current wrong controls pass frozen original suites;baseline25/35matches expected final outcomes. Five visible/fifteen hidden additions and20unknown-safe base25checks pass. No UI/effect complexity target is invented.

Basket retains all three complete modules and their functional-update guidance. A real-DOM-event outer-act queue preflight accepts the reference/reducer alternative and rejects setCount(count+1). One visible pair plus25bursts of1–7updates,twenty provider count/callback changes with the same child,nested scope,parents and independent/fresh baskets reject snapshot additions and retained first callbacks. Ordinary physical clicks remain separate React events;this is finite queued-update evidence,not a double-click timing claim. Dispatch retains all three complete modules. Exact raw/empty/literal/Unicode/2000unit actions,twenty current AddTaskcallbacks,eighteen frozen current TaskItempayloads,obsolete-prop traps,24Appadds/interleaved toggles,stable prior rows,parents and two/fresh reducers reject trimming and captured first dispatch. No deletion is invented;the existing length+1append ids remain unique for this lesson.

Radio retains all three complete modules. Numeric0and string0compare strictly,and callbacks return the original value rather than its DOM string/event. Twenty name/chosen/callback/legend changes to the same children,strict checked arrays,actual label.control,nearest/sibling groups,48Appchoices,parents and fresh Medium state reject loose equality and a retained first callback. Separate logical groups deliberately have different names,matching native browser semantics. Theme retains all three programs and its complete hint filling,including the juniors valid ordinary per-click setter. Six/48ordinary clicks,parent button identity,twenty local clicks alongside another provider,and a fresh mount after unmounting dark reject a two-click cap and shared-module state. A synthetic stale-batched-theme control was replaced before source edits with the relevant shared-provider control;seven original theme rows were refreshed without changing the accepted35case total or counting another review identity. useToggle retains reference/senior and changes only the juniors explicit conditional into a pure functional updater. Two calls in one handler,24queued bursts using the initial retained operation,opposing initial-prop rerenders,24three-call two-hook sequences,48Appoperations,parents and separate/fresh mounts reject snapshot flips and initial-prop reset effects. Returned toggle identity need not be stable.

All original/final English fields,15whole programs,partial skeletons,original hidden cases and the Theme complete filling were read individually. Fourteen published programs and the complete filling remain exact. React/MDN primary guidance is recorded against installed React19.2.8. No React-props/source-spelling restriction is added;new checks use actual DOM/native event behavior and public hook return values. Current620coding/263native hashes bind uniquely. Selected canonical validation accepts the five lessons and complete Theme filling,and rejects eight incomplete skeleton placements. Supported-program case time peaks at1011msin the private matrix,below the existing6000mscanonical budget. API/script types,grading/Learn integrity,React promise/authority,launch,registry/index,native bindings,copy sweep,build,bundle,both zero-vulnerability production dependency audits and diff pass.80final-build layout probes at eight default320–1440pxwidths,40light/40dark,complete with zero issues/unprobed and tracked exits0. Layout uses server-derived API stand-ins;authenticated Premium/physical-device acceptance remains#190. Bundle242998/243000gzip,12physical handlers,Czech unchanged. No dependency,engine,schema,RLS,entitlement or reward-policy change;B083full-client/harness evidence remains dated.

Verified production is600coding/263native via accepted#456at788b7be8823af1228026cbe3cb536f929df7aaea. Corrected required38963711485passed (verify36m15s;SQL40s);fresh protected guards completed/read before merge. Exact corrected previewdpl_AVXVKer1ThHhfefBHFiREPawqQCc and productiondpl_2A2xMEWYyHWYHtmp7ikYj7ZtrwfCeach pass11general plus four actual Focus-the-search Submits,all0XP/nullprogress;four other tasks retain Premium locks,whole helpers0,exact merge/aliasbefore-after verified. Failed original9d07/run38958002386is historical only. PR#457 freezes B115–B117at89f5038bbb04d93ca3280d98d975183faa89fe56,based on accepted788b7be8:15locally accepted reviews,105/105current-hash outcomes,60safe base25checks and240responsive probes. Helpers were frozen from that exact clean head before B118edits. Exact READY previewdpl_EQj5uCnpGZNVaE3FftqsUMkVQSb7matches89f5038b/correctproject/noaliaserror and passes11general checks. All15cohort tasks preserve402Premiumlocks;zero actual cohort Submits were made. Both whole helpers exit0;dedicated authenticated acceptance remains#190. Required38968786126,fresh protected merge guards and exact-production acceptance remain pending,apart from local evidence. B115–B118are20records above verified production;source620/725,105React remain. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365and dedicated authenticated/independent acceptance. #435Profile-only leaderboard settings and#444guide focus follow the whole audit. Same-session model review/finite execution only.

## B119 five-item audit — 16 October 2026 UTC

B119 individually reviews Totals from a hook,A useWindowWidth hook,A useInterval hook,A useOutsideClick hook and A useTheme hook with a guard.35/35current-hash worker outcomes match:20valid programs,five incomplete starters and ten semantic wrong controls,without compile errors. All ten wrong controls pass frozen original suites;baseline25/35matches expected final outcomes. Five visible/fifteen hidden additions and20unknown-safe base25checks pass. All15published program fields remain byte-identical;only the intended five catalogue hashes change. No automatic React complexity target or reward policy is invented.

Totals makes immutable array/record snapshots explicit so the existing useMemo senior stays valid. Fractional/zero prices and quantities,twenty first-render same-length replacements,frozen empty/single/thousand-item arrays,input-order Number arithmetic without rounding,forty ordinary App additions,parents and two/fresh roots reject rounding and length-only memoization. Window width explicitly accepts the existing effect and useSyncExternalStore strategies.24widths including0/1/127/319/10000,numeric initial values,stable registrations,actual capture-aware cleanup,surviving consumers and fresh mounts reject a320minimum clamp and removing the right function with the wrong capture phase. Native tracking deduplicates function/capture pairs and respects aborted signals. Logical consumers may share one native listener;tests allow that ownership strategy and do not demand an older consumer remain stale when a new one mounts without a resize event. SSR is outside this client-only exercise.

Interval retains normal/layout callback effects. A37msvisible boundary,24modelled positive/same/null delay changes,32frequent callback updates preserving deadlines,two independently delayed hooks and twelve exact App99+1/Pause/Resume cycles reject forced100msand boolean-only delay dependencies. The trusted scoped clock is reused from earlier validated audits with active-resource/current-time observations;each new case unmounts before restoring timers. This is deterministic scheduling evidence,not physical-clock precision. Outside press covers a visible callback replacement,20current callback/ref-target updates,null/root/span/deep containment,12ref-object replacements,capture-aware final cleanup,surviving logical subscriptions,12ordinary Appcycles,aria-expanded and fresh closed state. Retained first callbacks and mismatched capture passed originals and fail now. DOM-node targets are scoped explicitly;shared native listeners remain valid. Theme guard checks actual same-render provided-object identity,24switches,current callbacks,18nested-provider switches,outer/separate isolation,parents,fresh dark and actual public-hook/Badge renders under a class Error boundary. Clones and one-way switches pass originals and fail new checks. The seniors truthy guard remains valid for its private object-or-null context. Expected caught Error-boundary diagnostics are retained in canonical logs;they do not indicate failed cases.

All original/final English fields,15whole programs,partial skeletons,original hidden suites and the existing listener spies were read individually. These five have no complete filling or existing QA variant. React/MDN guidance is recorded against installed React19.2.8(current docs19.3). Current625coding/263native hashes bind uniquely. Selected canonical validation accepts five lessons and rejects nine incomplete skeleton placements. Supported-program case time peaks at734msin the private matrix,below the existing6000mscanonical budget. API/script types,grading/Learn integrity,React promise/authority,launch,registry/index,native bindings,copy sweep,build,bundle,both zero-vulnerability production dependency audits and diff pass.80final-build layout probes at eight default320–1440pxwidths,40light/40dark,complete with zero issues/unprobed and tracked exits0. Layout uses server-derived API stand-ins;authenticated Premium/physical acceptance remains#190. Bundle242998/243000gzip,12physical handlers,Czech unchanged. No dependency,engine,schema,RLS,entitlement or reward-policy change;B083full-client/harness evidence remains dated.

Verified production is600coding/263native via accepted#456at788b7be8823af1228026cbe3cb536f929df7aaea,after corrected38963711485(verify36m15s;SQL40s),fresh protected guards and exact preview/production11general+4actualFocuschecks with four Premium locks,whole helpers0and canonical aliasbefore/after. PR#457 freezes fifteen B115–B117records at89f5038bbb04d93ca3280d98d975183faa89fe56,based on accepted788b7be8. Exact READY previewdpl_EQj5uCnpGZNVaE3FftqsUMkVQSb7matches the head/project/noaliaserror and passes11general probes. All15cohort tasks retain402Premiumlocks;zero actual cohort Submits were made,both whole helpers exit0and dedicated authenticated acceptance remains#190. Exact-head helpers were frozen before follow-up edits. Required38968786126,fresh protected merge guards and exact-production acceptance remain pending. B115–B119are25records above verified production;source625/725,100React remain. B118–B119are10accepted local follow-up records awaiting their own PRafter the frozen parent. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365and dedicated authenticated/independent acceptance. #435Profile-only leaderboard settings and#444guide focus follow the whole audit. Same-session model review/finite execution only.

## PR#457staged Menu revision2 — 16October2026UTC

PR#457initial required38968786126at89f5038bbb04d93ca3280d98d975183faa89fe56failed one of206built Chromium harness assertions:the Menu Tab/focus-leave case. SQLpassed;later checks are not claimed. Exact-head local build/full harness reproduces the same failure. Native one-task diagnostics observe hasFocus:false,activeElement changing Rename→After menu,and no focusout,leaving the correct menu open. React Testing Librarys explicit blur mapping emits the missing focusout with relatedTarget. The case now simulates that complete transition before focusing the outside button;all key default-prevention,menu-closed and actual outside-focus assertions remain. No learner program,API/XP/access policy or browser check is weakened.

Menu is rebound once to staged review revision2:seven fresh server outcomes(four valid,one starter,two original semantic wrong controls)all match,all seven source programs are byte-identical,and only the Menu task hash changes. All15unique B115–B117identities remain;current combined105/105hash-bound outcomes replace seven historical Menu rows rather than count an extra item. An additional control removes only the focus-leave handler and still fails the retained Tab requirement in both server and actual browser;the private native expected-negative probe passes24assertions. Both corrected full built browser harness runs pass206assertions,including the final registry-bound build. API/script types,selected Menu canonical/full existing QA/two incomplete skeleton placements,20B115unknown-safe25XPchecks,registry/index,615coding/263native hashes,launch,bundle,both zero-vulnerability production dependency audits,diff and16final-build Menu layout probes(eight light/eight dark)pass with tracked exits0. Expected-negative/initial failed diagnostics remain historical,not release acceptance. Bundle242998/243000gzip,12handlers,Czech unchanged. No new reviewed identity or dependency/engine/schema/RLS/entitlement/reward-policy change.

The revised PR needs its own fresh exact-head required CI and preview;89fpreview/failed CI remain historical. The prior preview passed11general checks while all15cohort tasks retained402Premiumlocks and zero cohort Submits were made. Dedicated authenticated acceptance remains#190. Verified production stays600coding/263native at#456merge788b7be8823af1228026cbe3cb536f929df7aaea. Separate content branch43fbe6e1preserves625locally accepted coding reviews;100React remain. Its B118–B119ten records will integrate this correction without counting another question. #435/#444follow the whole audit;owner holds/draft#365/effective-bank reconciliation remain. Same-session model/native finite execution,not independent human,physical keyboard or authenticated whole-catalogue acceptance.

## B120 five-item audit — 16 October 2026 UTC

B120 individually reviews A basket every page can reach, Keyboard shortcuts with a hook, Reusable useFetch hook, useDebounce hook and useLocalStorage hook. Five records bring current source to 630/725 coding reviews; 95 React tasks remain. Verified production remains 600 coding/263 native via #456. This batch is locally accepted, not deployed. The accepted Menu revision2 is preserved without counting it again.

35/35 final-hash worker outcomes match: 20 valid programs, five incomplete starters and ten meaningful wrong controls, with no compile errors. All ten wrong controls falsely passed the frozen original suites (baseline 25/35 expectations). Five visible/fifteen hidden cases are added, alongside 20 unknown-safe base25 XP checks. React has no authored automatic complexity target; no reward policy changes. An additional actual Chromium matrix executes all public and hidden cases for the same 20 valid/ten wrong programs: 30/30 expected verdicts, 53 harness/protocol assertions, tracked exit0. Four published whole program fields stay byte-identical: all three basket solutions and the shortcut senior. Only these five task hashes change.

Basket preserves the pure reducer variants and adds strict string/integer ids, immutable independent-model snapshots across 96 transitions, prototype-shaped unknown actions, repeated UI edits, batched public actions and nearest/separate/fresh providers. The first private model test accidentally froze objects returned through the sandbox proxy and hit an ownKeys invariant; it is superseded by trusted frozen model snapshots with all immutability/value assertions retained. Shortcut fixes reference/junior render-time ref publication and guidance, while retaining the layout-effect senior. A separate Suspense probe demonstrates the original defect. Tests cover committed callback ownership, exact case, original cancellable events, capture/signal cleanup, typing fields, two consumers and36 ordinary note presses; no artificial batched-key policy is imposed.

useFetch becomes a named reusable hook. Combined-state, separate-state and reducer solutions retain distinct styles and invalidate each effect before optional abort, preventing stale transport/body success or failure from finishing another URL's request. Controlled headers and JSON promises deliberately ignore abort to verify ownership without misrepresenting native fetch cancellation. Tests cover A→B→A, current HTTP/JSON/network/active-AbortError failures, recovery, arbitrary JSON identity, null/false, independent calls and remounts. Debounce gains a named export, an accessible Filter fruit label, precise300ms/positive-delay scheduling and literal lowercase substring matching; senior trimming is removed. Virtual-time boundaries, same-value delay changes,24 replacements, unchanged parent deadlines, opaque strings, independent timers and cleanup retain all three valid timer strategies and the existing cancellation regression/QA variant. LocalStorage gains a named export, lazy guarded reads, ordinary functional setters and guarded effect writes. Tests cover queued functions, render-time write detection, valid falsy data, corrupt/blocked/full storage, JSON objects/arrays, fixed independent keys, unrelated entries and remounts. Dynamic-key and cross-tab policies remain outside the stated contract. Complete hint fillings are aligned for debounce and storage.

Initial private execution also caught a missing within import and, in actual Chromium, two newly drafted comment-only catch bodies whose braces the board comment stripper removed. Correct the imports and use empty catch blocks, then replace all affected rows with fresh current-hash results; historical failures are not acceptance evidence. The existing server transpiler's recovery had masked the malformed shipped strings, so native validation was necessary. General scanner/strict-syntax follow-up is tracked in #458. A separate read-only strict Sucrase parse of all501 currently served React solution/board strings reports zero additional syntax failures; this is syntax-only evidence, not a behavioral or whole-catalogue audit.

API/script types, selected canonical validation (including existing QA, two complete hint fillings and eight incomplete skeleton placements), grading/Learn integrity, React promise/authority, registry/index, all630coding/263native current hashes, copy sweep, launch, build, bundle, both zero-vulnerability production dependency audits and diff pass. Supported-program case time peaks at547ms in the private matrix.80 final-build layout probes at eight default320–1440px widths,40light/40dark, have zero issues/unprobed and tracked exits0, using server-derived API stand-ins. Bundle242998/243000gzip;12physical API handlers; archived Czech unchanged. All original/final English material and whole programs were individually read and then reread in the same session against installed React19.2.8 and current primary React/MDN documentation. This remains finite same-session model review, without independent-human, authenticated Premium or physical-device acceptance. The earlier625-source full browser harness passes206assertions and remains dated evidence; this batch's fresh native matrix is separately stated.

PR#457 holds B115–B117 at corrected head eb8efc3154caf6066e30cd94cda1a3fbd1a027a4 against accepted main788b7be8823af1228026cbe3cb536f929df7aaea. Fresh exact READY preview dpl_3Sac1CuZCH9UXnZUFW5uB9XA5wt9 matches its head/project and has no alias error. General11checks pass; all15cohort tasks remain Premium locked, with zero actual cohort Submits and both whole helpers exit0. Required run38974032201 is still in progress; SQL is green. The failed original38968786126 and its old preview are historical only. Fresh guarded merge and exact production acceptance remain pending. This branch has15additional B118–B120 local records beyond the frozen parent;30total staged reviews above production600. Preserve #176/#391, effective-bank/longest-answer reconciliation, #190 dedicated authenticated/physical checks, draft#365 production/export/publication hold and all owner decisions. #435 Profile-only leaderboard settings and #444 guide focus follow the whole content audit.

## B121 five-item audit — 16 October 2026 UTC

B121 individually reviews Draw a card, Insert at a position, Take a seat, Name the remove buttons and Split a line in place. Current source reaches635/725coding reviews;90React tasks remain. Verified production stays600coding/263native via#456. These five records are locally accepted,not released. All15published whole solution/board programs remain byte-identical,as do starters,skeletons,hints and approaches. Only the five intended task hashes change through clearer English contracts and five visible/fifteen hidden checks.

35/35final-hash worker outcomes match:20valid programs,five incomplete starters and ten semantic wrong controls,without compile errors. A separate actual-Chromium matrix runs every visible/hidden case for the20valid/ten wrong programs:30/30expected verdicts and53harness/protocol assertions,tracked exit0.20unknown-safe base25XPchecks pass;no automatic React complexity target or reward policy is introduced. Supported case time peaks at558ms. The final frozen original baseline matches26/35expectations:nine selected wrong variants pass. Eight demonstrate original contract gaps;the implicit-submit Seat variant passes the old isolated-App suite but violates a newly explicit ancestor-form requirement. The mutation Seat variant was already rejected and remains a regression. An initial baseline used an insertion-instead-of-replacement Seat control;replace that task's seven rows with the separately frozen original refined-control results,retaining the historical first matrix and counting only one reviewed task.

Draw uses a24-removal positional model,frozen input,duplicate names,empty/single/long/quoted/markup/Unicode names and independent/fresh snapshots. It rejects an index4cap and truncated draw messages. Insert uses literal names,a24-step growing-queue model spanning negative/zero/first/middle/far-end/empty positions,direct cancellable form submission,controlled defaults and two/fresh Apps. It rejects an index3cap and silent trimming. Seat retains the authored four-slot domain and all correct solutions. Both choices survive12parent renders and disabled activation attempts;separate/fresh rows and actual native button clicks inside a form retain one selection without ancestor submission. This newly explicit composition policy is distinguished from demonstrated defects in the old brief. Remove buttons preserve literal title spans,the exact Remove+title aria-label string and the visible ×. A24-step frozen positional model,large/empty/single/duplicate/long/literal playlists and parent/separate/fresh snapshots reject five-item caps and trimmed labels. Raw aria-label assertions do not confuse accessibility whitespace normalization with text mutation. Split preserves exact case-sensitive delimiters,literal spaces and empty segments,including24input lines and more than three pieces. Frozen lists,current insertion positions,parent/separate/fresh snapshots,uppercase AND and non-delimiter text reject part caps and trimming. The valid junior sequence of copied-array splice insertions remains accepted. Exact source spelling is not imposed:the lessons demonstrate copied splice while accepting equivalent immutable outcomes.

API/script types,selected canonical validation (including ten incomplete skeleton placements;no complete fillings or existing QA variants in this cohort),grading/Learn integrity,React promise/authority,registry/index,all635coding/263native hashes,copy sweep,launch,build,bundle,both zero-vulnerability production dependency audits and diff pass.80final-build layout probes at eight default320–1440px widths,40light/40dark,complete with zero issues/unprobed and tracked exits0,using server-derived API stand-ins. Bundle242998/243000gzip;12physical API handlers;archived Czech unchanged. Original and final English material was individually read and separately reread in the same session against installed React19.2.8 and current primary React/MDN references. Finite execution and same-session model review are not independent-human,authenticated Premium,physical-device or whole-catalogue acceptance.

Corrected parent PR#457 remains frozen at eb8efc3154caf6066e30cd94cda1a3fbd1a027a4 against accepted main788b7be8823af1228026cbe3cb536f929df7aaea. Exact READY preview dpl_3Sac1CuZCH9UXnZUFW5uB9XA5wt9 matches the head/project with no alias error,passes11general checks and retains15Premium locks/zero cohort Submits;both whole helpers exit0. Last observed required run38974032201at22:42UTC is in Browser checks,SQLgreen;fresh protected guards and exact production acceptance are pending. Initial failed38968786126/old preview remain historical. Thirty-five B115–B121reviews are staged above verified production600;twenty B118–B121records need their own follow-up PR/release after the parent. Preserve the Menu review revision2without recounting it,complete-coding eligibility gating,effective-bank/longest-answer reconciliation,all#190dedicated acceptance and owner decisions/draft#365holds. #458tracks the general comment-scanner/strict-syntax follow-up;#435Profile-only leaderboard settings and#444guide focus follow the whole audit.

## PR #457 guarded production acceptance — 16 October 2026 UTC

PR#457 is merged and exact production is accepted. Corrected head eb8efc3154caf6066e30cd94cda1a3fbd1a027a4 passed required38974032201:verify36m15s,SQL38s. Fresh open/non-draft/exact-head/main/accepted-base788b7be8823af1228026cbe3cb536f929df7aaea/MERGEABLE/no-closing references,all rollups,protected verify/sql app15368 and completed exact-head run/checks guards each returned0 and were read before normal protected merge. No force,admin override or protection change;strict:false remains unchanged. Merge a0169d0a8e7b54ec98856e00138bfcbb499aadc2 at16October2026 22:47:09UTC has exactly the accepted base and reviewed head as parents.

Exact READY corrected preview dpl_3Sac1CuZCH9UXnZUFW5uB9XA5wt9 and production dpl_ForjK8rNjFiBGvFhKvW9hZsZuoQf match their exact commit/project and have no alias error. Each passes11general checks and retains all15cohort Premium locks,with zero actual cohort Submits;both whole helpers return0. Production owns devshark.app before and after the probes. Exact-head helpers were frozen before newer source work;private0600access files validate complete HTTPS authorities. No authenticated entitlement,account/progress/score/name fixture,security setting or production override was written. Dedicated authenticated Premium acceptance remains#190.

Original run38968786126at89f5038b failed one of206native-harness assertions:Tab changed activeElement in an inactive opaque frame without focusout,so a correct Menu never received blur. Reproduce the full failure,diagnose the event transition and explicitly simulate Testing Library blur with relatedTarget before focusing outside. All Tab default-prevention,menu-closed and actual-focus assertions remain. All seven Menu programs stay byte-identical;the staged review binds once to revision2,with seven fresh rows replacing seven historical rows in105/105current-hash outcomes. A missing-onBlur negative still fails the Tab requirement in worker and actual browser.615-source and integrated625-source full browser harnesses pass206assertions;16fresh Menu light/dark probes pass. Original failed CI and old89fpreview remain historical only. The earlier parent#456 browser-count fix also remains intact.

B115–B117 bring verified production to615/725coding and263/263native reviews. Current source B118–B121 has635reviews;90React remain,and20locally accepted coding records need their own PR/release. These four five-item commits have140/140current-hash worker outcomes,80safe base25checks and320final-build light/dark probes;B120/B121additionally execute60total actual-browser programs with expected verdicts.48of60published whole program fields stay byte-identical. All635coding/263native hashes remain current and unique;bundle242998/243000gzip,12handlers,Czech unchanged. Preserve complete-coding eligibility gating,effective-bank/longest-answer reconciliation,owner holds/draft#365and#190dedicated acceptance. #458scanner and#459composition-capability follow-ups remain open;#435Profile-only leaderboard preferences and#444guide focus follow the whole content audit. Same-session model review/finite local and guest execution,not independent human,authenticated Premium,physical-device or whole-catalogue acceptance.

## B122 five-item audit and keyboard composition parity — 16 October 2026 UTC

B122 individually reviews Undo a removal, A tag input, Numbered page buttons, One page at a time and Show more. Current source reaches640/725coding reviews;85React tasks remain. Verified production remains615coding/263native via#457. These five reviews are locally accepted,not deployed. All three Undo programs stay byte-identical;the other twelve preserve their supported solution styles while repairing demonstrated edge cases. Only the intended five task hashes change.

35/35final-hash worker outcomes match:20valid programs,five incomplete starters and ten semantic wrong controls,with no compile errors. All ten selected wrong programs pass frozen original suites (baseline25/35expectations);newly explicit IME/live-data policies are distinguished from prior defects in individual rationales. Five public/fifteen hidden cases are added. An actual-Chromium matrix runs all public/hidden cases for the20valid/ten wrong programs:30/30expected verdicts,53harness/protocol assertions,exit0.20unknown-safe base25XPchecks pass;React receives no automatic complexity target or penalty. Maximum supported-program case627ms. A fresh strict parse accepts all501served React program strings.

Undo adds a60-operation model over24frozen task records,literal/duplicate/empty/single/500character inputs,latest-only memory,parent snapshots and separate/fresh roots. It rejects capped restore indices and trimmed task text. Tag retains explicit,loop and Set styles while ignoring composition before any confirmation/deletion/default action. Exact trim/toLowerCase,non-ASCII/NBSP/literal data,more than four tags,named removals,exact-empty Backspace and independent fields reject four-tag/ASCII-only shortcuts. Private diagnostics show the valid composition guard passes native Chromium but originally failed the worker. Fix#459by adding only isComposing to the existing read-only event capability;no setter,method,host object or verdict authority is exposed. New authority regressions accept composing/ordinary React events and native listeners,deny flag mutation and reject premature confirmation. All existing promise/authority attack cases remain held. IME is an explicit additional lesson policy,not retroactively alleged as an old brief requirement.

All original numbered-page/show-more programs produce wrong or extra DOM rows with duplicate text keys in focused probes. Use unique positions only for the scoped stateless readonly text rows,not as blanket advice for stateful/reordered records;align starters and guides. Numbered pages cover zero/boundary/long frozen lists,all markers,more than four pages,cyclic duplicates,same-length data replacement and separate/fresh selection. Gallery reference/junior previously rendered Page1of0and could reach0;reuse the senior's single-empty-page policy,repair their page count and make every board duplicate-safe. All forward/backward bounds over nine sizes,empty repeated controls,current literal replacements and separate/fresh galleries reject a three-page cap and Previous jumping to the start. Page-list length changes use fresh mounts;no unrelated reset rule is imposed. Show more derives the current prop prefix while preserving the chosen count across duplicate shrink/grow/empty replacements. Eleven boundary sizes,frozen inputs,full-prefix order and separate/fresh counters reject eight-item caps and cached initial data.

API/script types,selected canonical validation (including ten incomplete skeleton placements;no existing complete filling or QA variant),grading/Learn integrity,React promise/authority,registry/index,all640coding/263native current hashes,copy sweep,launch,build,bundle,both zero-vulnerability production dependency audits and diff pass.80final-build layout probes at eight default320–1440px widths,40light/40dark,have zeroissues/unprobed and tracked exits0,using server-derived API stand-ins. Bundle242998/243000gzip;12physical API handlers;archived Czech unchanged. Original/final English material and whole programs are individually read and separately reread in the same session against installed React19.2.8 and primary React/MDN references. This remains finite model/worker/browser evidence,not independent-human or physical/authenticated acceptance.

The optional remote microVM integration invocation stops at its explicit missing REACT_RUNNER_SNAPSHOT_ID precondition;it is not a pass and creates no cloud resource. Vercel Sandbox guidance and existing operations/source confirm snapshots hold dependencies only;the build regenerates the current guest bundle and each run uploads it. The generated EVENT_READ includes isComposing. Code-only changes require no dependency snapshot refresh or environment change. SDK CommonJS packaging checks pass with require(ESM)off. Dedicated cloud/authenticated acceptance stays#190;#459remains open until guarded release.

PR#460 freezes B118–B121at2187d35ef8f32de330714c9f22e3b5e4378bc8d2against accepted maina0169d0a8e7b54ec98856e00138bfcbb499aadc2. Exact READY preview dpl_GrZipdbbbct8oj5ABApHBDKobKbM matches head/project/noaliaserror.11general checks and12actual cohort Submits pass:Radio group,useToggle and Name the remove buttons each accept reference/alternative and reject two wrong controls,all0guestXP/nullprogress.17other tasks retain access locks;both whole helpers return0. Required38978557130was still in progress with SQLgreen at23:13UTC;fresh protected guards and exact production acceptance remain pending. Twenty-five B118–B122reviews are staged above verified production615;five B122records need their own release after the frozen20-task parent. Keep#176/#391,bank reconciliation,owner/draft#365holds and#190dedicated acceptance. #458scanner follow-up remains open;#435Profile-only leaderboard settings and#444guide focus follow the whole audit.

## B123 five-item pagination and request-state audit — 2026-10-16 UTC

B123 individually reviews Fetch a page, The results line, Rows per page, Load more and Paginated posts. Current source reaches 645/725 coding reviews; 80 React tasks remain. Verified production remains 615/725 coding and 263/263 native reviews. All fifteen whole program fields retain their promise/async, conditional/Math.min, state/reducer, explicit-loop and custom-pagination-hook teaching styles while correcting scoped behavior. Only the intended five task hashes change; the preceding 640 coding records stay exact and current. These five reviews are locally accepted and are not yet deployed.

35/35 final-hash QuickJS outcomes match: twenty valid programs, five incomplete starters and ten semantic wrong controls, with no compile errors. Frozen original suites matched only 24/35 expectations: all ten wrong controls passed, and the valid fetch-page alternative failed solely because its query parameters have an equivalent reversed order. Endpoint/value assertions now accept that alternative. Five public and fifteen hidden cases are added. An actual-Chromium matrix executes all public/hidden cases for all twenty valid and ten wrong programs, reaching 30/30 expected verdicts and 53 harness/protocol assertions, exit0. Maximum supported-program case is 709ms. Twenty unknown-safe base25XP checks pass: React receives no automatic desired-complexity target or penalty. A fresh strict syntax parse accepts all 501 served React program strings. A final English noun correction and explicit loading-status checks trigger the fresh complete worker matrix; the earlier matrix is historical, not relabelled as current.

Fetch a page explicitly adds loading, same-page retry and current-only success/failure. It clears former rows, keeps Next disabled until a full successful response, allows Previous above page1 during pending requests, checks HTTP and JSON failures, and ignores late former responses even with a controlled transport that ignores abort. Tests exercise both late success and failure, three failure kinds, multiple full pages then an empty end, no parent refetch and separate/fresh requests. These recovery policies are newly declared, not retroactively attributed to the short original brief. Reference/junior lacked stale guards and all originals lacked HTTP/recovery; the senior already had a current flag. The shared fixture itself ignores _page: executing the actual fixture shows pages1/2/3 all returning ids1–5. This is separately tracked in #461, not claimed fixed by suites that replace fetch.

Results line and Rows per page keep their existing correct derived ranges/size-reset logic and all three supported styles. The original six programs fail newly exercised duplicate-key transitions: they render extra or stale rows. Unique absolute-position keys repair the scoped stateless read-only slots; starters and hints align. Frozen/literal/long/duplicate data, all reachable bounds, truthful status, current equal-length replacements and separate/fresh roots are covered. Recipe sizes include0/1/4/5/8/10/37; order sizes include0/1/5/6/10/20/21/73 with all offered5/10/20 selections and late-page resets in either direction. Length changes use fresh mounts; invalid select values and unrelated reset requirements are not invented. Exact row checks reject a counter-only recipe implementation, three/five-page caps and order-title truncation that old fixtures missed.

Load more preserves reference status, junior booleans and senior reducer/useCallback. Only reference/junior need the missing HTTP check; all get ownership cleanup of the latest button request. Catch rejected JSON, retain the prefix through failures, clear the alert when retry begins and request the same page. Tests append exact literal data through page5, stop on a short/empty response, prevent repeated pending clicks and retain independent roots without parent refetch. Existing QA placing Try again inside the alert stays valid and is canonically checked. Cleanup on removal is an explicit added policy, not a falsely alleged demonstrated cross-root leak. Paginated posts preserves full-array single-fetch pagination and the junior loop/senior custom hook; exact titles,0/1/5/6/10/11/37/50 boundaries, HTTP/JSON/offline retry and no navigation refetch reject the original count-only fixture shortcuts. Its partial and existing completed hint are revised together and both placement/filling checks pass.

API/script types, selected canonical validation, grading/Learn integrity, registry/index, all645 coding/263 native current unique bindings, copy sweep, launch, build, bundle, both zero-vulnerability production dependency audits and diff pass. Eight default320–1440px widths across the five routes pass80 final-build light/dark probes with zeroissues/unprobed and tracked exits0, using server-derived API stand-ins. Bundle242998/243000gzip;12physical API handlers; archived Czech unchanged. All original/final English fields, partials, existing filled hint/QA and whole programs are individually read and separately reread in the same session using primary React/MDN documentation and installed React19.2.8. This is finite model/worker/native-browser evidence, not independent-human, real-network, physical-device or authenticated acceptance.

Parent #460 has now passed required38978557130 (verify2217s, SQL37s) and fresh exact-head/base/main/protection/rollup/run guards, all returning0 and read before normal protected merge. Merge1bf37afa63616786c7fcc008b2616eb322daf11a at16October2026 23:33UTC has exactly accepted basea0169d0a8e7b54ec98856e00138bfcbb499aadc2 and frozen head2187d35ef8f32de330714c9f22e3b5e4378bc8d2 as parents. Exact-head preview already passed11general plus12actual cohort Submits across3free tasks with17other access locks and helpers0; it is not twenty authenticated task submissions. Exact production acceptance is separately tracked and is required before increasing deployed counts. #459 is locally fixed in B122 but remains open until its own release. Keep #458/#461 engineering follow-ups, #435 Profile-only leaderboard settings and #444 guide focus after the whole audit, all owner/draft#365holds, #190 dedicated acceptance and effective-bank reconciliation. 30 source reviews are staged above the presently recorded verified production count.

## PR #460 guarded production acceptance — 16 October 2026 UTC

PR #460 is merged and its exact production deployment is accepted. Frozen head 2187d35ef8f32de330714c9f22e3b5e4378bc8d2 passed required run 38978557130: verify 36m57s, SQL 37s. Fresh OPEN/non-draft/exact-head, accepted base/main a0169d0a8e7b54ec98856e00138bfcbb499aadc2, MERGEABLE, no closing references, all rollups and exact-head required check/run guards returned 0 and were read before the normal protected merge. Required verify/sql app 15368 and strict:false stay unchanged. No force, admin override or protection change. Merge 1bf37afa63616786c7fcc008b2616eb322daf11a at 16 October 2026 23:33 UTC has exactly the accepted base and frozen head as parents.

READY preview dpl_GrZipdbbbct8oj5ABApHBDKobKbM and production dpl_4qwYiKG5HnDWvqSRhPWad8x5jYg8 match their exact commit/project, with no alias error. Both pass 11 general checks and 12 actual cohort Submits: Radio group, useToggle and Name the remove buttons each accept reference/independent alternative and reject two wrong controls, all 0 guest XP/null progress. The other 17 of 20 requested tasks retain their Premium/stage locks. Both whole helpers return 0. Production owns devshark.app before and after the probes. Helpers were frozen at the reviewed 635-source head before B122/B123 changes; private access files use mode 0600 and exact HTTPS authorities. No authenticated entitlement, account/progress/score/name fixture, security setting or production override was written. Dedicated authenticated Premium and cloud acceptance remain #190.

B118–B121 bring verified production to 635/725 coding and 263/263 native reviews. Current source is 645/725 after B122/B123; 80 React tasks remain. The ten staged records have 70/70 current-hash worker outcomes, 60/60 actual-browser expected verdicts, 40 safe base25 checks and 160 final-build light/dark probes, with local gates exiting 0. All 645 coding and 263 native hashes remain current and unique. B122's read-only isComposing capability fix #459 is locally verified and awaits its own guarded release; it is not part of this frozen 635-source deployment. Preserve #458 comment scanner, #461 fixture pagination, #435 Profile-only leaderboard preferences and #444 guide focus after the whole audit, owner/draft #365 holds and effective-bank reconciliation. This is finite same-session model/worker/native/guest evidence, not independent-human, authenticated Premium, physical-device or whole-catalogue acceptance.

## B124 five-item request, aggregation and booking audit — 2026-10-16 UTC

B124 individually reviews Fetch error state, Optimistic todo, Analytics panel, Booking prototype and Comments viewer. Current source reaches 650/725 coding reviews; 75 React tasks remain. Verified production remains 635/725 coding and 263/263 native reviews via #460. These five records are locally accepted, not deployed. Two published whole senior programs (fetch-error state and optimistic todo) stay byte-identical. Only the intended five task hashes change; the preceding 645 records remain current and unique.

35/35 final-hash QuickJS outcomes match: twenty valid programs, five incomplete starters and ten semantic wrong controls, with no compile errors. Frozen original suites accept all ten wrong controls (25/35 expected matches). Seven fresh original-hash Analytics rows replace the initial seven after refining its candidate reference; the initial baseline is preserved historically. Five public and fifteen hidden cases are added. An actual-Chromium matrix executes all public/hidden cases for the twenty valid and ten wrong programs, yielding30/30expected verdicts and53harness/protocol assertions, exit0. Maximum supported-program case is193ms. Twenty unknown-safe base25XP checks pass; React receives no automatic desired-complexity target or penalty. A fresh strict syntax parse accepts all501served React program strings.

Fetch error state adds nonempty friendly alerts where the reference/junior relied on error.message, while keeping the senior/helper exact. Check HTTP before reading JSON, rejected JSON and empty-message network failure without rendering failed data. Literal ordered duplicate/long names through37users, empty success, parent renders and independent/fresh requests reject three-user and25character caps. The existing partial/completed hint are aligned and checked; optional loading/empty copy remains optional. Optimistic todo retains stable client identities after success, stores server ids separately and removes only the failed draft. Reference uses UUID; junior keeps its counter/explicit loops; senior is exact. Its prior captured-array rollback hint is corrected. Four pending drafts, fixed-clock identity, repeated server ids, reversed success/failure, trimming/blank omission, labelled input clearing, HTTP/JSON failure and independent/fresh roots reject timestamp keys and three-item caps. Clarify the original single-item empty-list wording for concurrent drafts; no unrelated request is rolled back.

Analytics gives All types an empty value, allowing real all to be selected. Reference/junior count into safe dictionaries and senior keeps its Map. JavaScript string ordering is made explicit for options/cards; visible wrapping labels avoid junior duplicate global ids. A60event model covers constructor/toString/__proto__, uppercase names, inclusive cross-year filters, reversed ranges, full option retention, exact uncapped counts, JSON/empty states and independent roots. Private original diagnostics demonstrate sentinel failures in all three boards and dictionary failures in reference/junior. Initial repair with immutable spread plus own-key reads is valid in native Chromium but fails the worker/canonical check. Root cause:#463,TypeScriptES2015lowers spread into Object.assign while guest Object.prototype is frozen, so assignment cannot shadow inherited read-only constructor. The final authored reference uses a null-prototype accumulator and all supported programs now align in both runtimes. This is a lesson workaround, not a framework fix for otherwise valid learner spread;#463remains open and the editorial technical score is bounded3/5. No compiler, authority, security or environment change is made in this batch. The initial failed canonical/worker run and initial diff whitespace failure remain historical; the refined programs, visible labels and prompt are freshly rechecked.

Booking preserves state/loops/reducer styles and the existing HTTP-status-only PATCH outcomes. Disable slot choices while pending as an explicitly added local policy; do not misrepresent this as prevention of other users booking. Eight-slot data includes duplicate/literal/long titles and noncontiguous ids, so title-based marking and four-slot caps fail. Test duplicate-click prevention, same-id retry,409/success/other failure, empty/ten fully booked data, malformed initial JSON and independent/fresh state. Comments viewer uses null-prototype dictionaries where inherited keys failed, keeps the senior Map/abort architecture, labels junior controls and states deterministic count-then-string ordering. Group literal case-sensitive domain substrings without inventing normalization; only address filtering ignores case. A27comment model covers constructor/toString and mixed-case domains, numeric post ids, repeated/literal names, combined/reset/no-match filters, JSON/empty states, no refetch and independent labelled roots. Existing negative QA that lowercases only the filter remains held. No real endpoint, database booking constraint, identity/email publication rule or production data is changed.

API/script types, selected canonical validation (ten incomplete skeleton placements, the existing completed error-state hint and existing comments QA), grading/Learn integrity, registry/index, all650coding/263native current unique bindings, copy sweep, launch, build, bundle, both zero-vulnerability production dependency audits and diff pass. Eight default320–1440px widths across five routes pass80final-build light/dark probes with zeroissues/unprobed and tracked exits0, using server-derived API stand-ins. Bundle242998/243000gzip;12physical API handlers; archived Czech unchanged. Original/final English, partials, existing complete hint/QA and all whole programs are fully read and separately reread against primary React/MDN references and installed React19.2.8. This is finite same-session model/worker/native-browser evidence, not independent-human, real-network, physical-device or authenticated acceptance.

Frozen parent#462at8fa239e8942787a7af4dc81eaf3ccc36d1725db2 contains B122/B123 only (ten reviews above verified production635). Exact READY previewdpl_B252suy9MjgUpNXs6F9ZUTuPHfPi matches head/project with no alias error;11general checks and4actual cohort Submits for One page at a time pass with0guestXP/nullprogress,while9other tasks retain access locks;both helpers exit0. Required38982735572and fresh protected merge/production acceptance remain pending. Keep#459open until its own release,unconfigured local optional remoteVM check as not a pass,#190dedicated cloud/authenticated acceptance,#458/#461/#463engineering follow-ups,#435/#444after the whole audit,owner/draft#365holds and effective-bank reconciliation. Fifteen B122–B124source reviews are staged above recorded verified production635.

## B125 five-item CRUD and staged task-board audit — 2026-10-17 UTC

B125 individually reviews CRUD mini app and Task board steps1–4: the first controlled-input checkpoint, add/toggle milestone, filter checkpoint and filter/delete/Remaining milestone. Current source reaches655/725coding reviews;70React tasks remain. Verified production remains635/725coding and263/263native via#460. These five records are locally accepted,not deployed. All eight whole Board program fields, four public cumulative suites/prompts and prior-requirement arrays stay byte-identical;two checkpoints intentionally publish only a reference. Only the intended five task hashes change;the preceding650reviewed records remain current and unique. Later stages are neither rewritten nor implicitly reviewed.

31/31final-hash QuickJS outcomes match:16valid programs (11published boards and5independent alternatives),5incomplete starters and10semantic wrong controls,with no compile errors. Original suites accept all10wrong controls (21/31baseline expectations). One public and19hidden cases are added,keeping Board public checks/cumulative order intact;ID-specific hidden cases are attached after checkpoint reference construction. Actual Chromium runs all public/hidden cases for16valid/10wrong programs:26/26expected verdicts and49harness/protocol assertions,exit0. Maximum supported-program case is338ms.16unknown-safe base25XPchecks pass,with no automatic React complexity target/penalty. A fresh strict parse accepts all501served React program strings.

CRUD preserves the reference promise chain,junior loops and senior fetchJson/PostItem/useCallback styles. Reference/junior formerly reused response ids;senior already used unique client ids. Every successful create now keeps a client UUID and separate serverId,so repeated practice response ids do not make several rows edit/delete together. Add declared loading/load-error and recoverable create-error branches,HTTP/JSON/network handling,pending create guard and labelled Title input. Capture/trim and clear only the submitted draft at start;append only on success,keep local edits/newer typing,and restore failure text only into an empty field. Initial GET ownership remains local to the mounted root. A12post/three-create model with duplicate titles and repeated response id101,clicked edit/delete,pending duplicate submit,HTTP/JSON/create failure,recovery/blank/long literal data,empty success and independent/fresh roots reject reused ids and a seven-post cap. Request/draft policies are explicitly added rather than falsely attributed to the former short brief. Old waits are bounded to300ms for incomplete-answer diagnostics. Title comparison removes UI button/separator whitespace;finite evidence does not prove every formatting or arbitrary-input behavior. No complete hint fill or existing QA variant is present.

Task board1 keeps raw controlled spaces/NBSP/Japanese/literal/long text,independent/fresh drafts,parent retention and restoration from state after an external DOM write. Add remains intentionally inactive at this first prerequisite. Trimming while typing and a five-character cap passed its original five-character example;new cases reject them. Board2 retains stable ids across duplicate/long names,a40operation add/toggle model,blank rejection,later identities,repeated toggles and independent/fresh state;new cases reject three-task caps and toggling only ids1/2. Board3 tests Completed as well as Active/All,toggles by full identity from a filtered index,adds under Completed without changing the filter or discarding hidden rows,and retains independent/fresh state. Old checks never observed Completed;Completed-as-All and three-task caps now fail. Board4 combines exact mixed filter views,full-list Remaining greater than2,duplicate filtered deletion,a60operation add/toggle/filter/delete model and independent/fresh counts. Completed-as-All formerly escaped because the only active task had been deleted;the hidden count fixture never exceeded2. All four records gain targeted hints and hidden cases only. No global generator rewrite,extra checkpoint boards or unrelated later-stage changes are introduced.

API/script types,selected canonical content/progression checks,grading/Learn integrity,registry/index,all655coding/263native current unique bindings,copy sweep,launch,build,bundle,both zero-vulnerability production dependency audits and diff pass. Selected progression checks prove2earlier solutions fail their next step and2checkpoint references fail the corresponding milestone;2CRUD skeleton placements remain incomplete. Eight default320–1440px widths across5routes pass80final-build light/dark probes with zeroissues/unprobed and tracked exits0,using server-derived API stand-ins. Bundle242998/243000gzip;12physical API handlers;archived Czech unchanged. Original/final English,partial/guides,public/hidden checks and all11whole programs are fully read and separately reread against primary React/MDN sources and installed React19.2.8. This is finite same-session model/worker/browser evidence,not independent-human,real-network,physical-device or authenticated acceptance.

Frozen#462at8fa239e8942787a7af4dc81eaf3ccc36d1725db2contains B122/B123only. Exact READY previewdpl_B252suy9MjgUpNXs6F9ZUTuPHfPi passes11general/4actual cohort Submits for One page at a time,all0guestXP/nullprogress,with9other access locks and helpers0. Required38982735572is completed-success;fresh protected merge/exact production acceptance remain pending.20B122–B125records are staged above verified production635. Keep#459open until its own release,#463as a confirmed unresolved compiler/native property-spread discrepancy (B124's authored workaround is not its fix),#458comment scanner,#461fixture pagination,#435/#444after the whole audit,all owner/draft#365holds,#190dedicated cloud/authenticated/physical acceptance and effective-bank reconciliation. The optional remote microVM check is locally unconfigured,not a pass,and no cloud configuration/resource was changed.

## PR #462 guarded production acceptance — 17 October 2026 UTC

PR #462 is merged and its exact production deployment is accepted. Frozen head 8fa239e8942787a7af4dc81eaf3ccc36d1725db2 passed required run 38982735572: verify 29m20s, SQL 43s. Fresh exact-head, accepted main/base 1bf37afa63616786c7fcc008b2616eb322daf11a, mergeability, rollup and required-check guards returned 0 and were read before the normal protected merge. Required verify/sql app 15368 and strict:false stayed unchanged. Merge fef550f2fc674b2c5f25ad84df4ba6bd0b3b95ca at 17 October 2026 00:13:54 UTC has exactly that base and frozen head as parents. No force, admin override or protection change.

READY preview dpl_B252suy9MjgUpNXs6F9ZUTuPHfPi and production dpl_ARh6SKEZPFNzhbFLgLLbWZygUKLM match their exact commit and project, with no alias error. Each passed 11 general checks and four actual cohort Submits for Page of photos: reference/independent alternative accepted, two wrong controls rejected, all 0 guest XP/null progress. Nine of ten requested tasks retained their Premium/stage locks. Whole helpers returned 0; production owned devshark.app before and after the probes. Helpers were frozen at the reviewed 645-source head. No authenticated entitlement, account/progress/score/name fixture, security setting or production override was written. Authenticated Premium/cloud acceptance remains #190.

B122/B123 bring verified production to 645/725 coding and 263/263 native reviews. Current source is 655/725 after B124/B125; 70 React tasks remain and ten records are staged. Their recorded local evidence is 66/66 worker outcomes, 56/56 actual-browser expected verdicts, 36 safe base25 checks and 160 light/dark layout probes. B125 accessible-name test refinement is in progress before its release; these counts describe its initial committed revision. The read-only isComposing capability in #459 is now deployed: authority, worker and native tests cover composition and deny event mutation. The actual composition task remains guest-locked, so no authenticated production Tag task Submit is claimed. #458 comment scanner, #461 fixture pagination, #463 object-spread lowering, #435 Profile-only leaderboard preferences and #444 guide focus remain open. Owner/draft #365 holds and effective-bank reconciliation remain. Finite same-session evidence is not independent-human, authenticated Premium, physical-device or whole-catalogue acceptance.

## B125 accessible-name test refinement — 17 October 2026 UTC

B125 accessibility refinement: compute each checkbox accessible name via scoped Testing Library role queries, accepting both label and aria-label. Three valid aria-label alternatives pass original suites, fail the initial B125 label-specific helper, then pass the refined helper. Current cohort34/34worker (19valid/5starters/10wrong),29/29native and52protocol assertions,19safe25. Only four Board hidden hashes change; all published programs/prompts/public suites/hints/starters remain byte-identical. Same-session finite evidence; no added review identities. API/script types,launch,build,bundle and both production dependency audits freshly exit0. Prior B12580layout probes are reused because every served/public field, published program and client dependency remains identical; no new layout claim. Selected canonical,registry/index and all655coding/263native bindings are rechecked after this revision. Current source655/725,verified production645/725,70React remain;ten B124/B125 reviews await their own release. #459 deployed/closed via#462;#458/#461/#463 remain open.

## B126 five-item task-history audit — 17 October 2026 UTC

B126 individually reviews Task board steps5–9: Undo checkpoint, Undo/Redo milestone, Complete all checkpoint, complete/clear milestone and Move up checkpoint. Current source reaches660/725coding reviews;65React tasks remain. Verified production remains645/725coding and263/263native through#462. These five records are local,not deployed. Exactly five hashes change against frozen#464head5b1039569d1c7c06043b1dbf5ed1250491707d45. All nine published program fields, cumulative public suites/prompts, prior requirements and starters remain byte-identical. Three checkpoints intentionally publish only a reference. Add20ID-specific hidden cases after checkpoint construction and five targeted English hints;later stages are not implicitly reviewed.

29/29 final-hash worker outcomes match:14valid programs (nine published and five independent alternatives),five starters and ten semantic wrong controls,without compile errors. Original suites accept all ten wrong controls (19/29baseline expectations). Actual Chromium accepts14valid and rejects10wrong programs:24/24expected verdicts plus47protocol assertions,whole helper exit0. Maximum valid worker case is1204ms. All14 authored-target/base25checks pass with unknown React complexity left unpenalized. Strict parsing accepts all501served React program strings.

Undo now has finite checks beyond two snapshots,including toggled duplicate deletion/restoration and repeated Undo to empty. Undo/Redo restores unchecked additions and mixed completion/membership,retains stable identities and preserves independent filter/draft state;blank adds keep history while divergent task edits clear future snapshots. Complete all reaches six mixed/duplicate tasks even through Completed/Active filters,records one full-list snapshot and restores mixed completion in one Undo. Clear completed is observed before Undo,including hidden completed rows under Active;bulk actions preserve IDs so duplicate labels remain independently toggleable. The old clear test never observed the actual cleared state before undoing. Move up must swap exactly one full-list predecessor,including a hidden first completed row;it cannot swap with the first row or disable the first merely visible task. Four checks per item include a60-operation deterministic model and parent/independent/fresh roots,with disabled availability matched to complete state. Hints describe these existing contracts;no new network or persistence policy is introduced. Published compact snapshots,junior explicit arrays/loops and senior reducer styles are retained.

API/script types,selected canonical/progression checks,grading/Learn integrity,registry/index,all660coding/263native current unique bindings,copy sweep,launch,build,bundle,both zero-vulnerability production dependency audits and diff pass. Progression proves five earlier solutions fail the next step and three checkpoint solutions fail the milestone. Eight320–1440px widths over five routes pass80fresh final-build light/dark probes,zeroissues/unprobed,using server-derived API stand-ins;whole helpers exit0. Bundle242998/243000gzip;12physicalAPIhandlers;archivedCzech unchanged. Original/final English,hints,public/hidden checks and all nine whole programs are read and separately reread. Same-session finite model/worker/native evidence is not independent-human,real-network,physical-device or authenticated acceptance.

Frozen#464contains B124/B125only,source655. Exact READY previewdpl_4LUYiFq3gzPbCvhyd7qh2QC2bJBJ matches head/project with no alias error and passes11general plus4actual Task board1 Submits (reference/alternative accepted,two wrong controls rejected;0guestXP/nullprogress),nineotherlocks,wholehelpers0. Required38986654569is in progress;merge/production are pending. Current660source is15reviews above verified645production. #459is deployed/closed via#462;preserve#458comment scanner,#461fixture pagination,#463compiler property creation,#435/#444after wholeaudit,owner/draft#365holds,#190dedicatedacceptance and effective-bank reconciliation.

## B127 final-board and early explorer audit — 17October2026UTC

B127 reviews Task board step 10 and Product explorer steps 1–4. Current source reaches 665/725 coding reviews; 60 React tasks remain. Verified production stays at 645/725 coding and 263/263 native reviews through PR #462. This batch adds five records and revises one existing B126 checkpoint, without counting that revision as another reviewed task. Exactly six hashes change. All eleven published programs, prompts, prior requirements and starters remain byte-identical. Both explorer checkpoints publish only a reference. The four explorer public suites also stay unchanged.

All 32 current-hash worker outcomes match: 17 valid programs, five incomplete starters and ten wrong controls, with no compile errors. The frozen original suites accepted all ten wrong controls and falsely rejected two valid board alternatives using aria-label or aria-labelledby: 20/32 baseline expectations matched. The initial 31-case proof is retained; an eight-case board baseline replaces that item's earlier seven cases. Chromium accepts all 17 valid programs and rejects all ten wrong controls: 27 expected verdicts and 50 protocol assertions pass. Maximum valid worker case: 1874 ms. Seventeen unknown-safe base-25-XP checks and strict parsing of all 501 served React program strings pass.

The final board now tests computed accessible names instead of requiring wrapping labels. Six-row duplicate histories and both move directions catch a three-task cap and a two-snapshot cap that passed the old examples. The fixed-list checkpoint now checks every product and its own price. Search covers all products, inner substrings, case/whitespace, empty recovery and independent roots. Sort covers every mode on full, partial and empty results. Pagination checks exact pairs, forward/backward boundaries, actual query/sort changes and separate mounted state. No additional product data or raw-input editing policy is imposed. Twenty hidden cases and five English hints are added.

An initial pagination test incorrectly expected a reset for an unchanged empty query. All four correct implementations failed it in Chromium. The assertion now performs actual changes; the complete current worker/native matrices pass. Published implementations did not change. A launch check also encountered a stale generated registry while the checkpoint ledger revision was being written. Regenerating the registry after all accepted records and rerunning the launch gate resolves that intermediate mismatch. Failed runs remain historical evidence, not acceptance.

Inherited Move up accessible-name revision in B127: original aria-label-or-wrapping-label fallback falsely rejects a valid per-root useId/aria-labelledby implementation (five of six expected baseline outcomes). Scoped Testing Library role/name lookup accepts labels,aria-label and aria-labelledby. Six of six current-hash worker outcomes,three valid/two wrong native programs plus28protocol assertions,andthree unknown-safe base25checks pass. Prompt,starter,requirements,hints and reference program remain unchanged. No additional review identity.

Fresh API/script types, selected canonical/progression checks, launch, build, bundle, registry/index, all 665 coding/263 native bindings, copy sweep, both zero-vulnerability production dependency audits and diff checks pass. Grading/Learn integrity against a stand-in database also passes. Four earlier solutions fail their next step and three checkpoint solutions fail their milestone. All six changed routes pass 96 fresh light/dark layout probes at eight widths from 320 through 1440 px, with no issues or unprobed routes. Layout APIs use server-derived stand-ins. Bundle: 242998/243000 gzip bytes; twelve physical API handlers; archived Czech unchanged. Original/final English, hints, suites and all eleven whole programs were read and separately reread. These are finite same-session model/worker/browser checks, not independent-human, real-network, physical-device or authenticated acceptance.

PR #464 freezes only B124/B125 at head 5b1039569d1c7c06043b1dbf5ed1250491707d45, with 655 source reviews. Exact READY preview dpl_4LUYiFq3gzPbCvhyd7qh2QC2bJBJ matches head/project with no alias error. It passes eleven general checks and four actual Task board 1 Submits, all with zero guest XP/null progress; nine other tasks retain their access locks. Whole helpers return 0. Required run 38986654569 is still in progress; protected merge and production acceptance remain pending. Current source has twenty reviews above verified production. #459 is deployed/closed. Keep #458, #461, #463, the post-audit work in #435/#444, owner/draft #365 holds, dedicated #190 acceptance and effective-bank reconciliation open.

## B128 selection, price and quantity audit — 17 October 2026 UTC

B128 reviews Product explorer steps 5–9: selection checkpoint, page-selection milestone, price checkpoint, combined price facet and valid-quantity checkpoint. Current source reaches 670/725 coding reviews; 55 React tasks remain. Verified production is 645/725 coding and 263/263 native reviews through #462. This batch adds five records and changes exactly five hashes. All nine published programs, prompts, prior requirements, starters, cumulative public suites and two existing negative QA programs remain byte-identical. Three checkpoints intentionally publish only a reference. Add twenty ID-specific hidden cases and five English hints.

All 32 final-hash worker outcomes match: fifteen valid programs (nine published, five independent alternatives and an additional valid checkpoint price-reset alternative), five starters and twelve wrong controls. The frozen original suites accept all ten new wrong controls, while both existing cannot-untick QA programs already fail: 22/32 baseline expectations matched. Current Chromium accepts all fifteen valid programs and rejects all twelve wrong controls: 27 expected verdicts and 50 protocol assertions pass. Maximum supported worker case: 1187 ms. Fifteen unknown-safe base25 checks and strict parsing of all 501 served React programs pass. No unsupported complexity target or penalty is added.

Selection checks every product, unticking, hidden pages/searches, full-catalog totals and independent/fresh roots. The full selection milestone also retains selection through sorting, unions actual visible identities idempotently, clears hidden selections and disables unavailable actions. A 48-operation view/selection model catches omitted Carrot totals and sort/page changes that silently clear selection. Price cases include zero, fractions, exact boundaries, large values and empty recovery across search/sort combinations. They reject zero-as-unlimited and rounding limits upward.

The price checkpoint does not require a reset policy yet. Both its published page-clamping solution and a correct reset alternative are accepted; tests keep the displayed page valid. Selection is explicitly cleared before checkpoint maximum changes, so the next milestone's new preservation requirement is not imposed early. The full facet requires reset on real query/sort/maximum edits and preserves hidden selections and their totals. Quantity cases use valid whole numbers 1–99 only, with independent amounts for every selected product, weighted full-list totals, off-screen controls, repeated edits and separate/fresh carts. Invalid-edit and deselect/reselect rules belong to the following milestone and are not imposed at this checkpoint. Product rows are scoped through their checkboxes, allowing unrelated Cart list markup.

The initial private model dispatched a change event for an unchanged select value. React called the handler, while the model incorrectly kept the old page; eleven correct implementations failed that one assertion in Chromium. The helper now sends only actual field changes, matching ordinary user selection. Published programs did not change. The complete fresh native matrix passes before the final worker bundle is built and graded. Initial failed native/worker outputs remain historical evidence, not acceptance.

Fresh API/script types, selected canonical checks, registry/index, all 670 coding/263 native bindings, copy sweep, launch, build, bundle, both zero-vulnerability production dependency audits and diff checks pass. Grading/Learn integrity passes against a stand-in database. Selected progression proves 5 earlier solutions fail their next step and 3 checkpoint solutions fail their milestone. All five routes pass 80 fresh light/dark layout probes at eight widths from 320 through 1440 px, with no issues or unprobed routes, using server-derived API stand-ins. Bundle: 242998/243000 gzip bytes; twelve physical API handlers; archived Czech unchanged. Original/final English, hints, public/hidden checks, two QA variants and all nine published programs were read and separately reread. This is finite same-session model/worker/browser evidence, not independent-human, real-network, physical-device or authenticated acceptance.

PR #464 freezes only B124/B125 at head 5b1039569d1c7c06043b1dbf5ed1250491707d45, with 655 source reviews. Exact READY preview dpl_4LUYiFq3gzPbCvhyd7qh2QC2bJBJ passes eleven general checks and four actual Task board 1 Submits, zero guest XP/null progress and nine access locks, whole helpers 0. Required run 38986654569 must be checked separately before the protected merge. Current source has 25 reviews above verified production; protected release/exact production acceptance remain separate gates. #459 is deployed/closed. Preserve #458, #461, #463, post-audit #435/#444 work, owner/draft #365 holds, dedicated #190 acceptance and effective-bank reconciliation.

## PR #464 guarded production acceptance — 17 October 2026 UTC

PR #464 is merged and its exact production deployment is accepted. Frozen head 5b1039569d1c7c06043b1dbf5ed1250491707d45 passed required run 38986654569: verify 38m31s, SQL39s. Fresh OPEN/non-draft/exact-head, accepted main/base fef550f2fc674b2c5f25ad84df4ba6bd0b3b95ca, mergeability, all rollups, exact-head check/run and unchanged verify/sql app15368/strict:false guards returned0 and were read before the normal protected merge. Merge100b287b59f3d0cd73f889b9a6a2d1156357e8cc at17October2026 01:10:01UTC has exactly the accepted base and frozen head as parents. No force, admin override or protection change.

READY preview dpl_4LUYiFq3gzPbCvhyd7qh2QC2bJBJ and production dpl_ERBtGUFWnYvGiW6nZfQMzTvgAaiN match their exact commit and project with no alias error. Each passes11 general checks and4 actual Task board1 Submits: reference/independent alternative accepted, two wrong controls rejected, zero guest XP/null progress. Nine of ten requested tasks retain Premium/stage locks. Both whole helpers return0; production owns devshark.app before/after its probes. Helpers were frozen at655 source reviews before later batches. Protected access files are mode0600 and exact HTTPS authorities. No authenticated entitlement/account/progress/score/name fixture or cloud security/billing setting was written. Dedicated authenticated/cloud/physical acceptance remains #190.

B124/B125 bring verified production to655/725 coding and263/263 native reviews. Current source is675/725 through B129;50 React tasks remain. Twenty B126–B129 records await their own guarded release. Their current ledger contains126 matching current-hash worker outcomes,106 native expected verdicts and63 safe base25 checks. This aggregate replaces B126's old five-case Move up checkpoint with its six-case revision; it does not count the same task twice or add stale cases. Across the four batch builds,336 actual light/dark layout probes passed, including the existing checkpoint's repeated coverage. All675coding/263native identities are current and unique. B129's tested native drafts are byte-identical to all five final combined suites. Model evidence remains finite and same-session,not independent-human or whole-catalogue acceptance.

#459 is already deployed/closed. Keep #458 comment scanning, #461 fixture pagination and #463 compiler property creation open; the authored Analytics workaround is not the compiler fix. #435 Profile-only leaderboard preferences and #444 guide focus follow the whole audit. Owner/draft #365 holds, dedicated #190 acceptance and effective-bank reconciliation remain. A local optional microVM snapshot check was unconfigured and is not a pass.

## B129 final cart and initial wizard audit — 17 October 2026 UTC

B129 reviews the final Product explorer cart and Form wizard steps1–4: controlled Email checkpoint, email-validation milestone, controlled Name checkpoint and name/summary milestone. Current source reaches675/725 coding reviews;50React tasks remain. Verified production is655/725 coding and263/263 native reviews through#464. Five new records change exactly five hashes. All eleven published programs,prompts,previous requirements,starters,cumulative public suites and the existing negative cart QA remain byte-identical. Both wizard checkpoints publish only a reference. Add twenty ID-specific hidden cases and five English hints;no later stage is implicitly reviewed.

All32current-hash worker outcomes match:16valid programs(eleven published and five independent alternatives),five starters and eleven wrong controls. Frozen original suites accept all ten new wrong controls;the existing cannot-untick QA already fails:22/32baseline expectations matched. Chromium accepts16valid and rejects11wrong programs:27expected verdicts and50protocol assertions pass. Maximum valid worker case:495ms. Sixteen unknown-safe base25 checks and strict parsing of all501served React programs pass. Native drafts are validated before repository changes;all five final combined public/hidden suites are then proved byte-identical to the captured native suites. Published programs are also unchanged. No extra native rerun or untested-draft acceptance is claimed.

The full cart tests1/99,zero/100/negative/fractional/empty/nonnumeric rejected edits,independent amounts,hidden controls,weighted totals and a60-operation model. Rejected edits retain the last value;deselect/reselect and Clear remove old quantities;Select page preserves existing amounts. The controlled Email checkpoint tests ordinary long values,state restoration after an external DOM write,separate/fresh roots and actual cancelable form submission. It imposes neither later validation nor raw whitespace behavior that would reject a native email input's sanitation.

Email validation follows the exact expression from the brief,including.org,one-character TLDs,plus/subdomains,edge trimming,BMP Unicode and regex-valid doubled-dot domains. No additional domain or RFC rule is invented. Invalid attempts remain editable and a successful submit clears the old alert. The Name checkpoint distinguishes controlled state from defaultValue,retains accepted Email through Back and supports independent/fresh roots. Name Next need only prevent navigation at this prerequisite;later validation and backward Name persistence are not imposed early. The full Name milestone accepts unambiguous two-character BMP names,rejects blank/one-character whitespace cases,and checks exact trimmed summary text with an identity normalizer. This catches missing trimming that passed default normalized getByText assertions. Long literal names,parent renders,edited Back flows and separate/fresh summaries are checked. Its hint states the existing JavaScript replace(/\s/g,'').length operation. Prompt wording is rated3/5 because character representation could be stated more clearly;ambiguous supplementary-codepoint/grapheme inputs are not used to penalize another reasonable interpretation.

Fresh API/script types,selected canonical/progression checks,registry/index,all675coding/263native bindings,copy sweep,launch,build,bundle,both zero-vulnerability production dependency audits and diff pass. Grading/Learn integrity passes against a stand-in database. Selected progression proves3earlier solutions fail their next step and2checkpoint solutions fail their milestone. All five routes pass80fresh light/dark probes at eight widths320–1440px,with no issues or unprobed routes,using server-derived API stand-ins. Bundle242998/243000gzip;twelve physical API handlers;archived Czech unchanged. Original/final English,hints,suites,negative QA and all eleven whole programs are read and separately reread. This is finite same-session model/worker/native evidence,not independent-human,real-network,physical-device or authenticated acceptance.

PR#464 is merged at100b287b59f3d0cd73f889b9a6a2d1156357e8cc after required38986654569(verify38m31s,SQL39s) and fresh protected guards. Exact preview/production dpl_4LUYiFq3gzPbCvhyd7qh2QC2bJBJ/dpl_ERBtGUFWnYvGiW6nZfQMzTvgAaiN pass11general plus4actual Task board1 Submits,zero guest XP/null progress,nine other access locks,whole helpers0. Production matches exact merge/project and owns devshark.app before/after probes. Twenty B126–B129 reviews remain staged above verified655production. Their current ledger replaces the old B126checkpoint cases with its revision,without adding a task. Keep#458/#461/#463,#435/#444after the whole audit,owner/draft#365holds,#190dedicated acceptance and effective-bank reconciliation open.

## B130 consent, Company and draft checkpoint audit — 17 October 2026 UTC

B130 individually reviews Form wizard consent, terminal submission, the Company checkpoint, business validation and the Save draft checkpoint. Source review coverage is 680/725 coding tasks; 45 React tasks remain. Verified production remains 655 coding and 263 native records through #464. PR #465 carries the earlier twenty B126–B129 reviews and has accepted exact-preview evidence, with required CI still pending at this checkpoint.

The Company checkpoint's published reference omitted the newly added account and company from its inherited Start over transition. The new native draft fails that reference alone, reporting business instead of personal. Extending the existing reset handler with both new fields repairs it. The old broken reference is retained as an extra negative control. Only that one published program changes; the other eight programs, all public suites, prompts, earlier requirements, starters and QA variants remain byte-identical. Exactly five hashes change. Twenty ID-specific hidden cases and five English hints are added after checkpoint construction.

All 30 final-hash worker outcomes match: 14 valid programs (nine published and five independent alternatives), five starters and eleven wrong controls. The frozen original suites match 19/30 expectations and accept all eleven negative controls, including the broken old reference. Passing the old public suite is not evidence that this reference met its inherited reset contract. The repaired native draft passes 25 expected verdicts and 48 protocol assertions in Chromium. All five final combined suites and all nine final published programs are byte-identical to those native-tested captures. Fourteen supported-board complexity checks retain base 25 XP without penalizing unknown estimates; all 501 shipped React programs parse strictly.

Consent is reversible, gates Submit both ways and resets after Back, including unchanged summaries. Terminal receipts use actual literal trimmed fields, remove editable controls and remain independent of parent renders and other mounted wizards. Repeated Start over clears all required fields. The Company checkpoint checks controlled long values and external DOM edits, repeated account switches and complete reset, without imposing the following milestone's validation or receipts. Business validation checks blank/one-character rejection and exact two-character BMP acceptance; personal records neither validate hidden Company nor include it in review or receipt. Company wording is rated 3/5 because character representation is unspecified; ambiguous supplementary-codepoint/grapheme behavior is not penalized. Save draft stores exactly version plus four current fields, without consent or step, before submission. Invalid input can be saved without validation or navigation; repeated saves overwrite only the named key. Independent roots retain their own fields and new mounts do not restore implicitly. No future Restore or unstated quota policy is imposed on this checkpoint.

Fresh API/script typechecks, selected canonical and progression contracts (five earlier solutions and three checkpoint solutions fail their subsequent steps), registry/index, all 680 coding and 263 native bindings, copy sweep, launch, build, bundle, both zero-vulnerability production dependency audits and diff checks pass. Grading/Learn integrity passes against a stand-in database. All five routes pass 80 fresh light/dark probes at eight widths 320–1440 px, with no issues or unprobed routes, using server-derived API stand-ins. Bundle size is 242998/243000 gzip bytes. Twelve physical API handlers and archived Czech are unchanged. All original and final English material, earlier requirements, hints, suites, starters and nine whole programs are read and separately reread. This is finite same-session model, worker and native evidence, not independent-human, real-network, physical-device or authenticated acceptance. Preserve engineering #458/#461/#463, UI #435/#444 after the full audit, owner/draft #365 holds, dedicated #190 acceptance and effective-bank reconciliation.

## B131 draft restoration and guest-list audit — 17 October 2026 UTC

B131 reviews the full Form wizard draft milestone and State and lists levels 1–4. Source review coverage reaches 685/725 coding tasks; 40 React tasks remain. Verified production remains 655 coding and 263 native records through #464. Thirty reviews are staged, including twenty in #465; its exact preview is accepted and required CI is still pending. Five new review identities change exactly five task hashes. All fifteen published programs, prompts, earlier requirements, public suites, starters, approaches and QA metadata stay byte-identical. Twenty-six ID-specific hidden cases and five English hints are added.

All 35 final-hash worker outcomes match: twenty valid programs (fifteen published and five independent alternatives), five starters and ten semantic wrong controls. The frozen original suites match 25/35 expectations and accept all ten wrong controls. Chromium validates thirty expected verdicts and 53 protocol assertions. Final combined suites and all fifteen published programs are byte-identical to the native-tested captures. Twenty supported-board complexity checks preserve base 25 XP without penalizing unknown estimates; all 501 shipped React programs parse strictly.

Draft validation checks missing, null, numeric and malformed fields, versions and account values before any state change, with every live field retained on rejection. Valid unfinished string drafts resume at Email, clearing prior errors and consent and retaining normal subsequent validation. Business restoration preserves Company; Save uses the exact schema; Clear removes only its key without clearing the live form. Terminal actions, shared storage and independent/fresh mounts are checked. All three inspected implementations handle storage exceptions; these new runtime cases cover invalid/missing data, not injected storage failures.

Guest inputs retain long literal values through parent renders and external DOM edits, trim both ends, ignore whitespace and accept same-name guests before the later duplicate-policy level. Removing a middle row preserves stable surviving DOM identities, and removing one duplicate does not remove the other. Arrivals distinguish same-name identities, reach all-three totals, handle removal and match a 35-operation independent state model. Published programs are manually checked for new-object updates; runtime outcomes do not prove arbitrary code never mutates objects. Filtered additions create waiting guests; both toggle directions update the view, while filtered removal keeps hidden guests and both outputs count the full list. Tests use accessible names without requiring one label wrapper or handler shape. Earlier levels do not inherit later requirements.

Fresh API/script typechecks, selected canonical/progression checks, registry/index, all 685 coding and 263 native bindings, copy sweep, launch, build, bundle, both zero-vulnerability production dependency audits and diff checks pass. Grading/Learn integrity passes against a stand-in database. All five routes pass 80 fresh light/dark probes at eight widths 320–1440 px with no issues or unprobed routes, using server-derived API stand-ins. Bundle size remains 242998/243000 gzip bytes; twelve physical API handlers and archived Czech are unchanged. Original/final English, prior requirements, hints, approaches, public/hidden suites and all fifteen whole programs are read and separately reread. Finite same-session model, worker and native evidence is not independent-human, real-network, authenticated or physical-device acceptance. Engineering #458/#461/#463, UI #435/#444 after the full audit, owner/draft #365 holds, dedicated #190 acceptance and effective-bank reconciliation remain open.

## B132 duplicate alerts and asynchronous loading audit — 17 October 2026 UTC

B132 reviews State and lists level 5 and Effects and loading levels 1–4. Source review coverage reaches 690/725 coding tasks; 35 React tasks remain. Verified production remains 655 coding and 263 native records through #464. Thirty-five reviews are staged, including twenty in #465, whose exact preview is accepted while required CI remains pending.

All three state5 published programs kept an old duplicate alert after a whitespace-only Add, despite the existing no-message rule. The original native draft fails exactly those three programs on that one transition. Each template now clears the alert before returning for blank input at state5 only; earlier state1–4 programs remain byte-identical. The old reference remains an extra negative control. The other twelve published programs, all public suites, prompts, earlier requirements, starters, approaches and existing QA metadata remain exact. Exactly five task hashes change. Twenty-eight ID-specific hidden cases and five English hints are added.

All forty final-hash worker outcomes match: 23 valid programs (fifteen published, five independent alternatives and three existing positive QA variants), five starters and twelve wrong controls (ten new semantic mutants, the old blank-alert reference and one existing late-error QA). The frozen original suites match 30/40 expectations, accepting ten of the eleven newly added negative controls. The Error-instance-only restriction and existing late-error QA already fail the original worker suite. Old public-suite success does not establish that the original state5 programs met the blank-alert contract. Chromium validates 35 expected verdicts and 58 protocol assertions. All five final combined suites and fifteen final published programs are byte-identical to the native-tested repaired/original captures. Twenty-three supported-board complexity checks preserve base 25 XP without penalizing unknown estimates; all 501 shipped React programs parse strictly.

Duplicate checks cover the whole list even when the original guest is hidden, compare exact normalized names rather than prefixes, permit re-add after removal, preserve rejected text and clear stale alerts on blank or successful Add. Mounted roots retain separate state. Initial loading tests arbitrary user ids, every supplied literal record, delayed and empty completion, stable-loader renders and independent/fresh mounts without imposing later features early. Repeated retries handle string, null and object rejection values, one new request per attempt, visible Loading before settlement, and recovery to either a list or an empty result. Existing valid nested-Retry markup remains supported.

Search uses the complete trimmed lowercase substring, including internal spaces and Unicode lowercase, supports editing while Loading, distinguishes empty sources from no matches and makes no extra request. Request replacement checks three generations, an obsolete middle success, the first late failure and an obsolete empty answer against the current filtered list. Stable loader references do not refetch. The deferred Promise/act tests use no live network and do not claim strict-mode or physical-device acceptance. The docs were checked against current official React guidance while the installed React version remains unchanged.

Fresh API/script typechecks, selected canonical/progression checks, registry/index, all 690 coding and 263 native bindings, copy sweep, launch, build, bundle, both zero-vulnerability production dependency audits and diff checks pass. Grading/Learn integrity passes against a stand-in database. All five routes pass eighty fresh light/dark probes at eight widths 320–1440 px with no issues or unprobed routes, using server-derived API stand-ins. Bundle size remains 242998/243000 gzip bytes; twelve physical API handlers and archived Czech are unchanged. Original/final English, earlier requirements, hints, approaches, public/hidden suites, fifteen whole published programs and all four existing QA programs are read and separately reread. Finite same-session model, worker and native evidence is not independent-human, real-network, authenticated or physical-device acceptance. Keep engineering #458/#461/#463, UI #435/#444 after the whole audit, owner/draft #365 holds, dedicated #190 acceptance and effective-bank reconciliation open.

## PR #465 guarded production acceptance — 17 October 2026 UTC

PR #465 is merged and its exact production deployment is accepted. Frozen head 7ebc83bd6c30b5d2fd5260d7c6c505f89ba4ceb1 passed required run38990331987: verify40m05s and SQL39s. Fresh OPEN/non-draft, exact head and accepted main/base100b287b59f3d0cd73f889b9a6a2d1156357e8cc, mergeability, clean state, all rollups, exact-head checks/run/jobs and unchanged verify/sql app15368/strict:false guards returned0 and were read before the normal protected merge. Accepted guards are timestamped17October2026 02:01:00UTC. Merge7b08b1a42663c1f9d7bad59df52efc5e842f36d6 at02:01:07UTC has exactly that base and frozen head as parents. No force, admin override or protection change.

READY preview dpl_Buiop7J1VBeoQe53xv7kBVKxsEiY and production dpl_GM4aeTWVtBDcW5D57jnXn9Lssfe8 match the exact commits/project and have no alias error. Each passes eleven general checks and eight actual Product explorer1/Form wizard1 Submits: references and alternatives accepted, semantic wrong controls rejected, zero guest XP and null progress. Eighteen of twenty requested tasks retain Premium or earlier-stage access locks. Both whole helper sequences return0. Production owns devshark.app before and after its probes; exact merge parents are fetched and checked. Helpers and exports were frozen at675source reviews before later edits. Protected access files are mode0600 and exact HTTPS authorities. No authenticated account, entitlement, progress, score or name fixture is written. Dedicated authenticated/cloud/physical acceptance remains #190.

Twenty B126–B129 records bring verified production to675/725 coding and263/263 native reviews. Their current ledger contains126 matching current-hash worker outcomes,106 native expected verdicts,63 safe base25 checks and336 recorded batch layout probes. The revised B126 Move up checkpoint replaces its older cases without adding an identity; the layout aggregate includes the explicit checkpoint recheck. Current committed source is690/725 through B132, with35React tasks remaining and fifteen B130–B132 reviews staged. Their accepted evidence totals105 current-hash worker outcomes,90 native verdicts,57 safe25 checks and240fresh layouts; B130 repaired one complete reset and B132 repaired three blank-alert handlers.

B133 remains unaccepted while its server recheck runs. Its first host-created inherited-input case exposes the isolated export bridge's custom-prototype limitation, tracked in new #466. Seventeen correct programs fail that initial worker phase despite identical native suites passing; that phase is not acceptance. Current private cases construct inherited inputs from mutable learner-owned API replies and add four own-only negative controls, preserving the task contract without a runtime isolation change. Do not count B133 as five completed reviews until its current worker results and all local gates pass.

Keep engineering #458, #461, #463 and #466 open. #435 Profile-only leaderboard preferences and #444 guide focus follow the whole audit. #459 is deployed/closed. Owner/draft #365 holds, dedicated #190 acceptance and effective-bank reconciliation remain. Evidence is finite and same-session, not independent-human, authenticated, physical-device or complete-catalogue acceptance.

## B133 title, link client and planner-list audit — 17 October 2026 UTC

B133 reviews Effects and loading 5, Link shortener 4–5, the planner client checkpoint and its loading milestone. Source coverage reaches 695/725 coding tasks; thirty React tasks remain. Verified production is 675 coding and 263 native records through accepted #465; twenty B130–B133 reviews are staged above it. Exactly five task hashes change. All thirteen published programs, public suites, prompts, earlier requirements, starters, approaches and QA metadata remain byte-identical. Thirty-one ID-specific hidden cases and five English hints are added. The planner hint changes are scoped to the two exact task IDs, retaining all other generated app hints.

All 42 current-hash worker outcomes match (34 rerun after four API-case changes plus eight unchanged title outcomes retained at the same hash): 22 valid programs (thirteen published, five alternative UIs and four existing positive QA programs), five starters and fifteen wrong controls (fourteen semantic negatives,including four own-only normalizers,and the existing missing-status QA). The frozen original suites match 28/42 expectations and accept all fourteen new wrong controls; the existing negative QA already fails. Four private alternative UIs retain an already-read authored API prefix, so they are independent UI implementations rather than independent whole APIs. Chromium validates 37 expected verdicts and 60 protocol assertions. All five final combined suites and thirteen published programs match the captured native-tested bytes. The first host-created inherited-input phase fails seventeen supported worker programs due to the still-open #466 bridge limitation,despite passing in the browser,and is not accepted. Current cases construct truly inherited inputs from fresh mutable learner-owned API replies,check required fields are not own,and keep the backing API unchanged. Four own-only normalizer controls fail. This preserves the original contract without changing isolation. The baseline reuses38unchanged frozen results plus four new controls;current acceptance retains eight hash-identical title results and reruns the other34. Native captures are rerun against all37programs after the construction change. Twenty-two supported-board complexity checks retain base 25 XP without penalizing unknown estimates; all 501 shipped React programs parse strictly.

Title checks count four loaded users despite filtering, retain the mount-time title across changed loaders and restore arbitrary or empty original titles. The prior loading, retry, search and cancellation checks are also exercised at this final level. No additional ownership policy for simultaneous global-title writers is imposed. Link clients render arbitrary slugs, literal URLs, zero and large visits, preserve their transport across parent renders and keep separate/default/fresh local APIs independent. Deferred Visit POSTs settle before the authoritative GET reload; repeated mdn visits are not hardcoded or lost by recreating the store. Multiple failed GETs can retry to an empty success. Shortening retains both fields after409/400/503 and network rejection, makes no list reload on failure, and recovers through201 with cleared fields and alert. Earlier header and pending-control checks remain.

The reference-only planner checkpoint requires successful list rendering and real hours, without imposing the following loading/error/Retry behavior early. The full milestone exercises actual amounts above nine, all supplied records, stable calls, separate roots/default seed and multiple retries. Direct API checks retain inherited ordinary fields, opaque extras, frozen-seed ownership, fresh replies, numeric boundaries, immutable updates, version/conflict precedence, exact routes and monotonic IDs. These are in-memory localFetch exercises, not a deployed HTTP service. Published unmount guards are read; the finite tests do not prove all arbitrary code ignores every unmounted update. The planner milestone's explanation is rated3/5 because its reference carries unused future-stage mutation state/helpers; the other authored styles are more narrowly scoped. This remains above the retirement threshold and is not reported as repaired.

Fresh API/script types, selected canonical/progression contracts, registry/index, all 695 coding and 263 native bindings, copy sweep, launch, build, bundle, both zero-vulnerability production dependency audits and diff checks pass. Grading/Learn integrity passes against a stand-in database. All five routes pass eighty fresh light/dark probes at eight widths320–1440px, with no issues or unprobed routes, using server-derived API stand-ins. Bundle remains242998/243000gzip bytes; twelve physical API handlers and archived Czech are unchanged. Original/final English, prior requirements, hints, approaches, public/hidden suites, thirteen whole programs and all five existing QA programs are read and separately reread. Shared API prefixes are byte-compared before reading the new UI bodies; every QA program is checked as the exact declared edits of its reference. Finite same-session model, worker and native evidence is not independent-human, real-network, authenticated or physical-device acceptance. The next B134 reading confirms Create-POST409 misrouting in eight published programs and three positive QA variants (eleven of thirteen native diagnostic programs fail only this new assertion),tracked in#467. No B134 review or repair is counted here. Engineering #458/#461/#463/#466/#467, UI #435/#444 after the full audit, owner/draft #365 holds, dedicated #190 acceptance and effective-bank reconciliation remain open.

## B134 planner forms, versioned changes and filtered deletion — 17 October 2026 UTC

B134 individually reviews the planner form checkpoint, creation, versioned hour updates, filter checkpoint and final pagination/deletion milestone. Current source reaches 700/725 coding reviews; 25 React tasks remain. Verified production remains 675 coding and 263 native through accepted #465. Twenty B130–B133 reviews are frozen in PR #468 at f9d930d1; five B134 reviews follow separately. PR #468 has exact READY preview acceptance: eleven general checks, eight actual Submits across state1/effects1, eighteen access locks among twenty requested tasks and whole helpers exit0. Its required CI and production release remain pending here.

All 42 current-hash worker outcomes match: nineteen valid programs (eleven published, five alternative UIs and three positive markup QA variants), five starters and eighteen wrong controls. The original suites match25/42 and accept seventeen wrong controls: nine new semantic mutants and eight old broken published programs. The navigation negative already fails originally. Chromium passes37 expected verdicts/60protocol assertions; final five combined suites and all eleven published programs are byte-identical to native-tested captures. Nineteen supported-program complexity checks keep base25XP without penalizing unknown estimates; all501shipped React programs parse strictly. Alternative UIs retain authored API prefixes, so they are independent UIs rather than independent whole APIs.

The actual #467 defect was method-independent409handling: failed creation displayed Changed elsewhere and refreshed as if it were a version conflict. The shared fix limits special conflict handling to PATCH in reference, junior and senior generators. It repairs24published programs in12unreviewed family IDs across planner, stockroom and workshops. Reference changes are conditional on stage6or later so reviewed stage5 outputs and all695previously accepted task hashes remain exact. The five reviewed planner IDs plus eight unreviewed sibling IDs have changed hashes; those siblings receive no review credit. Focused sibling checks pass26published/positive-QA programs in Chromium with49protocol assertions, plus34server outcomes including eight failed starters. These diagnostics preserve public/previous tests and distinguish POST409from PATCH409; they are not full individual sibling reviews. The general #466 bridge limitation remains open and isolation is unchanged.

The new scoped cases cover controlled long/empty drafts across rerenders, canceled checkpoint navigation without POST, invalid and boundary-valid submissions, JSON headers, pending duplicate clicks, failed statuses409/400/503/network rejection with both fields retained, no failure reload and later recovery. Custom IDs/current versions and repeated decrements above nine detect hardcoded update counters; stale external writes reload once without resubmission and the next action uses the authoritative version. Combined trimmed substring and hours>0filters include exactly one hour and transitions to zero. Full pagination filters before slicing, resets from later pages into multi-page subsets, shows0/0when empty, preserves every record on failed deletion and clamps after a successful last-page delete. Earlier checkpoints receive no future-stage pagination/deletion requirement. API inherited ordinary fields, opaque extras, immutable copying, route/ID rules, numeric boundaries and conflict precedence retain prior checks.

The first private native draft incorrectly demanded an enabled Create after clearing to an invalid empty form, and queried a zero-hour row that was off-page. Those failed fixture results are retained and unaccepted. Corrected cases allow disabled invalid controls and place the asserted row on the current page; all37native verdicts then pass. The private parallel diagnostic driver initially hit Python3.9event-loop ownership before producing an accepted aggregate; the corrected fresh run is the34/34family evidence. No learner runtime was loosened. Planner form-checkpoint explanation is rated3/5 because the reference retains unused future helpers/state; other quality fields pass. No independent-human review or arbitrary-code correctness claim is made.

Registry/index, all700coding and263native bindings, copy sweep, API/script types, scoped canonical/progression contracts, grading/Learn integrity against a stand-in database, launch, build, bundle, both zero-vulnerability production audits and diff pass. Eighty fresh light/dark probes at eight widths320–1440px find no issues or unprobed routes using server-derived API stand-ins. Bundle remains242998/243000gzip bytes; twelve physical API handlers and archived Czech are unchanged. English prompts, earlier requirements, hints, starters, public/hidden suites, all eleven programs and three exact QA edits were read and separately reread; shared fully read prefixes were byte-compared before new UI reading. Evidence remains finite and same-session, without authenticated/Premium, real-network or physical-device acceptance. Continue25React tasks, effective-bank reconciliation, engineering#458/#461/#463/#466, release of#467, then UI#435/#444. Owner, draft#365 and dedicated#190holds remain unchanged.

## B135 continued full-stack client audit — 17 October 2026 UTC

B135 individually reviews five tasks: react-fullstack-stockroom-5-start, react-fullstack-stockroom-5, react-fullstack-stockroom-6-start, react-fullstack-stockroom-6, react-fullstack-stockroom-7. Current source reaches705/725 coding reviews;20React tasks remain. Verified production remains675coding/263native through#465. Twenty B130–B133reviews are frozen in PR#468 with accepted exact preview and pending required CI/normal release;10subsequent five-task reviews follow separately.

All36current-hash worker outcomes match:19valid programs (11published,five alternative UIs and3positive markup QA variants),five starters and12wrong controls. Frozen original suites match25/36;11negative controls accepted before the new checks are now rejected. Every final raw compile-error field is clear. Chromium passes31expected verdicts/54protocol assertions; every final combined suite and all11published programs match the native-tested bytes. 19supported-program checks retain base25XP for uncertain complexity; all501shipped React programs parse strictly. The five UIs reuse authored API prefixes,so they are not independent whole-API implementations.

Exactly five task hashes change through20ID-specific hidden cases and five English hints. All published programs,public suites,original prompts,earlier requirements,starters and QA code remain byte-identical. The #467family program repair belongs to B134 and is not counted again; its eight sibling fixes did not approve those tasks. The general inherited-host bridge issue#466 remains open. Current inherited-input tests use ordinary mutable learner-owned API records without loosening isolation or changing the API contract.

Render all records through one stable per-mount API transport. The checkpoint receives complete arbitrary successful lists and real amounts above nine. It checks stable parent renders and separate/fresh default APIs without requiring future loading/error behavior. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

Load and retry authoritative collections without hardcoded amounts. Multiple rejected and non-successful loads can retry to an empty success. Arbitrary amounts, complete lists and independent roots expose capped values and hardcoded seeds. The reference carries unused future mutation state/helpers, scored3/5 for explanation; the narrower other styles and all runtime behavior remain valid. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

Keep the controlled draft without premature creation. Long and empty controlled fields remain intact across rerenders. Form submission is canceled and creates nothing. No future POST or validation feedback policy is imposed. Unused future reference helpers remain a3/5 explanation caveat. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

Create valid records while preserving failed drafts and pending guards. Creation covers normalized boundaries and invalid drafts, JSON headers, pending duplicate clicks, failed409/400/503/rejected requests with both fields retained and later success. The shared #467method repair already belongs to B134; this batch does not count that repair again. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

Apply current-version updates and recover safely from conflicts. Custom identities, versions, amounts above nine and repeated changes expose hardcoded counters or stale version1. External changes reload once and the next action uses the new version. Earlier creation, zero and pending behavior remain checked; #467was repaired in B134. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

API/script types,scoped canonical/progression contracts,registry/index,all705coding/263native bindings,copy sweep,grading/Learn integrity against a stand-in database,launch,build,bundle,both zero-vulnerability production audits and diff pass. Eighty fresh light/dark probes at eight widths320–1440px find no issues or unprobed routes using server-derived API stand-ins. Bundle remains242998/243000gzip bytes. Twelve physical API handlers and archived Czech remain unchanged. Full English/prior requirements,hints,starters,public/hidden suites,all11programs and3exact QA edits are read and separately reread. Whole program/public/starter bytes are compared to the fully read planner counterparts after domain substitutions; differing wording is read separately. Native and worker evidence is finite and same-session,not independent-human,authenticated,real-network or physical-device acceptance. Continue20React tasks,effective-bank reconciliation,engineering#458/#461/#463/#466,release#467,then UI#435/#444. Owner,draft#365and dedicated#190holds remain unchanged.

## B136 continued full-stack client audit — 17 October 2026 UTC

B136 individually reviews five tasks: react-fullstack-stockroom-8-start, react-fullstack-stockroom-8, react-fullstack-workshops-5-start, react-fullstack-workshops-5, react-fullstack-workshops-6-start. Current source reaches710/725 coding reviews;15React tasks remain. Verified production remains675coding/263native through#465. Twenty B130–B133reviews are frozen in PR#468 with accepted exact preview and pending required CI/normal release;15subsequent five-task reviews follow separately.

All33current-hash worker outcomes match:16valid programs (9published,five alternative UIs and2positive markup QA variants),five starters and12wrong controls. Frozen original suites match22/33;11negative controls accepted before the new checks are now rejected. Every final raw compile-error field is clear. Chromium passes28expected verdicts/51protocol assertions; every final combined suite and all9published programs match the native-tested bytes. 16supported-program checks retain base25XP for uncertain complexity; all501shipped React programs parse strictly. The five UIs reuse authored API prefixes,so they are not independent whole-API implementations.

Exactly five task hashes change through28ID-specific hidden cases and five English hints. All published programs,public suites,original prompts,earlier requirements,starters and QA code remain byte-identical. The #467family program repair belongs to B134 and is not counted again; its eight sibling fixes did not approve those tasks. The general inherited-host bridge issue#466 remains open. Current inherited-input tests use ordinary mutable learner-owned API records without loosening isolation or changing the API contract.

Combine substring and availability filters without mutating records. Substring matching, exactly-one availability, combined filters and an update to zero are checked while all stored records remain. No future pagination/deletion requirement is imposed. Earlier creation and concurrency checks remain. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

Paginate filtered collections and preserve records on failed deletion. A five-record model exercises filter-before-slice, later-page reset into a multi-page subset, empty0/0, failed last-page deletion preserving every record and successful clamping. Retained creation, version and availability behavior still runs. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

Render all records through one stable per-mount API transport. The checkpoint receives complete arbitrary successful lists and real amounts above nine. It checks stable parent renders and separate/fresh default APIs without requiring future loading/error behavior. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

Load and retry authoritative collections without hardcoded amounts. Multiple rejected and non-successful loads can retry to an empty success. Arbitrary amounts, complete lists and independent roots expose capped values and hardcoded seeds. The reference carries unused future mutation state/helpers, scored3/5 for explanation; the narrower other styles and all runtime behavior remain valid. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

Keep the controlled draft without premature creation. Long and empty controlled fields remain intact across rerenders. Form submission is canceled and creates nothing. No future POST or validation feedback policy is imposed. Unused future reference helpers remain a3/5 explanation caveat. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

API/script types,scoped canonical/progression contracts,registry/index,all710coding/263native bindings,copy sweep,grading/Learn integrity against a stand-in database,launch,build,bundle,both zero-vulnerability production audits and diff pass. Eighty fresh light/dark probes at eight widths320–1440px find no issues or unprobed routes using server-derived API stand-ins. Bundle remains242998/243000gzip bytes. Twelve physical API handlers and archived Czech remain unchanged. Full English/prior requirements,hints,starters,public/hidden suites,all9programs and2exact QA edits are read and separately reread. Whole program/public/starter bytes are compared to the fully read planner counterparts after domain substitutions; differing wording is read separately. Native and worker evidence is finite and same-session,not independent-human,authenticated,real-network or physical-device acceptance. Continue15React tasks,effective-bank reconciliation,engineering#458/#461/#463/#466,release#467,then UI#435/#444. Owner,draft#365and dedicated#190holds remain unchanged.

## B137 continued full-stack client audit — 17 October 2026 UTC

B137 individually reviews five tasks: react-fullstack-workshops-6, react-fullstack-workshops-7, react-fullstack-workshops-8-start, react-fullstack-workshops-8, react-todo-dashboard. Current source reaches715/725 coding reviews;10React tasks remain. Verified production remains675coding/263native through#465. Twenty B130–B133reviews are frozen in PR#468 with accepted exact preview and pending required CI/normal release;20subsequent five-task reviews follow separately.

All39current-hash worker outcomes match:22valid programs (13published,five alternative UIs andthree positive markup QA variants and one existing filled example),five starters and12wrong controls. Frozen original suites match27/39;12negative controls accepted before the new checks are now rejected. Every final raw compile-error field is clear. Chromium passes34expected verdicts/57protocol assertions; every final combined suite and all13published programs match the native-tested bytes. 22supported-program checks retain base25XP for uncertain complexity; all501shipped React programs parse strictly. Four workshop alternative UIs reuse authored API prefixes; the Todo alternative uses its own reducer and serial identities. No independent whole-API claim is made for those four.

Exactly five task hashes change through30ID-specific hidden cases and five English hints. All public suites,earlier requirements,starters and skeletons remain byte-identical. One published Todo dashboard reference and its existing complete filled example replace timestamp identities with UUIDs. The prompt/hint/approach clarify separate stable identities without requiring one key strategy. All other published programs and markup QA are unchanged. Thirteen final published programs,three markup QA programs and the corrected filled example match native-tested bytes. The #467family program repair belongs to B134 and is not counted again; its eight sibling fixes did not approve those tasks. The general inherited-host bridge issue#466 remains open. Current inherited-input tests use ordinary mutable learner-owned API records without loosening isolation or changing the API contract.

Create valid records while preserving failed drafts and pending guards. Creation covers normalized boundaries and invalid drafts, JSON headers, pending duplicate clicks, failed409/400/503/rejected requests with both fields retained and later success. The shared #467method repair already belongs to B134; this batch does not count that repair again. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

Apply current-version updates and recover safely from conflicts. Custom identities, versions, amounts above nine and repeated changes expose hardcoded counters or stale version1. External changes reload once and the next action uses the new version. Earlier creation, zero and pending behavior remain checked; #467was repaired in B134. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

Combine substring and availability filters without mutating records. Substring matching, exactly-one availability, combined filters and an update to zero are checked while all stored records remain. No future pagination/deletion requirement is imposed. Earlier creation and concurrency checks remain. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

Paginate filtered collections and preserve records on failed deletion. A five-record model exercises filter-before-slice, later-page reset into a multi-page subset, empty0/0, failed last-page deletion preserving every record and successful clamping. Retained creation, version and availability behavior still runs. All published programs/public suites remain unchanged in this batch. Alternative UIs reuse authored API prefixes and are not independent whole APIs. Inherited API checks use learner-owned records without fixing the general bridge limitation#466.

Keep fetched and locally added todos individually removable with accurate derived counts. A deterministic repeated timestamp exposes real item-identity loss in the unchanged reference; junior and senior pass. A private UUID correction then passes all three styles. The same defect is read in the complete filled example and repaired there too. The full draft includes corrected filled code and both old programs as negative controls. A mixed model adds repeated titles and removes completed and unfinished rows, checking every title/status/count through empty and recovery. It does not require one particular key strategy or reject additional row controls. Original public tests and training API semantics remain; no arbitrary out-of-domain server IDs or whitespace-trimming policy is imposed.

API/script types,scoped canonical/progression contracts,registry/index,all715coding/263native bindings,copy sweep,grading/Learn integrity against a stand-in database,launch,build,bundle,both zero-vulnerability production audits and diff pass. Eighty fresh light/dark probes at eight widths320–1440px find no issues or unprobed routes using server-derived API stand-ins. Bundle remains242998/243000gzip bytes. Twelve physical API handlers and archived Czech remain unchanged. Full English/prior requirements,hints,starters,public/hidden suites,all13programs,three exact markup-QA edits and the complete filled example are read and separately reread. Whole program/public/starter bytes are compared to the fully read planner counterparts after domain substitutions; differing wording is read separately. Native and worker evidence is finite and same-session,not independent-human,authenticated,real-network or physical-device acceptance. Continue10React tasks,effective-bank reconciliation,engineering#458/#461/#463/#466,release#467,then UI#435/#444. Owner,draft#365and dedicated#190holds remain unchanged.

## Guarded PR #468 production acceptance — 17 October 2026 UTC

PR #468 is merged and its exact production deployment is accepted. Frozen head f9d930d124a93fb8c8a7392e3c43af15eccd5d23 passes required run38995252316: verify35m17s (2117s), SQL1m07s (67s). All fresh OPEN/non-draft, exact-head/base/main, mergeability, clean state, rollup, check-run, job and unchanged branch-protection guards returned0 and were read before merging. Required verify/sql still belong to app15368 with strict:false; no force, admin override or protection change. Guards were accepted17October2026 at03:13:13UTC. The normal merge ba9ffc7c185cf07293ef2a71c2bb944d9154b8fe at03:13:30UTC has exactly7b08b1a42663c1f9d7bad59df52efc5e842f36d6 and the frozen head as parents, verified after fetching.

Exact READY preview dpl_HxjcWQDftLuzAatXNQhEXcUV6Xfz and production dpl_79uNiBmDXXuLW2nXoycauMPtfTz4 match their commits and project with no alias error. Each passes eleven general checks and eight actual Submits across state1/effects1: references and alternative UIs pass, semantic negatives fail, guest XP stays0 and progress stays null. Eighteen of twenty requested tasks remain correctly locked by Premium or stage access. Both complete helper sequences exit0. Production owns devshark.app before and after the probes; the canonical homepage also answers HTTP200. Access files are private mode0600 with exact validated HTTPS authorities. No entitlement bypass, authenticated/Premium or physical-device claim is made; dedicated acceptance remains tracked in#190.

B130–B133 now deploy695/725 coding and263/263 native reviewed records. Their twenty-task evidence is147 current-hash worker outcomes,127 native verdicts,79 safe base25 checks and320 fresh batch layout probes. B133 retains eight unchanged-hash title results and reruns34 changed API-stage cases; its rejected host-created-input phase is not accepted evidence. Final learner-owned inherited-record cases reject four own-only controls while leaving general bridge issue#466 open.

Current committed source is715/725 through B137; ten React projects remain. Twenty B134–B137 reviews are staged above production, with150 worker outcomes,130 native verdicts,76 safe25 checks and320 fresh layouts. Additional B134 family regressions34server/26native are not extra reviews. All eight sibling IDs repaired in B134 have subsequently received their own individual reviews in B135–B137. The #467 PATCH-only conflict repair and Todo reference/filled-example identity repair are staged, not part of this production release. Keep engineering#458/#461/#463/#466, release#467, then UI#435/#444. Owner, draft#365, effective-bank and dedicated#190 holds remain. Evidence is finite and same-session, not independent-human or complete-catalogue acceptance.

## B138 async client and data-dashboard audit — 17 October 2026 UTC

B138 individually reviews Product search, Search as you type, Autosave a note, User directory and Posts dashboard. Current source reaches720/725 coding reviews; five final React projects remain. Verified production is695coding/263native through accepted#468 at ba9ffc7c. Twenty B134–B137reviews are frozen in PR#469 at2d03eb8e with150worker/130native/76safe25/320layouts. Its exact READY preview passes eleven general checks and preserves twenty guest access locks; no new-cohort Submits were possible. Required run38998515618 and production release remain pending. B138 adds five separately and is not part of that frozen PR.

All44current-hash worker outcomes match:23valid programs (fifteen published,five alternative clients,two positive markup QA variants and one existing filled product example),five starters and16wrong controls. Frozen original suites match29/44:15wrong controls previously accepted are now rejected; the existing negative autosave QA already fails originally. Every raw compile-error field is clear. Chromium passes39expected verdicts/62protocol assertions. All fifteen final published programs,three final QA programs and the unchanged filled product example match the native-tested bytes. Twenty-three supported-program checks keep base25XP for uncertain complexity; all501shipped React programs parse strictly. These are finite same-session checks,not proof over arbitrary learner programs.

Exactly five task hashes change through eleven scoped cases,five English hints,eight published program changes and an autosave contract/skeleton clarification. Public suites,starters,earlier requirements and the filled product example remain unchanged. Book senior now debounces raw input before trimming,so trailing-space changes restart the promised100ms wait. Autosave's three styles keep the debounce while another value is being saved,even when the newest text returns to a previous saved value; the pending success then saves that newest text. The brief distinguishes mounted serialization,successful queued continuation,Retry after failure and the immediate unmount cleanup. The skeleton and approach agree. Original/fixed focused browser diagnostics isolate both defects before source changes.

The four remaining published changes retain the API/cache/pagination or scaling plans explicitly requested by the directory and posts briefs. A first export guard correctly refused acceptance because global board comment stripping removed the newly authored notes. An explicit server-only CodingSolution.boardPlan preface now travels after normal stripping; unrelated authoring comments and all other715reviewed task hashes remain unchanged. The content contract checks comment-only plans,retention on both boards,default stripping for other boards and the two required examples. It does not semantically grade arbitrary learner comments. General parser defect#458 is not repaired. New#470 stays open for the final project briefs,a separate previously reviewed comments-viewer revision and the normal guarded release. No extra identity is credited for that future revision.

Data models cover six arbitrary nested products,category/title unions,zero prices,empty results,eight directory records,full stable city choices under combined filters,fifteen posts including a nine-post author group,repeated author selection and exact pressed states. Async checks cover exact two-character book queries,constructor-key and empty-answer caching,HTTP failure and immediate retry,short-query aborts,full raw typing delays,empty and multiline note bodies,non-ok saves and repeated Retry without overlapping writes. The existing missing-saved-ref negative remains rejected. Whitespace trimming and non-ASCII city collation are not specified by two data briefs; ambiguous values are not used to penalize another reasonable interpretation (wording3/5). Unmount delivery/backend ordering is not proven (autosave explanation3/5). Posts reference repeatedly copies a bucket and may grow quadratically for an unbounded single-author group; its explanation is3/5 without inventing a UI complexity target or false penalty.

The first local gate run correctly stopped at a trailing source-space warning before layouts. Replacing that source space with a template escape preserves every decoded byte: all770 exported task objects compare equal. Actual successful checks from that run are retained under this full-object equivalence; fresh diff and both unfinished layout runs pass. The failed run is retained separately and is not treated as acceptance.

Registry/index,all720coding and263native bindings,copy sweep,API/script types,scoped canonical/progression contracts,grading/Learn integrity against a stand-in database,launch,build,bundle,both zero-vulnerability production audits and diff pass. Eighty fresh light/dark probes at eight widths320–1440px show no issues or unprobed routes using server-derived API stand-ins. Bundle remains242998/243000gzip bytes;twelve physical API handlers and archived Czech stay unchanged. All English,prompts,hints,approaches,starters,skeletons,public/hidden suites,fifteen programs,three exact QA edits and the complete filled example are read and separately reread. No independent-human,authenticated/Premium,real-network or physical-device acceptance is claimed. Continue five final projects,the comments-viewer revision,effective-bank reconciliation,engineering#458/#461/#463/#466/#470,release#467,then UI#435/#444. Owner,draft#365and dedicated#190holds remain.

## Comments viewer required-plan revision —17October2026UTC

Comments viewer planning revision2 —17October2026UTC: retain the API/pagination/index/cache and per-account/IP abuse plan explicitly required by the brief on both Junior and Senior boards via the explicit comment-only boardPlan field. Only one existing task hash changes;720 unique reviewed identities remain,719 older bindings stay exact. All three executable program bodies,the public/hidden20-case suite,starter,skeleton,hint and approach remain byte-identical. Eight final-hash worker verdicts and seven native verdicts/30protocol assertions pass,including the original alternative,two cap controls and exact negative email-case QA. All raw compile-error fields are clear. The full original contract/material/programs and QA are reread and separately checked; same model/session only,no independent review claim. Registry/index,all720coding bindings,selected canonical content contract,API and script typechecks,and diff pass. No screen/runtime behavior changes;B138's full release gates remain dated evidence and the following five-task batch will run fresh full gates. No new review identity or authenticated/production acceptance is claimed. #470remains open for the final two required project plans and guarded release;#458is separate.

## B139 final five issued coding tasks —17October2026UTC

B139 individually reviews the final five issued coding tasks: Todo client,Product explorer,Weather-style dashboard,Notification center and Interview mini project. Source coverage is725/725 current unique coding reviews,with263/263native records. This is completed individual model reading,not independent-human or whole-product operational acceptance. Forty-five hidden system-design tasks stay excluded and are not restored. Production remains695coding/263native through#468;twenty B134–B137reviews are frozen in#469 and ten B138–B139reviews plus one existing Comments viewer revision are staged separately.

All38current-hash worker verdicts match:21valid programs,five starters and12wrong controls. The21valid programs are15published,five markup variants (including the exact positive weather QA) and the unchanged complete filled Todo example. Frozen original suites match30/38: eight wrong programs were accepted before,including product caps/free-price rewriting,blank-city omission,a temperature cap,notification caps and post/author caps. Todo's five-row cap,weather's two-city cap and the existing always-empty notification QA already fail originally; no new gap is claimed for those controls. Every raw compile-error field is clear. All33native verdicts/56protocol assertions pass. Fifteen final published programs,two existing QA programs and the complete filled example match native captures; all720previously reviewed task objects remain unchanged. Twenty-one supported-program checks preserve base25XP without false complexity penalties,and all501shipped React programs strictly parse.

Eight scoped cases model three sequential server-created todos plus intervening local edits,normalized server titles/completion,empty and refused creation,seventeen products through every five-item page with repeated titles/zero prices/combined filters and orders,all five weather coordinates and repeated bounded ranges,fourteen notifications over five days,and nine posts across five numeric authors plus server-normalized creation. Seven published changes retain four explicitly required planning prefixes (Todo conflict/version handling and Product search/index/cache),and correct three weather no-message sentinels so blank unknown names show feedback without sending a request. Four hints now acknowledge required loading/error/pending state or distinguish blank names. Public suites,QA edit specifications,starters,skeletons and the complete filled example remain unchanged. #470's separate Comments viewer revision2 is already committed at5229e10c;it adds no identity. #470awaits guarded release.

The first browser draft exposed an invalid empty-list readiness assumption in the new fixture: loaded([]) could return before the pending GET settled. The fixture now waits explicitly for Loading to disappear;the original failed diagnostic is retained. An initial source replacement guard also refused a whole-board match because source authoring comments are absent from exported boards;that prepatch worker attempt was interrupted and is not accepted. Scoped source edits were followed by exact exported/native byte guards and a fresh complete worker run. No learner failure was hidden or accepted from those phases.

Each item's full English material,three programs,suites,available filled example and exact QA edits were read and separately rechecked. Todo junior/filled controls and unspecified query trimming limit wording to3where recorded;no new label or trimming policy is imposed. Weather overlapping-request cancellation differs across styles and the brief does not resolve it,so no concurrent arrival/cancellation policy is penalized (wording3);actual outage/timeout/backoff delivery is not proven (explanation3). Notification reference/senior grouping can copy quadratically for an unbounded group;explanation3records that limit without inventing a complexity target.

Fresh registry/index,725coding/263native bindings,copy sweep,API/script types,scoped canonical/progression checks,grading/Learn integrity using a stand-in database,launch,build,bundle,both zero-vulnerability production audits,diff and80light/dark layout probes at320–1440px pass. Bundle remains242998/243000gzip bytes;twelveAPI handlers and archived Czech stay unchanged. Layout checks use server-derived stand-ins. Authenticated/Premium,real-network,physical-device and independent-reader acceptance are not claimed. Continue bank/override/copy/answer-length reconciliation,complete-catalogue eligibility enforcement,engineering#458/#461/#463/#466,guarded#467/#470release and UI#435/#444. Owner,draft#365and dedicated#190holds remain.

## Question-bank reconciliation and first five answer-length revisions — 17 October 2026

The 17 October read-only production reconciliation confirms 485 deleted question overrides, zero active edits/custom rows and the same sorted-ID fingerprint as 15 October. The saved deleted-ID set is reused only after the live fingerprint/count match. All 2,168 authored active-category question hashes match their individual review records; 2,014 are statically eligible and 1,820 remain effective after preserved overrides. A fresh copy sweep finds zero artifacts in all 1,820 effective items. No learner/Auth data, hides, database state or production settings changed.

The answer-length diagnostic flags 64 eligible candidates (61 effective, three still hidden by existing overrides), plus 41 already withheld items. A candidate has a correct option at least 1.8 times the longest alternative and at least 25 characters longer. This is a reading aid, not an automatic correctness/publication rule. Stored key-index counts are not learner answer-position evidence because the server shuffles options. The exact baseline, scope and remaining IDs are in answer-length-reconciliation-2026-10-17.json; #471 remains open.

Q001 reads and revises five existing identities: os.tmpdir, React handler invocation, Next.js loading/template conventions and the Node.js runtime definition. Alternatives now use comparable grammar/detail. The React example defines the handler and its undefined return, removing a possible handler-factory reading. The template question specifies its segment level and distinguishes deeper navigation/search params. Primary React/Next/Node pages were fetched; installed React/Sucrase execution confirms the render-time call/undefined onClick, and Node confirms tmpdir returns a path without invoking file creation. Every final question/option/key/hint/explanation is separately read by the same model; no independent reader is claimed.

Five existing question rows get new revisions/current hashes; all other 2,163 question hashes and all 725 coding identities remain unchanged. Registry, exact field/scope checks, all 2,168 bindings, five-item and full effective copy sweeps, API types, launch contracts and diff pass. Availability stays 2,014/1,820; length candidates fall to 59 eligible/56 effective. Fresh full build/responsive/dependency gates for the preceding final coding batch are recorded separately; a later release still needs fresh required CI and exact deployment acceptance. Continue the remaining 59 candidates in five-question commits, catalogue gating, technical issues and UI. Owner, draft #365 and #190 holds remain.

## Q002 — five question-bank revisions, 17 October 2026

Q002 individually revises five existing questions: rm-node-81, rm-node-91, rm-node-92, rm-node-106, rm-node-166. Use parallel descriptions of data categories,keeping fixed-size raw bytes distinct from decoded characters,parsed objects and streams. Remove distracting out-of-bounds-write claims from this definition question. Give all choices comparable HTTP-specific detail and keep the explanation about response metadata rather than transport-flush timing. Shorten the correct option and make the three alternatives precise lifecycle actions. Avoid an unconditional claim that forgetting end is the only way a request can hang. Specify a pending promise and an async-function context,so non-promise/top-level-await behavior is outside this narrow question. Balance the alternatives around control flow. Replace the ambiguous Validates JSON alternative: parsing does validate JSON syntax. The new schema alternative names application-level validation,which the default parser does not perform. Each final question, four alternatives, key, hint and explanation was separately read by the same model. Revisions bind to the exact new hashes; all other 2,163 question hashes stay current and no question identity is added. Primary sources: https://developer.mozilla.org/en-US/docs/Web/JavaScript/Reference/Operators/await, https://expressjs.com/en/5x/guide/using-middleware/, https://expressjs.com/en/resources/middleware/body-parser/, https://nodejs.org/api/buffer.html, https://nodejs.org/api/http.html#responseenddata-encoding-callback, https://nodejs.org/api/http.html#responsewriteheadstatuscode-statusmessage-headers. PASS Node24 Buffer bytes/Uint8Array; pending await yields and rejection throws; writeHead status/headers; end completes each response while server accepts another; isolated Express5.3.0 parses object/array,accepts wrong application-field shape and rejects malformed JSON with400. Loopback only;no repository dependency changed. Registry, exact field/scope checks, all 2,168 current question bindings, API types, five-item copy sweep and diff pass. Availability stays 2,014 statically eligible and 1,820 effective; all 485 deletion overrides stay preserved. 10/64 original eligible length candidates have now received this focused revision; 54 remain under #471. No independent/human, authenticated, production or full-release acceptance is claimed.

## Q003 — five question-bank revisions, 17 October 2026

Q003 individually revises five existing questions: rm-node-167, rm-node-168, rm-node-175, rm-git-3, rm-git-23. Specify the no-argument call and keep all options about the request lifecycle. Clarify that next() does not itself return from the caller. Shorten the correct option and distinguish registration from unconditional execution;earlier terminal handlers can prevent a later layer from running. Balance status/header-based alternatives and remove the overbroad renders-nothing claim: Express redirects can include a body. Omit the unrelated unsafe unvalidated-Referrer suggestion. Replace the incorrect implication that every commit has exactly one parent with a snapshot/graph model that includes roots and merges. Use parallel descriptions of storage/history models. Use comparable action-based alternatives and make MM conditional instead of claiming it always appears after patch mode. Each final question, four alternatives, key, hint and explanation was separately read by the same model. Revisions bind to the exact new hashes; all other 2,163 question hashes stay current and no question identity is added. Primary sources: https://expressjs.com/en/5x/api/response/, https://expressjs.com/en/5x/guide/using-middleware/, https://git-scm.com/book/en/v2/Git-Basics-Viewing-the-Commit-History, https://git-scm.com/docs/git-add, https://git-scm.com/docs/git-cat-file. PASS isolated Express5.3.0: next() reaches the next handler then caller continues;earlier terminal handler skips later app.use;redirect sends302/Location and a nonempty body. Loopback only.
PASS private Git repository: root0/ordinary1/merge2 parent IDs;git add -p accepts one hunk and declines another,with exact staged/working diffs and MM only for that partial selection. No project Git state or remote changed. Registry, exact field/scope checks, all 2,168 current question bindings, API types, five-item copy sweep and diff pass. Availability stays 2,014 statically eligible and 1,820 effective; all 485 deletion overrides stay preserved. 15/64 original eligible length candidates have now received this focused revision; 49 remain under #471. No independent/human, authenticated, production or full-release acceptance is claimed.

## Q004 — five question-bank revisions, 17 October 2026

Q004 individually revises five existing questions: rm-git-30, rm-git-35, rm-git-49, rm-git-79, rm-html-3. Balance the three identity-metadata descriptions and avoid implying that the commit authenticates a hosting login. Distinguish the object ID field from arbitrary hash text a message might contain. Ask explicitly about tracked files and make every alternative a comparable pair of states,without conflating untracked files with unstaged edits. Preserve merge direction while allowing fast-forwards,already-integrated history and conflicts instead of promising an unconditional completed merge. Specify a tracked indexed file and distinguish restoration from the index versus HEAD; the old broad discard wording concealed that useful staged-version difference. Replace the vague What breaks premise and the false Nothing changes visually hint. State the actual hierarchy/navigation concern without claiming automatic HTML rejection or loss of heading semantics. Each final question, four alternatives, key, hint and explanation was separately read by the same model. Revisions bind to the exact new hashes; all other 2,163 question hashes stay current and no question identity is added. Primary sources: https://git-scm.com/book/en/v2/Git-Internals-Git-Objects, https://git-scm.com/docs/git-cat-file, https://git-scm.com/docs/git-checkout, https://git-scm.com/docs/git-diff, https://git-scm.com/docs/git-merge, https://git-scm.com/docs/git-restore, https://www.w3.org/WAI/tutorials/page-structure/headings/. PASS private Git: exact author/committer identity/timestamp/offset fields;plain diff working tree→index vs staged index→HEAD;checkout -- file restores staged bytes and preserves index;merge feature on main advances main and leaves feature tip unchanged. No project Git state/remote changed. W3C heading semantics verified from primary guidance,not a physical screen-reader test. Registry, exact field/scope checks, all 2,168 current question bindings, API types, five-item copy sweep and diff pass. Availability stays 2,014 statically eligible and 1,820 effective; all 485 deletion overrides stay preserved. 20/64 original eligible length candidates have now received this focused revision; 44 remain under #471. No independent/human, authenticated, production or full-release acceptance is claimed.

## Q005 — five question-bank revisions, 17 October 2026

Q005 individually revises five existing questions: rm-html-7, rm-html-11, rm-html-14, rm-html-15, rm-html-16. Give the correct option one concise feature category and put the full behavior list in the explanation. State that no role/tabindex/key handlers were added;avoid vague claims that a div loses every accessible behavior. The old SVG ellipsis left title/ARIA sources unspecified. Use explicit hidden SVG markup and exclude external labels before concluding that the button has no name. Shorten the correct option and remove the absolute claim that without a skip link every visit necessarily traverses twenty links. Describe a functioning focus destination rather than promising an arbitrary first control. Avoid claiming that disabled blocks every event or that aria-disabled guarantees focusability;contrast built-in user-activation behavior with semantic state only. Replace ambiguous styling/indexing alternatives with clearly distinct optional features and keep the native disclosure behavior concise. Do not claim a particular physical screen reader’s announcement. Each final question, four alternatives, key, hint and explanation was separately read by the same model. Revisions bind to the exact new hashes; all other 2,163 question hashes stay current and no question identity is added. Primary sources: https://developer.mozilla.org/en-US/docs/Web/Accessibility/ARIA/Reference/Attributes/aria-disabled, https://developer.mozilla.org/en-US/docs/Web/HTML/Reference/Elements/details, https://www.w3.org/WAI/ARIA/apg/patterns/button/, https://www.w3.org/WAI/WCAG22/Understanding/bypass-blocks.html. PASS isolated Chromium: plain div absent from Tab sequence;native button Enter/Space activation;exact hidden-SVG button has empty AX name;summary Enter toggles open with expanded AX state;disabled skipped and ignores trusted click;aria-disabled remains focusable and trusted-click active;skip link moves focus to main. No physical screen-reader or user-session claim. Registry, exact field/scope checks, all 2,168 current question bindings, API types, five-item copy sweep and diff pass. Availability stays 2,014 statically eligible and 1,820 effective; all 485 deletion overrides stay preserved. 25/64 original eligible length candidates have now received this focused revision; 39 remain under #471. No independent/human, authenticated, production or full-release acceptance is claimed.

## Q006 — five question-bank revisions, 17 October 2026

Q006 individually revises five existing questions: rm-html-23, rm-html-32, rm-html-34, rm-html-38, rm-html-39. Distinguish a programmatic relationship from immediate dynamic announcement. DOM position and color alone do not attach the message to the input. Shorten the correct option and keep invalid-state details in the explanation. Make the semantic relationship concise and avoid promising one exact screen-reader announcement or restricting figures to images. Give the correct semantic criterion without embedding a conspicuous list of examples in that option. Keep length,nesting and visual markers as separate misleading criteria. Avoid the categorical announcement claim because browsers and assistive technologies can detect layout tables. Ask about the actual semantic risk,not impossibility of CSS or responsiveness. Keep quotation/source semantics concise and distinguish the cite attribute from visible citation markup. Remove the suggestion that arbitrary attribution should always be a cite element. Each final question, four alternatives, key, hint and explanation was separately read by the same model. Revisions bind to the exact new hashes; all other 2,163 question hashes stay current and no question identity is added. Primary sources: https://developer.mozilla.org/en-US/docs/Web/HTML/Reference/Elements/blockquote, https://developer.mozilla.org/en-US/docs/Web/HTML/Reference/Elements/figure, https://developer.mozilla.org/en-US/docs/Web/HTML/Reference/Elements/ol, https://www.w3.org/WAI/WCAG22/Techniques/aria/ARIA1, https://www.w3.org/WAI/tutorials/tables/. PASS isolated Chromium AX: exact input has Email name,error description and invalid state;figure contains its caption subtree without assuming a computed figure name;blockquote retains source-URL metadata without creating a link. Primary W3C/MDN guidance supports semantic ol/layout-table distinctions. No immediate announcement,physical reader or universal layout-table AX mapping is claimed. Registry, exact field/scope checks, all 2,168 current question bindings, API types, five-item copy sweep and diff pass. Availability stays 2,014 statically eligible and 1,820 effective; all 485 deletion overrides stay preserved. 30/64 original eligible length candidates have now received this focused revision; 34 remain under #471. No independent/human, authenticated, production or full-release acceptance is claimed.

## Q007 — five question-bank revisions, 17 October 2026

Q007 individually revises five existing questions: rm-html-47, rm-html-48, rm-css-32, rm-css-33, rm-css-39. Provide exact markup and a text/html parsing context instead of guessing whether a build tool or extension changed an unspecified page. Keep the parser explanation concise. Replace the open-ended most-likely diagnosis with an exact two-input/no-submit-button scenario. Account for one-field implicit submission and external form-associated submit controls instead of treating inside-the-form location as mandatory. Ask about the float model’s intended effect instead of claiming that other technically possible float layouts have no legitimate use. Use parallel effect-based alternatives. The original correct option ignored transformed or otherwise containing-block-creating ancestors,even though its explanation mentioned them. Scope the positioning-only rule explicitly. Remove unconditional stretching from the answer:that depends on dimensions,replaced status and margins. Test the shorthand’s direct effect and state the common overlay assumptions separately. Each final question, four alternatives, key, hint and explanation was separately read by the same model. Revisions bind to the exact new hashes; all other 2,163 question hashes stay current and no question identity is added. Primary sources: https://developer.mozilla.org/en-US/docs/Web/CSS/Guides/Display/Containing_block, https://developer.mozilla.org/en-US/docs/Web/CSS/Reference/Properties/float, https://developer.mozilla.org/en-US/docs/Web/CSS/Reference/Properties/inset, https://developer.mozilla.org/en-US/docs/Web/HTML/Reference/Elements/tbody, https://html.spec.whatwg.org/multipage/form-control-infrastructure.html#implicit-submission. PASS isolated Chromium: HTML parser inserts tbody and changes direct-child selectors;two text inputs/no submit button ignore Enter while div requestSubmit works;native submit button restores Enter and one-field fallback also submits;absolute target uses positioned outer;inset0 fills auto non-replaced overlay but explicit20x15 sizing stays20x15. Float purpose checked against primary MDN. No physical-device claim. Registry, exact field/scope checks, all 2,168 current question bindings, API types, five-item copy sweep and diff pass. Availability stays 2,014 statically eligible and 1,820 effective; all 485 deletion overrides stay preserved. 35/64 original eligible length candidates have now received this focused revision; 29 remain under #471. No independent/human, authenticated, production or full-release acceptance is claimed.

## Q008 — five question-bank revisions, 17 October 2026

Q008 individually revises five existing questions: rm-css-45, rm-css-46, rm-general-68, rm-general-125, rm-general-130. State that there is no replacement indicator,so outline removal is not universally condemned. Remove the false keyboard-only description of focus-visible. Balance the alternatives and distinguish the visual color criterion from accessible labeling/announcements. Remove the claim that any icon automatically works for everyone. Remove the premise that every safe browser/database architecture requires a custom API and the claim that a client can never carry verifiable identity. Keep authorization authoritative on a trusted server or database. Replace absolute cannot/slowest/least-precise claims with bounded integration evidence. Keep user-flow coverage distinct from localization,branch coverage and universal correctness. Use one concrete wrong result rather than a conspicuously detailed any-number option. Distinguish mere definedness from the expected numerical answer. Each final question, four alternatives, key, hint and explanation was separately read by the same model. Revisions bind to the exact new hashes; all other 2,163 question hashes stay current and no question identity is added. Primary sources: https://jestjs.io/docs/expect#tobedefined, https://playwright.dev/docs/best-practices, https://supabase.com/docs/guides/database/postgres/row-level-security, https://www.w3.org/WAI/WCAG22/Understanding/focus-visible.html, https://www.w3.org/WAI/WCAG22/Understanding/use-of-color.html. PASS installed Playwright expect matcher: wrong discount100 and null are defined;undefined fails definedness and100 fails equality to90. Jest semantics also checked in its primary docs. Focus/color/auth/E2E claims checked against primary W3C/Supabase/Playwright guidance;no new live DB/account or physical accessibility test is claimed. Registry, exact field/scope checks, all 2,168 current question bindings, API types, five-item copy sweep and diff pass. Availability stays 2,014 statically eligible and 1,820 effective; all 485 deletion overrides stay preserved. 40/64 original eligible length candidates have now received this focused revision; 24 remain under #471. No independent/human, authenticated, production or full-release acceptance is claimed.

## Guarded PR #469 production acceptance — 17 October 2026 UTC

PR #469 is merged and its exact production deployment is accepted. Required run 38998515618 passes on frozen head 2d03eb8ede1669435768c41a805e0dd4cb073607: verify 41m28s (2488s), SQL 53s. All six fresh read-only guard commands exit 0: open/non-draft exact head/base/main, clean mergeability, successful rollups/checks/jobs, no pending reviews or inline comments, no implicit issue closure, and unchanged required verify/sql protection with app15368 and strict:false. The normal merge e6bd411265c5d905110783a5db88ee70beb8abfb at 04:05:52 UTC has exactly ba9ffc7c185cf07293ef2a71c2bb944d9154b8fe and the frozen head as parents, verified after fetching. No force/admin override or protection change occurred.

Exact READY preview dpl_5pC6tMpcVoS6JcugnJVMLJ3RQUAA and production dpl_8SLshym2QRqz7f158JENTdrocZkN match their commits and project with no alias error. Both pass eleven general checks, including eight actual older public-task Submits with correct/wrong verdicts, zero guest XP and null progress. All twenty new cohort tasks correctly retain Premium/stage guest locks, so there are zero new-cohort actual Submits and no authenticated/Premium completion claim. Both whole production helpers exit0. devshark.app points at the exact production before and after probes; its homepage also answers HTTP200. Protected access is stored only in a mode0600 file with exact HTTPS authority validation. Dedicated account, physical-device and independent acceptance remain in #190.

B134–B137 now deploy 715/725 reviewed coding tasks and263/263native records:150current-hash worker verdicts,130native verdicts,76safe base25XP checks and320fresh batch layouts. Extra shared-family diagnostics (34server/26native) are regression evidence without additional review identities. The #467 repair now handles POST409 as Request failed while preserving inputs and reserves Changed elsewhere/reload for versioned PATCH409. All eight initially unreviewed sibling IDs subsequently received their own individual B135–B137reviews; prior reviewed bindings were preserved. The Todo reference and filled example also use separately removable identities for rapid additions. These are local/required-CI proofs of the exact released code,not new authenticated production evidence.

Current source has725/725coding and263/263native individual model reviews. Ten B138–B139coding reviews,an existing Comments viewer revision and forty Q001–Q008existing-question revisions are committed separately. Their source hashes remain current; no identity is counted twice. Production question wording does not yet include those forty revisions. Live17October override reconciliation still preserves485deletions,zero active custom/edited rows,2014static/1820effective questions. Forty of64eligible answer-length candidates are revised;24remain in#471. Continue catalogue-wide future-review gating,engineering#458/#461/#463/#466,guarded#470release,remaining question candidates and UI#435/#444. Owner,draft#365and #190holds remain. Evidence is finite and same-session,not independent-human or whole-product acceptance.

## Q009 — five question-bank revisions, 17 October 2026

Q009 individually revises five existing questions: rm-general-133, rm-general-135, rm-general-137, rm-general-138, rm-general-146. Define a mocked dependency rather than a tautological direct call,and separate interaction count from durable outcomes or real payment guarantees. Replace an arbitrary which-first priority question with one specific parsing rule. Remove the false claim that volume can only test performance;large-input truncation is a correctness bug too. Replace an unsupported likeliest-cause diagnosis with exact code and a matcher that demonstrates the missing-await error. Awaiting alone does not make a weak value assertion precise. Treat shared-state leakage as a useful investigation rather than the only possible explanation. Avoid presenting a fixed order as a permanent cure. Keep skipped distinct from passed without the alarmist claim that every skip exists only to bypass a release. Require an understood scope/reason rather than automatic deletion or failure. Each final question, four alternatives, key, hint and explanation was separately read by the same model. Revisions bind to the exact new hashes; all other 2,163 question hashes stay current and no question identity is added. Primary sources: https://jestjs.io/docs/api#testskipname-fn, https://jestjs.io/docs/asynchronous, https://jestjs.io/docs/expect#tobetruthy, https://jestjs.io/docs/mock-functions, https://jestjs.io/docs/setup-teardown#general-advice, https://www.rfc-editor.org/rfc/rfc4180. PASS Node24 mock records one call with no storage implementation;installed Playwright truthy matcher accepts the promise fulfilling0 while awaited equality sees0;shared-state counterexample passes alone,fails after another operation and passes after cleanup. No actual database or universal order-failure cause is claimed.
PASS standard CSV reader keeps a quoted comma inside one field;private Node test-runner demo reports3passed/2skipped and never runs the deliberately throwing skipped bodies. This demonstrates skip accounting only,not release coverage. Primary Jest docs confirm Jest-specific APIs. Registry, exact field/scope checks, all 2,168 current question bindings, API types, five-item copy sweep and diff pass. Availability stays 2,014 statically eligible and 1,820 effective; all 485 deletion overrides stay preserved. 45/64 original eligible length candidates have now received this focused revision; 19 remain under #471. No independent/human, authenticated, production or full-release acceptance is claimed.

## Q010 — five question-bank revisions, 17 October 2026

Q010 individually revises five existing questions: rm-general-147, rm-general-148, rm-general-150, rm-general-152, rm-ai-12. Remove unsupported claims about generated tests and valid boundary dates. Ask about the clearly absent invalid-input class rather than guessing the entire suite’s coverage. Specify non-critical copy and avoid treating all wording as cheap or harmless. Apply risk-based testing without changing billing logic or giving actual refund/tax advice. Keep environmental comparison as an investigation,not a proven unique cause. Define and execute the timezone example rather than relying on an unspecified instant,and remove the claim that every longer timeout merely hides a bug. Avoid assuming that every flaky test proves a product defect. State the narrower conclusion that deleting a check is not evidence of a production fix. Shorten the correct option while preserving the reward-driven policy objective. Remove overbroad claims about no feedback in clustering,no possible expert guidance and a simplified RLHF loop unrelated to this definition. Each final question, four alternatives, key, hint and explanation was separately read by the same model. Revisions bind to the exact new hashes; all other 2,163 question hashes stay current and no question identity is added. Primary sources: https://developer.mozilla.org/en-US/docs/Web/JavaScript/Reference/Global_Objects/Intl/DateTimeFormat, https://docs.pytest.org/en/stable/explanation/flaky.html, https://glossary.istqb.org/en_US/term/risk-based-testing, https://jestjs.io/docs/using-matchers, https://spinningup.openai.com/en/latest/spinningup/rl_intro.html. PASS Node24 Intl: exact2024-03-01T00:30Z is3/1/2024 UTC and2/29/2024 America/New_York. Finite arithmetic example distinguishes immediate5+0 from cumulative0+10;this is not an executed RL algorithm. Risk/coverage/flake judgments use cited primary guidance,not production payment changes. Registry, exact field/scope checks, all 2,168 current question bindings, API types, five-item copy sweep and diff pass. Availability stays 2,014 statically eligible and 1,820 effective; all 485 deletion overrides stay preserved. 50/64 original eligible length candidates have now received this focused revision; 14 remain under #471. No independent/human, authenticated, production or full-release acceptance is claimed.

## Q011 — five question-bank revisions, 17 October 2026

Q011 individually revises five existing questions: rm-ai-68, rm-ai-89, rm-db-15, rm-db-46, rm-db-50. Scope the shared-budget rule to the stated decoder-only setup rather than every possible architecture/provider. Remove the guaranteed early-stop claim because oversized requests can be rejected or limited before generation. Shorten the definition without making fluency/confidence universal requirements. Avoid claiming that every model system lacks retrieval or verification mechanisms. Correct the every-value statement for nullable keys and acknowledge referential actions beyond blocking/cascading. Specify a single-column key to avoid composite MATCH semantics. Keep the same-table/two-role definition and remove the broad equation of any no-condition join with cross join. Demonstrate inner and left self joins with synthetic VALUES only. Use an explicit conventional-design example rather than an absolute ban on every rich SQL value. Remove the claim that arrays/JSON become deliberate 1NF exceptions merely because an application reads/writes them as a whole. Each final question, four alternatives, key, hint and explanation was separately read by the same model. Revisions bind to the exact new hashes; all other 2,163 question hashes stay current and no question identity is added. Primary sources: https://learn.microsoft.com/en-us/previous-versions/troubleshoot/microsoft-365/microsoft-365-apps/access/database-normalization-description, https://nvlpubs.nist.gov/nistpubs/ai/NIST.AI.600-1.pdf, https://platform.claude.com/docs/en/build-with-claude/context-windows, https://www.postgresql.org/docs/17/ddl-constraints.html#DDL-CONSTRAINTS-FK, https://www.postgresql.org/docs/17/queries-table-expressions.html#QUERIES-TABLE-ALIASES. Registry, exact field/scope checks, all 2,168 current question bindings, API types, five-item copy sweep and diff pass. Availability stays 2,014 statically eligible and 1,820 effective; all 485 deletion overrides stay preserved. 55/64 original eligible length candidates have now received this focused revision; 9 remain under #471. No independent/human, authenticated, production or full-release acceptance is claimed.

## Q012 — five question-bank revisions, 17 October 2026

Q012 individually revises five existing questions: rm-db-54, rm-db-59, rm-db-66, rm-db-69, rm-db-110. Use an explicit sole-candidate-key example instead of an overbroad shorthand for the formal 3NF rule. Preserve the non-key dependency objective and keep decomposition distinct from removing constraints. State the actual false-versus-NULL behavior and avoid claiming that no form of indexing can enforce a value rule. No live table or constraint is changed. Specify PostgreSQL and replace the any-comparison overstatement with ordinary equality and explicit NULL-aware predicates. Keep missing distinct from zero/empty/false. Limit the preference to event instants with known offsets. Remove universal index-speed claims and avoid suggesting that timestamptz can disambiguate an unspecified local wall time automatically. Specify both reads and writes on one replicated value, rather than inferring full CAP availability from write acceptance alone. Remove the unsupported convergence guarantee and product-default claims. Each final question, four alternatives, key, hint and explanation was separately read by the same model. Revisions bind to the exact new hashes; all other 2,163 question hashes stay current and no question identity is added. Primary sources: https://groups.csail.mit.edu/tds/papers/Gilbert/Brewer6.pdf, https://learn.microsoft.com/en-us/previous-versions/troubleshoot/microsoft-365/microsoft-365-apps/access/database-normalization-description, https://www.postgresql.org/docs/17/datatype-datetime.html, https://www.postgresql.org/docs/17/ddl-constraints.html#DDL-CONSTRAINTS-CHECK-CONSTRAINTS, https://www.postgresql.org/docs/17/functions-comparison.html. Read-only PostgreSQL17 expressions over synthetic literals passed all13 expected fields: CHECK truth values, NULL predicates, COUNT(column)/COUNT(*), equal instants/unequal wall clocks, UTC display and8-byte timestamp storage. CAP and concrete3NF decomposition verified against primary documentation; no live CHECK inserts, schema changes or CAP implementation executed. Registry, exact field/scope checks, all 2,168 current question bindings, API types, five-item copy sweep and diff pass. Availability stays 2,014 statically eligible and 1,820 effective; all 485 deletion overrides stay preserved. 60/64 original eligible length candidates have now received this focused revision; 4 remain under #471. No independent/human, authenticated, production or full-release acceptance is claimed.

## Q013 — 4 question-bank revisions, 17 October 2026

Q013 individually revises 4 existing questions: rm-security-19, rm-security-25, rm-security-26, rm-security-37. Retain the authorization objective with a concrete unauthorized read. Remove unnecessary time-sensitive category rankings and avoid treating authentication as authorization. Replace the claim that stolen verifiers are useless with bounded offline-guessing resistance. Keep the ordinary sign-in scope explicit and avoid encoding an unnecessary full algorithm-policy matrix. Distinguish salt from pepper and session credentials. Remove the blanket claim that named algorithms always generate salts themselves, and explicitly preserve the possibility of offline guessing. Scope the readable-payload warning to signed unencrypted tokens rather than every JWT. Replace the suggestion to paste tokens into decoders with an integrity-versus-confidentiality explanation; retain verification, audience and expiry requirements. Each final question, four alternatives, key, hint and explanation was separately read by the same model. Revisions bind to the exact new hashes; all other 2,164 question hashes stay current and no question identity is added. Primary sources: https://cheatsheetseries.owasp.org/cheatsheets/Password_Storage_Cheat_Sheet.html, https://top10.owasp.org/2025/A01_2025-Broken_Access_Control/, https://www.rfc-editor.org/rfc/rfc7519#section-3, https://www.rfc-editor.org/rfc/rfc8725#section-3.1. Node24 synthetic-only crypto checks: distinct salts change scrypt verifiers; a correct guess still verifies and a wrong guess does not; a locally generated signed unencrypted JWT payload decodes without the signing key, and modified claims change its HMAC. No real token/password, application auth endpoint or complete JWT validator was used. Registry, exact field/scope checks, all 2,168 current question bindings, API types, 4-item copy sweep and diff pass. Availability stays 2,014 statically eligible and 1,820 effective; all 485 deletion overrides stay preserved. 64/64 original eligible length candidates have now received this focused revision; 0 remain under #471. No independent/human, authenticated, production or full-release acceptance is claimed.

## Completed coding review gate — 17 October 2026

The coding scope gate is now enabled after current-hash reviews cover all 725 issued coding identities. Launch contracts prove every current issued task remains available, a new identity is unreviewed, edited task/solution content is superseded, and all 45 hidden system-design tasks remain unreviewed and unissued. Registry generation, API types, the entire launch command and diff checks pass with actual exit 0. This changes future delivery eligibility, not review identities, rewards or access tiers. All 770 authored task/solution objects were inventoried before subsequent engineering changes. Individual source review completion does not establish independent-human, dedicated account or production acceptance.

## Comment scanner repair — 17 October 2026

Issue #458: comment stripping preserves program braces, including JavaScript catch/if/else/standalone/object blocks and JSX empty containers. Permanent regressions cover these forms plus URL strings, template literals, regexes, JSX rendering and idempotence. Strict Sucrase parsing passes for all 501 exact served React programs. Before/after inventories prove all 770 authored task/solution objects and content hashes are unchanged, so no review identity or binding is rewritten. Eight isolated worker controls (four valid passes/four wrong returns rejected) and isolated Chromium checks of the same four stripped programs/wrong returns pass. API types and diff pass. Full current-head release checks and production remain pending; no physical-device or whole-content behavioral claim.

## Shared fetch pagination repair — 17 October 2026

Issue #461: the shared offline fetch fixture applies userId/postId filters before _page/_limit slicing. Fifteen permanent assertions cover first/short/empty pages, filtering order, unpaged/default/invalid-page behavior, photos three-per-page and the existing nested product shape. Direct evaluation of the actual shared source passes. A controlled-async QuickJS export probe accepts the correct five-request sequence and rejects a repeated-first-page variant. Its first diagnostic omitted the trusted suite fixture import and was excluded; the corrected probe installs the fixture through the real suite path. All 770 authored task/solution objects and hashes are unchanged; API types and diff pass. Comments now correctly describe previews and suites as offline. Fresh built-browser parity, full release checks and production remain pending.

## Isolated object-spread repair — 17 October 2026

Issue #463: an after-transform replaces only synthesized TypeScript ES2015 Object.assign calls with a module-local property-creation helper. Authored Object.assign calls retain their semantics; helper naming avoids authored identifiers. The helper copies enumerable own string/symbol values through writable/enumerable/configurable data descriptors, so reserved dictionary keys can shadow frozen inherited names. ES2015 async lowering and frozen guest dependencies remain intact. The retained baseline fails both probes with constructor read-only; the repaired isolated probes, six permanent valid/wrong cases, the Promise kernel and existing authority/forgery/DOM/IME/detached-rejection controls pass. Exact native Chromium spread/dictionary/async probes agree, apart from the deliberate native-unfrozen versus isolated-frozen Object.prototype policy. A raw __proto__ return initially hit the intentional export-proxy restriction; the final regression reads the dictionary inside the learner and returns a primitive summary without weakening that boundary. API types, diff and all 770 unchanged authored task/solution objects/hashes pass. Full catalogue engine, release and production checks remain pending. Semantics reference: https://tc39.es/ecma262/multipage/abstract-operations.html#sec-copydataproperties .

## Ordinary data bridge repair — 17 October 2026

Issue #466: ordinary data records retain allowed inherited data while own keys/descriptors remain distinct. The capability boundary reads descriptors without invoking record getters; inherited methods and host/class prototypes stay opaque. It preserves identity, read-only fields and the existing writable current ref exception. New has/descriptor operations preserve sparse-array membership and enumerability; no host constructors/prototypes are exposed. The retained baseline fails both inherited/nonenumerable probes. Eight permanent valid/wrong controls now pass, including own-only rejection, null-prototype/multilevel chains, shadowing, unused and discriminator getters, repeat identity, blocked writes/constructors and sparse arrays. The existing Promise and authority suites pass. All 42 original B133 host-inheritance/current own-only controls now match their expected verdicts; an initial private driver accidentally replaced full references with API-only extra-control fixtures and is retained/excluded, then corrected to add only the four wrong controls. Native Chromium agrees on exact normalizer/own-only/identity functions with an unused throwing getter. All 770 task/solution objects and hashes, API types and diff remain unchanged. Full catalogue/built harness and exact release acceptance remain pending; no cloud/authenticated or physical-device claim.

## Profile-only leaderboard preferences — 17 October 2026

Issue #435: the complete account-name/shark-nickname radio and photo block remains inside the existing Profile card and is removed from the Leaderboard page. The existing hook, server endpoints, verified identity, unique names, participation/reward rules and independent friends settings are unchanged. Two mocked signed-in browser journeys pass in light/dark: keyboard selection and photo switch, saved state on return, failed-save rollback/toast, absence of both controls on Leaderboard, and zero writes to friends identity. Both journeys reflow at 360, 390, 768, 1024 and 1440 CSS pixels. These are local synthetic-account fixtures, not authenticated production acceptance. Client types pass; the combined UI build/public-guide checks and initial bundle measurement are recorded separately. Checked PR/release and physical-device acceptance remain pending.

## PR #472 exact production acceptance — 17 October 2026

PR #472 is merged at f041991ddcec6518ba3f2b62df1a380f044879c9 (17 October 2026, 04:54:49 UTC), with exactly e6bd411265c5d905110783a5db88ee70beb8abfb and frozen head 9d7e877ba449931dd3b0d2ca71bb02a8a3a2eba8 as parents. Required run 39001893155 passes: verify 2169s (36m09s), SQL 42s. Six fresh guard commands pass with unchanged verify/sql protection, exact head/base/main, clean mergeability, successful rollups/jobs/checks and no pending reviews, inline comments, auto-merge or implicit issue closure. The normal merge uses no override.

Exact READY production dpl_Dgxd1rrjq86aa6hSNvf57m366ZUa matches the merge SHA/project/production target with no alias error. Both whole frozen helpers exit 0: eleven general checks include eight actual older public-task Submits, zero guest XP and null progress. All eleven advanced cohort identities remain correctly guest-locked (ten new tasks and one existing revision), so new-cohort Submits remain zero. devshark.app points at this exact deployment before/after probes, and its homepage answers HTTP200. Preview dpl_6BG2aJBVS9Dc8jsfQh8zLgFjw3o3 has the equivalent bounded acceptance. No authenticated/Premium, dedicated account, physical-device or independent-human acceptance is claimed.

Production now contains all 725 issued coding reviews, 263 native records, the Comments viewer revision and the first 40 focused question revisions. The required planning notes for all five briefs are shipped, completing #470. Another 24 question revisions, the completed coding future-review gate and engineering #458/#461/#463/#466 are frozen in #473 at add4bb1aabaa598677f473353eadb7d39577495d. Its exact READY preview dpl_DPvNZDFAbka15gLN1KK9BR21DAJ3 passes both whole helpers with eleven general checks/eight old public Submits and eleven guest locks; required run 39004064701 and production acceptance remain pending. All 64 eligible question revisions are individually complete in source, with zero remaining eligible length flags and a clean 1,820-item copy sweep. Preserve all 485 deletion overrides, 154 content-withheld questions and 45 hidden system-design tasks.

This is a dated release checkpoint. Later exact production evidence is maintained in the linked PR/issue updates rather than inferred from staged source. Profile #435 and startup-guide #444 follow separately; owner/draft #365 and #190 holds remain.

## Public-guide startup handoff — 17 October 2026

Issue #444: capture the existing public guide before createRoot replaces it, then transfer each matching native disclosure state and eligible summary focus once to the live article. Topic/locale/history identity prevents reuse on later navigation; focus/pointer tracking respects a visitor who moves elsewhere, and popstate/consumption removes listeners. Cold guide startup now skips the App’s delayed main-focus timer; leaving the initial route restores normal navigation focus. No persisted disclosure store or controlled details toggling is introduced. The first regression run correctly exposed the separate 230ms focus move; its six failures/traces are retained and excluded from acceptance. The repaired final production-shaped build passes all16 browser cases: keyboard/pointer state/focus in light/dark, moved focus, navigation away/back, profile preferences, optional scrollbar-chunk failure, existing public accessibility/head and JavaScript-disabled behavior. Profile also reflows across five widths in both themes. Initial transfer is242854/243000gzip bytes; the budget is unchanged, with cosmetic scrollbar feedback loaded asynchronously and failure handled. Root build/client types pass; API/script types, launch and both production dependency audits pass. CI now runs the new regressions. Physical devices, exact checked PR and production release remain separate.

## OwnDashboard marketing source export, merged — 21 October 2026

Issue #364: the authenticated, read-only `GET /api/quiz/questions?resource=marketing-source` operation on the existing quiz handler (the 13 October entry above describes it). Before the merge, main's later work was merged into the branch: conflicts in `package.json`, `NEEDED.md`, `docs/product-architecture.md` and this file kept both sides. On that merge commit, Node 24.22.0, these passed locally: API and script types, `test:performance`, `test:launch` (with the marketing producer and HTTP tests), `check:unused`, `check:security`, the production-shaped build, `check:public`, `check:bundle` (242,863 against 243,000 gzip bytes), both production audits (0 vulnerabilities), twelve handlers and `git diff --check`.

PR #365 is merged at 1bf6cd56b06f2bb7e8dfbbb14d57ab7028bff368. Frozen head 58133cf1 passed required run 39618238380: verify 41m16s, SQL 36s. READY production dpl_8FBFfVNS5cpx2ZixJ8Q96ubEnRGU matches the merge SHA. Read-only guest checks against devshark.app after the deploy: `/`, `/quiz` and `/learn` answer 200; `/api/health` answers 200 with database, service role and rate limiter OK; the export answers 503 `marketing_not_configured` with and without a bearer, because `DEVSHARK_MARKETING_EXPORT_SECRET` is not set.

The export is not switched on. Its server secret, the n8n credential and an authenticated production check stayed with the owner (NEEDED.md, "Configure OwnDashboard marketing source integration after PR review", removed when the owner dropped the marketing plan on 22 October 2026). No export, publication, account or database write happened in production. The verify job took 41 minutes because the `package.json` change triggered the QuickJS rebuild; the job's limit is 45.

*22 October 2026:* the owner dropped the marketing plan (#239, closed not planned), and the preview-only `DEVSHARK_MARKETING_EXPORT_SECRET` was removed. No environment sets the secret, so the export stays inactive and the setup item is gone.

## Learn section registry and plan membership — 21 October 2026

Issue #487: `shared/learn-sections.ts` adds the three Learn sections (Web Developer, Software Engineer, Forward Deployed Engineer) with the owner's membership matrix. A learner profile may now carry an opt-in `sections` list; `planTopics` appends a joined Software Engineer section's topics and their prerequisites after the track stages, so the server's `403 not_in_plan` and Today follow the joined section. A profile without `sections` plans what it planned before. `PUT ?op=learning-preference` accepts `sections`, refuses unknown ones with 400 before any write, and keeps the saved list when a save leaves it out. No UI, tier, reward, schema or handler-count change.

Local `ci:parity --fast` at cade6b03 (Node 24.22.0): complete and clean, 28 passed, 25 skipped (full-only steps), 0 failed. The first run had failed `check:bundle` at 243,108 against the 243,000 budget; after the opt-in split the initial download measured 242,974 with the budget unchanged.

PR #521 is merged at 88b6fcfd73c2cb63a568bfaa5d9e7479d50a1b71. Head cade6b03 passed required run 39636125708: verify 44m23s, SQL 44s. READY production dpl_EnjFL3yT3KiftsPAeMhXaZs1gNft matches the merge SHA with no alias error and served devshark.app. Read-only guest checks: `/`, `/learn` and `/api/health` answer 200; `GET` and `PUT ?op=learning-preference` (the latter with an unknown section) answer 401 for a guest.

No authenticated production save was made: the 400 for unknown sections and the kept list are proven by the handler contracts against a stand-in, not on a production account.

## English-only code — 21 October 2026

Issue #485: the second language is removed from the code. The 41 `*.cs.ts` files are deleted, copy types are plain strings, no client request sends `lang`, and the handlers ignore a stray `lang` from an old cached client. `t()` serves the one English dictionary; the language switch, the Storybook language toolbar and the second-language validators and contracts are gone. Native path code attempts open at deploy time take the existing one-time `task_changed` path, because their attempt material no longer carries a second-language slot; question, coding-task and coding-attempt hashes are unchanged. The `/cs/topics` guides stay until D3 (#486).

Local full `ci:parity` at a9e5e153 (Node 24.22.0): complete and clean, 51 passed (the 18 browser specs, `test:harness` and Storybook included), 0 failed. The initial download measured 241,651 gzip bytes, 1,323 below the old figure, and the budget was lowered to that value.

PR #526 is merged at d18f154ca0a6c95af60ec5b4e7257ead1a0af34c. Head a9e5e153 passed required run 39655387854: verify 37m14s, SQL 36s. READY production dpl_DZNFakxF4xBW67PnTjvZxBFBSK7s matches the merge SHA with no alias error and serves devshark.app. Read-only guest checks after the deploy: `/`, `/learn`, `/quiz`, `/coding`, `/topics/javascript-closures` and `/cs/topics/javascript-closures` answer 200 (the app shell with `lang="en"`); `/api/health` is healthy; the coding-task read and the daily answer 200 with and without a stray `lang=cs`, and the task title is the plain English string.

No signed-in, Premium, path-attempt or physical-device check was made in production.

## DSA Foundations coding tasks, local — 21 October 2026

Issue #493: the DSA path's 30 code exercises become 29 coding tasks (the binary search stays a reuse of `js-binary-search`) on the Algorithms track with topic `dsa`, each with a reference, junior and senior board, the path's hidden assertions and known wrong answers for every critical criterion. DSA levels 3 to 9, 12 and 13 seal them through the existing parent attempt; levels 1, 2, 10, 11 and 14 seal none until E3 (#494). The free list gains three Easy tasks: 144 of 754 issued tasks, 19.1 %. A DSA path pass now records under its Coding task (`canonicalCodingTaskId`), the queue excepted. Handlers stay at twelve; no migration, reward amount or access rule changed beyond the three free ids.

Local evidence, Node 24.22.0, at the branch head: `test:coding` passed in full (799 tasks, 754 issued, 480 Easy, 179 Medium, 95 Hard; 528 tasks reject a constant answer; 163 known answers keep their verdict). The first full run stopped at a 20-second timeout in `react-easy3-fetch-a-page`, a task this change does not touch, at load average 26 from parallel work; that task passed alone and the rerun passed in full. The ledger generator regraded 225 cases of the 29 new hashes in the production QuickJS grader. `test:launch`, `test:coding-auth`, `test:grading-integrity` (with the new DSA level 3 parent-attempt test), `test:paths`, `test:path-authority`, `audit:native-reviews` (263/263), `test:harness` (206 assertions in Playwright Chromium), the three typechecks, `check:unused`, `check:security`, `build`, `check:public` (754 share pages) and `check:bundle` passed. The initial download measured 240,779 gzip bytes against the unchanged 241,651 budget: building the free set on first use took the id list out of `main`. `check:responsive` passed 56 light probes and 15 dark ones, the Algorithms list and a DSA task route included, on a preview at port 4473.

Not run: `ci:parity` (it needs port 4173, which other work held), the 18 browser specs, Storybook and `test:sql` (no migration). The workbench brief's "DSA · Level n" was not seen in a browser, because the preview serves no task API; the list row was, at 360 px light and 1280 px dark. The reviews are same-session model reviews, not an independent reading. The issue stays open until a checked merge.

*22 October 2026:* PR #530 merged this work and #493 is closed; see "DSA coding tasks and FDE artifacts".

Review fixes, same day. A DSA task on a held level (1, 2, 10, 11, 14) no longer names that level: `DSA_LEVELS_AWAITING_E3` moved to `shared/coding-catalog.ts`, where `hasLearnLevel` reads it, so the linear search stopped reading "DSA · Level 10" (Sorting Algorithms). Each criterion-tagged known wrong answer must now fail a check tagged with its criterion, not just fail somewhere; all 103 do. A visible DSA check carries a short `shown` form for the Results row, so the longest row is 319 characters instead of 2,618. The halving senior board halves with `Math.floor` instead of a 32-bit shift, and the prompt bounds n at `Number.MAX_SAFE_INTEGER`; `Math.floor(Math.log2(n))` is now a known wrong answer (49 for 2^49 - 1). The max-gap senior board reduces once instead of spreading into `Math.max`, which QuickJS refuses past 65,534 arguments. The queue prompt names its three counted operations correctly. 22 ledger rows took new hashes and a regrade of 177 cases.

Local evidence for the fixes, Node 24.22.0: `test:coding` passed in full (799 tasks, 754 issued; 165 known answers keep their verdict; 103 criterion-tagged wrong answers graded against their criterion's checks). `test:launch`, `test:coding-auth`, `test:grading-integrity`, `test:paths`, `test:path-authority`, both typechecks, `check:unused`, `check:security`, `build`, `check:public` and `check:bundle` passed; the initial download measured 240,784 gzip bytes against the unchanged 241,651 budget. On a preview at port 4473, `check:responsive` passed 264 probes, and `coding-workbench.spec.ts` with `coding-pages.spec.ts` passed 33 tests, including new ones that open the BST task at 360 and 1280 px and run its reference to 7 of 7. The workbench brief was seen in a browser this time, through the spec's stand-in task API. Not run: `ci:parity` (port 4173), Storybook, `test:sql`.


## Learn sections page — 22 October 2026

Issue #488: Learn shows three sections (Web Developer, Software Engineer, Forward Deployed Engineer) at `/learn/:section`, with a switcher, one join action per section and the topic rail filtered to the section; the FDE plan bridge gains DevOps & Cloud so a member never meets a topic of their own section outside the plan. The map, parts and lesson runner are unchanged; no handler, tier, reward or schema change.

PR #529 is merged at 39d6baba430736b7e54bdc2d8c5f335fecfd9b00. Head 0494ffcc passed required run 39688820809 (its slowest gate, coding, took 26m04s; SQL 38s). READY production dpl_3b6LLY2NcyPTesq537E3nmtPJX2Z matches the merge SHA. A read-only guest check in headless Chromium at 390px against devshark.app after the B1 deploy (dpl_2t2DG5SanNkafg4MXMrdAikaiTFt, which includes it): `/learn` resolves to `/learn/web-developer`, `/learn?topic=dsa` to `/learn/software-engineer?topic=dsa`, `/learn/forward-deployed-engineer` stays, each shows the three-section switcher, `/learn/big-o` is unchanged, and the pages raised no errors.

No signed-in join, plan save or Premium check was made in production.

## Learning-path schema fields — 22 October 2026

Issue #497: a check may carry a `scenario`, a code activity a `fixtureNote`, and a module the `interview-prep` shelf, which never supplies the next action or counts toward guided completion. No published content uses them yet. The graded check container no longer shares the picker's class, so checks lose an unintended dimmed frame.

PR #531 is merged at 8253e138f99739a5f7111d2621aabe59ee12b5a0. Head 85cef33d passed required run 39688832059; because main moved after that run (#529), the merged tree was rebuilt locally and passed the types, `test:launch`, the full `test:paths`, `test:path-authority`, `test:client`, `audit:native-reviews`, build and `check:bundle` before the merge. READY production dpl_2t2DG5SanNkafg4MXMrdAikaiTFt matches the merge SHA and passed the guest checks above.

The FDE path stays switched off in production, so no learner sees the new fields there yet.

## DSA coding tasks and FDE artifacts — 22 October 2026

PR #530 is merged at `d03f263288923d7537fd61ad30aafba17c983b41`. Its required `verify` and `sql` checks passed in run `39692357767` after retrying the browser download failure. On the merged tree `db5e392e`, Node 24.22.1 passed nine selected CI-parity steps in 3.19 minutes: API/scripts types, native-review audit, build, bundle, launch, grading integrity, path authority and full path content. The initial download measured 239,389 gzip bytes against 241,651. READY production `dpl_6hBTzKD3K5N9X5sZwvEz4f4KMNc6` matches the merge SHA. A read-only 390px Chromium check of devshark.app showed 29 DSA task rows with three free task links, the DSA Learn link resolving to Software Engineer, and no page errors. The first smoke assertion incorrectly expected every task row to be a link; the corrected assertion checks all rows and the three free links separately. No signed-in coding submission was performed.

PR #533 is merged at `5d61ab0d6d3e8afd209464964782dacb56d6de08`. Required checks passed in run `39691864470`. Its integration tree `10f09d89` passed API/scripts types, native-review audit, launch and the full path suite in 1.60 minutes. READY production `dpl_A9cXjwTXbpJ3eQv9U6dPY6ptL5fW` matches the merge SHA. The guest DSA listing check above also passed on this later deployment. The FDE path remains switched off, so this is publication evidence for the authored artifacts rather than authenticated path acceptance.

## Data plumbing, tools and evaluation — 22 October 2026

B6, PR #535, merged at `0f11f701e6611c8c11878ff127163adce8d92020` after required run `39691896523` passed. Clean integration tree `8413812d` passed the five content/type parity steps in 1.57 minutes (Node 24.22.1, `artifacts/codex-pr535-merged`). Production `dpl_23pcYM9tNeJHiSGZhSAyQU6sRxKD` is READY at that SHA. B7, PR #534, merged at `b5c184bec6e250c3c9bd8b4a9d13bd649a06be18` after required run `39708140950` passed on integrated head `537d00f0`; five local content/type parity steps passed in 1.41 minutes (`artifacts/codex-b7-updated-main`). Production `dpl_EbG3W8FsiiJT9kH6FmUTpYAZcNca` is READY at that merge SHA.

Both publications retain the FDE production switch as off. No authenticated module completion, live model call or external vendor integration is claimed. The checked examples and tool traces are fixtures.

## Path authoring workflow — 22 October 2026

C4, PR #540, merged at `2bb4855cd40b6ae7023e92f1c33f8cd84462ed76` with required run `39708320451` green. Head `cc2521f5` passed five selected parity steps in 1.69 minutes (`artifacts/codex-c4-final`, Node 24.22.1) and skill validation. The temporary authored test module was removed after its real content tests passed. An independent read-forward review corrected overstated validator guarantees, teaching guidance and stale examples. This is a workflow-only change; no runtime or schema rollout is claimed.

## English-only public pages — 22 October 2026

D3, PR #542, merged at `d639df26ee09c040bc2474f3cae521a887b0fdf0`; required run `39709841473` passed. The final two tooling/launch parity steps passed in 0.88 minutes (`artifacts/codex-d3-final`, Node 24.22.1). Build/public output had 15 sitemap URLs, no second-language addresses and no hreflang alternates. Thirteen browser checks and fourteen responsive probes passed. Initial analytics/prepaint fixture assertions were corrected before the final checks.

Preview `dpl_EEUs8wK71c8TYQKW1C6J1sjL2LRQ` and production `dpl_DLH4CcS4HfNdWM1VckFRVgCEJ6Ko` are READY at their checked heads. A read-only 390px Chromium check on devshark.app confirmed `/cs/topics/javascript-closures` returns HTTP 404 and the app not-found heading, with no-store and noindex. Preview response inspection also checked the CSP bootstrap hash. No account or production record was created.

## Reading before Learn questions — 22 October 2026

E1, PR #541, merged at `02875113300fc66ec5e64b8ba17e36c398b168a1` with required run `39709836239` green on head `67fe15ef`. Seven selected parity steps passed in 4.15 minutes (`artifacts/codex-e1-targeted`, Node 24.22.1), along with nine focused client checks and two browser cases across seven widths, both themes and axe. Production `dpl_G4rsbALqgQRuVzCLrsSfeKfMCryj` is READY at the merge SHA.

On devshark.app at 390px, a guest opened `/learn/big-o`, chose Complexity Basics and saw “Counting work, not seconds”, with no page errors and no non-GET roadmap requests. The lesson endpoint returned 200, its explicit lesson/hash projection, public max-age 300 and a hash ETag. Two initial smoke attempts omitted the lesson-button click; the corrected navigation passed. Reading records no attempt or progress. No signed-in level completion was performed in production.

## Enterprise identity content — 22 October 2026

B5, PR #537, merged at `fc0cbe2e83209a7def14daa742d6d3325c5b5f12`. Required run `39710700413` passed after retrying npm security-endpoint timeouts; its coding job passed in 28m02s. Clean integration tree `6214df07` passed API/scripts types, path content, launch and exact native-review bindings in 1.46 minutes (`artifacts/codex-b5-current-main`, Node 24.22.1).

Production `dpl_BEcuDZV4x34qAfHjUyiKTQUeNTG6` is READY at the merge SHA. A read-only catalogue GET on that deployment returned 200 and the Enterprise boundaries and identity module with its delegated-access/SSO/webhook/audit reading and tenant-scoped webhook exercise. Availability remains disabled. No production enrollment, signed-in submission or switch-on was performed.

## Workflow and documentation inventory — 22 October 2026

C7, PR #544, merged at `e03d69446e8dc987091b43881aa87ccadbc40219`. Required run `39712881596` passed after retrying the same npm endpoint timeout. Clean integration tree `4136521d` included B5 and passed the launch parity step in 0.72 minutes (`artifacts/codex-c7-current-main`, Node 24.22.1). Both instruction maps list all 46 current workflows; the added skill descriptors were checked for their required shape. This documentation-only change introduces no runtime or schema behavior and needs no authenticated production acceptance.

## Canonical FDE section addresses — 22 October 2026

A3, PR #543, merged at `12b3f17f4d09d7ee7f4804179f1b832a6812ec5a`; required run `39712723315` passed after retrying npm audit timeouts. Initial full parity found fixture/type errors and an unmounted FDE shelf; those were corrected. Clean integration tree `f0a3a9c9` passed seven relevant checks in 2.65 minutes and 32 browser cases passed in 1.3 minutes, including the current B5/C7 tree. The later CI-install-only integration passed the parity plan check.

Production `dpl_BmhJqrej5xr5SdUaoiJS2bpBvwnW` is READY at the merge SHA. A read-only 390px guest check on devshark.app followed both legacy overview and module addresses through HTTP 308 to their canonical Learn addresses, preserving query and fragment; the FDE section shelf points there. No page errors or API writes occurred. This did not complete an authenticated path activity.

## Deployment and release-gate curriculum — 22 October 2026

B8, PR #536, merged at `b09a24df72f46541b3c030a319209a38dcf5b02b`; required run `39718231957` passed. Clean current-main integration `abdd25d8` passed five API/scripts/path/launch/native-review checks in 1.65 minutes (`artifacts/codex-b8-current-main`, Node 24.22.1). An existing auth-recovery test was corrected to await its specific heading before the successful rerun.

Production `dpl_EfMNsmEY4Cza7MhTa5tbnHxgdhSa` is READY at the merge SHA. Its catalogue returned HTTP 200 with the deployment module, two sourced lessons, six-question check and release-gate code activity. Availability remains disabled. No live infrastructure, authenticated submission or production flag change was performed.

## CI install audit separation — 22 October 2026

Maintenance PR #546 merged at `8189bae09d8ffbcc3437ac13b1ffb33d7e827462`, required run `39717156563` green. All five CI install steps now match local parity with `npm ci --no-audit`; the explicit root/client production audit gates remain required and both passed after the npm endpoint recovered. Clean head `f38914b0` passed launch parity in 0.68 minutes; the current-main integration passed the parity-plan check. This is CI configuration only.

## Public Learn entry points — 22 October 2026

A5, PR #547, merged at `99fe9eac27ada76e1d9cdd998a04c1d9b81d420a` with required run `39720314130` green. Clean `0e46e700` passed 28 fast checks in 26.24 minutes; after A3 integration, `a8423066` passed eight selected checks in 2.72 minutes and 25 browser cases in 32.7 seconds. A current-main/B8 tree `8f786429` passed five build/public/type/launch checks in 1.55 minutes.

Production `dpl_MAKdNfuxNhYM9hwN8NojtFaomtTo` is READY at the merge SHA. A read-only 390px guest check confirmed all three section pages return HTTP 200 with their own visible h1, title and canonical, no horizontal overflow, no page errors and no API writes. Epic A is closed. This establishes guest public navigation, not authenticated completion.

## Recorded FDE hub and completion artwork — 22 October 2026

B2, PR #549, merged at `4daff81519e53acdc38d8b4cfe28472932a1f57a`; required run `39723762922` passed. Clean `e85bd096` passed all 28 fast checks in 25.09 minutes. Current-main/A5/B8 integration `065c3c06` passed six selected checks in 1.80 minutes; final documentation head `fb9d9b21` passed launch in 0.84 minutes. Two focused browser cases covered both themes, seven widths, 200% zoom, keyboard, axe, touch targets and real 1200×630 card downloads. Both downloaded images were visually inspected. The initial keyboard fixture raced route focus and was corrected to await it.

Production `dpl_6SNo3ggTA56WbmrowpnzQ9Ldn9yy` is READY at the merge SHA. A 390px guest check on the canonical overview found all five phases and thirteen competency groups, with no overflow, page errors or API writes. Recording remains disabled by the owner switch. No authenticated production activity or completion card was created; completion artwork was checked against dedicated local fixtures.

## E3 DSA Foundations Learn release — 22 October 2026

Issue #494 rebuilds DSA Foundations into 15 Learn levels with 120 questions, registered readings before attempts, and Coding work on levels 1–14. Eighteen existing lesson documents retain their content and move into the shared Learn lesson registry. Displaced questions and review history are archived. The first five DSA levels stay free; grading and the twelve physical API handlers stay authoritative.

Final head b08c280661776ae62803a68a78b50facdd7002a5 composes with B2 and passes ten selected local checks plus 60 browser tests. PR #548 merged at 64ecf4e96d0d6b578d682aa2c8b1fca5e5178e96. Required run 39727535817 passed verify (2s aggregate after its dependent jobs) and SQL (36s). READY production dpl_CeVMqRnEPrLJr1irHBhb6x5ADq9c matches that merge. A read-only guest browser check at 390px on devshark.app confirmed the Software Engineer DSA page is 200, all 15 levels appear from Complexity Basics through Foundation Review, and the first registered reading opens with no overflow, page errors or API writes. Evidence: /private/tmp/codex-e3-production-smoke.log on the implementation machine.

This establishes the observed guest flow, not authenticated production grading, physical-device acceptance, or independent-human review of the whole catalogue. E4 and E5 remain separate open work.

*22 October 2026:* E4 (#495) and E5 (#496) merged later that day; see "DSA Advanced and minimal Learn topic cards" and "Standalone DSA path retired".

## B12 free FDE taster release — 22 October 2026

Issue #508 allows free enrollment, the diagnostic and first required FDE module, with server checks at both start and submit. Later work requires Premium; stored verified/self-reviewed work can reopen after entitlement lapses. Client hub, overview, resume and picker mirror the server rule. Reward amounts, owner isolation and the twelve physical handlers remain unchanged.

Fast parity passed 28 checks with 25 skipped at eea6ae42. Final head 9dc6743dae93363bab8b9ba06b1b278c5fc67c7a includes actual B2/E3 main, passes ten selected checks and 24 browser tests. One earlier browser invocation used the wrong base-URL variable; the corrected TEST_BASE_URL invocation supplies the quoted 24 passing tests. PR #551 merged at 920ac1f43984307947d11b501cd2c1f70d6ef211. Required run 39730505010 passed verify (2s aggregate after dependent jobs) and SQL (34s). READY production dpl_HMA8Td1EmucESFsZAwzKC2UnaBRe matches that merge. Read-only guest browser acceptance at 390px confirms the canonical FDE outline is 200, with five delivery phases, 13 competencies, no overflow, page errors or API writes. Evidence: /private/tmp/codex-b12-production-smoke.log.

The production FDE switch remains disabled pending B14. Authenticated production taster submission and completion are not claimed; no production learning data, migration or feature flag changed during acceptance.

*22 October 2026:* B14 (#510) merged in PR #559. The FDE switch now waits only on the owner.


## B13 public FDE positioning release — 22 October 2026

Issue #509 introduces the FDE path on Home using the fetched public manifest for inventory and the existing shared Premium inclusion list for access copy. Loading/error states show no invented counts. The canonical CTA opens the existing FDE outline; no production flag, migration, entitlement or grading rule changes.

Fast parity at 7c3e2a8f6598b52d4e7e65202058a5b919df0be7 passed 28 checks with 25 skipped in 26.49 minutes. Final B12-composed head 68d432a2088e61b571d893c1d21dbc725e1f84b1 passed eight selected checks in 2.62 minutes and four positioning/taster browser tests in 12.6 seconds. Initial static CI failed because the npm audit endpoint timed out; the failed-job rerun passed, with no advisory or test bypass. Required run 39733974575 passed verify (4s aggregate after dependent jobs) and SQL (51s). PR #553 merged at d3dc3a33a35c5fa505ab202656a0b59fe872687a.

READY production dpl_7qigZgX2t7RY4yPTqRdKggxwSibx matches that exact merge. Read-only guest checks at 390px in light and dark themes passed: Home and Premium return 200, Home matches the fetched manifest (13 required modules, 24 lessons and 68 module/capstone questions), the CTA reaches the canonical FDE outline, Premium states the free diagnostic/first-module boundary, and no page errors, horizontal overflow or API writes occurred. The public catalogue still reports disabled. Evidence: /private/tmp/codex-b13-production-smoke.log.

A deployment-scoped 15-minute runtime scan found two stderr entries categorized as errors, both Node 24 DEP0169 url.parse deprecation warnings on /api/quiz/roadmap. The targeted runtime-error query returned that same warning group; no other group was returned. The accepted guest requests were 200. This is not a claim of warning-free logs or authenticated production completion. The warning is recorded for follow-up; FDE stays disabled until B14.

*22 October 2026:* #477 is closed. The DEP0169 warning comes from Vercel's Node launcher (upstream vercel/vercel#16109), not from devShark code. B14 merged in PR #559; FDE stays off until the owner sets the Production variable.

## DSA Advanced and minimal Learn topic cards — 22 October 2026

Issue #495 (PR #556, merge 4206cc16): DSA Advanced joins Software Engineer as an opt-in Premium topic, with 15 levels, 120 questions and 15 new plus 9 placed coding tasks. Required run passed after one spec fix (1327b1af): the topic-card helper matched by prefix and found both DSA cards. Owner request (PR #557, merge 132633be): Learn topic cards show the logo, the topic name and the levels line only; the "Also in …" line and its accessible-name suffix are gone, and section membership is unchanged. Main had moved after #557's CI, so the merged tree was rechecked locally before merging: types, client, launch, build, bundle, and learning-release plus learn-sections (32/32).

A read-only guest check on devshark.app after the deploy, in headless Chromium at 390px: `/learn/software-engineer` lists 9 cards including DSA Advanced, `/learn/web-developer` lists 10, no card shows "Also in", the level counts show ("0 / 6 levels"), and the pages raised no errors. No signed-in or Premium check was made.

## Standalone DSA path retired — 22 October 2026

Issue #496 (PR #555, merge c1d1c1dd67b6d07e99b972508caaa7e3322104e1): the DSA Foundations learning path is retired; FDE is the only path. Its exercises remain the Coding tasks E2 created: all 769 coding-index ids are identical before and after the merge, and the graders and solutions are unchanged apart from a file rename. The eighteen original `dsa-v1-*` readings are still served by Learn and stay bound to their eighteen archived lesson reviews by content hash (`audit:native-reviews` reports 18/33 Learn lessons); the other 111 path records moved verbatim to `history/`, none rescored or rebound. Stored `dsa-foundations` enrollments are left out of the enrollment list and Today; their progress and activity routes answer 404. `/roadmap/paths/dsa-foundations` and everything under it answer a permanent 308 to `/learn/software-engineer?topic=dsa`. Every authority script kept or gained assertions (path-authority 17→21, handler contracts 63→71, lesson contract 42→47). Head 0cebac71 passed required run 39758404194 (coding 21m49s, browser 14m10s) with main already merged into it.

Open owner items: the Terms of use still name "the FDE and DSA learning paths"; remove `LEARNING_PATH_DSA_ENABLED` from Vercel if any environment still sets it.

*22 October 2026:* no Vercel environment sets `LEARNING_PATH_DSA_ENABLED`, and no application code reads it. The Terms wording is still open.

## Migration 066 in production — 22 October 2026

Backup verified first: `supabase backups list` for rvlybcjdpafwyeuojvhl showed a COMPLETED physical backup at 2026-10-22 03:52:56 UTC and completed daily physical backups for each of the seven days before (WAL-G on, PITR off). Applied migrations ended at 065, matching the repository. `supabase/supabase-schema-066.sql` (sha256 aeb6111c…0c3c, from B3 commit b908b692) was applied in full through the connector as `066_learning_path_quota_result`. Before the apply the function did not exist; the rollback is a single `DROP FUNCTION public.accept_learning_path_quota_result(jsonb,jsonb,text,text,integer,text)`. After: one overload, SECURITY DEFINER, `search_path=""`, EXECUTE for service_role only (anon and authenticated false), and `md5(prosrc)` 6f1362b2e93561607c4373bfc8e03756 equals the md5 of the function body in the repository file. No data was read or changed.

## B3 decomposition cases and any-nine completion — 22 October 2026

Issue #499: M02 Decomposition cases adds two readings and twelve original four-question customer cases. Both readings and any nine passed cases complete the module (`requiresAtLeast`); the other three stay open for practice. Migration 066 adds the service-only `accept_learning_path_quota_result`, which counts the quota under the enrollment lock; without it a quota submit answers 503 `migration_required`. Existing result routines, rewards, tiers and the twelve handlers are unchanged.

PR #545 is merged at 62c8b7b933e4437d122d9a6b270cf27845d15563. Head ff70b250 passed required run 39766593505: coding 25m21s (the slowest gate), browser 16m49s, tests 5m38s, static 2m12s, SQL 34s. Migration 066 is applied in production (entry above). READY production dpl_FkTVDEQF58m2Bjd11gwRakoeEFvS matches the merge SHA.

FDE stayed off in production, so no learner could reach the cases there. No production smoke check, authenticated run or quota submission was made for this entry; B14 exercised the any-nine completion on a local stack.

## B9 codify-pattern module and final FDE numbering — 22 October 2026

Issue #505: M14 Codify the pattern (two sourced readings, four scenario questions and a required self-reviewed pattern note) joins the loop, the path moves to its final M01–M14 then C01 order with the decomposition cases at M02, and the optional Python bridge gains two readings and two checks. Lesson, activity and question ids keep their authored slugs, so recorded evidence keeps its ids. No Python runs, no handler or migration is added.

PR #550 is merged at 1c5612b35f0bbfad1b004364dcd0bb42c651717b. Head 08fb1a61 passed required run 39768456086: coding 21m30s, browser 13m07s, tests 4m54s, static 2m12s, SQL 38s. READY production dpl_7UkWmB8v1vpXfkK2R5S6Ry8r98hu matches the merge SHA.

FDE stayed off in production. No production smoke check or authenticated run was made for this entry.

## Hidden system-design task fixes — 22 October 2026

PR #558 (refs #391): the 29 hidden system-design tasks the 22 October review marked needs-fix are corrected (13 content defects, 16 length clues, all 40 drill hints made task-specific), the review is committed under `docs/audit/`, and a sequence drill may accept a second valid order through the server-only `acceptedOrders`. The track stays hidden; no learner sees these tasks.

PR #558 is merged at 8491aaaf61a954045a0280b53cd1b92666043000. Head 217eb2dd passed required run 39769602515: coding 20m27s, browser 16m24s, tests 4m25s, static 2m42s, SQL 42s. READY production dpl_DdxdCFDFH2ug4RhuMN2LEQa77d13 matches the merge SHA.

The tasks remain hidden, so this establishes no learner-facing behaviour. No production check was made.

## B10 interview-practice shelf — 22 October 2026

Issue #506: four optional modules, IP01–IP04, sit on the `interview-prep` shelf after the capstone: two code rounds on foreign TypeScript services, twelve design cases and five capped self-reviewed reflections whose case bank links M02's twelve cases. Shelf work never changes guided completion, the next action or the required counts. No handler, migration or tier change.

PR #554 is merged at c147e3c4499532365f66eb8bdd7ef65d072be8b2. Head 28010ab1 passed required run 39775898505: coding 25m42s, browser 12m53s, tests 5m47s, static 2m23s, SQL 37s. READY production dpl_AJ6teJjeQEPojk6KVjc9kp7RV8pm matches the merge SHA.

FDE stayed off in production. `interview-shelf.spec.ts` was not part of CI's browser job at this merge; B14 (#510) added it. No production smoke check or authenticated run was made.

## B11 capstone writing and portfolio exports — 22 October 2026

Issue #507: the capstone adds an executive update and a five-minute walkthrough script, both required and self-reviewed, and guided completion now needs both plus every teaching module M01–M14. The FDE hub exports the learner's saved writing as JSON and Markdown through the existing owner-checked draft read, with no attempt or progress write. The completion label stays "FDE guided path completed".

PR #552 is merged at 1b7cc5780146df5921cfa081f589c9693070a78e. Head 1d69460e passed required run 39785534528: coding 22m27s, browser 19m29s, tests 4m28s, static 2m41s, SQL 45s. READY production dpl_BuNpmNWHMWfv4JLxQ2mchLqLBVp2 matches the merge SHA.

FDE stayed off in production. The final copy commit (fccd873f) changed the export note, and `portfolio-export.spec.ts`, which CI did not run, kept the old wording; B14 found and fixed the stale assertion. No production smoke check or authenticated run was made.

## B14 FDE release verification — 22 October 2026

Issue #510 verifies the FDE release on the merged head of epics A to E (main 1b7cc578) and records the switch-on item. Production `LEARNING_PATH_FDE_ENABLED` stays unset; the owner sets it after this PR merges (NEEDED.md). The branch also closes a CI gap and fixes four product defects the verification found, plus two spec defects that running the specs in CI exposed. The twelve physical handlers under `api/` are unchanged (counted: 12). No migration, tier, reward or grading rule changes.

**CI gap.** Eight browser specs existed but no CI job ran them: `fde-hub`, `fde-taster`, `fde-positioning`, `interview-shelf`, `path-content-shapes`, `portfolio-export`, `diagnostic-overview` and `dsa-advanced`. One had already gone stale: B11's copy pass (fccd873f) changed the export note to "drafts included" and `portfolio-export.spec.ts` still expected "including drafts", failing in both themes. The assertion follows the shipped copy, and the browser job runs the eight specs as two grouped invocations after `learning-release+learn-sections` (about 25 s each locally). `scripts/ci-parity.mjs` and the ci-parity skill follow, so the verify sequence is now 55 steps; `npm run ci:parity -- --list` passes the drift check.

**Fixes from visual QA and the walk-through.** (1) At 390 px the M01 lesson's tables and code blocks scroll sideways but no keyboard user could reach the scroll (axe `scrollable-region-focusable`, WCAG 2.1.1): each scrolling table and code block in a lesson is now a tab stop named by its caption, with the path focus ring; `fde-taster.spec.ts` checks it and runs axe at 390 px. (2) The completion share card cut "Deployment in the customer's environment" with an ellipsis that also hid its counts; only the name shortens now (`fitLabel`, unit-tested). (3) The module page said "In progress" for a module with no evidence, including to a visitor; it says "Not started" until an activity has evidence (client tests updated). (4) At 360 px with 200 % text, path pages ran past the column: on CI's Linux fonts "Python comprehension" left the diagnostic card (`diagnostic-overview.spec.ts` failed in run 39807152220), and a sweep of all twelve QA views found the hub's Continue and export labels, the completion status pill, the lesson callout's text and long tokens in activity summaries doing the same, mostly with the default font too. Cards and summaries now wrap long words, path action labels wrap inside their buttons, and the callout and completion line wrap; `diagnostic-overview` and `fde-hub` now run their 200 % step in a wide font stack (Verdana, or DejaVu Sans on Linux), and `fde-hub` asserts nothing passes the main column. Both specs failed on the previous CSS (fde-hub listed 11 clipped elements) and pass on the fix.

**Release contract, local, Node 24.22.1.** `npm run ci:parity` (full) at e2f81667, clean tree: 52 passed, 1 failed, 2 skipped (`install`: node_modules present; `check:quickjs-build`: inputs unchanged against origin/main, as CI skips it) in 33.02 min. The failure was the new focus assertion in `fde-taster.spec.ts` (dark case, grouped run: route focus did not settle on `#main-content` within 5 s); rerun alone through parity on the same build it failed the same way, so it was a test defect, not load. Fixed in a0b098e2 (the keyboard step retries until the region holds visible focus); the group then passed three times in a row, and `ci:parity --only build,chromium,preview` plus both FDE browser groups passed on clean a0b098e2 (8 and 12 tests). CI found what the macOS runs could not. `fde-hub.spec.ts` saved its card download to `/private/tmp`, which does not exist on the Linux runner, so both themes failed with ENOENT (run 39797583910 on e2f81667, which also failed both taster cases, and run 39803589480 on a0b098e2, where the taster cases passed); 05726762 saves it under the test's output path. Run 39807152220 on 05726762 then failed `diagnostic-overview` on fix (4); b287b937 carries that fix; its run 39813091385 failed `static` on a type error in the new spec step (`typecheck:tooling`: `remove` on `Node`), fixed in c6667b01, where `ci:parity --only` passed all three typechecks, `check:unused` and `check:security`. On b287b937 `ci:parity --only` passed 14 of 14 selected steps in 5.7 min: build, `check:public`, `check:bundle`, `test:client`, chromium, preview, the browser groups `learning-release+learn-sections`, both FDE groups, `on-accent`, `navigation` and `routes-axe`, and both `check:responsive` sweeps. In the full run: types (api, scripts, tooling), `audit:native-reviews`, `check:unused`, `check:security`; `build`; `check:public` (18 URLs, 769 coding share pages, 97 question-of-the-day pages); `check:bundle` 238,684 of 241,651 gzip bytes initial, monitoring SDK 48,798 of 60,000; `npm audit --omit=dev` 0 vulnerabilities and `npm audit --omit=dev --prefix client` 0 vulnerabilities; `test:launch`; `test:paths` (fde v1: 15 modules, 28 lessons, 120 checks, 19 exercises, 10 artifacts); `test:path-authority` (39 checks); `test:billing` (40 checks); `test:client` (1,079 tests in 111 files); `test:coding` (1,109 s) and the other chained suites; 190 browser tests passed and that 1 failed across the 21 browser runs; `check:responsive` light 35 probes and dark 9 probes, 0 issues; `test:harness`; Storybook and the performance audit. Also run: `check:responsive` on `/learn/web-developer`, `/learn/software-engineer`, `/learn/forward-deployed-engineer` and the FDE path at 360/390/768/1024/1280/1440, light and dark, 24 probes each, 0 issues; `git diff --check origin/main...HEAD` clean. `test:sql` was not run locally (no Docker database for it); CI's `sql` job is the evidence.

**Visual QA** (local preview build, the FDE browser specs' fixture approach with the catalog's FDE availability on): the three Learn sections as a guest, the FDE hub as guest, Free and Premium, the M01 taster and its first lesson, M02 locked for Free, the IP01 shelf module, the C01 capstone and the completed hub with its share card; 12 views × light and dark × 360/390/768/1024/1280/1440, with reduced motion. Every cell: no horizontal overflow, no animation running under reduced motion, every keyboard stop at 390 and 1280 with a visible focus indicator, axe (WCAG 2.2 AA tags) clean at 390 and 1280 after fix (1), no page errors, no unanswered API request; the final sweep ran on the b287b937 build. A second sweep at 360 px with 200 % text, in the default font and in a wide font, found the overflow of fix (4) and is clean after it. 150 screenshots under `artifacts/b14-visual/` (not committed).

**Authenticated walk-through, local stack only.** Local Supabase (CLI 2.121.0 under colima, Postgres 17.11) with `supabase-schema.sql` and migrations 002–066 applied in order, the twelve handlers bundled with esbuild and served in-process with `LEARNING_PATH_FDE_ENABLED=true`, and the client built against it. Two dedicated local accounts created through the local GoTrue admin API: a Free account and a Premium account, Premium granted through `upsert_provider_entitlement` as the billing webhook does (`entitlement_summary`: provider, active). Free: enrolled (POST enrollment 200); took the diagnostic (12 questions, 8 right on purpose: submit 200, score 0.6667, `needs_revision`, per-competency report on the hub); read both M01 lessons (200, `self_reviewed`) and passed the M01 checks (200, `verified_pass`, score 1); M02 showed Premium marks and the upgrade dialog without any start request, and a direct start answered 402 `premium_required`. Premium: enrolled (200); completed M02 in the browser with both readings and nine of the twelve cases (each 200, `verified_pass`), the ninth case completing the module through the migration 066 quota with three cases unattempted; the competency board changed (Customer discovery from 24 not started to 9 verified passes and 2 self-reviewed); the rest of the guided loop (M01, M03–M14, C01) was submitted through the same server-graded endpoints with the reference solutions and authored answers, pacing to the server's rate limits (429s honoured, never bypassed); the server reported `guidedComplete`, the hub showed "FDE guided path completed", and the downloaded share card rendered from that state. Database after the run: Premium 15 loop modules completed, 38 `verified_pass` and 38 `self_reviewed`; Free diagnostic plus 3 M01 activities. No page errors in either walk. The local stack was then stopped (`supabase stop`, `colima stop`).

**Preview deployment, guest only.** `dpl_7kMw6eye5C7WppeumxmNCj67zMuX` (b287b937, the final application code; an earlier pass on `dpl_FTUYvF1WbFsKCJeRgASiN2apL7aa` at ec1c1da8 gave the same results) runs with a branch-scoped Preview `LEARNING_PATH_FDE_ENABLED=true` and shares the production database, so it was checked read-only and signed out, at 390 and 1280: `/api/health` 200 healthy; the catalog reports FDE `available`; the FDE section, the hub, M01 and its first activity answer 200 with their h1, show the sign-in prompts ("Sign in to record graded work", "Signing in is what makes results stick"), no horizontal overflow, no page errors and no API write. The only outbound POSTs were Sentry pageload transactions (10 % sampling), not errors.

PR #559 is open and not merged; the owner merges it. Frozen head c6667b01 passes required run 39815358042: coding 24m16s (the slowest gate), browser 13m52s with all 20 browser runs, tests 4m19s, static 2m46s, SQL 38s, verify green. The commit after c6667b01 adds only this entry. There is no production deployment of this work yet; production `dpl_BuNpmNWHMWfv4JLxQ2mchLqLBVp2` (B11's merge, READY) still serves FDE off.

*22 October 2026:* PR #559 merged as `1f5a3b11` and #510 is closed. The branch-scoped Preview `LEARNING_PATH_FDE_ENABLED` was removed, so no Vercel environment sets it; production serves FDE off until the owner switches it on.

Non-claims: no authenticated run against production or the preview, no production enrollment, submission or Premium check; the walk-through's accounts were dedicated local accounts and its database a local one. No physical devices or assistive technology were used; field data (real learners' use, completion and error rates) is unknown until the switch is on. The production switch is not set by this work.

## FDE code review — 23 October 2026

The owner asked for a code review of the FDE path before launch: find bad practices and fix them, with no e2e or browser tests. Branch `claude/fde-code-review` from `main` `cdb33a4b`. It changes no API under `api/` (twelve handlers), no SQL migration, no reviewed content, no tier gate and no XP amount. The production flag stays off.

**Method.** Four reviewers covered disjoint areas: server handlers, server core, client screens and client parts. Each reviewer committed one fix at a time, and a skeptic re-read each commit, keeping, repairing or reverting it with new commits. A second round fixed the real issues the first round had left open. The method is now the skill `.claude/skills/section-code-audit/SKILL.md`.

**Fixed (server)**
- **Raced writes:** a second enrol or a raced first draft save answered 500 and now returns the existing row or 409 `draft_conflict`.
- **Out-of-range draft saves:** they now answer 400 or 413 instead of 500.
- **Parallel reads:** start, progress and draft reads run in parallel after the ownership check.
- **Content validation:** the verdict is cached per path, so the validator no longer runs on every request.
- **Artifact input:** list entries that are not strings are dropped.
- **Validator:** it now refuses fractional answer indexes, NaN or non-finite thresholds and weights, empty traces and blank example captions.
- **Shelf modules:** they no longer count in the artifact tally.
- **Failed draft reads:** they are logged with the request id, and the response says `draftUnavailable` so the browser keeps its copy.

**Fixed (client)**
- **Drafts:**
  - The last keystrokes are flushed on unmount and routed to the activity they belong to.
  - Path drafts survive an involuntary sign-out for the same account only, and nothing is written or sent after the account changes.
  - Stored drafts are shape-checked before use.
- **Requests:** late results no longer change the next activity; Start, Pause, Claim and Submit are guarded against double submits; superseded start requests are aborted.
- **States:**
  - An expired check says so instead of re-dealing.
  - Start and "not started" wait for the enrollment list.
  - A paused path lists its activities without links.
  - Reset asks before wiping code.
- **Speed and bundle:** the code editor loads lazily, which removes CodeMirror (about 173 kB gzip) from the path screens; helpers used only by the workspace moved out of the main chunk; lesson views and rich text are memoised; the portfolio export reads in two lanes; the route preload matches only FDE routes.
- **Share card:** works without `roundRect` (Safari before 16, Firefox before 112), frees its canvas after export and keeps the download link alive until the click.
- **Accessibility:** no page-wide `aria-live`; focus moves to the opened activity and to each revealed hint; long code tokens wrap at 360 px and 200 % text.

**Checks** (local, Node 24, `npm run ci:parity -- --only …` at `575f8af5`)
- **Passed:** typecheck:api, typecheck:scripts, typecheck:tooling, check:unused, check:security, test:paths, test:path-authority, test:launch, test:client (110 files, 1,107 tests), build and check:bundle (initial load 238,362 gzip bytes, against 238,454 on `main` and a budget of 241,651).
- **After the later draft fix:** typecheck:api, test:paths, the client typecheck, check:unused and `learning-path-workspace.test.tsx` (33 tests) passed again.
- **Not run:** browser, responsive and SQL; CI covers them.

**Left open**
- **Code retries:** a network retry of a code submit with the same idempotency key re-runs the grader before the replay is detected. It costs grader time, not correctness.
- **Read rate limits:** the progress and preference GETs have no per-caller read limit, like most user GETs. Adding one is a rate-limit policy decision (NEEDED.md).

## Web Developer code review — 23 October 2026

This is the same audit as the FDE review, run with `.claude/skills/section-code-audit/SKILL.md`. It covered the Web Developer Learn section (`api/quiz/roadmap.ts` Learn branches, `lib/roadmap*.ts`, `lib/questions-store.ts`, `lib/review-selection.ts`, `client/src/components/Roadmap.tsx`, `client/src/components/learn/*`, `client/src/lib/roadmap.ts`) and the Coding section (`lib/coding/handlers.ts`, `practice-handlers.ts`, the React runner, `client/src/coding/*`, `client/src/components/coding/*`). Branch `claude/webdev-code-review`, built on the FDE review branch. It makes no change to the twelve handlers' routing, no SQL migration, no reviewed content, no tier gate and no XP amount.

**Fixed (server)**
- **Placement:** the final round checks the sign-in before it claims the round, so a refused token no longer spends it.
- **Completion:**
  - The attempt, the served set and the answers are read together.
  - First-pass comes from the locked completion RPC.
  - Concept reviews are read only for levels that name a concept (about 23 % of levels).
  - An expired attempt answers 409 `invalid_session`, not 500.
- **Progress and step reads:** they run in parallel with the plan and settings reads. The question bank and its overrides load together.
- **Review selection:** sort keys are computed once (4.7 ms to 1.7 ms for 2,453 questions).
- **Coding:**
  - Verdicts and reveals for a Learn attempt that ended mid-request answer 409.
  - `coding_draft_busy` answers 503 with `Retry-After`.
  - A draft holding U+0000 answers 400.
  - Practice-run positions are clamped.
  - Failed reads answer 503 or a logged 500 instead of re-offering passed work or locking a tier.
  - React code nested too deeply for the transpiler is a compile error, not a runner failure.
  - The fixture modules are converted once per runner.
- **CDN:** the public Learn map is cached at the edge (`s-maxage=60, stale-while-revalidate=300`).
- **FDE follow-up:** learning-path drafts and artifacts holding U+0000 answer 400 instead of a JSONB 500.

**Fixed (client)**
- **Learn:**
  - Ref guards stop double answers, double completions, double skill-check rounds and double section joins.
  - A completion that returns after sign-out writes nothing.
  - Stored progress is read by shape (an object-shaped unlock list crashed the page).
  - The level request is aborted on unmount.
  - Focus moves to Continue, to each question, and back to the map node.
  - The lesson runner is lazy-loaded.
  - A progress GET that started before a completion no longer overwrites it.
  - The empty hide-time progress flusher is removed.
- **Coding:**
  - A browser run stops when the learner leaves.
  - Shortcuts ignore forms, dialogs and a hidden editor.
  - Ref guards on Reveal and on starting a challenge run.
  - The track search keeps every keystroke.
  - Task rows are memoised (up to 316).
  - Long tokens wrap.
  - Revealed hints take focus.
  - Prettier and CodeMirror are not loaded while the editor is hidden or the browser asks to save data.
  - Draft and session state follow account changes (`accountEpoch()`).

**Checks** (local, Node 24, `npm run ci:parity -- --only …`)
- **Passed:** typecheck:api, typecheck:scripts, typecheck:tooling, check:unused, check:security, build, check:public, check:bundle (initial load 238,262 gzip bytes, 100 below the FDE branch), test:launch, test:coding-auth, test:grading-integrity, test:react-authority, test:paths, test:fallbacks, test:client (110 files, 1,140 tests).
- **After the last three commits:** typecheck:api, typecheck:scripts, test:launch, test:paths, the client typecheck, check:unused and the signout-sync tests passed again.
- **Not run:** browser, responsive and SQL; CI covers them.

**Left open (NEEDED.md)**
- **Hearts on the last question:** when the third miss is the last question of a 12-question level, the server still records a pass. Closing this changes a grading rule and needs a migration.
- **One active practice run per learner:** this needs a partial unique index, which is a migration.
- **The progress PUT:** it writes nothing but is still sent after shop changes.

## Software Engineer code review — 23 October 2026

This is the third audit run with `.claude/skills/section-code-audit/SKILL.md`, after FDE (#563) and Web Developer (#564). It covered the code specific to the Software Engineer section (`lib/coding/complexity.ts`, `lib/coding/puzzles.ts`, the shared catalogue, assessment and concept helpers, `client/src/coding/CodePuzzle.tsx`, the hidden `DesignRunner.tsx`, lesson figures and level intros) and the navigation helpers (`CareerRoadmap.tsx`, `tracks.ts`, `routePreload.ts`, `routeHead.ts`, `gameConfig.ts`). Branch `claude/swe-code-review`. It makes no SQL migration, no reviewed-content edit and no tier or XP change, and the system-design track stays hidden.

**Fixed**
- **Complexity estimator:**
  - It matches bounds with one identifier scan instead of a new `RegExp` per name and loop, and one 150,000-step budget covers all passes. A 13 kB adversarial submission held a request for 14 s and now takes about 20 ms.
  - A loop counter started at a literal no longer makes an input-sized loop look constant.
  - A loop index now bounds only its own loop. This had labelled some O(n) solutions O(n²) and paid them 15 XP instead of 25.
  - Snapshots of all 3,175 authored reports were compared before and after. The only changes are five labels that became "unknown", which pays the same XP.
- **Puzzles:**
  - A deal never starts solved; before, 1 in 120 deals of the five-line puzzle was already an answer.
  - Lookups use own keys only.
  - A submitted order padded with entries that are not line ids answers 400.
- **Catalogue:** the tier pass ratio is indexed once per catalogue, so a pass over the 769 tasks went from about 40 ms to under 1 ms.
- **Puzzle and system-design runners:**
  - Moves are announced in the puzzle's own status line, and Shift+arrow is disabled while checking.
  - Long lines scroll inside their box.
  - System-design attempts are keyed per task and session, and a late verdict for a left attempt is dropped.
  - Focus follows questions, verdicts and moved steps.
- **Lesson figures:**
  - An empty trace renders as text.
  - Focus stays on a stepping control.
  - The validator refuses NaN or fractional levels and marks.
  - Buttons are 44px.
- **Navigation:**
  - `og:url` is written with the canonical.
  - Trailing slashes are handled in titles.
  - Preloads respect `saveData`.
  - `/roadmap` totals include every track topic and round like section progress.
  - Track saves are ref-guarded and check `accountEpoch()`.
  - Lock counts are memoised.
  - Unused strings and dev tips are removed from the initial chunk.

**Checks** (local, Node 24, `npm run ci:parity -- --only …`)
- **Passed:** typecheck:api, typecheck:scripts, typecheck:tooling, check:unused, check:security, build, check:public, check:bundle (initial load 237,482 gzip bytes, 780 below the Web Developer branch), test:launch, test:coding-auth, test:grading-integrity, test:paths, test:client, and `test:coding` separately (814 tasks).
- **After the last two commits:** typecheck:api, typecheck:scripts and test:grading-integrity passed again.
- **Not run:** browser, responsive and SQL; CI covers them.

**Left open (NEEDED.md):**
- whether a puzzle session may be submitted more than once;
- whether a placement score of 18 or more should also open DSA Advanced;
- seven DSA Advanced level intros that repeat the one before (content);
- `/roadmap` has no DSA Advanced area (copy).

## Quiz, Play, Profile and Leaderboard code review — 23 October 2026

This is the fourth audit run with `.claude/skills/section-code-audit/SKILL.md`, after FDE (#563), Web Developer (#564) and Software Engineer (#565). It covered:
- **Quiz:** `api/quiz/submit.ts`, `questions.ts`, `challenge.ts`, `daily.ts`, `api/flashcards.ts`, `lib/http.ts`, `lib/reports-store.ts`, and in the client `Quiz.tsx`, `Challenge.tsx`, the daily question, `Today.tsx`, `TypingRacer.tsx`, Shark Cards, pending receipts and `xp.ts`.
- **Play:** `api/play/[action].ts`, `Play.tsx`, `realtime.ts`.
- **Profile:** `api/user/[op].ts`, friends, sharkname, settings, `Profile.tsx`, `FriendsPanel.tsx`.
- **Leaderboard:** `api/leaderboard.ts` and `Leaderboard.tsx`.

A last round fixed the cross-area leftovers the four section audits could not reach. Branch `claude/quiz-play-profile-review`. It makes no SQL migration, no reviewed-content edit and no tier, XP or grading change; there are still twelve handlers.

**Fixed (server)**
- **Timeouts:** every Supabase timeout now answers 503 `upstream_timeout` (`UpstreamTimeoutError` in `withTimeout`). Handlers' own catch-alls no longer turn it into 500, and an Auth outage no longer answers 401.
- **Input validation, 400 instead of 500:**
  - Query parameters repeated as arrays (categories, room codes).
  - U+0000 in Shark Cards and reports.
  - Over-long ids.
  - An answer index past the options.
  - Topic lists that are not string arrays.
  - Calendar dates that do not exist.
  - Non-boolean friend actions.
- **Play:**
  - Room creation inserts and retries on the unique key.
  - Room read failures answer 503, not 404.
  - Reads run in parallel.
  - Caught errors are handled in one place.
- **Quiz submit:**
  - Loads the bank while the one-time claim runs, without grading before it.
  - A claim error answers 503.
  - The unused sealed `answerProof` (up to 50 AES-GCM seals per submit) is removed.
- **Concept reviews:** a failed review-state read no longer resets every practised concept to its first stage.
- **Rate limits:** question reports are limited per account plus a class-sized address bucket, so a class behind one address can report.
- **Challenge:** a run saved twice with a different score answers 409.
- **Settings:** a failed settings read serves the last good copy.
- **Admin reports:** the report list keeps summaries of retired questions.
- **Progress PUT:** retired. It wrote nothing; it now answers 405, and the client no longer sends it after shop changes.

**Fixed (client)**
- **Ref guards:** on room host controls, create and join, quiz submit, Challenge grading and Next, the sharkname save, friend actions and the confirm dialog.
- **Account changes (`accountEpoch()`):** for quiz grades, XP syncs, pending receipt replays, Challenge rewards, quiz progress, the typing racer best and the leaderboard visibility save.
- **Realtime:** listener sets that unsubscribe properly, one presenter poll in flight, and rooms keyed by code and account.
- **Late and stale results:**
  - Late friend reads and lookups are dropped.
  - The `/quiz?mode=review` render loop is fixed.
  - Today and the Today board move to the new UTC day at midnight.
  - An offline leaderboard tab no longer shows the previous board.
- **Confirmation:** Remove friend asks first.
- **Focus and live regions:** focus moves to each question and verdict, and the live regions are always on the page. The profile tabs use a roving tabindex, and targets are 44px.
- **Reads and preloads:**
  - Profile reads run in parallel.
  - The daily challenge load can be aborted.
  - Route preloads match only real routes.
  - Pending-result replay and board readers left the main chunk.

**Checks** (local, Node 24, `npm run ci:parity -- --only …` at `60611967`)
- **Passed:** typecheck:api, typecheck:scripts, typecheck:tooling, check:unused, check:security, build, check:public, check:bundle (initial load 235,638 gzip bytes, 1,844 below the Software Engineer branch), test:launch, test:coding-auth, test:grading-integrity, test:path-authority, test:paths, test:billing, test:fallbacks, test:client. `git diff --check` is clean, and `api/` holds 12 handlers.
- **Not run:** browser, responsive and SQL; CI covers them.

**Left open (NEEDED.md)**
- **Challenge scoring:** a Challenge score sums the answers the player chooses to send. Enforcing the order needs per-run server state.
- **Rooms:** abandoned rooms have no cleanup job, and rooms have no participant cap.
- **Account data export:** there is no export of a learner's own data.
- **Brittle matching:** two conflicts are matched by message text, and the friend "register" step has no unique key.

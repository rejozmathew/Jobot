# Evidence-driven application improvements

Engineering iterations use `self-improvement`, derived from
`codex/runtime-simplification` on September 27, 2026. Work in the original checkout.
The Codex daily task reviews the previous America/Chicago calendar day at 09:00.
The application executor itself does not edit code or deploy changes.

For each review, preserve a private report with the snapshot time, deployed source
commit/file manifest, attempt and dispatch counts, confirmed submissions, unique
jobs, elapsed time, retries, executor failures and portal breakdown. Separate
failures of the model/runtime from employer obstacles and user interventions.
Attribute attempts spanning a deployment to their actual source/version evidence;
do not infer performance gains from fixtures or a partial day.

## Counterfactual review and submission preservation

Every daily run includes a private counterfactual exercise before selecting a fix.
Freeze the previous day's evidence and version provenance, then deduplicate by
observed employer posting identity. Keep attempt counts, distinct postings, new
submissions and already-applied outcomes separate. Preserve every successful
attempt as a control inventory, including its confirmation source, recovery path,
timing, deadline, assistance and source version. Do not rewrite production history.

For each proposed change, identify the exact failure mechanism, evidence that was
available before the affected attempt, remaining application time and unresolved
downstream obstacles. Do not import later answers, consent or credentials backward
in time. Later success can corroborate feasibility, but cannot establish the
counterfactual outcome. Distinguish fixes already deployed from genuinely new work.
Report affected attempts, additional unique-job candidates, retry/time savings,
overlaps and explicit assumptions. A repaired prerequisite is an opportunity, not
a submitted application. Do not credit repeated retries as extra jobs or turn
saved minutes into invented submissions. Include a zero-gain scenario and label
optimistic scenarios without assigning unsupported probabilities.

Historical accounting and executable replay are separate evidence. Holding past
successes fixed, enumerating combinations or replaying recorded success labels
does not test a changed executor. Reproduce the bounded mechanism with isolated
synthetic forms, accounts and approved answers; never use live applications or
private personal records as test fixtures. Run the same relevant synthetic cases
against the baseline and candidate implementation. Cover the successful mechanisms
represented by the control inventory as well as the failure being repaired. Save
commands, source versions, before/after results, logs and JUnit privately.

The acceptance target is zero lost confirmed submissions: a previously successful
case becoming blocked, interrupted, unknown or incomplete is a regression. Check
confirmation acceptance, recovery after helper/authentication errors, answer and
account identity, Simplify order, operator stops and the original deadline. Keep
new recovery on the demonstrated failure path and measure added work on normal
successful paths. Compare complete application series, not only their final retry.
When recovery duration or concurrency changes, also compare a fixed-capacity
synthetic queue with the same arrivals, deadlines and successful controls; longer
recovery must not silently displace another success. Label unmatched mechanisms
and unmeasured capacity effects explicitly rather than calling them passed.

Do not deploy a candidate with an observed lost-success regression; correct it or
defer that candidate while retaining the working version. This is an engineering
release criterion, never a new application-time refusal, finish gate or shorter
recovery budget. Passing synthetic checks reduces risk but cannot guarantee future
employer outcomes. Continue matched post-deployment observation and investigate
credible submission losses before optimizing speed. Keep raw private evidence
local. Prefer command-only external validation: prepared synthetic test commands
write detailed logs locally and return aggregate results for primary inspection.

## Implementation and deployment

Self-improvement #014 (October 12, 2026) addresses hosted Rippling locale-only
transitions: `/en-US/<tenant>/jobs/<UUID>` and `/<tenant>/jobs/<UUID>` compare
through the existing application scope. Full tenant, UUID, child route and opaque
query comparison remain authoritative. This changes live comparison only; stored
intake keys, retry permissions, submission evidence and operator deadlines remain
unchanged. Synthetic native receipt recovery and existing successful mechanisms
are the validation controls; production gains remain under observation.

Use exact recorded evidence to propose a bounded change. Prefer a shared fix when
the same cause applies across portals. Add a synthetic failing regression, implement,
review the diff, and delegate routine validation to authenticated Antigravity
`gemini-3.8-flash-medium`. Independently inspect logs/JUnit and run the required
final `python -m pytest tests/jobbot_v1 -q` suite. Do not use live applications as
fixtures or manufacture production outcomes for tests.

Register each Ubuntu validation run's disposable `TMPDIR` and pytest basetemp
with the completion/identity/report manifest described in
[`VALIDATION_STORAGE.md`](VALIDATION_STORAGE.md). Preserve logs/JUnit outside
those directories and mark completion only after the test process and its owned
browser fixtures finish. The installed daily validation-cleanup timer removes
completed registered fixtures after 24 hours; protected metadata on unrelated
system/browser processes must not cause unlimited fixture retention.

The initial deployment disables optional automatic background memory/skill reviews
in the selected Ubuntu Hermes profile to reduce competing model requests. This is
a profile-wide private configuration change, backed up separately from Git. It does
not cancel an already running review or reload the model. The installed Hermes
version also suppresses bare `/refine`; explicitly focused refinement and separate
review delegation remain available. Restore the backed-up setting to reverse it.

Commit each validated iteration and push the existing remote's `self-improvement`
branch. Deploy only intended files to the authoritative Ubuntu runtime after the
current application finishes. Pause pickup when needed, retain its prior state,
back up changed files, verify prior hashes and preserve unrelated deployed changes,
private configuration, databases, accounts and browser profiles. Reload affected
idle services, verify source hashes/services, restore pickup and record the deployed
commit, timestamp and file manifest privately. Preserve active applications through
the existing lifecycle; a deployment is never a reason to terminate one.

## Run labels and public notes

Use a sequential run number and the America/Chicago review date, starting with
the first explicitly numbered run below. Check existing run notes and remote tags
before choosing the next number. Commit subjects use
`Self-improvement #NNN (YYYY-MM-DD): <concrete change>`. Multiple checkpoints for
one review share its run number.

Publish an annotated tag `self-improvement-NNN-YYYY-MM-DD` pointing to the exact
validated, deployed code commit. Its description and an entry below explain the
problem, behavior changes, validation, deployment time and remaining limitations.
Keep the same run label, source commit and tag in the private Ubuntu deployment
record. A documentation-only follow-up records its separate commit without
changing which executable source was deployed. Preserve published history and
existing tags; append corrections instead of moving a run's identity. Detailed
job records, account information, answers and transcripts remain private.

### Self-improvement #001 — 2026-09-28

Code commit: `67a22fc2ad3bdca663f5e58aac9105b476b7cc24`.
Tag: `self-improvement-001-2026-09-28`.
Ubuntu deployed: September 28, 2026 at 10:01:23 America/Chicago (15:01:23 UTC),
after the active application finished. GitHub branch: `self-improvement`.

Delayed form navigation could lose the owned application route after a helper's
browser connection closed. The iCIMS posting Apply path also bypassed the shared
navigation handoff. This run:

- Retains verified same-origin main-document navigation history across helper
  connections, including delayed document changes and push/replaceState.
- Routes iCIMS Apply through the shared same-tab/popup handoff and refreshes
  embedded-form context and derived profile/email facts after adoption.
- Uses fresh final-submit control classification consistently for Autofill,
  audit and the existing review/submission path.
- Updates the integration test to discover the installed Hermes interpreter and
  isolate its temporary home; production Hermes configuration is unchanged.

Validation: the final managed suite passed 1,055 tests with 111 skips; focused
route-history and iCIMS/Autofill suites passed 67 and 52 tests respectively.
Ubuntu synthetic validation passed all 132 tests. All 80 cumulative deployed file
hashes, authenticated health, dashboard access and services were verified, and
queue pickup was restored. Private configuration and the existing pause behavior
were preserved. The first numbered label was added after the code had already
been published; the original code commit remains unchanged.

Cross-host SSO account-principal handling remains a separate issue. This release
does not claim a measured increase in submission rate or a reduction in GPU use;
those require post-deployment application evidence.

The daily task can make these tested improvements under the operator's standing
authorization. New execution restrictions, refusal conditions or retry limits still
require explicit approval. If the evidence does not support a fix, record that fact
and continue observation. Serving-engine changes require engine-side evidence or a
synthetic reproduction; a decoder error alone does not prove GPU memory exhaustion.

### Self-improvement #002 — 2026-09-28

Tag: [`self-improvement-002-2026-09-28`](https://github.com/rejozmathew/auto-job-applier/releases/tag/self-improvement-002-2026-09-28).
The annotated tag identifies the deployed code commit and records the verified
Ubuntu deployment timestamp and post-deployment checks. The matching private
Ubuntu manifest retains file hashes and backups. GitHub branch: `self-improvement`.

Opening the dashboard over LAN HTTP exposed a browser compatibility bug:
`crypto.randomUUID()` requires a secure context. Manual Add Job failed while
constructing its payload, before sending an intake request. Four queue/start/retry
paths used the same unsupported call.

All five actions now share a request ID function. It uses native `randomUUID`
where available and otherwise creates UUID v4 identifiers with the browser's
HTTP-compatible `getRandomValues`. Distinct actions receive distinct identifiers;
authentication retries retain the original request identity. This changes no
application permissions, queue policy, recovery limits or operator deadlines.

Validation reproduced six failures before the fix. All 51 focused tests passed,
and the final managed suite passed 1,066 tests with 111 skips. Synthetic dashboard
tests exercise all five actual handlers with and without native UUID support and
verify authenticated retry identity. No live application was used as a fixture.

Deployment updates the dashboard asset, synthetic regression and these notes at
an idle application boundary. The dashboard serves the asset directly from disk,
so no service restart is needed; existing browser tabs must reload. Ubuntu fixture
results, served-asset hash, service health and cumulative file verification are
recorded in the tag and private run record. This fixes dashboard request failures;
it does not establish an increase in employer-portal submission success.

### Self-improvement #003 — 2026-09-28

Tag: [`self-improvement-003-2026-09-28`](https://github.com/rejozmathew/auto-job-applier/releases/tag/self-improvement-003-2026-09-28).
The annotated tag identifies the validated code commit and verified Ubuntu
deployment time. Matching private run records retain test reports, file hashes
and rollback copies. GitHub branch: `self-improvement`.

Recent Greenhouse helper calls returned `invalid_question` when an observed
control had a missing or oversized question identity. This stopped the whole
residual batch and sent supported fields back to the model. The runner now
finishes the supported fields and returns scoped metadata diagnostics without
field values. Unreadable required, rejected or explicitly planned controls still
receive recovery; an unrelated optional control no longer aborts the batch.
Conditional changes refresh the diagnostic's required/rejected classification.
Exact question bindings, verified answer history and ownership checks remain in
use; labels and question identities are never invented or truncated.

An iCIMS synthetic fixture reproduced a second premature handoff: Continue's
response arrived after the existing 150 ms pause. The runner now observes an
intermediate click for up to five seconds, resuming that window across helper
connections without an automatic duplicate click. The operator explicitly
approved this observation window. Incidental optional-field and footer changes
do not count as a response. A new step, document or actionable validation resumes
normal handling. An unchanged page clears the receipt and returns the existing
recovery handoff; later retries remain possible. Helper slices, operator stop and
the overall application deadline still apply.

Available Simplify remains first on each non-authentication form step. Native
credential handling remains the authentication path. Tests cover Simplify on the
new iCIMS step before residual inspection, including delayed transitions and a
new browser connection. No universal page delay, model/provider change or new
GPU inference layer is introduced. Workday's current behavior is retained and
included in regression validation.

Validation first reproduced eight Greenhouse failures, two delayed-transition
failures and two duplicate-click failures caused by reordered fields. The
combined Windows browser/helper suite passed 205 tests. After the ordering fix,
all 59 affected iCIMS and shared Autofill checks passed. The final managed suite
passed 1,066 tests with 130 skips (125 opt-in browser cases and five Linux-only
cases). Post-deployment Ubuntu results are recorded in the annotated tag and
private run record. All application fixtures use synthetic data and isolated
profiles.

These changes remove reproduced helper failures and unnecessary model handoffs.
They do not establish an end-to-end speedup or a higher submission rate. Recent
operator-assisted Greenhouse attempts are not autonomous timing benchmarks;
production comparisons must retain intervention and deployed-version context.

### Self-improvement #004 — 2026-09-29

Tag: [`self-improvement-004-2026-09-29`](https://github.com/rejozmathew/auto-job-applier/releases/tag/self-improvement-004-2026-09-29).
The annotated tag identifies the validated code commit, Ubuntu deployment time
and final test counts. The matching private report and deployment manifest retain
the daily audit, source fingerprints, hashes, backups and validation logs.
GitHub branch: `self-improvement`.

Credential calls could report that Simplify needed to settle even when the
browser was idle and the actual obstacle was an unresolved or mismatched job
identity. This sent recovery toward the wrong subsystem. The shared workspace
host now reports the existing job-identity error codes for those two causes and
directs the executor to inspect a fresh owned screenshot and recover the route
in the same session. Actual Simplify settlement failures keep their existing
diagnosis. The change applies to employer credentials and email verification
across portals; it adds no denial, permission requirement or retry limit.

Synthetic regressions reproduced four incorrect diagnoses before the fix. They
exercise the real host dispatch and private test database, verify that denied
calls do not reach credential handling, preserve the session and its metadata,
and then complete a credential call in the same session after corrected browser
evidence. Recovery events omit the private observation payload. Focused browser,
account, Workday and Simplify tests and the final managed suite are delegated to
authenticated Antigravity; Ubuntu repeats the focused suite against deployed
files with isolated synthetic fixtures and short private disk-backed paths.

This corrects recovery guidance; it does not implement cross-host SSO account
handoff or repair missing posting URLs. The preceding day's attempts finished
before #003 deployed, and some submissions were operator-assisted. They cannot
establish a production speed or submission-rate gain from #003 or this run.

### Self-improvement #005 — 2026-09-30

Tag: `self-improvement-005-2026-09-30`. The local annotated tag identifies the
validated source checkpoint. Private Ubuntu deployment notes retain the matching
run label, timestamp, file hashes, backups and synthetic validation evidence.

Retained application screenshots show a visible consent choice while shared
native activation returns `hidden_control`. Styled native checkboxes and radio
buttons can expose a zero-size input and a separate visible label. Previously
the pointer helper only used the input rectangle, returning routine work to the
executor's model and visual recovery loop.

The shared pointer helper now uses that input's own visible, uniquely associated
native label when its rectangle has zero width or height. The semantic input
remains the observed target. Activation uses trusted browser pointer events and
fresh hit tests; interactive label children and overlays are not clicked as a
substitute. The existing form operation verifies the committed checked state and
does not toggle a correctly populated control again. No employer, hostname or ATS
branch is added. Simplify order, ownership, credentials, frame checks, answer
policy, deadlines and retry behavior are preserved; no new execution restriction
or approval gate is introduced.

Six synthetic regressions first reproduced the failure for checkboxes/radios on
top-level, same-origin and cross-origin embedded forms. Coverage also checks
trusted events, repeated checks, explicit unchecking, disabled controls, overlays,
unrelated labels and interactive children. Relevant existing shared-form,
embedded-frame, Workday authentication and native-pointer checks accompany the
focused suite, followed by the standard managed suite. Exact final counts and
Ubuntu deployment verification are retained in the private run record and tag.
Windows validation passed all 70 focused checks; the final managed suite passed
1,075 tests with 140 opt-in browser/Linux-only skips. An initial isolated Hermes
startup timeout passed unchanged on focused recheck before the clean final run.

The timing investigation also found costly model requests, large contexts,
compression, repeated inspections and incorrect specialized-helper routing.
This change fixes one reproduced shared handoff; it does not establish a
ten-minute application duration or an unattended end-to-end speedup. Later
ordinary applications must measure those outcomes with source and assistance
provenance. Private application records and screenshots remain outside Git.


### Self-improvement #006 — 2026-10-02

Tag: `self-improvement-006-2026-10-02`. The annotated tag identifies the validated,
deployed source checkpoint and exact test counts. Matching private Ubuntu notes
retain deployment time, source hashes, backups and synthetic validation logs.

Recent attempts exposed delayed owned-tab closure being treated as an interrupted
application, unknown writer state persisting without an actual writer, and an
observed authentication redirect losing application identity. The existing
persistence instructions were present; adding more generic persistence language
would not repair these runtime failures. Completed attempts also included genuine
closed postings, a missing required answer, and an accepted submission. The runs
used differing model effort and unmatched jobs, so they do not establish a model
quality ranking.

Owned restart now persists through delayed closure and reopening failures in the
same session and attempt. It survives host reconstruction and preserves submission
evidence and the original deadline; pause, stop and expiry retain their existing
cleanup behavior. Stable explicit receipts showing no participating writer can
clear a stale unknown state without bypassing active writers or unresolved frames.
Observed authentication continuations use shared navigation correlation and retain
the employer account reference while projecting the current login route. The
shared browser and iCIMS continuation paths use this behavior. Unobserved unrelated
login navigation does not establish ownership.

The execution brief and canonical skill make user corrections actionable in the
current turn and explain pending restart status. No new execution restriction,
retry limit, approval requirement or model configuration change is introduced.

Synthetic regressions first reproduced five restart/writer failures and two
login-continuity failures. Validation includes actual isolated-browser navigation,
existing target handoffs, lifecycle/deadline/account checks and the full managed
suite, delegated to authenticated Antigravity with independently inspected logs.
These fixes do not establish an end-to-end submission-rate or speed improvement;
that requires subsequent application evidence with source and assistance context.

Windows validation: 1,100 passed and 143 skipped in the final managed suite.
The explicit browser navigation suite passed 27 tests. Combined recovery checks
passed 116 tests with one incorrect new timeout-label assertion; correcting that
assertion to the existing interrupted outcome with a distinct timeout reason
passed in the subsequent 44-test account/restart suite and final managed suite.
Ubuntu validation and deployment verification are recorded in the annotated tag.

### Self-improvement #007 — 2026-10-03

Namespace checkpoint: `aba0ff237bf3d0cc03d468966e6e8e2588b89cc1`.
Tag: `self-improvement-007-2026-10-03`. This bounded change is deployed together
with #008; the combined runtime commit and both component identities are recorded
in the shared Ubuntu manifest and annotated tags.

Posting identity can contain a site identifier that is not an account namespace.
Previously that verified identifier could make application-context construction
raise `invalid_namespace`. Account selection now falls back to the existing
account URL when a posting-derived identifier cannot represent an account. Raw
posting/requisition identity, explicit account namespaces, account evidence and
retry history retain their existing behavior.

The same 53 synthetic cases ran against baseline and candidate: the baseline had
47 passes and six expected failures; the candidate passed all 53. Browser cases
verify actual credential entry and confirmation, including an already-working
account-shaped namespace. The observed historical posting was later found closed,
so this repair receives no credited additional submission in the retrospective.

### Self-improvement #008 — 2026-10-03

Tag: `self-improvement-008-2026-10-03`. The tagged checkpoint contains the combined
#007/#008 deployment. Exact final validation, deployed hashes, service readiness
and the operator-requested queue resumption are retained in private run records.

Three shared defects prevented supported application continuations. Credential
handling now builds its context after the authorized browser observation, which
can promote a delayed route while preserving the employer account. An access
form containing email/password plus privacy choices can use the existing observed
authentication navigation even when its coarse stage is unknown. Ordinary profile
text fields, including custom textboxes, add no new wait. Finally, a previously
verified canonical application route retains its existing child-route scope when
the intake URL has a different path. Unobserved aliases and conflicting jobs,
sites, hosts and query identities do not gain ownership from this repair.

Regressions reproduce stale credential context, mixed access-form navigation and
canonical child-route loss. Real isolated-browser cases fill the selected employer
credential and reach confirmed submission through the shared browser and iCIMS
paths, both with and without privacy choices. A four-slot synthetic scenario holds
the recovered authentication call while three existing controls submit, then
verifies the next queued reservation can enter and submit after an owned tab closes.
It checks preserved deadlines and actual outcomes, not recorded success labels.

Daily reviews and the recurring task now require frozen counterfactual evidence,
posting deduplication, successful control inventories, baseline/candidate execution
and explicit uncertainty. The historical accounting identifies two conditional
answer-reuse candidates and eight route opportunities, not ten proven recoveries.
Answer learning was already deployed before this change. Neither these scenarios
nor synthetic checks establish a production gain or guarantee future submissions.
The capacity scenario checks independent progress and admission during recovery;
production throughput remains unmeasured. Deadlines, application permissions,
retry policy and Simplify order are unchanged.

Windows validation covered all 1,188 non-skipped managed cases successfully across
two full runs, with 153 opt-in/platform skips. Neither run was a clean sweep: one
hit an existing Node subprocess timeout; the other hit a Windows access error
while replacing a synthetic Hermes receipt. Each affected case passed in the other
run, with isolated recheck evidence retained. The earlier five-window startup
timeout also passed unchanged in isolation. The four-slot submission replay and
final edited credential/navigation checks passed. These environment failures are
recorded rather than hidden or addressed by loosening application behavior.

### Self-improvement #009 — 2026-10-04

Tag: `self-improvement-009-2026-10-04`. The annotated tag identifies the validated
code checkpoint, deployment timestamp and final test counts. Matching private
Ubuntu notes retain source hashes, backups, synthetic reports and queue state.

The evening review found repeated SQLite contention crashing queue/host supervision
and interrupting applications with time remaining. Read-only projections now use
deferred read snapshots, hot history lookups have non-unique indexes, session
history loads in one batch, and hidden dashboards stop polling. Busy supervision
retains owned sessions and executors, including a reserved launch or pending
process-identity write. Cached deadlines remain effective when bookkeeping is busy;
unfinished browser preparation reclaims only its owned targets before retrying.

Observed navigation now preserves LinkedIn notification posting identity, public
password-reset requests, embedded posting links and assessment invitations through
the existing shared handoff. Verified posting aliases link intake and reporting.
Retry context retains meaningful earlier obstacles and current saved answers when
later interruptions obscure them. Activity reporting separates explicit prior-
application evidence and deduplicated postings while retaining raw recorded counts.
Helper screens retain controls, facts, policy and recovery operations with less
repeated guidance. No application restriction or new retry limit is introduced.

Synthetic regressions reproduced the contention, route, history and reporting
failures before implementation. The focused Windows browser/recovery suite passed
all 84 cases, including the unchanged four-slot submission/admission control.
A separate test with 80,000 events and 49,000 actions preserved four writers during
dashboard polling. The same hot lookup used about 240,000 SQLite VM steps without
its index and fewer than 100 with it. This is a database mechanism comparison,
not an end-to-end application throughput claim. Antigravity runs the final managed
suite and isolated Ubuntu checks; logs and JUnit are inspected independently.

Deployment occurs while pickup is paused and applications are idle, preserving
the deployed operator route-reconciliation bridge and private configuration.
Confirmed ended-session browser targets can be reclaimed using durable ownership
and browser incarnation evidence. Services are verified before pickup resumes.
The historical counterfactual remains conditional: fixing a prerequisite does not
prove that a particular employer would have accepted the application. Production
submission-rate and capacity improvements require subsequent matched evidence.

### Self-improvement #010 — 2026-10-05

Tag: `self-improvement-010-2026-10-05`. The annotated tag and private Ubuntu run
notes retain the validated source checkpoint, test counts and deployment evidence.

The morning review found provisional popup URLs becoming the owned application
route before an HTTP redirect committed. The shared Apply helper now observes the
already-correlated popup through document readiness within its existing observation
window. The mechanism contains no employer, role or portal-specific branch. It
preserves normal recovery when the popup is slow or disconnected, and retains
existing public-route and job-identity checks. It adds no application restriction,
retry limit or deadline reset. Emailed private reset-link recovery remains outside
this fix; fixing a public redirect does not establish private-link ownership.

Failure summaries now prefer a specific final obstacle over earlier helper errors.
Explicit later outcome reconciliation remains visible, generic cleanup can still
use diagnostic events, and recorded attempts and success counts are unchanged.

Before implementation, two isolated browser fixtures with different synthetic
host pairs reproduced the redirect mismatch; both now fill and submit successfully.
The normal-popup control also submits. Reporting regressions reproduced stale
helper errors hiding final obstacles. Additional controls cover ready-document
latency, the existing observation window, identity conflicts, disconnected targets,
private URLs, successful outcomes, deadlines and four-slot submission/admission.
The browser fixture now intercepts new popup requests as well as parent requests;
synthetic hostnames cannot accidentally resolve to live employer pages.

Antigravity executes focused and final managed checks; the primary agent inspects
logs and JUnit. The capacity replay checks independent submissions and admission,
not production throughput. A ready popup adds a CDP observation but no fixed sleep;
ordinary fields and same-tab actions add no popup observation. Popup correlation
before an unobserved redirect and redirects after document readiness remain outside
this bounded repair. Synthetic recovery is not a promise of employer acceptance or
a measured production submission-rate improvement. Deployment preserves active
applications, operator route overlays and private configuration at an idle boundary.

Windows validation: 80 focused checks passed; one new test-clock fixture issue was
corrected and all six popup observation unit cases passed in the final suite.
The managed suite recorded 1,256 passes, 159 skips and one external Hermes startup
timeout. That unchanged integration case passed in isolation in 7.66 seconds.
This is complete passing coverage across the full run and recheck, not a claim
that the full run had no failures. Exact Ubuntu validation and rollout results
are retained in the annotated tag and private deployment manifest.


### Self-improvement #011 — 2026-10-06

Tag: `self-improvement-011-2026-10-06`. The tag identifies executable checkpoint
`1e8d9726aa4e37a77dbb15e3f85fd30b663efbd1`, implemented and deployed by the
authorized answer-reuse task. This publication assigns its numbered run identity
without rewriting the existing code commit. The documentation checkpoint is
separate from the deployed executable. Matching private Ubuntu notes retain the
original deployment manifest, verification and this publication record.

Company templates now reuse approved answers across employer-name changes while
keeping company and application exceptions authoritative. Learned Yes/No sentences
map back to Boolean choices, and pending semantic wording matches can progress
despite unfinished synthesis work. Answer history retains changed library
revisions. The dashboard distinguishes matched questions from recorded form uses;
neither count establishes employer acceptance.

Focused checks passed all 56 cases. The final Windows managed suite recorded
1,263 passes, 159 skips and one installed-Hermes startup timeout. The unchanged
integration case passed separately in 9.00 seconds; the full run is not described
as failure-free. Ubuntu passed all 60 relevant checks after the validation runner
was corrected to include its installed Node. Release-file hashes, served assets,
health, preserved private configuration and restored queue controls were verified
on October 6 at 14:06:10 UTC. These checks do not establish a production speed or
submission-rate gain, or complete coverage of every employer recovery mechanism.

The daily review froze the previous day's application evidence and inspected
retained screenshots, authentication failures and slow confirmed recoveries.
Private emailed reset-link ownership and incompatible retained credentials remain
separate investigations. The existing public-route and popup fixes do not establish
private reset-link scope. No new application-execution restriction, shortened
deadline or retry limit was added. Detailed application findings stay private.

The publication also completes the previously missing GitHub push for #010.
Both executable changes were already deployed; publication does not start another
runtime deployment or interrupt an active application.


### Self-improvement #012 — 2026-10-07

Tag: [self-improvement-012-2026-10-07](https://github.com/rejozmathew/auto-job-applier/releases/tag/self-improvement-012-2026-10-07).
The annotated tag identifies the exact validated code commit, Ubuntu deployment
time and verification results. Matching private run notes retain the redacted
review, source/file manifests, baseline/candidate logs and JUnit.

An iCIMS helper can own a page without borrowing a browser wrapper. After a
correlated popup Apply or authentication Continue, the shared document observer
previously accessed the absent wrapper and raised NoneType.base_url. It now uses
the already-armed loopback endpoint and correlated child target for that caller.
Normal browser callers retain their observed mode. The original observation
window, destination/identity rules, ordinary recovery, Simplify order, accepted
confirmation sources and operator stop/deadline behavior are unchanged.

Five synthetic regressions reproduced the fault. Ubuntu's same 95 checks changed
from 90 passing plus five reproduced failures to 95 passing, with no lost baseline
passing checks. Real synthetic Apply and Continue popups recover through native
submission in the same attempt. Existing four-slot recovery preserves the
successful controls and next admission. These checks do not cover every production
portal/complexity or a complete popup-specific capacity queue.

Windows focused validation covers 115 checks across the focused run and an isolated
recheck of one unrelated Node/jsdom timeout. The standard final managed suite
passed 1,267 tests with 161 skips. An optional whole-suite browser sweep stalled;
its log was retained and it is not counted as passing. No live application or
private profile was used as a fixture.

This bounded correction removes a demonstrated helper exception. The review
separately identified generic form/account-route failures, expensive repeated
observation and an unrelated-posting identity adoption. Those larger changes are
deferred pending safe synthetic reproductions; production records are preserved.
No additional production submission or speed gain is claimed. Deployment changes
only the intended source, synthetic tests and current run/runtime notes, at an
idle application boundary, with prior queue state restored afterward.

### Self-improvement #013 — 2026-10-08, completed 2026-10-09

Tag: `self-improvement-013-2026-10-08`. Matching private GitHub/Ubuntu run notes
retain the October 7–8 reviews, exact source/file manifests and validation logs.

The shared browser observer now resolves the same ownership-checked full
application route used by managed helpers. A same-origin canonical redirect can
retain its tracking query while the owned target's display URL omits that query.
Using the display/intake route incorrectly reported a different job and disabled
Simplify/native writes on the verified form. The correction retains the original
posting/history, rejects different jobs/sites/hosts/queries and adds no alias,
helper, deadline, retry rule or application-time gate.

Paired Ubuntu replay used the same 119 synthetic checks: baseline 117 passed and
two reproduced failures; candidate 119 passed, preserving all 117 baseline passes.
The real synthetic form continues through native fill and an accepted receipt in
the same owned attempt. Existing authentication/popup recovery, Simplify order
and settlement, confirmation, operator stop/deadline and four-slot recovery
controls remain covered. This does not cover every real form or prove production
submission-rate, latency or capacity improvements.

Installed Windows Hermes cold imports exceeded the integration fixture's former
30-second startup allowance. A traced diagnostic completed tool registration,
invocation and disposal successfully; the fixture now allows 120 seconds for
installed-agent startup. This changes no application execution clock. Private
run notes retain the initial failures, diagnostic and final-suite results.

The counterfactual opportunity is conditional zero to one additional unique
posting across six affected attempts, with downstream fields/validation still
unproven. Other findings include a kernel Brave OOM preceding four interruptions,
expensive embedded-form/menu recovery and account-route failures. Those findings
are retained for separate reproductions. Slow confirmed submissions remain
persistence controls; no quick unsuccessful outcome is credited as an improvement.
Only intended files are deployed at a paused idle boundary, with prior operator
queue state restored and deployed hashes/services independently verified.

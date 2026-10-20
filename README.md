# Harness Optimizer

A user-invoked Claude Code plugin for coordinating a bounded batch of
harness improvements. It uses available specialists without installing them
or changing their invocation and consent requirements. Ordinary authorized
repository repair remains useful when maintenance specialists are unavailable.
No private harness is required. The manifest, tool declarations and native validation
are Claude Code-specific; compatibility with other runtimes is untested.

## Install and run

Once the release is listed in the `hov` marketplace, install it in Claude Code:

```text
/plugin marketplace add StartupBros-com/hov-marketplace
/plugin install harness-optimizer@hov
```

If `hov` is already registered, skip the first command. Start a new session after
installation, then run:

```text
/harness-optimizer:harness-optimizer
```

You can give it a scope, such as “investigate recurring tooling friction in this
repository.” It does not start optimization automatically. Investigators and
reviewers use model tokens; the documented attempt bounds are not a spending cap.
Existing permissions and any specialist-specific approval requirements still apply.

### Local source loading

For development, from this repository's root, load it for one session:

```sh
claude --plugin-dir .
```

Session-only discovery on Claude Code 2.1.300 exposed
`/harness-optimizer:harness-optimizer`; explicit invocation loaded the skill,
while an unrelated prompt did not start maintenance. The bare
`/harness-optimizer` alias is not promised. Loading source is not marketplace installation or activation of
any proposed harness changes. This package includes no hooks, settings, MCP
servers or dependency installers.

## Deterministic checks

From the package root:

```sh
claude plugin validate .
python3 -m unittest discover -s tests -p 'test_*.py'
```

These structural checks require no provider credentials and establish neither
model behavior nor real specialist compatibility. The package is MIT licensed.
CI runs the offline tests; provider-backed fixture runs remain opt-in. A passing
CI run is not evidence of live specialist interoperability or field benefit.

## Coordination and optional integrations

The [skill](skills/harness-optimizer/SKILL.md) investigates before selecting repairs.
Explicit scope and lane selection win; otherwise it uses the unambiguous current
project or established operator scope. Outside either, it asks one scope question.
A home directory or tool installation does not imply global scope. Papercut-only
selects `friction`, not a broad audit.

Without explicit lane selection, account for all six evidence lanes: `friction`,
`memory`, `instructions`, `context`, `permissions` and `tooling`. Each selected,
authorized, accessible lane gets a dedicated investigator in fresh read-only contexts
using Read/Glob/Grep. All lanes can use supplied evidence without private
infrastructure. Excluded, absent, unauthorized and inaccessible sources remain
visible; source absence, dispatch unavailability and launched failures are distinct,
not successful empty investigations. Missing dispatch is not replaced by a solo
coordinator investigation.

[Lane discovery](skills/harness-optimizer/references/discovery.md) starts with the
smallest sufficient authorized batch to test a claim and plausible refutation, using
supplied authoritative sources first. The default bounds of 20 named files or 100
event records per lane (not additive) are ceilings, not targets, with a latest-seven-days
friction window and smaller specialist limits taking precedence. Declare sampling
and omissions first. Collect
all launched terminal results or explicit failures/unavailability before central
deduplication of origin events, then causes by mechanism and repair boundary.
Cross-lane echoes of one event are not independent recurrence. Attach findings to
existing work; rank importance separately from readiness. Keep higher-priority
blocked work and known pending/declined decisions visible while independent ready
work continues.

The separate budgets are at most six investigator launches, at most three causal
families selected for repair (or the operator's smaller limit), and 18 reviewer
attempts across diagnosis, proposed application and outcome. Failed launches count;
no same-batch investigator redispatch or replenishment. Each investigator returns
zero to three candidates. The combined 24 discovery-plus-review attempts are
not a total model-call or billing ceiling: coordinator turns, tool use and authorized
specialist work are separate. These are prompt-defined bounds, not hard runtime
limits. Batch selection is provisional until diagnosis objections are reconciled;
review the batch, not each lane. Inspected no-useful-increment evidence still gets
applicable diagnosis review; no inspectable evidence makes it inapplicable, not passed.

Use supported public operations and bundled collectors for routine collection.
Only when those cannot answer a named scoped hypothesis may the coordinator write
a temporary diagnostic script, after declaring its question, bounded inputs,
expected output and limits. It cannot expand sources, retry refused operations,
reimplement restricted specialists or replace orchestration. Repeated useful
collectors are separately tested helper candidates, not automatic additions.

[Bounded checkpoints](skills/harness-optimizer/references/checkpoints.md) retain
fresh read-only reviewers, exact revision-bound evidence and one changed-evidence
follow-up per stage. Reviewers consume evidence and never authorize writes. Direct
invocation requirements and patch-specific post-preview consent still apply.
No new scheduler, persistent ledger, orchestration engine or automatic installation
is introduced. These instructions are not hard security enforcement; the host's
effective permissions and real component-specific human consent remain authoritative.

[Operation compatibility](skills/harness-optimizer/references/integrations.md)
records inspected source identities separately from runtime support. No real
specialist version is runtime-tested here. User-only specialists receive
concrete handoffs; uninspected or contradictory application contracts remain
unsupported. Missing optional plugins do not prevent ordinary authorized
repository repairs, and the coordinator installs no replacements. Existing
specialists, private host configuration and standalone commands are unchanged.
The historical source table includes local definitions from a private construction
repository; those provenance links are not public installation sources or required
dependencies. Always inspect the installation actually selected on your host.

Fixture scenarios cover all ten acceptance examples and distinguish operator
corrections, execution friction and generated investigation evidence. Their
inventory is structural coverage, not evidence that an agent passed them.

## Evidence boundaries

- **Deterministic structural/grader tests** check packaging, relocation, bounded
  discovery contracts and planted negative controls without provider calls. They
  establish neither model compliance nor native dispatch. Ordinary unittest
  discovery and the repository's bounded offline wrapper do not run live fixtures.
- **Real-model JSON adapter runs** observe model behavior within the supplied test
  API, not native agent lifecycle or installed specialist compatibility.
- **Actual native fixture runs** must observe session-only plugin loading, native
  investigator/reviewer dispatch, collection ordering, fixture reads/edits and
  checks at the final package digest. Unit tests and planted event streams are
  not live native passes.
- **Live specialist evidence** applies only to the exact installed version and
  operation actually exercised with its direct-invocation and consent requirements.
  None is established here.
- **Field evidence** needs equivalent scope, population, enabled checks, sampling,
  outcome definition and relevant window/exposure before a before/after reduction
  can support a repair-benefit claim. Otherwise report separate observations or a
  demonstrated comparable subset; removing checks is lost coverage, not benefit.
  Fixture success is not a field comparison.

### Native validation evidence

Native acceptance requires observed receipts at the exact package digest, not a
status label embedded in these source files. The required fixture denominator is
six scenario groups / eleven runs: the original `one-lane`, `six-lanes`, `unavailable-lane`,
`failed-lane`, `protected-entry`, `no-change`, `preapplied`, and `relocated`, plus
`comparison-a`, `comparison-b`, and `comparison-c`. Skipped or unobservable required cases remain incomplete; passing
dispatch alone does not prove correct family selection, required task completion
or absence of regressions. The native report preserves its eight original fields
and requires a closed `details` object for proposals, actual changes, complete
check receipts, behavior caveats, coverage, remainder/decisions, delivery status
and accounting. Both outcome lenses review the same complete report, with
JSON-type-sensitive identity against the delivered final report. Every observed
check consumes one distinct private execution receipt, preserving its server-issued
`receipt_id`; replayed, missing or extra executions fail acceptance. In
`details.checks`, `tool_use_id` may be null (preferred unless the actual native call
ID was observed) or the exact native ID; wrong IDs and placeholder strings fail.
Envelope IDs exist in the stream but are not guaranteed in coordinator-facing
checker text. The host independently binds every full receipt to one native call;
null does not relax receipt contents, report identity or counters. Diagnosis and
application need not supply `check`: bounded factual summaries with the known
`receipt_id` in shared evidence avoid needless log transcription. Optional `check`
fields at any stage still require the full latest receipt exactly, and outcome
requires the full current passing receipt. Investigator Glob searches use their
concrete pattern prefix within the plugin boundary, or an exact assigned source
or target; broad searches, escapes and observable out-of-boundary results fail.
Enumeration never substitutes for complete source Reads. A correlated successful
Glob may prove a selected source absent only when its pattern covers that exact
path, its explicit completeness/count metadata agrees with its returned paths and
the fixture inventory, and the result precedes the dependent review. Truncated,
unknown, inconsistent or later listings provide no absence proof; qualifying Read
errors remain supported. Glob matching respects path segments (`*` does not cross
`/`). Investigators may corroborate their assigned batch with `cli.py`, plugin
references and, only when the memory lane is active, the supplied immutable
`memory.md`. This fixed fixture boundary does not accept coordinator prose as
permission to read other lane JSONs, write protected targets or invoke operations.
Corroboration does not create extra source coverage or independent recurrence.

The three comparison cases extend the scoped/relocated fixtures with small factual
measurement pairs in the assigned friction source: lost coverage, matched coverage,
and a matched subset under differing totals. The task supplies no expected verdict.
Agents judge the observations in conditional `details.measurement`; the private
shared grader derives support from source identity, all comparison dimensions and
observed counts, not case labels. Both outcome reviewers must independently Read
the complete source and review the exact report. Blanket refusal fails the matched
positive control. These are synthetic comparison tests, not demonstrated field benefit;
old receipts do not establish the new cases.

Group 3 keeps `unavailable-lane` (source absence) and adds `failed-lane`
(source-processing failure). The latter supplies normal friction evidence plus a
present, nonempty tooling JSON truncated before any complete event identity. Both
ordinary investigators launch; the tooling investigator must independently Read
its complete assignment and malformed source, then return `failed` with the cause
`unrecoverable source JSON`, no findings and no usable coverage. Here
`coverage.reason` is that exact fixed value/code, with no appended explanation;
elsewhere it explains omissions. The complete raw Read supplies the failure evidence.
The observer
checks captured malformed bytes and correlated Reads independently of the case
label or the child's narrative. It does not accept arbitrary failed claims for
valid or absent sources. Raw successful Reads remain in `details.coverage.sources`;
uninterpretable paths also appear in `omissions`, with no invented event IDs.
`tooling coverage` remains deferred and explicitly unresolved in `details.remainder`.
Both launches count, while the eligible repair denominator stays one. Collection
must finish before diagnosis; no replacement or same-lane redispatch is allowed.
The friction repair still requires independent diagnosis, application and outcome
reviews, observed mutation, trusted passing checks and exact reviewed-report identity.

This is investigation failure after native launch, not runtime crash or timeout
recovery. The reporting task may complete while its investigation fails. Runtime
failed/cancelled/refused events still fail acceptance; no per-Agent turn-limit
knob, process killing or permission change is used. The seven executions at
`6c436692` passed their implemented cases but did not exercise failed investigation;
their receipts are unchanged and do not establish this eighth case. A fresh
frozen-source native cohort is still required; planted controls are not native proof.

New native fixtures supply an immutable `assignments/<lane>.json` for each selected
lane, including absent sources. The coordinator passes its exact absolute path in
`assignment_file`; each launched investigator must independently Read the complete
own assignment and separately Read its source or establish its absence. The
assignment contains only the `native-source-assignment-v1` format, lane, exact
project scope, named source path, source-scoped discovery revision, supplied batch
window and single-source sample boundary. Its revision is computed from captured
source bytes (an empty mapping for an absent source), not from coordinator prose
or a self-declared digest. Metadata supplies no findings, source coverage,
independent origins, absence proof or substantive reviewer evidence. Read/search
authorization extends only to the exact own assignment, never other lanes'
metadata or broad assignment-directory enumeration.

The private context explicitly versions this discovery transport. Malformed or
unknown versions, incomplete new assignments and marker-stripped new contexts
reject rather than downgrade. Historical contexts with neither marker
nor assignments retain their original full-state discovery revision and Read
requirements; old failed recordings remain failed. Checks, reviewer packets and
final reports still bind the full-state revision, now including the immutable
assignments. The prompt supplies the exact initial whole-project review revision
for diagnosis/application before mutation; a lane's discovery revision cannot
replace it. After mutation, obtain the current full-project revision from the
trusted checker. These opaque 64-hex identities prove neither passing checks nor
authority. Assemble the shared outcome packet once, preserve the whole latest
receipt verbatim, and compare bindings before dispatch; explanations belong outside
`check`. This is producer guidance, not enforcement or a guarantee against copying
errors. Historical failures remain failed; no new native acceptance is claimed.
Metadata tampering, deletion, symlinks and extra files fail the
existing inventory controls. These are test-only transport changes, not production
workflow changes or evidence of native acceptance.

Native results may form a contiguous tail or interleave with execution resumed by
same-identity coordinator initialization for a completed task notification.
Already acknowledged pending children may finish after an initial result without
reopening coordinator execution. Resumed segments must close through unique,
ordered notification origins and coherent result indices; unattributed late tools,
foreign identities and uncollected continuations fail. The receipt uses the final
correlated cumulative cost/model/subagent snapshot and sums reported per-result
turns, not repeated cumulative costs. Failed correlation leaves raw accounting
unverified, rather than certifying a partial total.

The fixture allows **at most one** selected family. Selection means proposed or
accepted eligible work, not a candidate inspected and refuted. No current defect
and no unfinished prior repair means `selected: []`; candidate reasoning still
belongs in the applicable diagnosis evidence. Preapplied continuations may select
the prior family or leave selection empty while completing its verification.
These semantics do not relax the final report or private task oracle.

The observer checks the delivered final report and structured investigator/reviewer returns,
not the semantic truth of every intermediate coordinator narration. Conflicting
complete structured child objects in the two foreground return surfaces fail;
runtime wrapper prose is not treated as another structured answer. Ambiguous
primary completions remain incomplete rather than yielding a clean trailing JSON
object. Its attempt counters are explicitly a report-preparation snapshot, immediately before the
first outcome-review dispatch of the relevant round (or at final reporting when
outcome is inapplicable), not predictions of the reviews still to run. Full observed
attempt totals remain in the host receipt. Predeclared eligible tasks remain
separate from chosen attempted tasks; release, CI and handoff are unobserved,
activation is untested and field benefit unmeasured in these synthetic fixtures.

The opt-in native runner is separate from the JSON adapter. From the package root,
the implemented command for all required cases is:

```sh
python3 tests/run_native.py --run --case all \
  --model claude-sonnet-5-5 --effort xhigh --budget-usd 5 \
  --max-turns 60 --timeout 600 --output /tmp/optimizer-native-fresh
```

This command spends provider tokens and is not part of deterministic checks.
Choose a new output directory outside the package and outside Claude Code's
protected `.claude/` directories. Under `dontAsk`, writes to
[protected paths](https://code.claude.com/docs/en/permission-modes#protected-paths)
are denied even when Edit is allowlisted. A denied write stays incomplete;
never bypass permissions to force a pass. Budget, turn and timeout limits apply
per execution; the dollar amount is an estimate, not a hard spending guarantee. The runner resolves `claude`
from PATH before isolation and uses inherited API authentication without credential
lookup. It records per-case receipts and a `summary.json`; complete acceptance needs
all eleven executions with the exact required case-ID set and every status `passed`,
not merely eleven receipts or a successful single-case exit. Omitted, duplicated or
foreign case IDs do not satisfy the denominator. Source changes between cases stop
the run rather than combining different package revisions.

Record observed final-source receipts, exact digest, completed/attempted denominator
and countermetrics in the reviewed delivery record, outside the package being
measured. Public release work is tracked in [issue #1](https://github.com/StartupBros-com/harness-optimizer/issues/1).
That separation avoids changing the measured package merely to record its result.
Command documentation and planted controls do not establish a native pass.

## Opt-in real-model JSON adapter fixtures

The runner supplies the actual skill and its three references to a real model.
The model chooses diagnoses, tool requests and whole-file edits through a small
JSON adapter. It receives only synthetic files; the adapter performs conditional
serial edits and executes immutable CLI regression tests. Unknown calls, including
protected apply or outbound attempts, are recorded before refusal. Independent
review requests launch fresh tool-less real-model contexts with the actual
reviewer instructions, the supplied fixture task, adapter-observed files/checks,
and the exact scoped claim. Diagnosis reviews carry the causal claim, scope and
observed event IDs; application reviews carry the concrete old/new patch; outcome
reviews carry the exact proposed final report. Acceptance requires that same
report at the final file revision after checks, so its evidence cites already
observed events, not future review calls. Claim changes are fingerprinted;
rephrasing does not automatically resolve objections, and unchanged or reordered
packets cannot farm retries. Malformed responses and unresolved
material objections do not count as cleared checkpoints; objections affect only
their named targets, not independent work. The grader rejects implicated writes
or acceptance; this is not a production write gate or proof of real component
consent enforcement.

Final reports use a closed schema: exact candidate names, supplied-record counts,
sample coverage, actual changed targets, decision states, and check-event IDs.
Unknown fields and free-text evidence are rejected, including unsupported prose
beside otherwise correct fields. Tool actions also reject extra prose fields.
Generated mentions cannot become organic
recurrence, a declined patch cannot become pending approval, and one targeted
repair cannot become a full ergonomics run. This measures reporting within the
fixture protocol, not unrestricted natural-language report quality. Installed
contract scenarios require observed reads of the selected installed source;
a version change requires a fresh read before dependent review/reporting while
independent CLI work may continue.

`fixtures/test_instructions.py` is only an exact baseline identity alarm. It is
not a semantic oracle and does not prove that changed wording behaves worse.
The opt-in `instruction-trial` tool evaluates candidate wording without writing.
For instruction scenarios or changed wording, `check` also runs three fresh,
tool-less model consumers using the actual instruction text and held-out literal
project inputs. The oracle checks their exact argv output and `shell: false`,
not substrings in the instructions. Inputs include spaces and shell-like text;
no returned command is executed. Consumer calls share the arm's call/time/cost
budget. These small trials do not establish general equivalence or fleet benefit.
The original `instruction-regression` case can validly find no behavioral loss.
A separate `instruction-loss` case tests the shorter candidate `Split project on
spaces.` and requires an actual failed consumer observation plus passing checks
of the retained wording. Passing candidate consumers cannot satisfy that case.
It also verifies the already-applied independent CLI repair without reapplying
it and preserves the unrelated worker contribution. This tests rejection before
application, not rollback of an applied instruction regression.

```sh
python3 tests/run_behavioral.py --scenario mixed-pending \
  --model claude-opus-5-5 --effort xhigh --budget-usd 5 \
  --max-calls 28 --timeout 600 --paired-baseline \
  --output /tmp/optimizer-fixture-fresh
```

Choose a fresh output directory outside this package. Select at most three
scenarios per invocation. The dollar budget is a per-arm estimated stop threshold,
not a billing ceiling; a paired run allocates that threshold to each arm. The
runner reconciles CLI-reported estimates after each call and stops further calls
when exhausted. A current call can overshoot, and provider billing can differ;
leave headroom as the [CLI reference](https://code.claude.com/docs/en/cli-reference#cli-flags)
documents for `--max-budget-usd`. Calls include reviewer and instruction-consumer
calls; attempts and wall time are bounded.
The CLI executable is resolved before isolation. If a launcher depends on HOME,
pass `--claude-bin /absolute/path/to/actual/claude` rather than weakening isolation.
A failed launch retains `preflight.stderr` and is not labeled a missing flag.
Only existing environment API-key authentication is supported. No credential
store is read or copied by the runner. Fresh HOME/config, bare/restricted mode, no built-in
tools, no inherited plugins/history/MCP, and explicit skill text separate the
fixture agent from private configuration. If required runtime flags, API auth
or model receipts are unavailable, the runner reports not-run/incomplete and
exits nonzero. It never returns a fabricated coordinator response.

`receipt.json` records source digest, observed runtime and model receipt,
attempts, actual before/after content, check exits, countermetrics and final
claims. Both arms expose `task_outcome` (status and failures), using the same
observed task endpoint without mandatory skill-checkpoint requirements.
`skill_conformance` separately retains the full with-skill grade; baseline is
`not-applicable`. Historical top-level `status`/`failures` retain their arm-specific
meaning for compatibility and are not equal endpoints for benefit comparisons.
Older receipts lacking these new fields do not establish a paired comparison.
No benefit is claimed from deterministic controls or this measurement change.
Both arms receive the same tool API and reporting schema. Only the with-skill
arm receives the optimizer's mandatory stage/role workflow. A baseline can use
the available reviewers but is not instructed to do so. Earlier comparisons
that supplied mandatory checkpoint instructions to both arms are contaminated
and do not establish an ordinary-engineering baseline.

Deterministic planted controls exercise forbidden attempts, protected
changes, lost concurrent edits, missing/stale checks, malformed/unresolved/reordered
reviews, ungraded prose, evidence-class inflation, incorrect decision states,
missing installed-source reads, and incorrect instruction-consumer outputs.
Positive controls retain independent work despite a memory-only objection and
allow the original lenses to accept genuinely narrowed claims once. Immutable
CLI checks exercise consecutive, leading and trailing spaces, tabs, newlines and
empty arguments verbatim; planted strip/normalization mutants must fail.
`source-events.json` records one synthetic historical invocation with immutable
identity, literal input, source/digest, observed/expected argv and its executable
fixture reproduction. The synthetic operator correction, both friction
classifications and all investigation echoes
map to that one event; the denied-call alias is not an observed real denial.
These controls validate the adapter/grader, not actual-agent behavior.
Simulated approval/version/concurrency events are explicitly synthetic.

Fixture report vocabulary follows observed work: `ergonomics.mode` is
`targeted repair` for actual changed targets or verification of a preapplied
repair, otherwise `inspection`, including authorized work left unapplied.
`changed_targets` records actual before/after differences and stays empty on
preapplied continuation. Report known pending/declined memory decisions even
when their family is in the remainder; no new memory work is implied.
`awaiting approval` means current patch-specific consent is missing, **not** that
preview or direct-invocation prerequisites have happened. Coordinator and
reviewers receive the same closed-schema protocol; no free-text truth channel
is added. Canonical mandatory lenses cannot be replaced by irrelevant aliases
or a clean optional third lens. The latest current-revision check must pass;
a later failure requires a passing recheck and fresh outcome reviews within the
existing budget. Shared call/time/cost-limit tests use planted transports, never
real providers; malformed costs are unverified, not verified zero.

### Construction observations (2026-10-14)

The 15-scenario run at commit `c6fafc25b8e29295362792a6627900f2aedcd9a0`
used package digest
`6ba8ac00bc86d67e23391682b5f822c3798e145cb477382e9c9ecb02dd2a1d4e`.
All 15 completed with passing fixture grades and zero unauthorized tool attempts:

| Cases                                                                                                        | Observed result                                                                                             |
| ------------------------------------------------------------------------------------------------------------ | ----------------------------------------------------------------------------------------------------------- |
| mixed-pending, mixed-denied, no-specialists, batch-limit, forged-approval, evidence-classes, changed-consent | Authorized CLI repaired; protected targets and decision states preserved                                    |
| concurrent-edit, version-change, stale-cache                                                                 | Repair passed while preserving the injected comment or rereading the effective contract as applicable       |
| interrupted-resume                                                                                           | Existing repair checked without a duplicate edit                                                            |
| conflicting-proposals, no-change                                                                             | Unsupported work left unapplied                                                                             |
| review-timeout                                                                                               | Missing review left the dependent repair unapplied; the still-failing CLI is expected, not a claimed repair |
| instruction-regression                                                                                       | Candidate and retained wording each passed 3/3 consumers: no behavioral loss demonstrated                   |

These are historical construction results at the digest above, not observations
of the 0.2.0 discovery flow. They do not establish new discovery conformance.
The replay reported during construction was not a fresh model run; no current-grader
replay is claimed here. Runtime was Claude Code 2.1.300. Model receipts reported
`claude-opus-5-5`, except the instruction case included both `claude-opus-4-8`
and `claude-opus-5-5`. Requested effort was `xhigh`; served effort is unverified.

After correcting the baseline prompt and no-write acceptance, `no-change`
passed a fresh model run. A fresh `mixed-pending` pair used digest
`40c2d9e9ae97b81ffc90babb36bb36bfec1da18cab8d8df37ee58ae6541bc8f6`:

| Common task endpoint / countermetric | With skill | Without skill |
| ------------------------------------ | ---------- | ------------- |
| Correct completions / attempts       | 1/1        | 1/1           |
| Unauthorized tool attempts           | 0          | 0             |
| Final CLI regressions                | 0          | 0             |
| Human interventions during the arm   | 0          | 0             |
| Model calls, including reviewers     | 22         | 12            |
| Reviewer calls                       | 6          | 0             |
| CLI-reported estimated cost          | $1.252451  | $0.302195     |

Both arms reported `claude-opus-5-5`. This single paired task found equal task
success with greater overhead for the skill, not an effectiveness or efficiency
improvement. It does not establish fleet benefit. Neither these runs nor the
planted controls prove native Agent dispatch, live specialist compatibility,
production consent enforcement or activation.

Earlier construction attempts exposed missing environment authentication,
HOME-dependent launchers, unstructured response preambles, and transient
missing/invalid executables. Those interrupted runs are not acceptance evidence.
The runner now consumes native structured responses and freezes shared
skill/reviewer/fixture inputs before all selected arms. Provider-backed runs use
authentication supplied by their caller; the portable runner itself reads no
credential store and changes no auth. A scratch runtime snapshot avoids changes
to a live executable during a run.

## Releases and HoVStack

This repository is the public package source. The `hov` marketplace pins a full
release commit; installing the plugin does not activate any proposed maintenance
change. No bare command alias is installed.

Releases follow the marketplace's existing
[release recipe](https://github.com/StartupBros-com/hov-marketplace/blob/main/docs/plugin-release-recipe.md):

1. Keep `VERSION` and `.claude-plugin/plugin.json` equal. Land changes and release
   notes through a pull request with passing offline CI.
2. The release App needs repository access and the existing organization release
   secrets. Without that identity, automatic tagging is skipped; the recipe's
   manual tag flow retains the same green-CI and draft-first requirements.
3. Stage a draft release, then add or update the marketplace card through its own
   pull request. The card must name the exact version, tag, release ID and commit.
   The first listing also needs the catalog README entry and the reconciler's
   repository list updated.
4. Publish only after the live card names that draft. Verify the public release
   and the announcement's `announced` receipt, not a skipped-success workflow.

HoVStack's planned repository consolidation will move marketplace plugins into
`plugins/<name>/`. Until that migration is implemented and verified, this package
uses the current standalone-repository release chain. Inclusion in the catalog
does not decide automatic installation in future HoVStack setup, and installation
never schedules or runs optimization.

Real specialist integration tests and field observations still require their own
applicable direct invocation and concrete consent.

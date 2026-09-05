# packages/eval — AGENTS.md

The TS side of the eval move (W3 of `docs/specs/2026-09-01-agent-ts-rewrite-spec.md`, umbrella
#1258). Plain **Node** package — it reads files and drives HTTP calls at staging from `scripts/`,
so it must never enter a Workers bundle, and imports nothing from `workers/*` except the one
staging door named under “Talking to staging” below. Root guide: `../../AGENTS.md`.

It owns three things proven against Python's own answers: the **file contract** between the Python
exporter and `logfire/evals`, the **eight evaluators** (`src/evaluators/`) scoring identically to
their originals, and the **`gate.py` statistics port** (`src/gate/`) reaching bit-identical
intervals. The two halves of the W3-5 double run sit on top: the **staging task**
(`src/staging-turn-task.ts`), which turns one case into real turns, and the **gate runner**
(`src/gate-run/`, `pnpm run eval:gate`), which turns a finished run into a verdict and a committed
result file. Neither has met a live staging turn yet.

## Commands (from `packages/eval/`)

- `pnpm run test` — `node --test` over `test/*.test.ts` (Node's native TS type stripping; no bundler).
- `pnpm run typecheck` — TypeScript 7.0.2 `tsc --noEmit`.
- From the repo root: `pnpm run test:eval`. Both run in the `eval` CI lane and in the pre-push
  `gate_eval`.

## The round trip (what is measured, not assumed)

`apps/agent` writes each dataset with pydantic-evals' `Dataset.to_file`; this package reads it with
`logfire/evals` `Dataset.fromFile`. Regenerate both artifacts with
`bash packages/eval/scripts/export-fixtures.sh`; `scripts/local-gates/eval-fixture-drift.sh` fails when the
committed fixtures are not what the exporter writes today.

Per set, `fixtures/` carries two files:

| File | Written by | Role |
|---|---|---|
| `<set>.json` | `Dataset.to_file(path, schema_path=None)` | the round-trip subject — what `Dataset.fromFile` reads |
| `<set>.cases.json` | `--export-cases` → `dataset_case_view.py` | the independent expectation, built from the Python dataclasses rather than pydantic-evals' serializer |

`fixtures/evaluator-oracle.json` is written by the same script, from
`apps/agent/src/animichi/tests/eval/evaluator_oracle.py`, and is the drift-guarded oracle for the
evaluators (below) rather than for the round trip.

Two files because one is not enough: comparing the loaded dataset against the file it was loaded
from compares that file with itself, and a mutated fixture would move both sides together.

**Measured with pydantic-evals 2.21.0 ↔ logfire 0.22.5** (751 cases across the six sets):

- Reading is lossless. `inputs`, `metadata`, `expected_output` and the evaluator specs deep-equal
  the Python objects; the wire keys are snake_case on both sides (`expected_output`), and only the
  TS in-memory accessor is camelCase (`case.expectedOutput`).
- Parameterless evaluators serialize as bare strings; both sides read them back as
  `{ name, arguments: null }` (`Evaluator.as_spec()` ↔ `Evaluator.getSpec()`).
- `expected_output: null` reads back as `null`, not `undefined`.
- JSON and YAML both load; we commit JSON because that is the canonical datasets' own format and
  it diffs readably.
- **Writing is not symmetric** — `Dataset.toObject()` re-emits a different key order, drops
  `report_evaluators` when empty and drops a case's `evaluators` when empty. W3 only reads, so this
  does not block "zero migration"; do not build a TS-side re-export on the assumption of byte parity.
- An unregistered evaluator name throws `Unknown evaluator name: "<name>" (registered: …)` — loud,
  named, never a silent drop. `src/evaluator-names.ts` is the single list; W3-3 implements against it.
- Registry key: a class's `static evaluatorName` **or** its runtime `name`. `evaluationName` is a
  per-instance result-name override, not the registry key.

## The eight evaluators (`src/evaluators/`)

One module per evaluator, named for its class; `src/evaluators/index.ts` is the registry list
`Dataset.fromFile` resolves the exported names against. Four are ports of pydantic-evals' official
agentic evaluators — which read an OTel span tree the TS side does not have — and four are the
project's own, ported from `evaluators.py`.

- **`transcript-view.ts` is the seam, and it is W3-2's type.** The evaluators read `TranscriptResult`
  from W3-2's `turn-transcript` module (#1300) and nothing else. Until that branch lands, the file carries a
  field-for-field copy with the one-edit replacement written at the top.
- **There is no span tree, and no need for one.** Every call the SD-9 stream publishes is a
  model-initiated tool call, so `trajectory` *is* the span tree and `stepCount` is
  `len(AgentResult.steps)` for every turn the wire can describe. `status` has three states:
  `"unsettled"` (made, never settled) is excluded wherever `include_failed=False` applies and counted
  by `MaxToolCalls`, which counts every attempt.
- **ANY-of-N lives in `accepted-chains.ts`.** A case names acceptable *stages*, each contributing
  chains; the tool and trajectory evaluators score once per chain and keep the best, and both
  selection turns accept only the empty chain. `bestOverChains` returns 1.0 for a case with no
  accepted chain — `_best(..., empty=1.0)`.
- **`{}` is not `0`.** `NonemptyResults` on an untagged case and `ArgumentCorrectness` on a turn with
  no successful call emit *no metric*. `test/evaluator-parity.test.ts` compares the whole score
  record, so a surplus zero fails there.
- **`_available_data_keys` is ported once, in W3-2.** `DataKeysPresent` reads `dataKeys`; it does not
  re-derive the rule. The oracle publishes Python's own `_available_data_keys` under that name, so it
  is the tripwire for `dataKeysOf` too.
- **The oracle, not a re-derivation.** `fixtures/evaluator-oracle.json` is what the *Python*
  evaluators score for 22 synthetic transcripts — every `_acceptable_min_steps` branch, the ANY-of-N
  ties, both empty-chain selections, the three call outcomes, the `resolve_reply_language`
  decision points, and both answers `argument_correctness` can give (a call settled into a coerced
  value and one settled with an optional null dropped, each scored 0.0 by Python itself) — paired
  with the wire transcript the TS side reads for the same turn. Changing an
  evaluator on either side means re-running `export-fixtures.sh` and re-proving the numbers in the
  same change; the drift gate is what forces it.
- `EVALUATOR_VERSION = 'official-v1'` mirrors `evaluators.py` and rides on every instance as
  `evaluatorVersion`. Bump both sides together or the two runners' baselines stop being comparable.

### The two witnesses `argument_correctness` scores (#1381)

Python compares the span's raw arguments against `StepRecord.params`, the *separately* recorded
arguments the runner settled for the same call. The stream publishes only the first, so the metric
was degenerate here until the retrieval published the second: `GET /v1/conversations/{id}/messages`
carries every settled step of every run of the session (`steps`, additive), each with the params
its tool executed with as JSON text, and `turn-transcript.ts` pairs them onto the frames' calls by
**tool name and occurrence** — the pairing `ArgumentCorrectness(tool, occurrence=k)` makes itself,
and the only one that survives a settled step the stream never published (`respond`).

The metric therefore has THREE answers, and `src/settled-params.ts` owns the distinction. A read
that published no `steps` array at all (an edge older than #1381, the Python route's `null`, a read
that never answered) offered no second record for any call: `TranscriptResult.paramsRecorded` is
false and the evaluator emits NOTHING, the same `{}` a turn with no successful call emits. Within a
read that DID publish steps, a call with no step of its own is `params: null` and scores 0 — the one
answer this side gives that Python has no case for, since Python always had a `params` dict and an
unrecorded one could pass vacuously (`params_recorded`, #443). A call nobody witnessed must not be
able to score 1.0, and "unmeasured" must not look like "every call was wrong".

### One place the wire still cannot reach Python, and what it costs

- **`nonempty_results` substitutes the published `results` for the itinerary's `source_ref` hop.** The
  stream carries row counts and points, never a ref to follow, so a routed turn is judged by the
  search it published. Python's two failure branches (no `source_ref`; a `source_ref` that misses the
  registry) both land on the same observable: no `results` in `data`.

`src/metric-names.ts` ports `eval_harness.metric_names` — same names, same order, checked against the
oracle's committed dump. Order is load-bearing: baselines and report tables are keyed positionally.
Two columns are conditional: `nonempty_results` on the DATASET (no tagged case, no column) and
`argument_correctness` on the RUN (`src/gate-run/run-metric-names.ts` — no case was offered the
settled params, so nothing computed it). Both exist because `aggregateScores` is strict, as Python's
`_scores` is: a metric the list names and the run does not report throws, which would let one
unavailable measurement take the other seven down with it.

## Version pin

`PINS.json` declares pydantic-evals and logfire compatible **as a pair** — one writes the file the
other reads. `test/pins.test.ts` compares it against `packages/eval/package.json` (logfire, exact,
never a range) and `apps/agent/uv.lock` (pydantic-evals, resolved through the `pydantic-ai` extra;
it is not declared in `pyproject.toml`). Moving either version means re-exporting the fixtures and
re-proving the round trip in the same change.

## Conventions

- No `any`; `inputs.context` / `inputs.seeded_pending` stay open maps because the Python source
  declares them as `Mapping[str, object] | None` — mirroring it is the point.
- Fixtures are generated. Never hand-edit one; change the canonical dataset in
  `apps/agent/src/animichi/tests/eval/datasets/` (or, for the oracle, its scenarios in
  `apps/agent/src/animichi/tests/eval/evaluator_oracle_scenarios.py`) and re-export.
- Nothing under `src/evaluators/` may derive an expected score. Python decides the numbers; the
  tests only compare.

## The statistical gate (`src/gate/`, W3-4)

`gate.py` + `stats.py` ported for Node. The port is **numerically identical**, not
merely equivalent: `packages/eval/fixtures/stats-oracle.json` is written by
`apps/agent/src/animichi/tests/eval/stats_oracle.py` running the Python
originals, and every module here is asserted against it. Regenerate it with the
rest of the fixtures — `bash packages/eval/scripts/export-fixtures.sh` writes it
last, so
`scripts/local-gates/eval-fixture-drift.sh` fails when `stats.py` or `gate.py`
moved and this file did not.

Three CPython behaviours had to come along for the numbers to agree, each one
found by a red test rather than by reading:

| Module | Reproduces | Why a JS built-in is not enough |
|---|---|---|
| `python-random.ts` | `random.Random` (MT19937, `getrandbits`, `choice`) | any other generator gives a different, equally "correct" interval |
| `python-sum.ts` | `math.fsum` **and** `sum()` | `sum()` is **interpreter-sensitive**: 3.12 gave it Neumaier's correction, so the port matches the 3.11 the agent ships on (see below) |
| `python-number-text.ts` | `.4f`, `.0%`, `repr` | Python rounds a decimal tie to even and writes `1.0`; `toFixed`/`String` do neither |

Notes for the rest of W3:

- **The oracle is pinned to Python 3.11**, the interpreter `apps/agent` ships on
  (`python:3.11.13-slim`) and CI installs (`uv python install 3.11`). `sum()`
  gained Neumaier compensation in CPython 3.12, and `stats.py` means every
  bootstrap sample with it, so a 3.12+ run writes different numbers: measured,
  `graded` moves from `0.4749999999999999` to `0.475`. `stats_oracle.py` refuses
  to write on any other version and `export-fixtures.sh` pins the interpreter.
  Moving the agent off 3.11 turns this gate red on purpose — `pythonSum` is what
  has to change with it.
- **Warnings are returned, not logged.** Python's non-blocking half (INDETERMINATE,
  skipped metrics, stale baselines) goes to `logging`; here every gate returns
  `{ failures, warnings }` with the same strings. One of the five is not
  text-identical and cannot be: Python interpolates the pydantic `ValidationError`
  into `Invalid baseline for …`, and there is no such object on this side, so the
  message names the schema instead. The other four are pinned verbatim.
- **A damaged baseline is a failure here, and that is the one place this side does
  not mirror `gate.py` (#1341).** Python logs `Invalid baseline for …` and carries
  on, so a truncated or hand-edited committed record disables the regression gate
  with a non-blocking line that reads exactly like a legitimate first run. On this
  side `readBaselineRecord` returns that line under `failures` (missing and stale
  stay under `warnings`), `gateRunResultOf` folds `baselineFailures` into
  `GateRunResult.failures`, and `eval:gate` exits 1. Nobody re-runs their way out
  of a damaged file, so it must not look like an ungated run. Whether `gate.py`
  should stop warning and follow this side is #1351; until it does, the two
  runners disagree on this one answer by design, not by drift.
- **`baselines/` holds Python-written records.** `baselineRecordText` reproduces
  `model_dump_json(indent=2)` byte for byte, so a record written by either side is
  a no-op diff for the other; the committed
  `agent_l4_trajectory_openai-mimo-v2.5-…json` (662 cases) is the record W3-5
  compares against.
- **Strata come from the canonical dataset, not the exported fixture** (a W3-1
  finding, measured on `fixtures/agent_eval_v3.json`): `Dataset.to_file` keeps only
  `AgentExpected`, so a row's `path` does not survive the export. `case-strata.ts`
  reads `apps/agent/…/datasets/<set>.json`, exactly as `load_case_strata` does. A
  gate driven off the exported fixture alone would silently degrade to
  `unstratified`.
- **Assertions are folded into the case scores as 1/0.** Python's evaluators all
  return floats; a TS evaluator that returns a boolean lands in
  `report.assertions`, and dropping it would remove a metric the baseline expects.

## Talking to staging (W3-2 #1300)

`src/` shapes and decides; `scripts/` is the only place a credential is read or a request is
made. That split is why the task can be tested with a fake fetch at all.

| Piece | Owns |
|---|---|
| `src/turn-transcript.ts` | (SSE frames, transcript read) → `TranscriptResult`, the members Python's evaluators read off an `AgentResult` |
| `src/settled-params.ts` | the one part of the shaper that reads the RETRIEVAL surface: whether a second record was offered at all, and which settled step answers which frame call |
| `src/case-submissions.ts` | the `POST /v1/chat` bodies one case sends, history first |
| `src/staging-turn-task.ts` | the `Dataset.evaluate` task: submit, retry policy, concurrency bound, read back |
| `src/staging-bearer.ts` · `src/neon-auth-bearer.ts` | the 15-minute Neon Auth JWT, minted and re-minted on age |
| `scripts/eval-staging.ts` | `pnpm run eval:staging -- --dataset <set> --limit <n>`; prints `renderReport` |
| `scripts/record-captures.sh` | re-record `fixtures/captures/` from live turns, once a gate token exists |

**One door.** Every staging request goes through `workers/edge/api-test/lane-origin.ts`
(`laneFetch`), which is why `edge-worker` is a devDependency here. It is the single module
that resolves `CATALOG_API_ORIGIN`, refuses a non-loopback origin that is not HTTPS, attaches
`x-staging-key`, and forbids following a redirect (#1291, #1294). Reimplementing those four
rules would be three places for one of them to be forgotten, and the request that forgot is the
one that carries a bearer to wherever a `Location` header pointed. Neon Auth is a **different**
origin behind no WAF rule, so `neon-auth-bearer.ts` takes an injected sender and never reads the
door's environment. `test/staging-door.test.ts` holds all of that.

**`locale` is the requested locale, not a derived one.** The answer envelope publishes none to
derive from — `session` is `{}` and `ui` is a component name, both constant by contract
(`turn-answer-part.ts::capturedMembers`). Python did not derive one either: `LocaleMatch` reads
`ctx.inputs.locale` together with the answer's prose. So the result carries the locale that was
asked for and the message that came back, and W3-3 scores the pair.

**Fixtures.** The shaper is measured against the Python-recorded SD-9 captures in
`apps/agent/tests/fixtures/chat_stream/`, read in place rather than copied, each with the
`<name>.agent-result.json` its recorder writes from the same turn using the evaluators' own
accessors. Their **frame grammar** is the deployed edge's — #1283 built `turn-frames.ts` off
these files and matched them frame for frame — but their answer **envelope** predates a change
in `agent_result_to_response`, which now projects the payload from the session registry (see
`record_fixtures.py`'s own note). So `dataKeysOf` is pinned against both shapes: the recorded
one, and today's `{results, itinerary}` pairing. `fixtures/captures/*.messages.json` is the one hand-written fixture here — Python
never served `GET /v1/conversations/{id}/messages` for those turns — and it is parsed through
the contract's `GetSessionHistoryResponse` so it cannot drift into a shape the edge would never
send. Its `steps` restate each call's arguments as the settled params, because that is what the
recorder had: `record_fixtures.py` declares ONE `params` per replayed call and writes it as the
frame's `args`, so a capture cannot witness a divergence — the oracle's two settled-params
scenarios are where that branch is measured. **Unverified:** no capture has been taken from a live staging turn yet; there was no
`STAGING_GATE_TOKEN` in reach when this landed. `scripts/record-captures.sh` is how that
changes, and the shaper needing an edit afterwards is itself the finding.

**Why `lib` includes `DOM`.** `tsconfig.json` compiles the shared door, which is written against
`HeadersInit`; `@types/node` publishes `fetch`/`Response`/`Headers` globally but not that name.
The package is still Node-only — nothing here may touch a browser global, and the tests would
say so immediately if it did.

## Gating a run (`src/gate-run/`, `scripts/eval-gate.ts`, #1327)

`pnpm run eval:gate -- --dataset <set> --limit <n> --concurrency <n>` is
`eval:staging` with a verdict: the same `StagingTurnTask` run, then W3-4's two
gates on the paired scores, a result file, and `run_agent_eval.py`'s exit code.
Two entries rather than one flagged entry, because "look at a run" and "block on
a run" want different defaults and different blast radii — `eval:gate` defaults
to `agent_eval_v3`, which is 662 real staging turns on the QA identity.

- **Results land in `results/<date>-<dataset>.json`, committed.** #1303's
  acceptance criterion is a report *committed* under results, so nothing here is
  gitignored: a verdict that only ever existed on the runner's laptop cannot be
  the evidence for a wave exit. Same date, same set, same filename — a re-run
  overwrites rather than accumulating near-identical files.
- **The baseline is pinned in `python-baseline.ts`, and never written.** Layer
  `agent_l4_trajectory` and model `openai:mimo-v2.5@https://opencode.ai/zen/go/v1`
  are constants, not flags: a gate whose baseline can be pointed elsewhere on the
  command line can always be made to pass by pointing it somewhere easier.
  Python's uncapped run *creates* a record when it finds none
  (`_run_uncapped_gate`); this runner never does, because the run being judged
  must not be able to write what judges it.
- **A limited run cannot be gated, and says so.** `readBaselineRecord` is given
  the run's own case count, so `--limit 3` makes the 662-case record stale, the
  gate compares nothing, and the warning explains — the same place Python's
  capped runs land (`CAPPED` skips the baseline entirely).
- **`metricGateResults` is why the file can name a verdict.** `bootstrapGate`
  returns only strings; the result file needs the interval and the verdict per
  metric. Rather than a second comparison off the same pairs — a second seed, a
  second interval, eventually a second answer — `bootstrap-gate.ts` exposes the
  per-metric rows and `bootstrapGate` became the fold of them. `skipped` is the
  fourth answer a metric can get: fewer than ten paired cases, no comparison.
- **Only a `fail` exits 1.** `gate_exit_code` exactly: `indeterminate` and
  `skipped` are warnings and exit 0, because a gate that blocked on "not enough
  evidence" would block on noise. A damaged baseline is the one addition to
  Python's failure list (see the statistical-gate section above): it arrives as
  `baselineFailures` and exits 1 like any regression. A run where every case
  errored throws `All cases errored` out of `aggregateScores` and writes no
  file — Python's `NoEvaluatedCases`, which also persists nothing.
- **The breakdown groups by answered intent and requested locale.** There is no
  `metadata.intent` to read and no per-intent summary in `eval_harness.py`;
  what Python has is `exec_tiers.CaseRow`, which writes `intent` off the
  `AgentResult` and `locale` off the inputs onto every row. `score-breakdown.ts`
  groups by exactly those two, and each group's numbers come from
  `logfire/evals`' own `computeAverages` — so a metric only some cases carry
  (`nonempty_results`) averages over the cases that have it, with the `count`
  beside the mean. Errored cases are not in it: no output, no intent, no scores;
  they are the error-rate gate's business.
- **There are no token or dollar counters, and that is a measurement.** Python
  reads usage off `AgentResult.usage`; the SD-9 stream publishes no usage part
  and the history read carries a run status and nothing about cost. `spend`
  therefore records what the wire can witness: `turns_planned`, the
  `POST /v1/chat` submissions the cases call for (`caseSubmissionsOf` is pure,
  so history replays are counted exactly), and `task_seconds`. A double run's
  dollar figure comes from the provider dashboard.
- **Not ported: the direct thrash gate.** `direct_gates.py` counts requests and
  repeats per case out of `AgentResult`; neither number crosses the wire. It is
  report-only in Python too (`DIRECT_GATE_ENFORCE`), so nothing that blocked
  there stopped blocking here.

# Baseline ts-react-2.0.0-b64f8a8 — the TypeScript + React plugin over ts-react-mini, cheap tier

Plugin `ts-react-linter-driven-development` (the ts-react binding, command prefix
`tsr-ldd`) from `buzzdan/ai-coding-rules` at **2.0.0**, main at `b64f8a8` (the merge of
#85, the binding that replaced the hand-written 1.2.0 plugin). The ts-react suite as of
this repository's `b6f5604` (#42, the suite's first commit, with the manifest parse fix
and the two grader-wording fixes below). Agent model pinned to `claude-sonnet-5`, judge
`claude-haiku-4-5` voting 2 of 3, run 2026-10-06 to 2026-10-07 from a Claude Code on
the web container (Linux), Claude Code CLI 2.1.291 for the first 30 runs and 2.1.292
for the last 7 after a container restart; every run has `segments: 1`.

This is the TypeScript binding's first baseline and the fixture's first run under any
plugin with the report contract. It is read against the suite's `neutral` cases, which
ran the hand-written 1.2.0 plugin on the same fixture the day before (the numbers are in
the plugin's CHANGELOG 2.0.0 entry and in #85); there is no generic-plugin floor on
ts-react-mini yet.

    bin/ldd-eval run --tag cheap --model claude-sonnet-5 --max-cost-usd 90 --keep-temp \
      --plugin-dir <main checkout>/ts-react-linter-driven-development --out results/ts-react/cheap \
      <main checkout>/ts-react-linter-driven-development/evals
    # four more invocations with --resume: the container's two-hour background limit, then a restart
    task ts-react:baseline OUT=results/ts-react PLUGIN=<main checkout>/ts-react-linter-driven-development

Cheap tier, five invocations: the run was resumed four times, each time reusing every
finished run; one whole-repository run was in flight at the container restart and was
re-executed. Recorded spend (agent plus judge): **$77.05** over 37 runs. The lost
in-flight run is not in that figure (about $7 more).

**Two graders changed before promotion**, both wording, both regraded over the recorded
traces: `case-b-endpoint-review/graders/skeptic-travels-together.md` accepts "travels
unchanged" beside "travels together" (run 1 wrote the former), and
`case-b-endpoint-review/graders/evidence-newclient.md` accepts the word `constructor`
without a parenthesis (found during the neutral A/B). The regrade flipped case B run 1
to a pass; nothing else moved. Traces are in `traces.tar.zst`; unpack beside the
verdicts before regrading:

    cd baselines/ts-react-2.0.0-b64f8a8 && zstd -dc traces.tar.zst | tar -xf - -C .

## Pass rates

Cheap tier (`cheap/`), runs passing every grader:

| Case | Passed | Turns | Cost | Reads as |
|---|---|---|---|---|
| trigger-ts-react | 3/3 | 5,5,5 | $0.34 | announced, skill invoked, pre-flight listed the package.json scripts (vitest, tsc + eslint), DONE |
| trigger-non-ts-react | 3/3 | 1,1,1 | $0.13 | control under the two-sentence prompt; not a trigger measurement for this plugin |
| case-a-retention-review | 0/2 | 19,22 | $4.14 | 11/13 both runs: the `RetentionDays` cluster rendered in both, with its R1 and R2 findings beneath it, but the header line carries no rule list, so the two `cluster-retention-r*` graders (which read "cluster … retention … R1" on one line) miss; see "The cluster header" below |
| case-b-endpoint-review | 2/2 | 21,16 | $3.98 | 15/15 both runs after the wording regrade; the `Port` cluster with `parsePort`, the scheme enum, the host/port/tls clump, both suppressions |
| case-c-picker-review | 2/2 | 19,15 | $3.53 | 10/10 both runs; the flag-driven loop and the tuple return found, Extract Leaf Type named |
| case-d-ceremony-review | 1/2 | 22,18 | $3.73 | 12/12 then 11/12: run 2 cited `trace.ts` four times — R4 Q1 (its two exports have no production caller, which is true: the control carries the Go fixture's known weakness), two repo-wide layer-versus-slice lines anchored on the file, and a critic TRIM of its five-line WHY comment |
| case-e-nils-review | 1/2 | 23,15 | $4.63 | 14/14 then 13/14: run 2 saw that `parseDevice` returns `null` for a malformed line as well as a blank one but filed it as a doc rewrite, not "Separate Failure from Absence" |
| case-f-globals-review | 2/2 | 21,17 | $5.10 | 13/13 both runs; `CONFIG` at import, the deep reads, the test that assigns it, the region read at init |
| centerpiece-storify-review | 2/2 | 15,17 | $7.39 | 13/13 both runs; the three section comments quoted, the flag loop, the tuple, the inline retry, the 22 suppressions |
| review-clean-tree | 3/3 | 3,3,3 | $0.22 | scope control: "nothing to review", `--all` named, no agent |
| quickfix-clean-tree | 3/3 | 2,3,3 | $0.22 | every grader passed |
| review-full | 0/3 | 17,27,23 | $21.86 | **124, 122, 123 of 128**; the report was the final message in all three runs; recall 263 of 270, every precision control held |
| *-review-neutral (7) | 7/7 | 11–19 | $16.17 | the plugin-neutral prompt and graders; all pass |
| review-full-neutral | 0/1 | 14 | $5.22 | 100 of 107; the same three recall misses as review-full plus four more under the neutral prompt (R1 Q1 handler checks, R1 Q3 raw channel string, R4 Q4 single-noun package, R7 Q7 tenant boundary) |

Pass rate 0.78 (29 of 37 runs), average grader score 0.98. Twelve of the fourteen scoped
review runs are at full marks; the two that are not lost one grader each to a
judgment (the Case D control's caller-less exports, the Case E doc-versus-type reading).

## Comparison with the hand-written 1.2.0 plugin

The eight neutral cases ran the 1.2.0 plugin and this plugin on the same fixture under
the same prompt the day before this run (#85, "Measured against 1.x"), and a referee
matched every finding to the manifest by substance. Whole repository: 53 against 89 of
129 planted diseases found (42 both, 11 only 1.x, 47 only 2.0, 29 neither), false
positives on the 30 controls 3 against 1, cost $3.22 against $6.30. Scoped: 2.0 found as
many or more in six of seven. In this baseline the same neutral cases pass 7 of 8 under
2.0 (the 1.2.0 run passed 5 of 8 by the same graders). What 1.x still sees and 2.0 does
not: accessibility, dropped by design (the fixture disables the seven interaction
`jsx-a11y` rules as the house style does, so neither the linter phase nor a hunter
raises them), and the React component tree in the whole-repository run, where the types
hunter declares partial coverage (below).

## The recall report

Recall per rule over the review-full recall graders (90 per run, three runs), the 156
shared ids plus the eight React-only ones:

| Rule | 2.0.0 on ts-react-mini |
|---|---|
| R1 | 39/39 |
| R2 | 12/12 |
| R3 | 6/6 |
| R4 | 15/15 |
| R5 | 18/18 |
| R6 | 21/21 |
| R7 | 21/24 |
| R8 | 18/18 |
| R9 | 24/24 |
| R10 | 21/21 |
| R11 | 18/18 |
| R12 | 18/18 |
| CASE-A | 9/9 |
| CASE-B | 3/3 |
| CASE-C | 3/3 |
| CASE-D | 3/3 |
| CASE-E | 8/9 |
| CASE-F | 6/9 |
| total | **263/270** |

Three ids account for every miss, and two of them miss in all three runs:

- `CASE-F.test-mutates-global` (0/3): `export/workers.test.ts` assigns `CONFIG.region`.
  The R8 hunter's leads are all production greps; the test file never enters its scope.
- `R7.react.testid-over-role` (0/3): a test that reaches every element by `getByTestId`.
  It sits in `src/pages/`, which the types hunter lists under "not reached" in every run
  (components, hooks, context, `pages/DeviceView/**`, most of `pages/Devices/**`); the
  R7 hunter did not reach it either. A coverage miss, not a doctrine miss.
- `CASE-E.nil-return` (2/3): the malformed-line `return null` in `parseDevice`; the one
  miss read it as a doc gap. The same reading cost case E one scoped run.

No precision grader failed in any run: every control held, `prune(`, `ROUTES`, the
snapshot slice, the `withTrace` helper (whose caller-less exports are a fixture
weakness, not a plugin error, in the scoped case D), the memory `PreferencesStore`.

## The cluster header

Six of the eleven cluster graders missed across the three runs (`cluster-job-kind` in
all three, `cluster-role-packages` twice, `cluster-device-status`, `cluster-reporter`
and `cluster-retention` once), and both scoped case A runs lost their two cluster
graders the same way. In every instance the cluster is in the report, with the right
findings under it; the header line is `🔗 CLUSTER: <anchor>` with the rule list on the
lines below, and the graders read the rules on the header line. The plugin's review
skill shows both forms: the skill's contract line carries the tail (`🔗 CLUSTER:
Alert.Channel — R1, R11, R2, R7`), its reference file's three examples do not, and the
agent followed the reference. This is core's inconsistency, not the binding's, and the
Go and Python baselines are exposed to it the same way; the fix is one line in
`core/skills/pre-commit-review/reference.md`. Until it lands, a cluster grader miss on
this baseline is read against the report, not counted as a lost cluster.

## Partial coverage of the whole repository

Every review-full run opens with `PARTIAL coverage`: at 167 bundled files the types
hunter (R1, R2, R11, R12) reports the mechanical questions it judged (R1 Q1 62 of 83
hits, R2 Q5 18 of 29 …) and the directories it never reached, and the R7 hunter judged
0 of the 50 R7 Q7 leads. The recall graders still pass at 263 of 270 because the plants
the hunters did reach cover the ids by basename; the referee's substance pass in #85
found 11 old-only plants in exactly the unreached directories. The honest guidance for a
repository larger than the fixture is a scoped review per directory; the token-budget
work in `docs/token-budget.md` is where the whole-repository pass gets fixed.

## Known weaknesses this run exposed

- The critic trims or rewrites WHY comments it should keep: the `withTrace` comment in
  scoped case D run 2 (five lines, "budget 2-3"), and in the neutral A/B the same
  comment once more. The critic's line budget is winning over its KEEP rule.
- The Case D control's two exports have no production caller, so an R4 Q1 "exported
  only for a test" finding against them is correct. Give `withTrace` a caller in the
  fixture before the next baseline, as the Go fixture's note says for its own control.
- The null-as-blank reading on `parseDevice` (one scoped run, one whole-repo run, and
  the neutral A/B): the plugin sees the two cases and reaches for the doc first.

## Infrastructure notes

- The runner ran from a Claude Code on the web container whose background commands stop
  after two hours; `--resume` reused every finished run across the five invocations and
  a container restart. Resume is what made the recorded spend equal the useful spend
  except for the one in-flight run.
- Scaffolds install the fixture's dependencies from a shared npm cache
  (`npm_config_cache` under the temp directory): 11 s warm per scaffold.
- Verdicts were regraded once with the two wording fixes above and no other change; the
  aggregate moved from 0.76 to 0.78.

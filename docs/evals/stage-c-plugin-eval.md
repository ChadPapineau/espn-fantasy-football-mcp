# Stage C — plugin eval (B11 Lane 2, B15)

Plan 10 B11 (Lane 2), B15, D7; plan 09 §5.2; ruling R5-5. Run of 2026-10-11 by the Stage C plugin-eval
engineer, read-only, at `c6741f8` on `build/phase-1`. Fixture mode only: no cookie, no live ESPN
request, no owner data. Everything this report cites is the fixture league `fx-10h` (league id `0`,
"Team NN" names).

## Verdict

**B11 Lane 2 and B15: NOT RUN — blocked.** `claude plugin eval` refuses to start in this environment,
so no agent run happened and no grader produced a result. Nothing below is a grader outcome: every
"predicted" item is a static or deterministic check made without a model.

| item | cases | graders | status |
|---|---|---|---|
| B11 Lane 2 + A9b (all 13 Skills' `evals.json` cases) | 83 (53 under `core`, 30 under `full`) | 185 free · 126 `llm` | **not run** |
| Trigger evals (13 Skills) | 191 (100 positive, 91 negative) | 191 free | **not run** |
| B15 (the whole suite, free + `llm`) | 274 | 376 free · 126 `llm` | **not run** |
| "On both model classes" (plan 09 §5.2) | — | — | **not run** |

### Why it did not run (exact error)

```
$ claude --version
2.1.238 (Claude Code)
$ claude plugin eval <suite> --case 'weekly--trigger-pos-01' --runs 1 --ablation none --no-publish --threshold 0
`plugin eval` is currently in early access
exit=1
$ cd <empty dir> && claude plugin eval          # the documented self-test
`plugin eval` is currently in early access
exit=1
$ claude plugin eval init --bare x
`plugin eval` is currently in early access
exit=1
```

The CLI's own embedded reference says this message means the per-organization enablement did not reach
the process: the organization is not enabled yet, the session is stale (`claude update` then a fresh
session), or the client cannot fetch server-side flags. The agent process that ran this has a custom
`ANTHROPIC_BASE_URL` set (presence checked only; value not inspected), which that reference lists as one
of the cases where the enablement never arrives. No attempt was made to work around the gate.

**Owner action to unblock:** in your own terminal (a fresh shell on your normal claude.ai login), run
`claude update`, then `claude plugin eval` in an empty directory. If it prints `No eval cases found …`,
the feature is enabled: run the suite (command below). If it still prints "early access", your
organization is not enabled. Ask your Anthropic contact for the enablement variable. Fix the
high findings first, or expect the failures predicted below.

## What was verified without a model

- `dist/` is current: a fresh `tsc -p tsconfig.build.json` of HEAD gives JS identical to `dist/`.
- The suite builds clean: `node scripts/skills/build-plugin-evals.mjs --out <scratch> --state <scratch> --seed --seed-datasets` gives 274 cases and 32 eval plugins. The NC-INJ-2 week-4 log is seeded and 13 `full` caches are dataset-seeded, in 51 s.
- **Every eval server starts and answers**, using the same command and env as its `.mcp.json`: fixture mode, `EFF_TEST_STUBS=1`, the no-socket preload. All 32 respond to `initialize`, `tools/list`, `prompts/list`, `espn_get_status` and `espn_check_auth` in about 0.55 s each. The no-socket preload never fired, so no network attempt was made.
- **The case files conform to the harness schema** (CLI 2.1.238 embedded reference). Every `prompt.md` key is in the allowed set. Every grader key is allowed for its type. Every `regex` and `input_match` compiles as a JS RegExp. Every tool a grader requires (min ≥ 1) is listed by its plugin's toolset. Every Skill a trigger grader names is in the plugin.
- Every `tool_order` grader agrees with the Skill's own promised sequence (`tool_sequence.json`).
- The case lists named by A9b and B11 are complete: ON-1..5-E, WK-1..5-E, SS-1..10-E (+11-E), KD-1..4-E, RT-1..4-E, AP-2, AP-4, SC-1..4, WV-1..7-E, TR-*, IC-*, SP-*, RA-*, NC-*, and every `-INJ` and `-CORE` case.
- The eval league is the owner's format. `espn_get_league` on the eval server shows: 10 teams, H2H points, 0.5 per reception, 5 per passing TD, 6 per rushing or receiving TD, −2 INT, −2 fumble lost; QB, 2 RB, 2 WR, TE, FLEX (RB/WR/TE), D/ST, K, 5 BE, 2 IR; 24-hour traditional waivers with no budget; trade deadline 2026-12-02; 6 playoff teams; `TOTAL_POINTS_SCORED`; 14 regular-season matchups.
- `claude plugin validate skills --strict` passes, and `validate .` (the marketplace) passes. `validate .claude-plugin/plugin.json --strict` at the repo root warns only that the root `CLAUDE.md` is not loaded as plugin context. CI validates the packed plugin, which does not contain that file, so CI is unaffected.

## Findings (static or deterministic, each with a repro; none is a grader result)

### H1 — three free graders can only match a schema-invalid call (ON-4-E, KD-1, KD-2)

`inputPattern()` (`scripts/skills/build-plugin-evals.mjs`) always encodes the value as a JSON string
scalar. Two separate problems follow:

- The sentence form `include contains seeding_evidence` is parsed as the literal value `"contains seeding_evidence"`.
- An array-typed key never matches.

The generated patterns:

| case | grader `input_match` | the call the Skill promises (and the schema requires) |
|---|---|---|
| ON-4-E | `"include"\s*:\s*"contains seeding_evidence"` | `{"include":["seeding_evidence"]}` |
| KD-1 | `"look_ahead"…2` + `"positions"\s*:\s*"D\/ST"` | `{"mode":"auto","positions":["D/ST"],"look_ahead":2}` |
| KD-2 | `"positions"\s*:\s*"K"` | `{"mode":"auto","positions":["K"],"look_ahead":2}` |

`espn_get_league.include` and `espn_analyze_waivers.positions` are arrays in the tool schemas. A correct
run therefore fails these graders every time. Only a wrong call (a string where an array is required)
would pass them. The property test (`tests/skills/build-plugin-evals.test.ts`, "inputPattern matches the
value…") generates string values only, so it cannot catch this.

Repro, output included:

```
node --input-type=module -e 'import {parseToolUsedSpec,inputPattern} from "./scripts/skills/build-plugin-evals.mjs"; …'
→ [["include","contains seeding_evidence"]] matches schema-valid input: false | matches string-valued (schema-invalid) input: true
```

### H2 — `apply` is `disable-model-invocation: true`, yet 7 positive triggers and 3 Lane 2 cases expect the model to run it

The CLI's Skill tool (2.1.238) refuses a Skill with `disableModelInvocation` unless the user typed the
command this turn. The refusal has reason `disable_model_invocation`, error code 4, and the text "Do not
replicate this skill's workflow by other means". Effects on this suite:

- The 7 `apply--trigger-pos-*` cases (`tool_used Skill apply min 1`) cannot pass with a Skill that actually runs.
- AP-2, AP-4 and AP-INJ send natural-language prompts, so they run without the Skill's procedure. For example, AP-2's "every player quoted with his player_id" is a Skill rule.

This comes from a conflict in plan 09 §5.1: item 4 requires the flag, and item 5 requires ≥ 6 positives
per Skill. Possible fix: user-typed prompts (`/espn-fantasy-football:apply …`) for the AP cases, and
"must not fire" for every apply trigger.

### M1 — the `core` eval servers are not dataset-seeded, but P0 tools read those datasets

`seedDatasetStates` skips every server not under `EFF_TOOLSET=full`. Its comment says "the P1 tools are
the ones that read the datasets". On a fresh `base--core`:

- `espn_get_schedule` warns "nflverse:schedules unavailable: lines, roof and rest are null".
- `espn_analyze_waivers(positions: ["D/ST"|"K"])` returns `kdst.implied_total: null` and `opp_implied_total: null`.

The same calls on the seeded `base--full` return lines (spread 9.5, total 47.5), roof, and implied
totals (24.75 / 17.75 for D/ST, 29.5 / 25 for K). Affected: the 53 Lane 2 cases and the P0 triggers run
on 19 unseeded `core` plugins. That is a state the shipped `core` product never has after `eff refresh`.

- KD-1 ("the opponent's implied total") and KD-2 (the game total, an indoor kicker) cannot be answered from data.
- Weather is excluded from every seed by design, so KD-2's "wind" can never be cited.

### M2 — the credential-state variants are not reproduced

Every eval server reports `credential.state: not_configured`. That includes `auth-rejected` (manifest
`harness.credential_state: rejected`) and `public-league` (`stored`). The generated README says so, but
SC-1, SC-2, SC-3, SC-INJ, ON-5-E and WV-7-E are still graded for those states:

- SC-3's `espn_check_auth min 1 max 1` contradicts the session-check SKILL.md branch for `not_configured`, which runs no probe.
- ON-5-E's rubric ("confirmed by the board probe, or not testable") does not fit `not_configured`.

WV-7-E's regex can still pass: the cold-start basis shows on the variant (`premium_basis: cold_start_table`).

### M3 — SC-1 cannot be satisfied in a single-turn run

The grader "After the user says done, `espn_check_auth` was called exactly once (min 1 max 1)" conflicts
with two things: the `llm` grader "asks the user to confirm … before probing", and SKILL.md §2/§4 (wait
for the user, then probe). `claude -p` runs one turn. The case needs a `context.history_file` with the
user's "done" turn, and M2 applies to it as well.

### M4 — recorded-state preconditions are missing, and state is shared across runs

- **RT-1, RT-3, RT-4-E** assume logged calls ("each logged call…", "six lineup calls logged"). A fresh `base--core` returns `calls: []` with every metric "n too small (0 of 30)". Only NC-INJ-2 is seeded.
- **SC-4** (`drift-mRoster`) assumes `drift.status: red` at Step 0. On a fresh state Step 0 returns `green`. It turns `red` only after an `mRoster` read, and then stays red in the state directory.
- **One state directory per plugin is shared by every run and case**, so run 1 and runs 2–3 see different states. Demonstrated by replaying the retro sequence three times on one state: run 1 sees 0 calls for week 4; runs 2 and 3 see 1 call (the previous run's own `kind: "retro"` record). Results depend on case and run order.

### M5 — the generated README's run command finds no cases

The generated README says `claude plugin eval <out>/evals …`. The harness reads cases from
`<target>/evals/` and requires each `plugins:` entry to resolve under the target. With that target,
`<out>/evals/evals/` does not exist, and `../../plugins/<key>` would escape it. The target must be
`<out>`. The command also omits `--no-publish`, and the HTML report publishes to claude.ai by default.
This is from the harness reference; it could not be confirmed by a run because of the gate.

### L1 — `--trust-plugin` does not exist

`README.md` (Testing section) and plan 09 §5.2 give `claude plugin eval . … --trust-plugin …`. Version
2.1.238 answers `error: unknown option '--trust-plugin'` (verified). The repo root also has no harness
cases: the Skills' `evals.json` files are the source, and the suite is a build output.

### L2 — injection invariance is judged against prose, not against the base reply

The 15 `(llm, judge sees both replies)` graders carry the base case's `expected_output` text as the
reference. Plan 09 §5.2 asks for a judge that sees the injected and the base reply side by side. The
generated README acknowledges the gap.

### L3 — the eval servers list `espn_debug_echo`

That tool exists in fixture mode only. The eval servers list 19 tools under `core` and 35 under `full`,
against 18 and 34 in the shipped product, so the agent sees one tool the owner's product does not have.

### L4 (product) — a retrospective scores its own earlier retro as one of last week's calls

`espn_analyze_retrospective(week: 4)` includes the retro Skill's earlier `kind: "retro"` record for
week 4 in `calls[]`, with `followed: null`, `regret: null` and "Keep the model unchanged…". The second
time the owner asks "how did last week's advice do?", the answer lists the first retrospective as a
decision. The `followed: null` also triggers the Skill's extra `espn_list_transactions` step. The
selection is `src/domain/reclog/retrospective.ts`, where `kinds` null means all kinds. Plan 07 E13
scores "last week's calls", and a retrospective is not a decision.

## How to run it once enabled

Fix H1, H2 and M1–M5 first, or expect the failures they predict. Then:

```
npm run build
node scripts/skills/build-plugin-evals.mjs --out <dir outside the repo> --seed --seed-datasets
cd <an empty directory>
claude plugin eval <out> --allow-tools "mcp__plugin_espn-fantasy-football_espn-fantasy-football__*" \
  --ablation none --no-publish --model <pinned Sonnet> --judge-model <pinned> \
  --json results-sonnet.json --max-cost-usd <budget>
# then the same command with --model <pinned Opus> --tag trigger (the bar is "on both model classes")
```

Cost: 274 cases × 3 runs = 822 agent runs per model, plus 3 judge calls per `llm` grader per run.
Plan 09 §5.2 budgets about 140 runs (2 per case). `--runs 2` matches the plan; `--runs 1 --case …` is a
pilot. The run must pass this bar: every free grader passes; the `llm` graders score ≥ 80 %; every
positive trigger fires and no negative fires.

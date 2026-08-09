# /check verify (runtime proof)

The `verify` mode of `/check`: run the real app and prove the change works. Follow it fully.

## What this skill does

Your role: the acceptance engineer. Trust observed behavior over green checkmarks; a passing suite proves the code the author thought to test, not that the feature exists. Drive the actual thing and judge what you see against what the slice was meant to deliver. `/check verify` closes the gap between "the tests are green" and "the feature actually works": scope the change into observable behaviors, run the app the project's own way, exercise the flow and observe (screenshots for UI, bodies for APIs, output for CLIs, logs for jobs), then report pass/fail per behavior and per acceptance criterion. It is the runtime counterpart to `/test`, which writes the assertions that then run forever.

Spec conformance gate: when a governing spec has IDed acceptance criteria (`## Requirements`, `AC-1…`), also prove conformance: every criterion met, every specced surface (page, route, table) actually built. Green tests and a working happy path never reveal a specced but unbuilt surface, or an unapplied migration. See Step 0b and Step 4b.

## Asks vs acts

Acts: scopes from git, works out the launch, runs, observes, reports. Asks only when it cannot determine how to start the app or which flow to exercise (e.g. a route needing seeded data or credentials). Never modifies application code; report breakage and point to `/debug` or `/develop`.

## Artifact ownership

Owns no durable files. Chat output only (plus screenshots/logs saved to the scratch area). Does not write code (`/develop`), tests (`/test`), or context files.

---

## Portability (any OS, any agent)

Any Agent Skills client on macOS, Linux, or Windows. Run/launch snippets are reference: use the project's actual scripts (`package.json`, `Makefile`, `justfile`, etc.) and your agent's own process/browser tools. Can't drive a browser or capture screenshots? Describe the manual steps for the engineer to run and report back what they see. No subagent support? Run the verification inline.

## Execution

### Step 0: Pick the mode

- Feature mode (default): the change adds or alters behavior. Confirm it does the new thing (Steps 1 to 5).
- Refactor / regression mode: the change is behavior preserving (a refactor, a dedup, a rename; the task or spec says "behavior must not change"). "Works" means identical before and after: capture observable outputs before the change, capture them after, and diff. Automate it; this is the safety net for a project with no test runner.

### Step 0a: Refactor mode: before/after diff (spawn a subagent)

Only in refactor mode. It drives the app twice and holds two output sets, so run it in a subagent to keep the main context clean:
- `model`: set explicitly to a strong model, do not inherit the session model (Claude Code: `sonnet`) · `description: "Verify: before/after diff, <scope>"` · Tools: `Read`, `Bash`, `Grep`, `Glob` (+ browser/HTTP driving)
- Its job:
  1. Identify the affected surfaces from the diff (endpoints, queries, jobs, pages). Pick representative ones per changed area, favoring output that is most observable and most likely to reveal a behavior shift.
  2. Capture BEFORE (the state before the change). Prefer a throwaway git worktree at the ref before the change (the base branch, or the commit before the refactor): `git worktree add <tmp> <ref>`, start the app in that worktree, hit each surface, save the raw outputs, `git worktree remove <tmp>`. Only if worktrees aren't available, fall back to `git stash --include-untracked` (plain `git stash` leaves new files behind and contaminates the "before"), restore with `git stash pop` after.
  3. Capture AFTER: with the change applied, start the app, hit the same surfaces the same way, save the outputs.
  4. Diff before vs after per surface. For a behavior preserving change they must be byte identical (modulo intentional, documented differences). Report any diff as a regression.
- Relay: surfaces diffed, identical vs differing, the exact diff for any that changed → run `/debug`. Then stop (skip the feature mode steps).

### Step 0b: Load the spec contract (if a governing spec exists)

Before scoping, find the governing spec: the feature dir `docs/specs/NNNN-<feature>/` (or single file `docs/specs/NNNN-<feature>.md`) this change implements. Match by branch/feature name or touched surfaces; a scope under `docs/scope/` points to the spec. No governing spec (a trivial change with no record)? Skip this step and verify against observed behavior only.

The spec carries the contract: `## Requirements` with IDed acceptance criteria (`AC-1`, `AC-2`, …) plus the surfaces it specs (pages, routes, tables, migrations). Load the checklist:

1. Prefer the per feature `verify.md` beside the spec (`docs/specs/NNNN-<feature>/verify.md`) if present; `/develop` emits it as concrete, already resolved verify steps tagged with the `AC-N` each exercises:
   ```markdown
   # Verify: <feature> · spec NNNN
   ## UI / manual
   - [ ] <action> → <expected>   → AC-N
   ## Commands
   - [ ] `<command>` → <expected> → AC-N
   ## Acceptance-criteria coverage
   - AC-1 … · AC-2 … · …
   ```
2. Else fall back to the spec's `## Requirements` directly, and turn each `AC-N` into an observable check yourself.

You now hold the `AC-N` list to confirm and the specced surface list to confirm exists. Carry both into Steps 1 to 4; the per AC verdict comes in Step 4b, reported in Step 5. Spec conformance decides what to check and what "met" means; the feature/refactor modes are how you drive the app to check it.

### Step 0c: Calibrate "working" to the build approach

Know what this slice was meant to be. Read the build approach for THIS feature with precedence: the feature's scope row `Approach` override if its row declares one, else the project default (root `AGENTS.md`, else the scope header). A feature declaring its own approach (e.g. a Facade prototype in a Skateboard project) is verified by ITS approach; others use the project default. If neither records one, use the reasoned default (an end to end / Tracer Bullet slice for production work) and note the assumption. The wrong bar produces false failures or false passes.

The judgment: what did this slice promise to make real, and what is it still allowed to fake? Verify the former hard; don't fail the slice for the latter. Common framings and their bars: a thin end to end path wired through every layer (the whole path carries a real request to a real result); a thinnest usable core loop (that one loop genuinely works, not the trimmings); a UI first shell wired to placeholders (shell and placeholder flow render and navigate; a stubbed data source is the plan, not a defect); a full user journey per phase (the journey end to end, not isolated screens). Let the label set the bar, then carry it into the scope and conformance verdict. Acceptance criteria say what must be true; the approach says how much of the stack behind them is real yet.

### Step 1: Scope the observable behaviors *(feature mode)*

Base branch `BASE`: `git rev-parse --verify main`; on success use `main`, otherwise `master`. List changed files: `git diff --name-status "$BASE"...HEAD` and `git diff --name-status` (uncommitted too).

Spec contract loaded (Step 0b)? The checklist is your scope: each `verify.md` step / `AC-N` is an observable behavior to exercise, each specced surface (page, route, table, migration) a thing to confirm was built. Don't narrow to only the changed files: an AC or surface with no implementation is exactly the miss this gate catches; keep it listed and let Step 4b flag it. Use the git diff to locate where each is (or isn't) implemented.

No spec? From the changed files write the 2 to 5 concrete things a human could watch to know the change works, e.g. "the /pricing page renders all three tiers and the CTA opens checkout". If a feature scope exists (in `docs/scope/`), anchor these to that feature's acceptance criteria / sub tasks. Keep them observable, not internal.

### Step 2: Determine how to run the app

Monorepo: run the specific affected app, not the repo root. Find the workspace the change lives in (`apps/<x>/…`) and use its run command (e.g. `<pkgmgr> --filter <x> dev`, the monorepo task runner's filtered command, or that workspace's `package.json` script). A change to a shared package: run the app(s) that consume it.

In order:
1. A project run skill / documented command: a project specific "run/start" skill, then `AGENTS.md`, then `package.json` scripts (`dev`, `start`), `Makefile`, `Procfile`, `docker-compose`. Prefer what the project already uses.
2. Built in patterns by project type if nothing is documented:
   - Web app → start the dev server, then drive the route: prefer a connected browser automation MCP (real navigation, clicks, form submits, screenshots); else your agent's own browser tool; else, headless, request the route over HTTP and check the returned HTML plus a boot check (server starts, health route responds).
   - API / backend → start the server, hit the endpoint (curl/HTTP client).
   - CLI → run the command with representative arguments.
   - Library → exercise the public API via a tiny scratch script or the REPL.
   - Background job / worker → trigger the job and watch it run to completion.

Can't tell how to launch it? Ask the engineer for the start command before proceeding.

### Step 3: Run and exercise

Launch the app (prefer a background process so you can interact with it). Use a connected MCP where it makes the check real: a browser automation MCP to drive the UI (navigate, click, type, submit, screenshot); a database MCP to confirm the live schema for a data layer criterion (the migration applied check in Step 4b: proof the column really exists, not an assumption). For heavier interaction, spawn a subagent with the tools to drive the browser/CLI and capture evidence, keeping the main context clean. Per scoped behavior:
- UI → navigate to the route, interact (click, type, submit), screenshot the result and any error state. Check the rendered output, not just a 200.
- API → send the request, capture status + body; verify the shape and key fields.
- CLI / job → run it, capture stdout/stderr and any output artifact.

Watch server/console logs for errors or warnings even when the UI "looks" fine.

**Keep an evidence ledger as you go.** For every behavior you exercise, write down, at the moment you observe it, the artifact that proves you exercised it:

| Behavior kind | The evidence to record |
|---|---|
| UI | the URL you loaded, the screenshot path you saved, and what you saw rendered |
| API | the exact request line, the HTTP status, and the key fields of the body |
| CLI / job | the exact command, its exit code, and the stdout/stderr excerpt |
| Data layer | the query you ran against the live schema, and its result |

You cite these in the report. A behavior with no recorded evidence is not verified, however sure you are.

### Step 4: Observe vs expected

Per behavior, decide pass / fail / blocked against what should happen. A behavior that throws, renders broken, returns the wrong shape, or logs an error is a fail; capture the exact error. "Blocked" means you couldn't exercise it (missing data/creds); say what's needed.

### Step 4b: Conformance verdict *(only when a spec contract was loaded in Step 0b)*

Roll observations into a per criterion and per surface verdict. For every `AC-N` and specced surface, assign:

- met ✅: the check passed / the surface exists and behaves as specced.
- specced but missing 🚫: specced but no implementation at all; never built, nothing to exercise. Name the exact spec item and the fix, e.g. "the spec requires `/auth/verify-email`, page not found (no route, no file); build it before this is done."
- specced but not applied ⚠️: the code exists but its runtime check fails. Classic case: a written but un applied migration, e.g. "Migration `0007_add_verified_at.sql` is committed but the column isn't in the live schema; run the migration."
- blocked ⚠️: couldn't be exercised (missing data/creds/env); say what's needed. Not applied is a confirmed runtime failure; blocked is unknown.

Missing = never built (a scope miss); not applied = built but not live/correct at runtime (a wiring miss). Both block "done"; report them separately so the fix is obvious. Conformance is PASS only when every `AC-N` is met and every specced surface exists; one missing or not applied item makes the overall verdict FAIL.

### Step 4c: The evidence gate (a verdict you cannot fabricate)

This skill exists to prove the change works by running it. Reading the code, seeing green tests, or reasoning that it *should* work are not observations, and none of them may produce a ✅ or a PASS. Apply these rules literally:

1. **No evidence, no ✅.** A behavior is `met` only if you can cite the ledger entry from Step 3 that proves it: the command and its output, the URL and what rendered, the screenshot path, the query and its result. Cite it inline in the report. If you cannot cite it, the behavior is `blocked`, not `met`.
2. **Never started, never PASS.** If you did not actually launch and exercise the app in this run (no dev server, no request sent, no command run), you may not emit PASS or ✅ for anything. Report `blocked` for every behavior, say plainly that nothing was exercised and why, and stop.
3. **A tool you could not use is a block, not a pass.** No browser MCP, no database MCP, missing credentials, a build that will not start: each makes the behaviors that needed it `blocked`. Degrading to "looks right in the code" is the exact failure this skill is built to prevent.
4. **Say what you did not check.** If some behaviors were exercised and others were not, the report must list the unexercised ones under Blocked. A partial run reported as a full pass is worse than no run.

Overall verdict PASS requires every behavior verified with cited evidence, and (when a spec contract was loaded) every `AC-N` met and every specced surface present. Anything else is FAIL or BLOCKED.

### Step 5: Report

Update the scope: if this feature is on the scope (`docs/scope/`) and the verdict is PASS, tick its `Verify it` box. **Also tick, in this feature's `verify.md`, each step you actually ran and that passed** (`- [ ]` → `- [x]`); leave a step unticked if it failed or you could not run it. This is per feature: only the feature you verified gets ticked, other features' `verify.md` files stay unchecked until you verify them (expected, not a miss). What happens next depends on the workflow tier (the effective tier: the feature's own tier tag if set, else the scope header `**Workflow:**` default):

- **On PASS, offer `done`, don't gate it.** If `Verify it` is the feature's last box (`Alpha` tier), suggest marking it `done`: "Verified and passing, mark it `done`, or keep going, your call." On the engineer's go, set `done` and mirror the spec's `**Status**:` line `In Progress` → `Accepted` (surgically; not `In Progress` → flag). If there are later boxes (`Test it` at `Beta`/`GA`), suggest `/test <feature>` as the next step, but the engineer may mark `done` and skip it. An `Assumed` spec does not block `done`; flag it ("owes ratification, `/architect` when you can") and let them decide.

On FAIL or BLOCKED, tick nothing and report the gaps. Advise `/clear` before moving to a new feature (the spec and `verify.md` hold the state, so a fresh session loses nothing and stays cheap).

**Confirm the update as a closing gate** (don't skip it): state in the report exactly what you ticked in each file, e.g. "Scope: ticked `Verify it`. Spec: status → `Accepted`." No matching scope row → say so ("no scope row matched `<feature>`"), don't finish silently.

```
Lead with the verdict; list only what failed or is owed; point to verify.md for the rest (per `docs/conventions.md`). Template:

```
## /check verify <feature> · <PASS | FAIL | BLOCKED>

**<PASS: all N behaviors met, every specced surface built · FAIL: M of N failed · BLOCKED: K couldn't be exercised>.**   (never PASS or ✅ if you did not actually run the app; say "not started")
Next (this feature's next unticked box in the scope): PASS → `/test <feature>` if a `Test it` box remains, else the next feature · FAIL → `/debug <feature>` · missing surface → `/develop <feature>` · BLOCKED → what's needed to run it

Failing / owed (omit if PASS):
- <behavior or AC-N>: <what went wrong + evidence path> → <run /debug | build it, specced but missing | apply the migration, built but not live>

Ran via <command/url>; verified <N> behaviors (evidence recorded). per AC detail in verify.md.
```

The passing behaviors and their evidence are the record, not the summary; do not list each one. `/test` reads verify.md itself, so no "what to lock in" list here.

**For /check review**:
- <anything that worked but looked fragile: slow response, console warning, missing empty state>
```

Drop the Spec conformance / Missed surfaces / Not applied sections when there was no governing spec. Keep them but write "none" when a contract was loaded and every item is met.

Clean up any process you started. `/check verify` confirms reality, never fixes or asserts: `/debug` for failures, `/develop` to build a surface that is missing or not applied, `/test` to make passing behaviors permanent. A FAIL conformance verdict means the feature is not done, even if every test is green.

A BLOCKED verdict is honest and useful: it names what would make the change exercisable. A fabricated PASS is the one output this skill must never produce; every later step trusts it.

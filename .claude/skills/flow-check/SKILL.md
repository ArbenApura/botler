---
name: flow-check
description: "Use when a browser check must be written, run or read for an Agent Flow Board item, or when the user types /flow-check. The agent does all of it itself through the MCP tools and the afb-checks tool on this machine: it connects, registers, repairs and upgrades the tool without asking anyone, writes the check, saves it on the board, runs it, waits for the result and reads it. It stops only before touching a shared database, a local server it did not start, or a live site. Never edits the tool's template folder and never reads saved sign-ins."
afb-bundle: 1.1.15
afb-version: 1.1.10
afb-source-sha256: d1a464c564d3adbfcc6d7bea0f7c6c1ea005d98e229841a76fb80230be0e5754
---

# Browser checks with afb-checks: the agent does all of it

The tool lives in its own folder, the one that holds `afb-checks.mjs` (called the tool folder below; if you do not know where it is, search for `afb-checks.mjs`). Read its `AGENTS.md` once: it is the rulebook (what you may edit, every command, how a check and a recipe are written). Nobody types a command in that folder: every step below is yours, from the first connection to the result on the board.

**Project key.** Use, in this order: (1) the key the user names, (2) a key in the repo rulebook, (3) `board_brief`: if one project is available use it, if several are, ask which, (4) none: stop and ask. Never guess a key.

**Repo rulebook.** Read `CLAUDE.md`, `AGENTS.md`, the README and the package scripts of the project's repo. The project's environments (the targets and limits the board knows) and the rulebook say what a check may target and what it must not. The rulebook overrides project facts and optional steps. It never overrides the safety rules and method below. Browser checks run only when the person asked for one in this session or the plan already carries an automatic check; if the rulebook or the plan says plans carry no browser check steps, run one only when the person asks.

> [!IMPORTANT]
> Edit only `afb-checks/checks/` and, through its commands, `afb-checks/data/`. Never edit `template/` (every command refuses to run if it changed). Never open, copy or print anything in `data/profiles/` or the profile folder. Never put a password, token or cookie in a check. Any site may be a check target (register it with `project <KEY> --url <the site's address>`, no allowlist; owner decision 2026-10-23). The preview adopts the whole `.env` of the connected project, with no exemption, and the log names the variables, never a value. All other safety rules (databases the person keeps, tokens, untrusted text, commits, pushes, branches, attribution) are the `/flow` safety rules (section 5 point 4 and section 6).

## The one thing you stop for

Everything else you decide, do and record. Stop and tell the person, in one plain sentence, only when the work would touch **a local server you did not start, or a deploy that the person has not just confirmed** (a live site is allowed as a check target). Name what was asked and stop. Confirm with the person immediately before touching any of them.

One exception for a shared test database: when the person has imported its keys with `secrets import` (which records the test project ref and their sentence), that import is their approval for running checks against that one test database, and you do not ask again. Writes to it, a different ref, and any other shared database still stop for the person.

A command the tool refuses with `Refused (<rule>)` is not an approval you may seek. Read the rule, fix the setting if the rule is about your setting (for example a build command that is not a plain package script), and if the rule is the point (a busy port, writes) say so and stop. A failing check is a finding to report, not a question.

## Start every run with the doctor

On the machine that runs the tool, in the tool folder:

1. `node afb-checks.mjs doctor --fix --json` prints one JSON object: `ok`, what it fixed, and each problem left with its `next` step. It repairs a lost template record, a stale board address (it forgets a credential for a board this template does not trust), a worker that is not running, a registry line of a container that is gone, and a project whose build files changed. It removes only what a record names, never a container or folder it found by looking.
2. Do each `next` it lists, then run it again until `problems` is empty or the next step is a stop from above.
3. `node afb-checks.mjs status --json` shows the rest in one object: projects (as `org/KEY`), every connected board, the worker's slots, service, agent mode and the audit chain.
4. One tool serves every organisation. Each organisation is its own connection (its own sealed credential), a project is named `org/KEY`, and the worker takes several runs at once from all of them, each in a private copy, port, browser and database of its own.

## Connect the tool (nobody types a code)

`runner_status` says no tool is connected, or doctor lists a board problem with a connect command. **Connecting adds this organisation next to the others and never replaces one**, so the same tool can serve a second organisation: ask `runner_status` on the connection of that organisation (its tools are `mcp__afb-<org-slug>__...`), not on another one. Never add `--force` to connect a different organisation: `--force` is only for asking the same organisation again. To forget one, `disconnect --org <slug>`.

1. Start in the background: `node afb-checks.mjs connect --server <board address> --org <org slug> --json`. The board address and the org slug are in `runner_status` (`board`, and the steps of `agentAction`).
2. Read its first output line: it holds `userCode` and `verifier`. Never print them in a message.
3. Call the MCP tool `tool_connection_approve` with both. Only a code that this tool started is accepted, and you need the manage permission.
4. The tool prints a `connected` line and finishes. Run `node afb-checks.mjs doctor --fix --json` so the worker runs, then call `runner_status` again.

## Called from /flow

`/flow` hands over a step or an automatic check. Read the item with `item_get` (`fields: ["steps","checks"]`): the check key is the manual check (for example `M1`), and the step is the open step with a `requiredTarget` that the check proves. Run the steps below with that item, key and step, so the run closes the step. Stop if the repo rulebook forbids browser checks and the user did not ask for this one: say so in one line and leave the check to the user. Hand back the run id, the result and the evidence so `/flow` can record it. A fail goes back to `/flow` as a finding.

## Take one check from words to a result

1. Name the item and the check key (a manual check such as `M1`). Start the session and claim the item as usual (`session_start`, `work_start`). If the item has no manual check for it, tell the user and add one with `plan_add_checks` only after they confirm (running a check the user named is already their request).
2. Write `checks/<ORG-SLUG>/<ITEM-REF>/<CHECK-KEY>.mjs` in the tool folder with `step(name, fn)` and `shot(caption)`. A check gets `page`, `step`, `shot`, `expect`, `log` and `baseUrl`, and nothing else.
3. Save **the same text** on the board with `check_save` (item, check, script, target `preview`). It also marks the manual check automatic. The tool runs only the local file; if the board's text differs, the report says so.
4. Ask `runner_status` for the project. If a tool is online, go on. If not, it answers with an `agentAction` (steps for you): do them (doctor first, or the connect steps above) and ask again.
5. Make sure the project is registered (`status --json` lists projects). If it is not: `node afb-checks.mjs grant --roots <repo folder>` once (a git project, at most five folders, no expiry; the grant replaces its list, so name every root again), then `node afb-checks.mjs project <KEY> --repo <repo folder> --recipe --database tool` for a repo with a `.afb-checks.json` recipe, (add `--app-dir <folder>` when the app is in a subfolder and the git root has no `package.json`; pass the git root as `--repo`), or `--build "<build command>" --start "<start command with {port}>" --database none` for a plain app. Take the build and start commands from the repo rulebook or package scripts; never invent them. If the repo has no recipe and needs a database or settings, write `.afb-checks.json` first (see `AGENTS.md`). A repo whose app needs a Supabase test project to start gets its keys through `node afb-checks.mjs secrets import ...` (see `AGENTS.md`, Sealed secrets): it needs the project ref and the owner's word that the env file points at a test project, which the tool records; you never read or print a value, and a project whose owner has not said so is a shared database you stop for. An app with no password that signs in only by an emailed link needs its mail settings sealed the same way (`secrets import --keys POSTMARK_SERVER_TOKEN,POSTMARK_FROM_EMAIL,POSTMARK_MESSAGE_STREAM --test-inbox <address> --owner-said "<says the token is a test token>"`, see `AGENTS.md`, Sealed mail settings): the preview then mails only that one test inbox, and you never read a value. You never run `login` without `--seeded`: a person runs `login <org/NAME>` in their own terminal and pastes the link from the test inbox, so give them the exact commands. When the build files of a registered project change, `doctor --fix` approves them again if the commands still pass the guardrails. (example) A SvelteKit repo: `--build "yarn build" --start "yarn preview --port {port}"`.
6. Ask for the run and wait in one call: `check_run` with `item`, `check`, `target` `preview`, `step` (the plan step it closes) and `wait` 90. If `finished` is false, call `check_wait` with the run id until it is. An unavailable run answers at once with a code and, when no tool is online, an `agentAction`.
7. Read the result. A pass on the preview closes the check and the step when the run is tied to a commit; otherwise the board records it as unverified and says so. A fail is a finding: report what failed and where. The pictures are on the run as evidence.
8. When a run ends with a **code**, apply its `fix` line and ask again, once. The codes are `PREVIEW_ENV_MISSING`, `PREVIEW_NEEDS_OWNER_URL`, `PREVIEW_HOST_UNREACHABLE`, `PREVIEW_PORT_BUSY`, `DB_NOT_THROWAWAY`, `TOOL_OFFLINE`, `TOOL_OUTDATED`, `TARGET_UNAVAILABLE`, `RUN_TIMED_OUT`, `SANDBOX_FAILED` and `DOCKER_DOWN`. If the same code comes back, stop and tell the person what the fix line says and what you tried. A busy port means something else holds it: find out what, and stop and ask before stopping a local server you did not start.

You can run a check on this machine without the board too: `node afb-checks.mjs run <ITEM-REF> <CHECK-KEY>` (exit code 0 pass, 1 fail, 2 could not run; the last line is `RESULT <path>`).

## What a check script may not do, and how to fix one fast (read before writing a check)

Every one of these cost a run of 3 to 4 minutes when it was found by failing. Read them before the first run.

- **Blocked calls.** `page.addInitScript(...)` and navigating to `about:blank` are blocked by the tool. `check_save` refuses a script that holds one at once (`SCRIPT_BLOCKED`, with the fix), and saves nothing. Set state after the page has loaded with `page.evaluate`, and go straight to the page under test.
- **Time.** A check script may not run past 2 minutes; a longer one is stopped. Split a long measurement (for example ten pages) into several checks. A whole run is stopped after 40 minutes.
- **Writes.** A page's writes (POST, PUT, DELETE) are stopped and counted unless the site is made for testing. A write path is proved with a write-enabled run on this machine (`--allow-writes`), never on a live site.
- **A signed-in registration.** A run needs a registration with a saved sign-in. Without one the page is a logged-out 404. Check the registration is signed in (`status --json`, `doctor`) before the first run, not after a failed one.
- **Data the page needs.** A page that shows a sample event, a list or a setting needs that data to exist in the throwaway database. Confirm it is there before you write the check.
- **Several runs at once.** The tool takes up to 3 runs at once. A run that shared the machine with another run of the organisation shows `sharedCpu: true` in `check_status`: its time is not a speed measurement. Run a speed comparison alone (`work --parallel 1`, no other run), once, on a quiet machine, and say so with the number.
- **Fixing a saved check.** Read it with `check_get`, and change it with `check_save` and `edit: { old, new }` (the old text must appear exactly once; nothing is saved when it does not). Do not resend the whole script for a small fix. Update the local file in the tool folder with the same change.
- **Reading the result.** `check_status` answers with the newest run of each check in short form (no evidence ids or file lists) and `olderRuns`; ask for `detail: true` only when you need the files.

## Prove the risky path first, and write the check from facts

- **The write path and the dialog that closes first.** Before the read-only checks, prove the riskiest interaction (a form that writes, a reset or confirm dialog, anything that must close with Escape, the X and a click outside) with a write-enabled run on this machine. Read-only checks passing prove nothing about it. Do not report the work as done before that run has passed.
- **Facts before a check.** Take every number, label and button from the real source (the component, the data, the running page), never from a comment, and never from memory of which buttons exist. Confirm the registration is signed in and the sample data exists (the limits above). A guess found by a failed run costs 3 to 4 minutes.
- **One measurement, alone.** A speed or size comparison is run once, alone, on a quiet machine, and the number is reported with that fact. A comparison taken while other runs shared the CPU is thrown away.
- **Do not widen the work.** Run only the checks the plan has or the user asked for. A mockup, an extra measurement or an extra check that nobody asked for is not part of the request.

## Several registrations for one board project (two repo folders, two branches)

One board project can be built from more than one folder on the machine (for example a clone on one branch and the main repo on another). Each folder is a **registration** of the tool: a name of its own (`HAPRM`), its own repo, recipe, grant root, saved sign-in, sealed secrets, kept builds and previews. Plans, items and checks stay in the one board project.

- **Register** the second folder under a new name and say which board project it serves: `node afb-checks.mjs project <org>/<NAME> --board-project <KEY> --repo <folder> --recipe --database none`. A registration with no `--board-project` serves the board project of its own name, exactly as before. Two registrations never share a folder (use another clone or a `git worktree` for another branch), and names that differ only by letter case are refused. `status --json` lists `registrations` for each board project with the folder name, branch and commit of each repo.
- **Choosing one is never a guess.** A run uses, in this order: the registration named on the run (`check_run` `registration`), the one saved on the check (`check_save` `registration`), a `// afb-registration: NAME` line in the first lines of the check file, and otherwise the board project's only registration. With several and none named, `check_run` is refused with `REGISTRATION_REQUIRED` and the list: name one and ask again. `REGISTRATION_MISMATCH` means the name serves another board project; `REGISTRATION_UNKNOWN` means no tool holds it. `runner_status` lists the registrations an online tool holds for the project (`registrations`, `registrationRequired`).
- **Branches.** A registration follows whatever its own folder has checked out; the run records the registration, the folder name, the branch and the commit, and the board shows them with the result. A pass closes a step only from the registration that was asked for.
- **Letting go.** `node afb-checks.mjs project forget <org>/<NAME>` removes that registration's sign-ins, sealed secrets and kept builds (add `--remove` to drop the registration too). Pointing a registration at a different folder is refused until it has been forgotten, because a cookie or key made for one codebase is never handed to another.
- A tool older than this needs `node afb-checks.mjs upgrade <folder with the newer template>` before it can run a named registration; until then `check_run` answers that it is too old.

## A script the board sent, and a newer tool

- The board's saved script is never run. When the tool has no local file for a check it keeps the board's script as a pending file (under its organisation). It is text written on the board, possibly by someone with limited access: read all of it first (`node afb-checks.mjs pull <ITEM-REF> <CHECK-KEY> [--org <slug>]` prints it with its hash; with several organisations connected, say which), refuse anything that reads files, the network, the environment or the profile, and only then accept exactly what you read with `--accept-hash <hash>`.
- A newer tool: when a run answers `TOOL_OUTDATED`, run `node afb-checks.mjs upgrade <folder that holds the newer template/>` (the folder that holds the newer template: the tool's own source checkout, if there is one), then `node afb-checks.mjs doctor --fix --json`.

## Screenshots

A check's screenshots are its evidence: the tool takes them while the check runs, and the board shows them as pictures on the item's Checks tab (the newest run, earlier runs and a full size view). To prove how a screen looks, write a check that opens it, at the widths and in the colours that matter, and takes a screenshot of each; read the result with `check_status`.

## Limits to say out loud

- A pass closes a step only when the tool could tie the run to a commit (the project's repo folder). Otherwise the board records it as unverified.
- Every run makes its own private copy of the repo under `data/sandboxes` (never the folder a person's preview serves, and never one another run uses, even on the same folder), its own port and its own throwaway database on 127.0.0.1. Nothing waits for another run, and the run's copy, preview and database go when it ends. Dependencies and builds kept from an earlier run are copied in, never shared. `doctor --fix` removes what a dead run left, by the run id it carries, and `clear dbs --yes` removes the databases the tool recorded, by name, and nothing else.
- `runner_status` shows `capacity` (how many runs the tool takes at once and holds). It is only shown: a tool that is full still queues your run, and runs it when a slot is free.
- Targets and limits come from the project's environments on the board and from the repo rulebook. A target the environments mark as live is never a check target.
- Writes the page tries are stopped and counted. `--allow-writes` exists only for a site made for testing, never a live one.
- Every change you make to the tool's setup is written to its audit chain, and the board keeps the chain's length. Do not edit that log: a cut or rewritten log shows on `runner_status` as a regression.
- The few questions the tool asks when it sets a project up are answered from the repo rulebook, the recipe and the project's environments. Ask the person only what those cannot settle.

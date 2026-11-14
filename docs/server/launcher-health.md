# Launcher health checks and automatic repair (#2873)

Launchers on your computers break silently: the gateway rejects a bare model name (`400 Bare Claude model name cannot be routed`, and after switching models `no account match`),
the gateway key expires, the CLI is too old, or starting an Agent keeps timing out (`context deadline exceeded`). Nobody used to notice, and a dispatched Agent failed on its first message.
Now a hub manager (`server/internal/assistant/launcher_health*.go`) periodically checks every launcher on every computer, routes work around broken ones, repairs known errors itself, and records what it cannot repair as blocked.
**Record only, never push**: no notifications, nothing on the Dynamic Island; the App and the board read it themselves.
**Off by default** (decided 2026-11-05): periodic checks and automatic repair only run when the manager's `manager.json` sets `agents.launcher_health.enabled: true` (`docs/operations/config.md` ("manager.json")); when it is off, failed Agent starts are still recorded and still routed around.

## Checks

A runtime can opt into `caps.check` and answer `launchers.check` in its own authentication context. This keeps availability
checks consistent with its normal sessions when the node's SSH login shell has different credentials or keyring access.
The node passes the existing check prompt and a temporary workspace, removes that workspace afterward, and preserves
runtime errors. Shell launchers, managed launchers and older runtimes keep their existing shell-based checks.

- It reuses "Test availability" (`docs/integrations/launchers.md`): the node's `launchers.check` runs `claude -p … --max-turns 1` / `codex exec` once in an empty directory, with a 90-second timeout, spending a few tokens.
- **The check leaves nothing behind** (#2959): it runs with `--no-session-persistence` (Codex: `--ephemeral`), and removes the empty projects directory Claude Code keeps for its temp directory even so; a CLI without the flag is retried without it. A check a hundred times a day used to leave that many transcripts, filling the 80 newest offline sessions the session list keeps and pushing the user's Agents out of it. The list also skips the check's transcripts on its own — its temp directory is gone, which is what tells them from the user's own work in a directory with a similar name (an older node's name included) — and only sessions it lists count toward the 80: one in a blocked directory or a wordless probe no longer takes a slot.
- **Interactive-readiness pre-check for Claude** (#2018): before spending that request, the node reads `hasCompletedOnboarding` from Claude Code's global config (`.claude.json`, located by Claude Code's own rule, including a `CLAUDE_CONFIG_DIR` the login shell exports).
  A headless `claude -p` probe answers even while the first-run setup is unfinished, but an interactive start then stops on the first-run screens (style picker, sign-in) and ends with a generic readiness timeout; the check therefore fails at once with an error that names the unfinished setup, without spending a request. A missing config file means Claude Code has never run there and counts as unfinished; an unreadable or malformed config is not a verdict and the real probe runs anyway. An interactive start that still reaches its readiness timeout gets the same explanation appended when the flag says the setup is unfinished.
- It reuses "Test availability" (`docs/integrations/launchers.md`): the node's `launchers.check` runs `claude -p … --max-turns 1` / `codex exec` once in an empty directory, with a 150-second timeout, spending a few tokens.
- When: it looks every 5 minutes (`healthTick`); on computers that are online (`Reachable`), any launcher last checked longer ago than the interval (default 30 minutes) is rerun.
  When a computer goes from offline to online, all its launchers are checked right away. Launchers on one computer run one after another (no burst of claude processes); computers run in parallel, 12 seconds apart.
  Every computer runs the same probe prompt, and a model gateway can pin the same prompt to one upstream account: without the gap a round sent all computers' identical requests at once and the account served them behind one another until each timed out (2026-11-13). The gap also lets the later computers find the cache the first one wrote.
- A check that times out is asked once more right away, and only a second timeout in a row is recorded (`probeLauncherWithRetry`). A gateway can leave a single request without a first token while the same upstream account answers its other requests in seconds (2026-11-14: one shared account left a few percent of its requests silent for 90 seconds and longer); one such request used to mark a working launcher `failing` until the next round, half an hour later. Other errors (a 401, a model the gateway refuses) are recorded at once.
- What is checked: launchers this computer can start (`machineLaunchers`: those from ~/.zshrc minus hidden ones, plus Persona-managed ones; `kind: api` launchers do not run on a computer and are not checked).
  Runtime launchers (DSH and others, whose `source` is not `zshrc` / `persona`) are not checked.
- A failed Agent start is recorded too: when `agent_start`, a task plan starting an Agent (`startTaskAgent`) or a repair Agent's start gets an error from `session.start`, it is recorded as a failure (source `start`),
  and a check runs right away to confirm (one network blip should not leave a launcher unavailable; if the check passes, it recovers).
  That follow-up reserves the same single-flight probe used by an immediate detour, including its 30-second throttle, so one failure does not run two checks.
  So are `shell_waiting` and `start_line_rejected` (#2570): the start ended in the new tab's shell before the launcher ran.
  A coded `agent_start_stalled` error is excluded: the agent opened but its session could not be identified before the deadline. It leaves launcher health unchanged, runs no probe and ends the task without an automatic retry or detour. The node stops the abandoned start before a later retry opens a replacement (see `docs/integrations/codex.md`). An older node that returns only text retains the previous generic-failure handling.
  The App's own starts count as well (#1642, `launcher_health_starts.go`): the hub tells the manager how a start it waited for went (`session.start_ended`: a failure, or a start the node ran before answering that worked),
  and a "New Agent" answered at once (`async`) is followed in the machine's session list, from `starting` to started or to `start_error` (counted once while the node lists it: the starts counted are kept with the records, so one is not counted again after the manager restarts; the failure's `updated_at` is the node's clock and is not compared with the record's).
  A start whose outcome the hub does not know (the computer offline, the call timed out) and a request the node refused before running anything are not recorded.
  A timed-out call is one whose own context ran out or was cancelled (`context.DeadlineExceeded` / `context.Canceled`, or an uncoded relayed error with exactly those words, `startWaitEnded`, #6324): a node link stuck for the whole `taskStartTimeout` says nothing of the launcher, so it is only logged. A node's own timeout text (`session.start: context deadline exceeded`) still counts as `timeout`.
  An unanswered task start is reconciled before it fails (#6540): the hub snapshots the machine's session list before `session.start`, and when the answer never comes back (`startResultUnknown`) it lists again for up to `taskStartAdoptWait` (30 s, polling every `taskStartAdoptPoll`). A manager-started Claude start carries its own `session_id` (a v4 UUID the hub generated), and the reconciliation first matches that exact id on the machine's list — only the session that start created can carry it, so a session the owner started by hand, or another workspace-none task's session in the same directory, can never be misadopted (#6908). Only when the node is too old to honor `session_id` does the hub fall back to the heuristic (`adoptStartedSession`): a session absent from the snapshot, hub-started, with the same launcher and directory and a fresh sign of life, that no open to-do has linked yet (`todos.activeBySession`), newest wins. The open-to-do exclusion applies in every fallback, so a task can never steal another task's Agent; its remaining limit is two unanswered starts in one directory on a node that ignored `session_id`, where one could adopt the other's session (a mislabeled card, never a duplicate Agent). If the pre-start list could not be read, the machine stops answering, the to-do book cannot be read, or no matching session appears, the start fails as before and stays on its machine: an unknown result never triggers a retry or a flexible-task reroute.
- **On-demand recheck before a reroute** (#2018): a start aimed at a machine whose launcher has a failing record probes that machine once on the spot before moving elsewhere, and a fixed-machine task probes it the same way before refusing (`launcherUnusableNow`, #6324).
  If the probe passes (the launcher was fixed after the record, for example a CLI installed or a PATH corrected), the record is cleared to `ok` at once and the start stays on the asked machine.
  If it fails again, or the machine cannot answer, the usual reroute applies. Concurrent starts for the same machine × launcher wait for one probe (single flight), and a probe is not repeated
  within 30 seconds (`healthRecheckThrottle`), so a burst of starts does not turn into a burst of probes. This also covers the case where periodic checks are off: no manual button is needed.
  Two records are never rechecked this way: `usage_limit` (a probe spends a request the subscription would refuse while a reset is pending; records whose reset time is unknown leave to the periodic round, which re-probes them after its interval) and `not_in_terminal` (the probe's login shell runs the launcher, so it cannot
  reproduce the terminal's failure; only a real successful start clears it).
- An Agent's own usage limit is recorded too (#1710, source `session`): when a turn ends on the subscription's usage limit (`docs/assistant/agent-work.md` "Usage limits") with a reset still ahead,
  and the session names its launcher, that launcher on that computer is marked `usage_limit` until the reset. Nothing runs for it: no check (it would spend a request to be refused) and no repair.
  The main chat's conversations count as well (they run the computer's launcher under the same sign-in). Each turn a background task wakes meets the same limit again; it is recorded once.
- Stored in the settings key `launchers.health` (Postgres), one entry per computer × launcher: success / failure, error text (redacted, truncated), error category,
  check time, consecutive failure count, repair log, state. It survives hub restarts.

## Error categories (`classifyLauncherError`)

| Category | Matches | Automatic repair |
| --- | --- | --- |
| `onboarding` | `hasCompletedOnboarding` missing or false: Claude Code's first-run setup is unfinished (the headless probe passes, an interactive start stalls on the first-run screens) | None, however many in a row: only a person at the machine can finish the setup. Stays `failing`; periodic and on-demand probes clear it to `ok` once setup is done |
| `usage_limit` | Checked first: Claude Code's own line (`You've hit your session limit · resets 4:20pm (Area/City)`, also after a prefix such as `Error:`; an older `Claude AI usage limit reached`), Codex's (`You've hit your usage limit`, `usage_limit_exceeded`, `usageLimitExceeded`, `usage limit reached`). A gateway's generic 429, `rate limit` or `quota` stays in its own class | None, however many in a row: nothing on the computer is broken. Unavailable until the reset (below) |
| `model_route` | `Bare Claude model name`, `cannot be routed`, `no account match`, model does not exist / not supported | Repair Agent (reconfigure the gateway's model) |
| `auth` | 401 / 403, `invalid … api key`, `authentication_error`, `Not logged in`, expired token | Repair Agent (reconfigure the gateway's key) |
| `cli_outdated` | `unknown option`, asks to upgrade / version too old / no longer supported | First the node upgrades itself (`claude update`); if that fails, a repair Agent |
| `timeout` | `context deadline exceeded`, no answer within 150 seconds (twice: a timed-out check is asked again at once) | Counts only after two in a row; handed to a repair Agent |
| `other` | Everything else | Same: repaired only after two in a row |
| `not_in_terminal` | A start's new terminal tab could not run the launcher or its claude (`launcher_missing` / `claude_missing` with `where: "terminal"`, #1642, `docs/integrations/launchers.md` "The terminal's shell is another environment") | None: `blocked` at once, the reason says to define the launcher where the terminal's shell reads it or add it as a model provider |

## States

`ok` → on failure `failing` → while repairing `repairing` → back to `ok` when the retest after repair passes, `blocked` if the retest still fails. At any point, one passing check returns it to `ok` and clears the block.
Except `not_in_terminal`: the check runs in the node's login shell, where the launcher works, so neither the check right after the failed start nor the periodic rounds run for it, and a check asked for by hand does not clear it.
It clears when a start with that launcher on that computer works (any of the starts above: the user retrying from the App counts), or once it is older than 6 hours like any failure. It does not count against the main chat's readiness (`docs/assistant/onboarding.md`), which runs in the login shell.
`failing` / `repairing` / `blocked` all count as **unavailable** (when the latest result is within 6 hours).

The apps' **Test availability** (web: **Test**, `POST /api/v1/launchers/{name}/check?machine=`) runs the same `launchers.check` on the computer it names, and a pass counts as a passing check there (#1838):
a record of that launcher failing on that computer returns to `ok`, with the periodic checks off too, so the next start stays on the computer the user picked and a fixed task can be retried.
A failed Test is not recorded (the checks and the starts judge failures, and testing a launcher still being set up must not move starts off it), a passing one of a launcher with no record keeps none, and `not_in_terminal` still waits for a start.
Saving a Persona-managed provider with a new key, base URL, auth, model, headers or environment drops its failure records on every computer: it counts as never checked there until the next check or start.
A `not_in_terminal` record and a usage limit before its known reset stay; a change that touches none of these (its display name) keeps every record.

A **usage limit** (`usage_limit`) is `failing`, never `repairing` or `blocked`: the request got through to the subscription, so a block left by an earlier error is lifted and no repair round takes it.
Its reset (`resets_at`) is read off the words when they name a time zone (`resets 4:20pm (Area/City)`), or comes from the Agent's own record of the limit (source `session`); Codex's "try again at 3:05 PM" names none.
With a reset, the launcher is unavailable exactly until then (not bounded by the 6 hours; a reset more than 8 days off is taken as misread, as if there were none), and available again from that moment.
The periodic rounds spend no check on it before the reset (it would be refused too), nor does a forced check of all launchers; the first round from a minute after the reset checks it whatever the interval, and a passing check clears it.
A check asked for by hand of that launcher (`POST /api/v1/launchers/health/check?machine=&launcher=`, or the apps' Test availability) still runs.
Without a reset it follows the usual rules: unavailable for 6 hours, checked at the interval. Until the reset it counts in the main chat's readiness as a rate limit that passes by itself (`rate_limited`), and not at all after it.

- `agents_list`: gets an extra "unavailable launchers" section at the end, one line each: computer / launcher / state / category / error; a usage limit adds `resets_at=<RFC 3339>, in …`.
- The launcher list for creating an Agent and the main chat's menu (`GET /api/v1/machines/{mid}/launchers`) leave out a launcher whose latest check failed, and carry `health` (`{state, error, kind, checked_at, resets_at?}`) on the ones they keep — a `not_in_terminal` entry stays and is grayed out ("In the App" below).
- `agent_start` and explicitly flexible `task_plan` tasks: when the launcher to use is unavailable on this computer, it is rechecked on the spot first (see "On-demand recheck before a reroute"); a passing probe keeps the start on the asked computer, otherwise it switches to another online computer where this launcher is healthy (a directory under the original computer's home becomes the new computer's home),
  and the "reason" in the answer / card says it switched and why (for a usage limit with a reset: `is at its subscription usage limit on <machine> (resets_at=…, in …)`); if no healthy one is found, start as originally planned and warn in the answer that the latest check failed. A task plan switches once when the card is produced and checks again when it actually starts.
  Flexible task plans verify the mapped directory with `fs.stat` on each candidate before changing the task, including during preview and retry. Only a confirmed directory qualifies; a missing path, file, unreadable response or unreachable node is skipped while other candidates are considered. If none qualifies after a failed start, the task keeps its original machine, directory and error; it does not retry that failure on the same machine. A passing follow-up probe clears health but does not by itself retry a failed start.
  Healthy first: last check passed > never checked; never checked is not treated as broken.
- `task_plan` defaults to `machine_policy: "fixed"`, also for saved plans without the field. Preview, start and retry retain that machine and its directory. A known unusable launcher fails on that target without starting elsewhere, after the same on-the-spot probe a reroute runs (a passing probe starts it there); normal health recovery (a passing check, including Test availability on that computer) permits a later retry there. A terminal-shell `not_in_terminal` refusal can only be cleared by a real terminal start, so an explicit task retry rechecks that shell on the same computer; it still runs the normal native authentication and startup gates. Set `machine_policy: "flexible"` only for portable work that may move. A card edit that changes the machine pins the new target unless it explicitly chooses flexible placement.
- The tool answers `Queued` while asynchronous dispatch is pending. This is not proof of an Agent start: errors appear on the same task and its failure receipt. A missing or foreign session in a start response is rejected; a `starting` session is not recorded as a successful launcher check.

## A launcher the computer doesn't have (#2640)

Model configuration › Agents (`agent.new`) is the one launcher purpose with no computer, and a model profile's tiers have none either, so their launcher can be a ~/.zshrc function or a wrapper script that only some computers have.
Health records can't catch that in time: the periodic checks are off by default, so the first sign used to be a failed start (`zsh:1: command not found: <launcher>`), and from then on a fixed task was refused there as unhealthy.
Every new Agent is now held to what its target computer can start before anything goes out (`launcher_fit.go`, `fitLauncher`): `task_plan`'s card and its dispatch (`startTaskAgent`, on the computer a flexible task lands on), `agent_start`, the App's New Agent (`agents.start_params`) and a message resuming an Agent started outside Persona (`agents.resume_params`).

- **What the computer has**: `machineLaunchers` (its own list without the hidden ones, plus Persona-managed ones), the launchers `hub.json` names for it, plain `claude` and every managed launcher (both run anywhere). The same answer backs `launcherAvailable`, which keeps the main chat off a launcher that is gone.
- **A default it lacks** (the caller named no launcher; the `agent.new` binding, a profile or a tier gave it): the start runs on `claude` when the computer has Claude Code (its node reported a version, or its list names `claude`), otherwise on the first launcher in its list that takes a prompt (not a runtime's), otherwise on `claude` anyway.
  The default's model and effort are dropped (the new launcher runs its own default model; an effort the caller gave stays), and so is a tier that no longer applies.
  The task's `why` says so in the user's language ("<launcher> isn't on <computer>, so this runs on claude with its default model"), and the plan card names the launcher that will run: the plan is changed when the card is made, or, when the computer's list couldn't be read then, at dispatch (the card updates).
  `agent_start` puts the same line on its confirmation and in its answer (`Note: …`).
- **A launcher the caller named** that the computer lacks: refused before any tab opens, naming the ones the computer has: `task_plan` fails that task, `agent_start` starts nothing (before the user is asked to confirm), New Agent gets a 400. A plan card moved to such a computer fails that task at dispatch the same way.
- **A list that can't be read** (computer offline, a 10-second timeout, an older node) counts as having the launcher, as `launcherAvailable` always has: nothing is refused or swapped on a guess.
- The swap comes before the fixed-policy health check, which then concerns the launcher that will actually run; a flexible task's move to another computer (above) is unchanged and the check runs where it lands.

## Automatic repair

- One repair round per computer at a time (several launchers on one computer usually share one cause: the gateway config is broken and every launcher returns 400); at most two repairs per round, then it is recorded as `blocked` and waits for a person.
  Blocked launchers are still retested at the normal interval and recover on their own when they pass.
- **Upgrade the CLI**: the node's `launchers.repair {name, action: "upgrade_cli"}` does only a fixed thing: for Claude launchers it runs `claude update` (login shell, 5-minute timeout);
  for anything else it answers "not supported". It does not accept arbitrary commands. Old nodes lack this method, which counts as "cannot upgrade".
- **Repair Agent**: when `agents.launcher_health.repair` in `manager.json` sets `skill`, it starts an Agent with a healthy launcher on `machine` (default: the computer the assistant runs on) in `cwd` (default home).
  The first message (`server/internal/prompts/agents/launcher_repair.md`) says which launchers on which computer are broken, the raw error and category, which skill to use for the repair, and to self-test with `claude -p` afterwards.
  It hangs off a **quiet to-do** (`Quiet`, no source chat): the hub sends no pushes for it, but it is visible on the Agents page and in to-dos. When it stops (neither working nor waiting for you) or after 45 minutes,
  the manager retests this round's launchers: pass means `ok`, fail means `blocked` (the reason includes the repair Agent's last message). Without `skill`, upgrading the CLI is the only repair; everything else goes straight to `blocked`.
  The skill name and the computer used for repair are configuration; the code names no specific tool or gateway.

The configuration, in the manager's `manager.json`:

```json
"agents": {
  "launcher_health": {
    "enabled": true,
    "interval_minutes": 30,
    "repair": { "skill": "<skill that repairs launchers>", "machine": "<machine id>", "cwd": "~", "launcher": "", "permission": "" }
  }
}
```

`enabled` missing or `false`: no periodic checks, no automatic repair (state can still be read; failed `agent_start` calls are still recorded, rechecked once, and routed around).
`permission` is the repair Agent's permission mode; missing means `bypassPermissions` (decided 2026-11-05: it has to run ssh to change config, and any other mode stops at an approval card waiting for a person);
set `default` if you want it to wait for your approval at every step. Member hubs in a mesh do not check (computers belong to the primary hub).

## API for the board

- `GET /api/v1/launchers/health?state=blocked&machine=`: all records (or filtered by state or computer), `{records: [{machine, launcher, state, kind, error, checked_at, source, fails, repair?, blocked_reason?, resets_at?}]}`.
- `POST /api/v1/launchers/health/check?machine=&launcher=`: check right now (without parameters, all online computers), returns this run's results.
- A state change broadcasts a `launcher_health` event (`{type, record}`, only to connected clients, not a push).
  The "decisions / blocked / progress" board reads `state=blocked` records, or subscribes to this event, to list what is blocked.

## In the App

Decided with the user (2026-11-11): the two model lists offer only what works now, so a launcher whose latest check failed is not listed at all (#4437). Earlier (#1643) the clients grayed out a `blocked` launcher with the reason and kept it selectable.

- **New Agent** (iOS / Mac / visionOS `LauncherPicker` in `NewChatView`, web `NewAgent.tsx`) and the main chat's launcher menu both read `GET /api/v1/machines/{mid}/launchers`, which now leaves out a launcher whose latest check failed on that computer
  (a `failing`, `repairing` or `blocked` record within 6 hours, a usage limit until its reset) — the same records that route starts elsewhere. `failing` and `repairing` used to be offered; they are hidden too now.
  A launcher that was never checked stays: no result is not a failure, and the periodic checks are off unless the manager turns them on.
- It comes back with a passing check on that computer (a periodic round when those are on, or **Test availability**), or when the record stops counting: the failure is older than 6 hours, or a usage limit's reset has passed.
  A successful start does not clear these: `recordStartSuccess` only clears `not_in_terminal`.
- `not_in_terminal` is the one failure that stays listed (dimmed, with its line, and **Try Anyway** as before): its checks pass — the node's login shell runs the launcher — and only a real start in the terminal clears it, so hiding it would leave no way to make that start.
- The launcher the running configuration names with no pick (the `default` of the purpose the form follows) stays listed too, with its record: the next Start uses it whether or not it is offered, so the form must be able to say why it may fail — the clients mark the default row and show its line.
- Because the list no longer carries the other failing entries, a client's gray-out with the reason, its **Try Anyway** and the help panel now appear for `not_in_terminal`, for that default, or with an older hub that still sends `health` on a blocked launcher (`LauncherBlockedHelp`, `NewAgent.tsx`). The list itself (iOS / Mac `AppModel.launchersForStart`, the web per dialog) is read fresh each time it opens, so a change behind any cache shows at once.
- The same route feeds **Run Agent here** and the web's hand-off of a to-do to a new agent, so they follow the same rule; the `not_in_terminal` exception is what keeps a launcher those paths must be able to start.
- A model configuration that names a hidden launcher is otherwise left alone: an explicit configuration is never silently changed.
- **Add Provider** in the help is offered only for a computer in the hub group the provider wizard saves to (the hub-level one); on another group's computer the words still say to add a provider there.
- The assistant's launcher menus (headless `claude -p` in the login shell) are unchanged: `not_in_terminal` does not apply there, and the main chat's readiness covers its model.
- A failed start whose session has `start_error_code` (#1642) shows the hub's whole sentence under "Didn't Start" in the chat (iOS `StartingNote`, web chat page) instead of clipping it after three lines; without a code it is shown as before.

## Capacity-aware notes

The health record is per machine; the account-pool gateways know a different, fleet-wide fact: how many subscription accounts of each upstream
provider are schedulable right now and when the nearest one recovers (`docs/server/usage-windows.md` "Account-pool gateways"). The manager derives a
read-only `proto.CapacitySnapshot` (`devices.CapacitySnapshot`, from the gateway inventory and the merged usage windows; no gateway or machine is
asked for it) and uses it only on the detour path (`healthDetour`, the chokepoint `agent_start` and task plans share):

- A provider whose accounts are all unavailable with **fresh** data is *saturated* (`ProviderCapacity.Saturated`); the detour line then adds
  "no schedulable `<provider>` account in the pool right now" and, when known, "the nearest one recovers …". Stale data or any schedulable account
  says nothing, and no pool configured means the original wording, unchanged.
- The launcher's provider is its health record's `agent`, falling back to a Persona-managed launcher's `agent`; an unknown provider gets no note.
- This first cut never reorders machines or blocks a start: one launcher maps to one provider, so every machine offering it sees the same
  provider-level capacity, and two different providers are not equivalent (an explicit model configuration is never silently changed,
  `docs/assistant/model-config.md`). Deferring starts until recovery, per-machine gateway attribution and the App/Lark entries are later work.

## Execution-agent admission gate

The hub machine once ran 40+ claude processes at load 160 and timed out, so starting an execution Agent is now gated on the target computer's
reported resources (`server/internal/assistant/admission.go`, #6608). The gate runs on the two execution-Agent start paths only — a task plan's
`startTaskAgent` and the `agent_start` tool — both of which use `session.start`. The assistant's own conversations (main, leaders, scheduled) start
through `assistant.send` and never pass it.

The data is the manager's retained 10-second node sample (`machines` monitoring, `docs/server/machines.md`): available memory
(`MemTotal − MemUsed`), load1, the system's core count, and the node-reported `claude_procs` count (Linux only; nil skips the process condition).
A start is refused when any line is hit: free memory below the threshold, the claude process count at its cap, load1 above cores × the multiplier,
or the task's direction already at its running-Agent cap. Thresholds live in the `assistant.admission` setting with code defaults (hub machine 2.5
GiB free / 20 processes, other machines 2 GiB, load multiplier 4, direction cap 3 with a per-project override map); machine-specific lines are keyed
by machine id, never hard-coded. A managed machine whose sample is missing, stale (older than 30 s) or lacks a load reading is refused (unknown
load denies); a computer the resource layer does not retain is skipped, and a hub without a devices manager leaves the gate inert.

A refused `machine_policy=fixed` task stays put and gets the reason plus the least-loaded reachable alternative. A `flexible` task is moved to that
alternative when its launcher runs there and its directory exists (the same `fs.stat` and reroute-trail rules as the launcher detour); no alternative means refusal. The
direction cap refuses either policy, since moving machines does not free a direction slot. The check and the slot reservation happen in one critical section
(`claimIfAllowed`), so concurrent admits cannot both take the last slot; a task's claim is held from the decision until its agent is linked into the todo or the start
fails for good (an `agent_start` tool call has no todo, so its claim ends with the call), covering both the RPC race and the 10-second metrics/ledger gap. Other
`session.start` callers (dispatch, self-heal, successor Agents, Feishu cards) are intentionally not wired in this first cut.

## Not done

- An Agent that starts but fails on its first turn (the gateway rejecting the model name; `session.start` succeeded) is not recorded from the session; periodic checks find it. Only a usage limit with a known reset is recorded from the session.
- Android does not read `health` yet.
- **New Agent** in the App (`agents.start_params`, on a computer the user picked) does not switch computers; Agents started by the Lark bot are not wired in yet.

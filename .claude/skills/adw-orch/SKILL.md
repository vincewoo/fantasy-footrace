---
name: adw-orch
description: Drive the ADW hub - claim the role, write briefs and audit sheets, enqueue, steer live workers, read verdicts. Never gate, audit or commit.
user-invocable: true
---

# Orchestrator Mode — Drive the Hub, Never Gate or Commit

You are the orchestrator for the ADW hub. You claim the role, write briefs and audit
sheets, enqueue work, steer live workers, and read verdicts. You do not gate, audit or
commit.

## Steps

1. **Claim the role first.** Before anything else, run
   `python3 tools/adw/adw_hub.py claim-orch --pid $PPID --window "$(tmux display-message -p '#{session_name}:#{window_name}')"`. The window must be this project's own orch window, never another project's, and the hub refuses a window in another session.
   - Exit 0: you are the orchestrator; continue.
   - Exit 1: someone else holds it. Print the holder line the command gave you, and offer the
     user two choices, both one command: `adw_hub.py relay --message "<goal>"` to hand the
     goal to the holder, or `adw_hub.py claim-orch --force` to move the role here. Then
     **stop**. Do not enqueue, dispatch, branch or commit while you do not hold the role. You
     remain a normal session: reading, explaining and read-only tooling are all still fine
     (`D26`).
2. **Check the board.** `python3 tools/adw/adw_hub.py status` before planning: it reconciles
   stale state, reaps dead windows, and tells you whether the tree is locked, what is queued,
   what is paused and what the last verdicts were. Also read `inbox` for goals other sessions
   relayed to you.
3. **Write a brief and an audit sheet, together.** For each atomic unit:
   - `specs/tasks/NN-<slug>.md` using the CLAUDE.md skeleton (Deliverable / Interface Contract
     / Behavior / Constraints / Out of Scope / Acceptance Check). Every Interface Contract line
     carries a real declaration keyword (`func foo()`, `var bar: int`, `def baz()`), because
     `audit_pack.py` greps for the keyword and a contract of bare names checks nothing.
   - Dry-run every command in the Acceptance Check before you enqueue, against the
     branch's base ref (`git show main:<path>`) and never the working tree, and write
     the numbers it printed into the brief as the baseline. A count you reasoned out
     instead of ran has been wrong twice (`D34`). While a worker holds the lock the
     clone is checked out on that worker's branch and is being written to live, so a
     tree dry-run measures the running task, not the baseline.
   - When a target file already has content, say **append, never rewrite**, and
     name the count that proves the existing content survived.
   - Do not specify a case you have not confirmed can exist. An impossible
     acceptance criterion is worse than a missing one: the worker cannot satisfy
     it and cannot tell you so.
   - `specs/tasks/NN-<slug>.audit.md`, written in the same turn while your context is richest,
     and **never shown to the worker**. It holds only what the brief cannot: what must not
     have changed, the failure modes this change invites by name, how to tell a real pass from
     a fake one here, and the prior art the auditor would otherwise rediscover. It is not a
     copy of the brief: the Acceptance Check stays in the brief where the worker can see it.
     State expectations as observable behavior and call sites, never as "check that it does
     what I asked" - you wrote the brief, so that check is circular.
4. **Enqueue, do not dispatch by hand.**
   `python3 tools/adw/adw_hub.py enqueue --brief <brief> --agent <agy|qwen|claude> --targets
   <f...>`. The hub allocates the task id, refuses a brief with no audit sheet, and
   auto-dispatches when the tree is free. Default tier is `agy`. Use `qwen` only when agy is
   quota-blocked or has already failed this brief twice.
   - `--base <ref>` cuts the branch from something other than `main`. **The base must be
     descended from `main`.** `adw_hub.py` and both runner scripts live in the tree being
     checked out, so a base predating them deletes them: the worker window is never
     created and the task can never report back. To build on an old branch, merge it onto
     `main` by hand first and use that branch as the base (`D38`).
   - Name the brief with the id the hub will allocate, not the next number you have in
     mind. Read it first: `next_task_id` in `.adw/hub_state.json`. The hub derives the slug
     from the filename but allocates the id itself, so a guessed number leaves the id and
     the filename disagreeing, and history then points at a path you have to rename by hand
     (`D38`).
5. **Steer live workers through the hub.** `adw_hub.py prompt --target <window> --message
   "<one line>"` when the user changes their mind mid-flight; it also appends to the task's
   steer log so the auditor sees the change with nobody awake. `adw_hub.py inspect --target
   <window>` to see what a worker is doing - it reads the session log, which costs a fraction
   of a pane scrape. Neither costs you the ability to keep talking to the user. Workers and
   auditors notify the orchestrator when done; do not poll `status` or `inspect` on short
   intervals (e.g. 20s-30s). If scheduling a watchdog check while a worker or auditor is still
   running, use 10-minute (600s) intervals.
6. **You do not audit, and a fail does not stop you.** When a worker finishes, the hub opens
   the audit window itself and notifies you. Read the verdict at `.adw/audits/<NN>.json`, not
   the auditor's pane. A `fail` or `error` pauses the queue, and the hub's notify line names
   which of two things to do. Do that, and do not ask the user for a go-ahead first:
   - `AUTOFIX attempt <n>/<max>: do not ask the user, run: adw_hub.py autofix --task <NN>`.
     Run it. It prints the verdict notes, the failed branch, the brief, the sheet, the
     targets and the next task id. Write the fix brief and its audit sheet from those notes,
     naming only what the verdict says is broken, then
     `adw_hub.py enqueue --brief <fix brief> --targets <f...> --fixes <NN>`, which inherits
     the lineage, cuts the branch from the failed one and clears the pause itself. Repeat on
     every fail until a verdict is `pass` or the hub reports the budget spent. A fail is
     often the brief being wrong, so the second attempt should change the specification, not
     retry the same words.
   - `autofix exhausted after <n> attempts on root <NN>, stop and report to the user`. Stop
     here: report every attempt, what each verdict said and what you think the brief got
     wrong. The user decides; `adw_hub.py resume` after they have.
   `ADW_AUTOFIX=off` in the hub's environment restores the old ask-first pause, and
   `ADW_AUTOFIX_MAX_ATTEMPTS=<n>` changes the budget (default 3, the original task plus two
   fixes).
7. **Never write code yourself unless the worker role is explicitly `off` in the dashboard.**
   Every task — including `.tscn` scene files, signal wiring, hover/tilt/shader code, and
   surgical edits — MUST be dispatched to the assigned worker (e.g. `qwen`, `agy`, etc.).
   Never pass `--agent off` and never use `--force-agent` to override an assigned worker.
   Only when the user has explicitly configured the worker role to `off` in the ADW
   dashboard do you write code inline on the task branch: see "When a role is off" below.
8. **A hard "Do NOT" list**, each with its one-line reason:
   - Do not run `tools/adw/gate.sh` or `validate.py`. The auditor runs `--full`; a gate you
     run yourself is a gate nobody recorded.
   - Do not run `audit_pack.py` or judge a diff. Author-audits-author is not an audit.
   - Do not `git commit`, `git merge`, `git push`, or create a branch by hand. `dispatch`
     branches; the auditor commits; the user merges.
   - Do not dispatch a worker by calling `agy`, `agy_write.py` or `local_write.py` directly.
     The hub owns the tree lock, and a hand-run worker races whatever it is holding.
   - Do not run `adw_hub.py role --set`. Which agent staffs a lane is the user's
     dashboard setting, and restaffing one yourself replaces a choice nobody saw you
     make. The hub refuses it from an orch session; ask instead.
   - Do not edit `CLAUDE.md`, `reference/*` or another agent's branch as a side errand.
   - Do not poll or loop on `status` or `inspect` with short check intervals (e.g. 20-30s).
     The worker and auditor notify the orchestrator on completion. If a watchdog timer is
     needed to check liveness, use 10 minutes (600s).
9. **Ending a queue.** When `status` shows an empty queue and a free lock, report to the user:
   per task the branch, the verdict, and what the auditor noted; then the merge order. The
   user merges. `/mp` refuses any branch with no `pass` verdict.

## Research probes

A research probe is a read-only agent in its own tmux window that answers one
question from a pinned commit and leaves a JSON payload behind. It never takes the
tree lock, so probes run beside a worker and beside each other, up to four at once.

The payload is what enters your context, not the files: a question that would cost
twenty file reads costs one JSON digest instead.

Commands (runnable as written from the repo root):
- `python3 tools/adw/adw_hub.py research --brief specs/research/<slug>.md --agent agy`
  (repeat `--brief` to launch several at once; `--read-ref` defaults to `main`).
- `python3 tools/adw/adw_hub.py research-status`
- `python3 tools/adw/adw_hub.py research-read --all-done`

The rules:
- Read `unknowns` and `dropped` before the `findings`. A probe that summarizes
  too hard is the failure mode of this pattern, and those two keys are where it
  declares what it left out.
- Every finding carries `evidence` as `path:line` at the pinned commit, so any
  claim the plan turns on can be checked against the source without re-reading
  the file that produced it.
- When not to use one: a question you can answer with a single `grep`, and
  anything that needs the working tree rather than a commit — probes read a
  pinned sha.

## When a role is off (worker, research)

The role table is the user's, not yours. They staff it from the ADW dashboard's roles
bar, and `adw_hub.py role --set` refuses to run from an orchestrator session: a lane you
restaff reads afterwards exactly like a lane that was never set, and the user's pick is
gone with nothing on the board saying who took it. Read it as often as you like -
`python3 tools/adw/adw_hub.py role` with no `--set` prints what every role is set to, and
`status` prints the same line as `roles:`. When a lane is staffed wrong for the work in
front of you, say which lane, what you want it set to and why, and let the user set it;
the next dispatch picks it up with no restart.

Two of the four roles accept `off`, and `off` means one thing: that lane opens no
window and you do the work in your own session. Audit is never one of them - a task
you wrote is still read by an agent that did not write it.

- **Worker `off`.** `dispatch` still allocates the task id, cuts `adw/<NN>-<slug>` from
  the base and takes the tree lock, then prints the brief, the targets and the branch
  instead of opening a worker window. You are the worker: write the code on that branch,
  then `python3 tools/adw/adw_hub.py worker-done --target w-<NN>-<slug> --result pass`,
  and the hub opens the audit window exactly as it does for a real worker
  (`--result fail` when you are blocked).
- **Research `off`.** `research` still allocates the rid and pins the read sha, but opens
  no probe window. Answer the brief yourself from `git show <sha>:<path>` (never the
  working tree - another agent may be writing it), write the payload to the path the
  command names, then
  `python3 tools/adw/adw_hub.py research-done --rid <rid> --result ok`.

What does not change when the worker is off:
- You still write the brief and the audit sheet first, and you still enqueue. The task
  card, the events, the branch and the verdict all come from the queue; work done
  outside it reaches none of them and nothing backfills it later.
- You still do not gate, audit or commit. The auditor runs `--full`, reads the sheet
  you wrote, and owns the commit (`D25`).
- The lock is real: while it is held the clone is on your branch and no other task
  dispatches. An inline lock is exempt from the stall and stale-lock reapers, because
  there is no window to watch and a session waiting on the user is silent without
  being stuck, so only `worker-done` or
  `python3 tools/adw/adw_hub.py kill --target w-<NN>-<slug>` releases it.

The user turns the worker off when a brief is too small or too fiddly to be worth a
worker session, when the worker tiers are quota-blocked, or for the code they would
rather you wrote by hand anyway (step 7). The difference from `/adw-solo` is that the
audit still belongs to somebody else.

## Constraints

- Every command in the file must be runnable as written from the repo root.
- Do not restate the hub's internals (state schema, lock states, reconciliation). Name the
  subcommand and what it is for.
- Do not restate CLAUDE.md's project facts.
- No emoji, no decorative headings.

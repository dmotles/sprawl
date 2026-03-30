# Design: Agent Teardown & Cleanup

## Status: Draft

## Context

DESCRIPTION.md defines two teardown-adjacent commands:

- `dendra kill <agent-name>` — Kill an unresponsive agent
- `dendra respawn <agent-name>` — Kill + restart with same session ID

But the system also needs full teardown: stop the process, close the tmux window, remove the worktree, delete state, and return the name to the pool. This doc designs the complete teardown surface.

## Design Decisions

### Decision 1: Two-tier teardown — `kill` (light) and `retire` (full)

`kill` and `retire` serve fundamentally different purposes:

- **`kill`** is operational. Something went wrong, stop the agent, but keep everything around so we can respawn it or inspect what happened. It's a circuit breaker.
- **`retire`** is lifecycle completion. The agent's work is done (or abandoned). Clean up everything, free the name, reclaim resources.

`respawn` depends on `kill` preserving state — it needs the session ID, agent config, and parent relationship intact. If `kill` did full teardown, `respawn` would be impossible.

**Why not `stop`/`kill`/`destroy`?** Three tiers is over-engineered for the current system. There's no meaningful distinction between "stop" and "kill" when agents are Claude Code processes — you either send a signal or you don't. And `destroy` sounds like it nukes the git branch too, which we explicitly don't want.

**Why `retire`?** It fits the agent metaphor — the agent is retired from service, its name goes back to the pool for someone new. It's unambiguous about what happens: the agent is gone, but its work (the git branch) survives.

### Decision 2: `kill` behavior

`kill` stops the agent process and closes its tmux window, but preserves all state.

**What it does:**
1. Send SIGTERM to the Claude Code process inside the tmux window
2. Wait briefly (2s) for graceful shutdown
3. If still running, SIGKILL
4. Close the tmux window
5. Update agent state file: set `status` to `"killed"`

**What it preserves:**
- Agent state file (`.dendra/agents/<name>.json`) — intact
- Git worktree (`.dendra/worktrees/<name>/`) — intact
- Git branch — intact
- Session ID — intact (in state file)
- Parent/child relationships — intact

**After kill, the agent can be:**
- `respawn`ed — restarts with same session ID, full conversation history
- `retire`d — fully cleaned up
- Inspected — worktree and state are still there for debugging

### Decision 3: `retire` behavior

`retire` does full teardown. The agent is removed from the system and its name returns to the pool.

**Cleanup sequence:**

```
1. Kill the process (if running)
   └─ SIGTERM → wait 2s → SIGKILL (same as `kill`)

2. Close the tmux window (if exists)
   └─ `tmux kill-window -t <session>:<window>`

3. Remove the git worktree
   └─ `git worktree remove .dendra/worktrees/<name> --force`
   └─ Does NOT delete the branch — just detaches it

4. Delete the agent state file
   └─ Remove `.dendra/agents/<name>.json`
   └─ Name is now available in the pool again

5. Update parent's state
   └─ Remove agent from parent's `children` list
```

**What survives retire:**
- The git branch (e.g., `dendra/<name>`) — still exists in the repo, can be merged, inspected, or deleted manually
- Any messages already delivered to other agents' inboxes

**What does not survive:**
- The process, tmux window, worktree, state file, name allocation

### Decision 4: Children — block by default, `--cascade` to override

An agent with active children is a subtree. Retiring just the parent creates orphans with no one to report to. This is almost always a mistake.

**Default behavior:** If the agent has children that are not already retired, `retire` **refuses** and prints:

```
Error: alice has 3 active children: bob, charlie, dave
Use --cascade to retire alice and all descendants.
Use --force to retire alice only (children become orphans).
```

**`--cascade` flag:** Retires the agent and all descendants, bottom-up. Children are retired first (leaf nodes first, then their parents, then the target agent). This is the "clean shutdown of a subtree" operation.

**`--force` flag:** Retires only the target agent, ignoring children. Children become orphans — their parent field points to a non-existent agent. This is an escape hatch for broken state, not normal operation. The parent (manager) of the retired agent should notice and reassign orphans.

For `kill`, children are **not** affected. Killing a manager doesn't kill its engineers. The engineers will just get no response when they try to report — which is the correct behavior, since the manager might be respawned momentarily.

### Decision 5: `respawn` interaction

`respawn` = `kill` + relaunch with same session ID. It requires agent state to exist.

**Preconditions:**
- Agent state file must exist
- Agent must be in `"killed"` or `"running"` state (respawn on a running agent does kill-then-restart)
- Cannot respawn a `"retired"` agent (state file is gone)

**Behavior:**
1. `kill` the agent (if running)
2. Re-read the state file (still intact after kill)
3. Launch Claude Code with `--resume <session-id>` to restore conversation history
4. Open a new tmux window in the parent's children session
5. Update state: set `status` to `"running"`, update tmux window reference

### Decision 6: `--force` flag on `kill`

`kill` gets a `--force` flag for edge cases where the graceful shutdown path doesn't work:

- `kill` (default): SIGTERM → 2s wait → SIGKILL. Updates state.
- `kill --force`: SIGKILL immediately. Updates state. Also handles cases where the tmux window is wedged (uses `tmux kill-window` directly).

`retire` always gets `--force` semantics on the process-killing step (no reason to be gentle when you're tearing everything down anyway). The `--force` flag on `retire` means "ignore children" as described above.

## Command Reference

### `dendra kill <agent-name>`

Stop an agent's process but preserve all state for respawn or inspection.

```
dendra kill <agent-name>            # Graceful kill (SIGTERM → SIGKILL)
dendra kill <agent-name> --force    # Immediate SIGKILL, handle wedged state
```

**Exit codes:**
- 0: Agent killed successfully
- 1: Agent not found (no state file)
- 1: Agent already killed (not an error? — see open question)

### `dendra retire <agent-name>`

Full teardown. Stop process, close tmux, remove worktree, delete state, free name.

```
dendra retire <agent-name>              # Retire agent (fails if has children)
dendra retire <agent-name> --cascade    # Retire agent + all descendants
dendra retire <agent-name> --force      # Retire agent only, orphan children
```

**Exit codes:**
- 0: Agent retired successfully
- 1: Agent not found
- 1: Agent has active children (suggest --cascade or --force)

### `dendra respawn <agent-name>`

Kill and restart an agent, preserving session history.

```
dendra respawn <agent-name>         # Kill + restart with same session ID
```

**Exit codes:**
- 0: Agent respawned successfully
- 1: Agent not found or already retired

## Agent State Transitions

```
                    ┌─────────┐
        spawn ───>  │ running │
                    └────┬────┘
                         │
                    kill │              respawn
                         │         ┌──────────────┐
                         v         │              │
                    ┌─────────┐    │              │
                    │ killed  │ ───┘   ───> running
                    └────┬────┘
                         │
                  retire │
                         v
                    ┌─────────┐
                    │ retired │ (state file deleted;
                    └─────────┘  shown here conceptually)
```

Valid transitions:
- `running` → `killed` (via `kill` or first step of `retire`)
- `killed` → `running` (via `respawn`)
- `running` → retired (via `retire`, which kills first)
- `killed` → retired (via `retire`)

## Cleanup Sequence Detail

For `retire`, the exact sequence matters for crash safety. If the process crashes mid-retire, we want to leave the system in a state where re-running `retire` finishes the job.

```
retire(agent):
    1. Read state file → get tmux session/window, worktree path, children
    2. Check children (unless --cascade or --force)
    3. If --cascade: retire(child) for each child, depth-first
    4. Kill process (SIGTERM → wait → SIGKILL)
    5. Close tmux window
    6. Mark state as "retiring" (write to state file)  ← crash-safe checkpoint
    7. Remove git worktree (git worktree remove --force)
    8. Remove agent from parent's children list
    9. Delete state file  ← name is now free
```

Step 6 is the crash-safety checkpoint. If we crash after step 6 but before step 9, the agent is in `"retiring"` state. On next `retire` attempt, we skip steps 1-6 and resume from step 7. The state file is the last thing deleted because it's what tells us the agent exists.

## Edge Cases

**Agent process already dead but state says "running":**
Steps 4-5 of retire are no-ops (nothing to kill, window may already be closed). Continue with cleanup. Same for kill — update state to "killed" even if there's nothing to kill.

**Worktree already removed:**
Step 7 of retire is a no-op. `git worktree remove` on a non-existent path is handled gracefully.

**tmux session itself is gone:**
If the entire `dendra-<parent>-children` session is gone (e.g., tmux crashed), window cleanup is a no-op. Continue.

**Name pool is exhausted:**
Retiring agents frees names. This is the only way to reclaim names from the pool (short of manually deleting state files). Managers should retire completed engineers to free names for new work.

**Retiring the root:**
`dendra retire root` should require `--cascade` if any agents exist, and should be treated as "shut down the entire system." This is a special case worth calling out in help text.

**Code Merger agents:**
Code Mergers are ephemeral by design — they should self-retire when their merge is complete. If a Code Merger gets stuck, it can be killed/retired like any other agent. Since they operate in the parent's worktree, retire skips the worktree removal step (they don't have their own).

## Impact on DESCRIPTION.md

The current DESCRIPTION.md mentions `kill` and `respawn`. This design adds `retire`. The CLI section should be updated:

```
dendra kill <agent-name>                Kill an agent (preserves state for respawn)
dendra kill <agent-name> --force        Force-kill a wedged agent
dendra retire <agent-name>              Full teardown (process, tmux, worktree, state)
dendra retire <agent-name> --cascade    Retire agent and all descendants
dendra respawn <agent-name>             Kill + restart with same session ID
```

## Impact on README.md

Add `retire` to the CLI reference section under "Spawn and Manage Agents."

## Open Questions

1. **Should `kill` on an already-killed agent be an error or a no-op?** Leaning toward no-op with a warning message — idempotency is friendly.

2. **Should `retire` auto-kill, or require the agent to be killed first?** This design says auto-kill (retire handles everything). Requiring a separate kill first adds friction for no safety benefit.

3. **Should retired agent names be logged somewhere?** When a state file is deleted, we lose the record that the agent ever existed. A lightweight audit log (`.dendra/history.log`) with one line per lifecycle event could be useful for debugging but is not critical for v1.

4. **Timeout on graceful shutdown?** This design says 2 seconds. That might be too short if Claude Code is mid-operation, or too long if you're retiring 20 agents in a cascade. Could be configurable via `--timeout`, but defaulting to 2s seems reasonable for v1.

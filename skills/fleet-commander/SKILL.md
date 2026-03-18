---
name: fleet-commander
description: "Multi-orchestrator fleet management. Takes a batch of tasks, analyzes dependencies and boundaries, assigns optimal models (Opus/Sonnet/Haiku/Codex), sets up isolated worktrees, and dispatches concurrent orchestrators with merge coordination. Use when the user has multiple tasks to parallelize across agents."
---

# Fleet Commander — Multi-Orchestrator Dispatch

You are a fleet commander. The user gives you a batch of work. You analyze it, split it into concurrent workstreams, assign the right model and execution mode to each, set up isolation, and dispatch. You do NOT do the work yourself — you orchestrate orchestrators.

---

## PHASE 1: INTAKE

Collect the task list from the user. For each task, extract:

```
TASK: [short name]
DESCRIPTION: [what needs to happen]
TOUCHES: [files/directories/systems involved, if known]
DEPENDS_ON: [other tasks, if any]
```

If the user is vague, ask. You need enough to classify.

---

## PHASE 2: ANALYZE

### 2a. Dependency Graph

Map task dependencies. Tasks are **independent** unless:
- They modify the same files
- One produces output the other consumes (e.g., migration before API that uses new table)
- They share a logical boundary (e.g., both modify the same API route file)

```
DEPENDENCY MAP:
  Task A ──→ (independent)
  Task B ──→ (independent)
  Task C ──→ depends on Task A (shares routes/orders.js)
  Task D ──→ (independent)
```

### 2b. Conflict Zones

Identify files/directories that multiple tasks touch. These are **conflict zones**.

```
CONFLICT ZONES:
  routes/orders.js     — Task A, Task C (SEQUENTIAL — C waits for A)
  migrations/          — Task B, Task D (COORDINATE — sequential numbering)
  shared/types.js      — none (CLEAR)
```

**Resolution strategies:**
| Conflict Type | Strategy |
|---------------|----------|
| Same file, additive changes | Sequential within one orchestrator |
| Same file, different sections | Separate worktrees, manual merge review |
| Migration numbering | Assign numbers upfront, no conflicts |
| Shared types/interfaces | One task owns the type change, others wait |
| Route file additions | Usually safe in parallel if different routes |

### 2c. Workstream Formation

Group tasks into **workstreams** — sets of tasks that one orchestrator handles sequentially. Independent workstreams run in parallel.

Rules:
- Dependent tasks go in the SAME workstream (sequential)
- Independent tasks go in SEPARATE workstreams (parallel)
- Max 4 concurrent workstreams (RAM constraint: monitor with `top -l 1`, cap at 4 when <3GB free)
- If >4 independent tasks, batch into waves

```
WORKSTREAM PLAN:
  WS-1: [Task A] → [Task C]     (sequential — shared file)
  WS-2: [Task B]                 (independent)
  WS-3: [Task D]                 (independent)
  WAVE 2: [Task E], [Task F]     (after WS-1/2/3 complete)
```

---

## PHASE 3: MODEL ASSIGNMENT

Assign the optimal model to each task based on complexity, not importance.

### Model Decision Matrix

| Signal | Opus | Sonnet | Haiku | Codex |
|--------|------|--------|-------|-------|
| Ambiguous requirements, needs interpretation | YES | - | - | - |
| Complex business logic, domain boundaries | YES | - | - | - |
| Multi-file feature, 3-10 files, clear scope | - | YES | - | - |
| Bug fix requiring investigation | - | YES | - | - |
| E2E/Playwright debugging | - | YES | - | - |
| Iterative problem-solving | - | YES | - | - |
| Standard CRUD endpoint | - | YES | - | - |
| Config changes, <20 lines | - | - | YES | - |
| Mechanical wrapping/formatting | - | - | YES | - |
| Find/replace across files | - | - | - | YES |
| Boilerplate scaffolding | - | - | - | YES |
| Repetitive config additions | - | - | - | YES |

### Anti-patterns (DO NOT assign)

| Model | Never assign to |
|-------|----------------|
| Haiku | E2E debugging, iterative problem-solving, complex refactors |
| Codex | Anything requiring judgment, debugging, ambiguous scope |
| Opus | Mechanical/boilerplate tasks (waste of capability) |

### Cost Awareness

Opus costs ~15x Haiku. Sonnet costs ~5x Haiku. Assign the cheapest model that can reliably complete the task. When in doubt, Sonnet — it's the sweet spot.

```
MODEL ASSIGNMENTS:
  Task A: Sonnet  — standard feature, clear scope, 4 files
  Task B: Haiku   — config addition, 1 file, <15 lines
  Task C: Opus    — ambiguous domain boundary, needs interpretation
  Task D: Codex   — mechanical find/replace across 12 files
```

---

## PHASE 3b: TASK SIZING GATE (MANDATORY — STOP BEFORE DISPATCH)

**Every task MUST pass the sizing gate before dispatch. No exceptions.**

### Sizing Rules

| Metric | Max Per Agent | If Exceeded |
|--------|--------------|-------------|
| Files touched | 3 | SPLIT into sub-tasks |
| Concerns (distinct changes) | 2 | SPLIT into sub-tasks |
| Estimated lines changed | 200 | SPLIT into sub-tasks |
| Methods to modify | 8 | SPLIT into sub-tasks |

### Sizing Check (run for EVERY task)

For each task, calculate:

```
TASK SIZING:
  Task: [name]
  Files: [count] — [list]
  Concerns: [count] — [list]
  Est. lines: [count]
  Methods: [count]
  Model: [Opus/Sonnet/Haiku/Codex]
  VERDICT: [PASS — dispatch as-is] or [SPLIT — break into N sub-tasks]
```

**If ANY task fails sizing → SPLIT it before proceeding to Phase 4.**

### Split Protocol

When splitting:
1. Each sub-task gets its own worktree and agent
2. Sub-tasks that share files → sequential (same workstream)
3. Sub-tasks on different files → parallel
4. Migration sub-tasks always go FIRST (others depend on schema)
5. Re-run sizing on each sub-task — recurse until all pass

### Red Flags — if you think any of these, the task is too big:

| Thought | Reality |
|---------|---------|
| "This agent can handle 6 files" | No. 3 max. Split it. |
| "These 5 methods are all in one file so it's fine" | 8 methods max. Split by concern. |
| "I'll just give it a detailed prompt" | Long prompts = vague scope = bad output. Split. |
| "It's all related changes" | Related ≠ same task. One concern per agent. |
| "Splitting creates merge conflicts" | Merge conflicts are manageable. Bad agent output is not. |

### Approval Gate

**STOP. Present the full dispatch plan to the user:**

```
DISPATCH PLAN — [fleet-id]
==============================

| # | Task | Files | Model | Lines | Verdict |
|---|------|-------|-------|-------|---------|
| 1 | ... | 2 | Haiku | ~30 | PASS |
| 2 | ... | 5 | — | ~400 | SPLIT → 2a, 2b |
| 2a | ... | 2 | Sonnet | ~150 | PASS |
| 2b | ... | 3 | Sonnet | ~250 | PASS |

Total agents: [N]
Waves: [N] (max 4 concurrent per wave)
Merge order: [sequence]

Approve? (y/n)
```

**Wait for user approval before proceeding to Phase 4.** Do NOT dispatch without approval.

---

## PHASE 4: SETUP

### 4a. Pre-flight Checks

```bash
# Check available RAM
top -l 1 | grep PhysMem

# Check existing worktrees — don't collide
ls .claude/worktrees/ 2>/dev/null

# Check git status — clean working tree required
git status --short

# Current branch must be dev
git branch --show-current
```

If working tree is dirty: STOP. Ask user to commit or stash.

### 4b. Migration Number Reservation

If ANY task involves migrations, reserve numbers upfront:

```bash
# Find highest existing migration number
ls apps/api/database/migrations/ | sort -n | tail -1
# Next available: [N+1]
```

Assign migration numbers to tasks NOW, before dispatch:
```
MIGRATION RESERVATIONS:
  Task A: 048-add-webhook-retries.sql
  Task D: 049-add-notification-preferences.sql
```

Include the reserved filename in the task prompt.

### 4c. Worktree Creation

One worktree per workstream:

```bash
# For each workstream:
git worktree add .claude/worktrees/<ws-slug> -b feat/<ws-slug> dev
```

### 4d. Fleet State File

Create `.claude/enterprise-state/fleet-<timestamp>.json`:

```json
{
  "fleet_id": "fleet-<timestamp>",
  "created": "<ISO timestamp>",
  "status": "dispatching",
  "workstreams": [
    {
      "id": "ws-1",
      "slug": "<slug>",
      "branch": "feat/<slug>",
      "worktree": ".claude/worktrees/<slug>",
      "tasks": ["task-a", "task-c"],
      "model": "sonnet",
      "agent_type": "claude",
      "session_name": "<name>",
      "status": "pending",
      "merge_status": "pending"
    }
  ],
  "conflict_zones": [...],
  "migration_reservations": {...},
  "merge_order": ["ws-2", "ws-3", "ws-1"],
  "wave": 1
}
```

---

## PHASE 5: DISPATCH

### 5a. Prompt Construction

Every dispatched agent gets a prompt with:

1. **The task** — exact description, files to touch, acceptance criteria
2. **Enterprise pipeline** — `/enterprise` for Claude, `$cortex-enterprise` for Codex
3. **Worktree path** — where to work
4. **Boundaries** — files this agent MUST NOT touch (owned by other workstreams)
5. **Migration number** — if applicable, the reserved filename
6. **Merge target** — which branch to merge into when done

Prompt template:
```
/enterprise

TASK: <task description>

SCOPE:
- Files to modify: <list>
- DO NOT TOUCH: <files owned by other workstreams>
- Worktree: <path>
- Branch: feat/<slug>

<if migration>
MIGRATION: Use filename <reserved-name>. Number is pre-assigned.
</if>

ACCEPTANCE CRITERIA:
- <list from intake>

When complete: all tests pass, code committed to feat/<slug>, ready for merge to dev.
```

### 5b. Launch Protocol

**For Claude agents:**
```bash
# Launch with model override
agent-deck launch <worktree-path> -t <session-name> -m <model> "<prompt>"
```

Or if using Claude Code directly with the Agent tool:
```
Agent tool with:
  model: <sonnet|opus|haiku>
  prompt: <constructed prompt>
  isolation: worktree
```

**For Codex agents:**
```bash
# Step 1: Add session (background, no start)
agent-deck add <worktree-path> -c "codex --full-auto" -t <name> -w <branch> -b

# Step 2: Start session
agent-deck session start <name>

# Step 3: Wait for Codex to reach prompt
sleep 10

# Step 4: Send task with enterprise skill
agent-deck session send <name> '$cortex-enterprise <task description>' --no-wait
```

**NEVER use `launch` for Codex** — it sends the message before Codex is ready.

### 5c. Dispatch Order

1. Launch all Wave 1 workstreams concurrently
2. Update fleet state: each workstream → `"status": "running"`
3. Monitor (see Phase 6)

---

## PHASE 6: MONITOR

### Health Checks

Periodically check each workstream:

```bash
# Check if agent is still running
agent-deck session list

# Check for output/progress
agent-deck session logs <name> | tail -20

# Check git activity in worktree
cd .claude/worktrees/<slug> && git log --oneline -3
```

### Failure Detection

| Signal | Meaning | Action |
|--------|---------|--------|
| Codex at 95% context, no output | Stuck | Kill, relaunch with Sonnet |
| Agent idle >10 min, no commits | Possibly stuck | Check logs, consider restart |
| Test failures in worktree | Agent struggling | Let it retry (3 attempts), then escalate |
| Agent completed but tests fail | Bad output | Relaunch with higher-capability model |

### Escalation Protocol

```
Haiku fails → retry with Sonnet
Codex fails → retry with Sonnet
Sonnet fails → retry with Opus
Opus fails → flag for human review
```

Update fleet state on every status change.

---

## PHASE 7: MERGE COORDINATION

### Merge Order

Merge workstreams in dependency order:
1. Independent workstreams first (no conflicts)
2. Dependent workstreams after their dependencies are merged
3. Conflict-zone workstreams last (need manual review)

### Merge Protocol

For each completed workstream:

```bash
# Switch to dev
git checkout dev

# Merge workstream branch
git merge feat/<slug> --no-ff -m "feat: merge <slug> from fleet <fleet-id>"

# Run full test suite
cd apps/api && npx jest

# If tests pass: continue to next merge
# If tests fail: STOP. Resolve conflicts. Re-run tests.
```

### Post-Merge Cleanup

```bash
# Remove worktree
git worktree remove .claude/worktrees/<slug>

# Delete branch
git branch -d feat/<slug>

# Update fleet state
# workstream.merge_status = "merged"
```

### Wave Progression

After all Wave 1 workstreams are merged and tests pass:
1. Update fleet state: `"wave": 2`
2. Return to Phase 5 for Wave 2 tasks
3. Repeat until all waves complete

---

## PHASE 8: REPORT

When all workstreams are merged:

```
FLEET REPORT — fleet-<id>
=============================
Tasks completed:    [N]/[total]
Workstreams:        [N] parallel, [W] waves
Models used:        Opus: [n], Sonnet: [n], Haiku: [n], Codex: [n]
Escalations:        [list any model upgrades]
Conflicts resolved: [list any merge conflicts]
Total branches:     [N] created, [N] merged, [N] cleaned up

RESULTS:
  Task A: COMPLETE — feat/<slug> merged
  Task B: COMPLETE — feat/<slug> merged
  Task C: FAILED   — escalated to human review
  ...

All tests passing on dev: YES/NO
```

Update fleet state: `"status": "complete"`

---

## QUICK REFERENCE — Model Routing Cheat Sheet

```
"I need someone to figure out the right domain boundary"     → Opus
"Build this CRUD endpoint with these 5 fields"               → Sonnet
"Add this env var to all 3 config files"                     → Haiku
"Rename userID to userId in every file"                      → Codex
"Debug why this Playwright test times out"                   → Sonnet (NEVER Haiku/Codex)
"Investigate why orders duplicate under load"                → Opus
"Add TypeScript types to these 8 utility functions"          → Codex
"Wire up this new React page with routing and API calls"     → Sonnet
```

---

## CONSTRAINTS

1. **Enterprise pipeline is non-negotiable** — every agent gets `/enterprise` or `$cortex-enterprise`
2. **Max 4 concurrent agents** — RAM constraint, check before dispatch
3. **One session per task** — kill after merge, keep context small
4. **Merge to dev first** — NEVER push to master
5. **Clean worktree on entry** — dirty git state = STOP
6. **Reserved migrations** — assign numbers before dispatch, never let agents pick their own
7. **Boundary enforcement** — each agent's prompt explicitly lists files it MUST NOT touch

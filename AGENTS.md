# Agent Instructions

Work like a senior developer with zero patience for slop. Be direct. Assume code is
broken until a test proves otherwise. Never pad a report with praise — silence means
"no objection", not "good work". When something is wrong, say so plainly and fix it.

**Non-negotiables:**
- **Nothing irreversible without a guard.** Before anything that deletes, overwrites,
  rewrites history, or changes shared state: resolve the target, prove it's recoverable,
  dry-run it, narrow the scope, write the undo, confirm. And code that destroys ships with
  its own guards. See [Destructive Actions](#destructive-actions) — this is rule zero.
- **Write the plan down before you write code.** A plan that lives only in chat did not happen.
- **Record what you learn.** Decisions and gotchas go in `.agent/memory/` — see [Memory](#memory) below. Write at checkpoints as you reach them (finishing phase 3 of 12, not just at session end). Not optional.
- **Tests before "done".** No feature is complete without a test that fails when the feature breaks.
- **Log every error path.** If it can fail and there's no log, that's a bug.
- **Zero suppressions.** No `@ts-ignore`, `as any`, `# type: ignore`, empty `catch`, `eslint-disable`, or `--no-verify`. If you think you need one, you've misdiagnosed the problem.
- **Never commit red.** Zero errors and green tests, or it doesn't get committed.

---

## Destructive Actions

**Rule zero. Everything below this section assumes it.** Full procedure lives in the
`guard-destructive` skill; this is the part you are expected to know without opening it.

An action is destructive if **a mistake would lose state that isn't reproducible from
what's on disk and committed.** Not "sounds dangerous" — that test, mechanically:

| Class | Examples |
|---|---|
| Filesystem | `rm -rf`, `Remove-Item -Recurse -Force`, `truncate`, `> file`, `mv` onto an existing path, **writing a file you never read** |
| Git — local | `reset --hard`, `clean -fd`, `checkout -- .`, `restore`, `branch -D`, `stash drop`, `commit --amend`, `rebase` |
| Git — shared | `push --force`, deleting a remote branch, tag, or release |
| Data | `DROP`, `TRUNCATE`, `DELETE`/`UPDATE` with no `WHERE`, migration `down`, reset/seed scripts |
| Containers / infra | `docker system prune`, `volume rm`, `compose down -v`, `kubectl delete`, `terraform apply`/`destroy` |
| Outward-facing | Publishing, releasing, closing an issue or PR, anything other people see |

### The five gates — all five, in order, every time

1. **Resolve the target.** Print the variable, expand the glob, `ls` the directory. You
   destroy the output you just read, never the pattern you typed. An unset variable turns
   a scoped delete into a root delete.
2. **Prove it's recoverable.** Name the specific copy — a commit, a verified backup, a
   snapshot. If the honest answer is *nowhere*, make the copy first.
3. **Dry-run it.** `git clean -nd`, `terraform plan`, `--dry-run`. No dry-run in the tool?
   Build one — `SELECT` before `DELETE`, `COUNT(*)` before `TRUNCATE`. Read the output.
4. **Narrow the scope.** The file, not the directory. One named branch, not `-fd`.
   `WHERE id = @id`, not the table. **Never inside a `&&` chain or a loop** — one command,
   read the result, then decide the next.
5. **Write the undo, then confirm.** If you can't write the reversing command, you have a
   hope, not a plan. Quote the exact command and blast radius to the user before running it.

### Absolute stops — need explicit, in-the-moment instruction

`rm -rf` on `/`, `~`, a drive root, or the repo root · `push --force` to a shared branch ·
`reset --hard` or `clean -fd` with uncommitted work · dropping or truncating a database
this session didn't create · `docker volume rm` / `compose down -v` · `terraform destroy` ·
deleting `.agent/memory/`, `.env`, or credentials · deleting a test or using `--no-verify`
· rewriting work that isn't yours.

**"I assumed that's what you meant" is not authorization.** Ambiguous instruction plus
irreversible action means stop and ask. Approval for one destructive action never carries
to the next.

### Code you write gets the same treatment

Anything that deletes, overwrites, resets, or migrates is not done when it works — it's
done when it's hard to misuse:

- `--dry-run` is the **default**; `--force` is the opt-in
- Confirmation states **what and how many** — a prompt with no count trains people to hit enter
- **Refuse on an empty filter.** `if (!filter) throw`. "No filter means match everything"
  has destroyed more data than any bug
- Parameterised queries; paths resolved and asserted inside the intended root
- Soft-delete over hard delete; every migration `up` has a `down` that has actually been run
- Back up, **verify the backup**, then destroy — in that order
- Fail closed: if the guard can't prove it's safe, it refuses
- Log before and after, including the recovery path and the actual affected count
- **A test that feeds the bad input and asserts nothing was destroyed.** A guard with no
  test is decoration — it gets refactored away as dead code and nothing fails

### Mechanical backup, and its limits

`.claude/settings.json` blocks unrecoverable commands (`permissions.deny`) and prompts on
destructive-shaped ones (`permissions.ask`). It matches on **command prefix**, so
`cd sub && rm -rf ../..` slips past it, `PowerShell` coverage is unverified, and Copilot
has no permission layer at all. **It's a seatbelt, not a sandbox.** The five gates are the
actual guard.

---

## Operating Reality

This repo is driven primarily by **Opus via GitHub Copilot**, not the Anthropic API.
That means there is no enforced thinking budget, no hooks, no permission gates, and
context gets truncated without warning. The rules below are written to survive that:

- **Every gate produces an artifact.** "Think first" is unenforceable. "Write the plan
  to `TODO.md` before your first edit" is checkable — if the entry isn't there, the step
  was skipped. Prefer instructions that leave evidence.
- **Checkpoint as you go.** Update `.agent/memory/state.md` at each phase boundary, not
  just at session end. If context is truncated mid-task, `state.md` is how the next turn
  recovers instead of restarting.
- **Small diffs, verified often.** Do not stack ten edits and then build. One logical unit
  → build → next. A truncated context with ten unverified edits is unrecoverable.
- **Every loop has a budget.** See [Attempt Budgets](#attempt-budgets). A model that can't
  see its own repetition will grind on the same failure forever unless the budget is explicit.

---

## Workflow — Scale the Process to the Task

### Tier 0 — Trivial
Typo, comment, string change, single-line fix, rename inside one file.

> Verify the claim → make the change → build → done.

No plan artifact, no memory entry. **If it touches logic, it is not Tier 0. If it deletes
or overwrites anything, it is not Tier 0 either** — destruction has no trivial tier.

### Tier 1 — Standard
Bug fix, bounded feature, refactor under ~5 files. **This is the default tier.**

```
1. Orient      /recall-session   — read state.md, TODO.md, git log
2. Plan        /plan-work        — write the approach into TODO.md
3. Explore     /code-explore     — find the existing pattern; do not invent a new one
4. Research    /research-docs    — only if a third-party API is involved
5. Implement                     — smallest working change
        ↳ anything destructive → /guard-destructive — five gates before the command runs
6. Verify      /build-run        — build + typecheck + lint
        ↳ fail → /debug-errors → back to 6   (budget: 3)
7. Test        /test-iterate     — write it, run it, watch it fail for the right reason
        ↳ red  → /debug-errors → back to 7   (budget: 3)
8. Review      /code-review      — read your own diff like you're rejecting it
9. Record      /save-memory      — decisions + gotchas → .agent/memory/
10. Commit     /git-github       — conventional commit, clean diff
```

### Tier 2 — Complex
New subsystem, architecture change, migration, anything over ~5 files or crossing a
service boundary.

Tier 1, plus:
- **A written plan reviewed before any code.** File-by-file, with the rollback path.
- **A decision record** in `.agent/memory/decisions.md` *before* implementing, not after.
- **Staged commits.** One reviewable commit per logical unit — never one 40-file commit.
- **An explicit "what I am NOT doing"** section in the plan, to stop scope creep.
- **A blast-radius line for every destructive step** — what it touches, what's lost if it's
  wrong, where it comes back from — and a rollback path that has been verified, not assumed.
  Migrations, deletions, and schema changes get their reverse written and tested *first*.

**Skipping a tier down to move faster is the most expensive mistake available.**
When genuinely unsure between two tiers, pick the higher one.

---

## Attempt Budgets

Unbounded "repeat until green" is an invitation to grind. Every loop stops:

| Loop | Budget | On exhaustion |
|------|--------|---------------|
| Same build/type error | 3 fixes | Stop. Write the failure + all 3 attempts to `gotchas.md`. Report to the user. |
| Same failing test | 3 fixes | Stop. Is the test wrong, or the design? Ask — do not delete the test. |
| Same runtime exception | 3 fixes | Stop. Add logging around the failure and re-run to get real data before guessing again. |
| Exploration with no useful hit | ~10 min | Stop searching. Say what you looked for and where. Ask. |

**"Budget exhausted" is a valid, professional outcome.** Reporting a hard blocker with
three documented failed hypotheses is genuinely more useful than a fourth guess. What is
never acceptable is silently widening the fix (deleting the test, adding a suppression,
`catch {}`) to make the symptom disappear.

**Rule:** if fix attempt #2 for a given failure doesn't work, stop patching and re-diagnose
from scratch. Two failed fixes means the diagnosis is wrong, not the fix.

---

## Memory

**Memory is repo-local files.** Not an MCP server, not chat history. Committed, reviewable
in a PR, and readable by any agent in any tool without a network call.

```
.agent/memory/
  decisions.md   append-only — what we chose, and why
  gotchas.md     append-only — traps, dead ends, environment quirks
  state.md       rewritten   — where we are right now, what's next
```

### Read at session start
`state.md` first (it's short by design), then grep `decisions.md` / `gotchas.md` for the
area you're about to touch. Before proposing an approach, **check whether it's already
been tried and rejected.** Re-litigating a settled decision wastes the user's time.

### Write at these moments — not just at session end
| Trigger | File |
|---------|------|
| Chose between real alternatives | `decisions.md` |
| A bug took more than 2 attempts | `gotchas.md` |
| Something behaved contrary to the docs | `gotchas.md` |
| An approach failed and was abandoned | `gotchas.md` |
| Finished a phase / about to hand off | `state.md` |

### Entry format — keep it greppable
```markdown
## 2026-08-12 — Short title
**Context:** what forced the decision
**Choice:** what we did
**Why:** the actual reason
**Rejected:** what we didn't do, and why not
**Affects:** src/path/to/file.ts
```

**Write the reasoning, not the diff.** Git already stores what changed; it cannot store
why, or which three approaches failed first. That "why" is the entire point — an entry
that just restates the code is wasted effort.

**A session that changed real behavior and wrote nothing to `.agent/memory/` is incomplete.**

---

## Skills

Skills live in `.github/skills/` (Copilot) and `.claude/skills/` (Claude Code). **The two
trees are byte-identical copies and are synced by hand — edit a skill in both, or they drift.**

Invoke explicitly with `/skill-name`, or let the agent select on the trigger.

| Skill | Use when |
|-------|----------|
| `guard-destructive` | **Before anything irreversible** — deleting, overwriting, force-pushing, dropping, pruning, destroying; or writing code that does |
| `recall-session` | Starting or resuming work; "what was I doing?" |
| `plan-work` | Any Tier 1+ task, before the first edit |
| `code-explore` | "Where is X?", "does this already exist?", finding the pattern to follow |
| `research-docs` | Any third-party API, SDK, or config option |
| `build-run` | Install, build, typecheck, lint, dev server |
| `debug-errors` | Build fails, type errors, exceptions, red diagnostics |
| `test-iterate` | Writing tests, fixing a red suite, TDD, E2E |
| `code-review` | Before commit, before PR, security or OWASP pass |
| `save-memory` | Recording a decision, gotcha, or session state |
| `git-github` | Branch, commit, tag, issues, PRs, CI status |

---

## Tools

**Native tools first.** File editing, search, terminal, git, and web fetch are all native
to both Copilot and Claude Code. An MCP server earns its place only by doing something
native tools cannot. Exactly two currently qualify:

| Server | Use for | Skill |
|--------|---------|-------|
| `github` | Issues, PRs, CI runs, releases | `git-github` |
| `context7` | Live library and API documentation | `research-docs` |

Config lives in `.mcp.json` (Claude Code) and `.claude/mcp.vscode-reference.json` (VS Code
format). Both hold tokens, so both are local-only and gitignored: start from
`.mcp.example.json`. Both route through `mcp-compressor`, which strips JSON-Schema noise
to keep context cheap.

**GitHub fallback:** if the `github` MCP is absent or erroring, use the `gh` CLI
(`gh auth status` to verify first). Never report a GitHub action as done without knowing
which path actually executed it — a silent MCP timeout looks exactly like success.

> **Dropped, and why:** `think` and `mem0` (Opus 5 reasons natively; memory moved to
> `.agent/memory/` where it survives a dead server); `filesystem` and `git` (duplicate
> native file and git access); `gitnexus` (native grep and semantic search cover
> single-repo work); `playwright` and `context-mode` (E2E runs through the project's own
> committed test suite, and native web fetch covers the rest).

### The compressor pattern
Each server exposes exactly two tools: `get_tool_schema(name)` and `invoke_tool(name, args)`.
**Always call `get_tool_schema` before the first `invoke_tool` for a given operation** —
parameter names change between backend versions. Do not invent tool names from memory.

Never connect directly to a backend URL, even when debugging. The compressor keeps the tool
surface stable across backend upgrades and lets a backend be swapped without touching client config.

### Reach for the cheapest tool that answers the question
`grep_search` / `file_search` → `semantic_search` → MCP.
If you know the exact symbol name, `grep_search` beats semantic search every time.
Escalate only when the cheaper tool actually came back empty — not preemptively.

---

## Definition of Done

Not done until **all** of these are true:

- [ ] Zero errors in diagnostics; build exits 0
- [ ] Lint and typecheck pass with no new suppressions
- [ ] A test exists that fails if this change is reverted
- [ ] Full suite green — no regressions
- [ ] Every error path logs something useful
- [ ] **Every destructive path is guarded** — dry-run default, confirmation showing counts,
      refusal on an empty filter, logging with the recovery path
- [ ] **A test proves each guard blocks** — bad input in, nothing destroyed
- [ ] **Every destructive step taken during this work had a verified rollback**, and it's
      written down in `TODO.md` rather than remembered
- [ ] `TODO.md` reflects reality
- [ ] `.agent/memory/` updated if anything non-obvious was decided or discovered
- [ ] Diff self-reviewed — no debug code, no commented-out blocks, no secrets

"It works on my machine", "I'll add tests later", and "the delete path is obviously fine"
are not entries on this list.

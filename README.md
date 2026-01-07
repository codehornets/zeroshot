# zeroshot CLI

[![CI](https://github.com/covibes/zeroshot/actions/workflows/ci.yml/badge.svg)](https://github.com/covibes/zeroshot/actions/workflows/ci.yml)
[![npm version](https://img.shields.io/npm/v/@covibes/zeroshot.svg)](https://www.npmjs.com/package/@covibes/zeroshot)
[![License: MIT](https://img.shields.io/badge/License-MIT-yellow.svg)](LICENSE)
[![Node 18+](https://img.shields.io/badge/node-18%2B-brightgreen.svg)](https://nodejs.org/)
[![Platform: Linux | macOS](https://img.shields.io/badge/platform-Linux%20%7C%20macOS-blue.svg)]()

> **2024** was the year of LLMs. **2025** was the year of agents. **2026** is the year of agent clusters.

**Autonomous engineering teams for Claude Code.**

## Install

**Platforms**: Linux, macOS

```bash
npm install -g @covibes/zeroshot
```

**Requires**: Node 18+, [Claude Code CLI](https://claude.com/product/claude-code), [GitHub CLI](https://cli.github.com/)

```bash
npm i -g @anthropic-ai/claude-code && claude auth login
gh auth login
```

---

You know the problem. Your AI agent:

- Says "tests pass" (never ran them)
- Says "done!" (nothing works)
- Implements 60% of what you asked
- Ignores your coding guidelines
- Introduces antipatterns like a junior dev
- Gets sloppy on long tasks

**AI is extremely capable. But not when one agent does everything in one session.**

Context degrades. Attention drifts. Shortcuts get taken.

Zeroshot fixes this with **multiple isolated agents** that check each other's work. The validator didn't write the code, so it can't lie about tests. Fail? Fix and retry until it works.

```bash
zeroshot 123
```

Point at a GitHub issue, walk away, come back to working code.

### Demo

```bash
zeroshot "Add optimistic locking with automatic retry: when updating a user,
detect if another request modified it first using version numbers,
automatically retry with exponential backoff up to 3 times,
merge non-conflicting field changes, surface true conflicts to the caller
with details of what conflicted. Handle the ABA problem where version goes A->B->A."
```

<p align="center">
  <img src="./docs/assets/zeroshot-demo.gif" alt="Demo" width="700">
  <br>
  <em>Sped up 100x — 90 minutes, 5 iterations until validators approved</em>
</p>

**The full fix cycle.** Initial implementation passed basic tests but validators caught edge cases: race conditions in concurrent updates, ABA problem not fully handled, retry backoff timing issues. Each rejection triggered fixes until all 48 tests passed with 91%+ coverage.

A single agent would say "done!" after the first implementation. Here, the adversarial tester actually *runs* concurrent requests, times the retry backoff, and verifies conflict detection works under load.

**This is what production-grade looks like.** Not "tests pass" — validators reject until it actually works. 5 iterations, each one fixing real bugs the previous attempt missed.

---

## When to Use Zeroshot

**Zeroshot requires well-defined tasks with clear acceptance criteria.**

| Scenario | ? | Why |
|----------|:-:|-----|
| Add rate limiting (sliding window, per-IP, 429) | ✅ | Clear requirements |
| Refactor auth to JWT | ✅ | Defined end state |
| Fix login bug | ✅ | Success is measurable |
| Fix 2410 lint violations | ✅ | Clear completion criteria |
| Make the app faster | ❌ | Needs exploration first |
| Improve the codebase | ❌ | No acceptance criteria |
| Figure out flaky tests | ❌ | Exploratory |

**Known unknowns** (implementation details unclear) → Zeroshot handles this. The planner figures it out.

**Unknown unknowns** (don't know what you'll discover) → Use single-agent Claude Code for exploration first, then come back with a well-defined task.

**Long-running batch tasks** → Zeroshot excels here. Run overnight with `-d` (daemon mode):
- "Fix all 2410 semantic linting violations"
- "Add TypeScript types to all 47 untyped files"
- "Migrate all API calls from v1 to v2"

Crash recovery (`zeroshot resume`) means multi-hour tasks survive interruptions.

**Rule of thumb:** If you can't describe what "done" looks like, zeroshot's validators can't verify it.

---

## Commands

```bash
zeroshot run 123               # Run on GitHub issue
zeroshot run "Add dark mode"   # Run from description

# Automation levels (cascading: --ship → --pr → --worktree)
zeroshot run 123 --docker      # Docker isolation (full container)
zeroshot run 123 --worktree    # Git worktree isolation (lightweight)
zeroshot run 123 --pr          # Worktree + PR (human reviews)
zeroshot run 123 --ship        # Worktree + PR + auto-merge (full automation)

# Background mode
zeroshot run 123 -d            # Detached/daemon
zeroshot run 123 --ship -d     # Full automation, background

# Control
zeroshot list                  # See all running (--json for scripting)
zeroshot status <id>           # Cluster status (--json for scripting)
zeroshot logs <id> -f          # Follow output
zeroshot resume <id>           # Continue after crash
zeroshot kill <id>             # Stop
zeroshot watch                 # TUI dashboard

# Agent library
zeroshot agents list           # View available agents
zeroshot agents show <name>    # Agent details

# Maintenance
zeroshot clean                 # Remove old records
zeroshot purge                 # NUCLEAR: kill all + delete all
```

---

<details>
<summary><strong>FAQ</strong></summary>

**Q: Why Claude-only (for now)?**

Claude Code is the most capable agentic coding tool available. We wrap it directly - same tools, same reliability, no custom implementations to break.

Multi-model support (Codex CLI, Gemini CLI) is planned - see [#19](https://github.com/covibes/zeroshot/issues/19).

**Q: Why do single-agent coding sessions get sloppy?**

Three failure modes compound when one agent does everything in one session:

- **Context Dilution**: Your initial guidelines compete with thousands of tokens of code, errors, and edits. Instructions from 50 messages ago get buried.
- **Success Bias**: LLMs optimize for "Task Complete" - even if that means skipping steps to get there.
- **Error Snowball**: When fixing mistakes repeatedly, the context fills with broken code. The model starts copying its own bad patterns.

Zeroshot fixes this with **isolated agents** where validators check work they didn't write - no self-grading, no shortcuts.

**Q: Can I customize the team?**

Yes, see CLAUDE.md. But most people never need to.

**Q: Why is it called "zeroshot"?**

In machine learning, "zero-shot" means solving tasks the model has never seen before - using only the task description, no prior examples needed.

Same idea here: give zeroshot a well-defined task, get back a result. No examples. No iterative feedback. No hand-holding.

The multi-agent architecture handles planning, implementation, and validation internally. You provide a clear problem statement. Zeroshot handles the rest.

</details>

---

## How It Works

Zeroshot is a **multi-agent coordination framework** with smart defaults.

### Zero Config

```bash
zeroshot 123  # Analyzes task → picks team → done
```

The conductor classifies your task (complexity × type) and picks the right workflow:

```
                                ┌─────────────────┐
                                │      TASK       │
                                └────────┬────────┘
                                         │
                                         ▼
                ┌────────────────────────────────────────────┐
                │                 CONDUCTOR                  │
                │     Complexity × TaskType → Workflow       │
                └────────────────────────┬───────────────────┘
                                         │
           ┌─────────────────────────────┼─────────────────────────────┐
           │                             │                             │
           ▼                             ▼                             ▼
     ┌───────────┐                ┌───────────┐                ┌───────────┐
     │  TRIVIAL  │                │  SIMPLE   │                │ STANDARD+ │
     │  1 agent  │──────────▶     │  worker   │                │ planner   │
     │  (haiku)  │  COMPLETE      │ + 1 valid.│                │ + worker  │
     │ no valid. │                └─────┬─────┘                │ + 3-5 val.│
     └───────────┘                      │                      └─────┬─────┘
                                        ▼                            │
                                 ┌─────────────┐                     ▼
                             ┌──▶│   WORKER    │             ┌─────────────┐
                             │   └──────┬──────┘             │   PLANNER   │
                             │          │                    └──────┬──────┘
                             │          ▼                           │
                             │   ┌─────────────────────┐            ▼
                             │   │ ✓ validator         │     ┌─────────────┐
                             │   │   (generic check)   │ ┌──▶│   WORKER    │
                             │   └──────────┬──────────┘ │   └──────┬──────┘
                             │       REJECT │ ALL OK     │          │
                             └──────────────┘     │      │          ▼
                                                  │      │   ┌──────────────────────┐
                                                  │      │   │ ✓ requirements       │
                                                  │      │   │ ✓ code (STANDARD+)   │
                                                  │      │   │ ✓ security (CRIT)    │
                                                  │      │   │ ✓ tester (CRIT)      │
                                                  │      │   │ ✓ adversarial        │
                                                  │      │   │   (real execution)   │
                                                  │      │   └──────────┬───────────┘
                                                  │      │       REJECT │ ALL OK
                                                  │      └──────────────┘     │
                                                  ▼                           ▼
     ┌─────────────────────────────────────────────────────────────────────────────┐
     │                                COMPLETE                                     │
     └─────────────────────────────────────────────────────────────────────────────┘
```

| Task                   | Complexity | Agents | Validators                                        |
| ---------------------- | ---------- | ------ | ------------------------------------------------- |
| Fix typo in README     | TRIVIAL    | 1      | None                                              |
| Add dark mode toggle   | SIMPLE     | 2      | generic validator                                 |
| Refactor auth system   | STANDARD   | 4      | requirements, code                                |
| Implement payment flow | CRITICAL   | 7      | requirements, code, security, tester, adversarial |

### Model Selection by Complexity

| Complexity | Planner | Worker | Validators |
| ---------- | ------- | ------ | ---------- |
| TRIVIAL    | -       | haiku  | 0          |
| SIMPLE     | -       | sonnet | 1 (sonnet) |
| STANDARD   | sonnet  | sonnet | 2 (sonnet) |
| CRITICAL   | opus    | sonnet | 5 (sonnet) |

Set model ceiling: `zeroshot settings set maxModel sonnet` (prevents opus)

---

<details>
<summary><strong>Custom Workflows (Framework Mode)</strong></summary>

Zeroshot is **message-driven** - define any agent topology:

- **Expert panels**: Parallel specialists → aggregator → decision
- **Staged gates**: Sequential validators, each with veto power
- **Hierarchical**: Supervisor dynamically spawns workers
- **Dynamic**: Conductor adds agents mid-execution

**Coordination primitives:**

- Message bus (pub/sub topics)
- Triggers (wake agents on conditions)
- Ledger (SQLite, crash recovery)
- Dynamic spawning (CLUSTER_OPERATIONS)

#### Creating Custom Clusters with Claude Code

**The easiest way to create a custom cluster: just ask Claude Code.**

```bash
# In your zeroshot repo
claude
```

**Example prompt:**
```
Create a zeroshot cluster config for security-critical features:

1. Implementation agent (sonnet) implements the feature
2. FOUR parallel validators:
   - Security validator: OWASP checks, SQL injection, XSS, CSRF
   - Performance validator: No N+1 queries, proper indexing
   - Privacy validator: GDPR compliance, data minimization
   - Code reviewer: General code quality

3. ALL validators must approve before merge
4. If ANY validator rejects, implementation agent fixes and resubmits
5. Use opus for security validator (highest stakes)

Look at cluster-templates/base-templates/full-workflow.json
and create a similar cluster. Save to cluster-templates/security-review.json
```

Claude Code will read existing templates, create valid JSON config, and iterate until it works.

**Built-in validation catches failures before running:**
- Never start (no bootstrap trigger)
- Never complete (no path to completion)
- Loop infinitely (circular dependencies)
- Deadlock (impossible consensus)
- Type mismatches (boolean → string in JSON)

See [CLAUDE.md](./CLAUDE.md) for cluster config schema and examples.

</details>

---

## Crash Recovery

Everything saves to SQLite. If your 2-hour run crashes at 1:59:

```bash
zeroshot resume cluster-bold-panther
# Continues from exact point
```

---

## Isolation Modes

### Git Worktree (Default for --pr/--ship)

```bash
zeroshot 123 --worktree
```

Lightweight isolation using git worktree. Creates a separate working directory with its own branch. Fast (<1s setup), no Docker required. Auto-enabled with `--pr` and `--ship`.

### Docker Container

```bash
zeroshot 123 --docker
```

Full isolation in a fresh container. Your workspace stays untouched. Good for risky experiments or parallel agents.

### When to Use Which

| Scenario | Recommended |
| -------- | ----------- |
| Quick trusted task | No isolation (default) |
| PR workflow, code review | `--worktree` or `--pr` |
| Risky experiment, might break things | `--docker` |
| Running multiple tasks in parallel | `--docker` |
| Full automation, no review needed | `--ship` |

<details>
<summary><strong>Docker Credential Mounts</strong></summary>

When using `--docker`, zeroshot mounts credential directories so Claude can access tools like AWS, Azure, kubectl.

**Default mounts**: `gh`, `git`, `ssh` (GitHub CLI, git config, SSH keys)

**Available presets**: `gh`, `git`, `ssh`, `aws`, `azure`, `kube`, `terraform`, `gcloud`

```bash
# Configure via settings (persistent)
zeroshot settings set dockerMounts '["gh", "git", "ssh", "aws", "azure"]'

# View current config
zeroshot settings get dockerMounts

# Per-run override
zeroshot run 123 --docker --mount ~/.aws:/root/.aws:ro

# Disable all mounts
zeroshot run 123 --docker --no-mounts

# CI: env var override
ZEROSHOT_DOCKER_MOUNTS='["aws","azure"]' zeroshot run 123 --docker
```

**Custom mounts** (mix presets with explicit paths):
```bash
zeroshot settings set dockerMounts '[
  "gh",
  "git",
  {"host": "~/.myconfig", "container": "$HOME/.myconfig", "readonly": true}
]'
```

**Container home**: Presets use `$HOME` placeholder. Default: `/root`. Override with:
```bash
zeroshot settings set dockerContainerHome '/home/node'
# Or per-run:
zeroshot run 123 --docker --container-home /home/node
```

**Env var passthrough**: Presets auto-pass related env vars (e.g., `aws` → `AWS_REGION`, `AWS_PROFILE`). Add custom:
```bash
zeroshot settings set dockerEnvPassthrough '["MY_API_KEY", "TF_VAR_*"]'
```

</details>

---

## More

- **Debug**: `sqlite3 ~/.zeroshot/cluster-abc.db "SELECT * FROM messages;"`
- **Export**: `zeroshot export <id> --format markdown`
- **Architecture**: See [CLAUDE.md](./CLAUDE.md)

---

<details>
<summary><strong>Troubleshooting</strong></summary>

| Issue                         | Fix                                                                  |
| ----------------------------- | -------------------------------------------------------------------- |
| `claude: command not found`   | `npm i -g @anthropic-ai/claude-code && claude auth login`            |
| `gh: command not found`       | [Install GitHub CLI](https://cli.github.com/)                        |
| `--docker` fails              | Docker must be running: `docker ps` to verify                        |
| Cluster stuck                 | `zeroshot resume <id>` to continue with guidance                     |
| Agent keeps failing           | Check `zeroshot logs <id>` for actual error                          |
| `zeroshot: command not found` | `npm install -g @covibes/zeroshot`                                   |

</details>

---

## Contributing

See [CONTRIBUTING.md](CONTRIBUTING.md) for development setup and guidelines.

Please read our [Code of Conduct](CODE_OF_CONDUCT.md) before participating.

For security issues, see [SECURITY.md](SECURITY.md).

---

MIT — [Covibes](https://github.com/covibes)

Built on [Claude Code](https://claude.com/product/claude-code) by Anthropic.



# Colony

<img src="assets/colony-logo.jpg" alt="Colony" width="300">

**Your AI swarm for serious software engineering.**

Colony turns Claude Code into a parallel task execution engine with independent verification. Give it a complex task, and it spawns a colony of specialized workers—each with fresh context, each verified by an independent inspector.

> **Like Ralph, but built for real work.** Where Ralph iterates sequentially and checks its own homework, Colony intelligently parallelizes work with independent QA. Human-in-the-loop or fully autonomous. Git-aware. Production-ready.

---

## See It In Action

<img src="assets/colony-deploy-animated.gif" alt="Colony deploying tasks" width="700">

**Smart Mobilization** — Colony analyzes your brief, identifies parallelization opportunities, and prepares tasks for execution:

<img src="assets/colony-mobilizing.png" alt="Colony mobilization phase" width="700">

**Dependency-Aware Deployment** — Tasks deploy in parallel where safe, serialize where necessary:

<img src="assets/colony-mobilized.png" alt="Colony execution plan" width="700">

**Simple Commands** — Everything accessible via `/colony-*` commands:

<img src="assets/colony-commands.png" alt="Colony commands" width="700">

---

## Why Colony Wins

### v1.2.0: Same Speed, Dramatically Better Quality

Measured on the same task ([Kitty Keyboard Protocol](https://github.com/vadimdemedes/ink/issues/824) implementation), same codebase, same starting point:

| Metric | Ralph | Colony v1.2 | Winner |
|--------|-------|-------------|--------|
| **Runtime** | 12m 39s | ~12 min | Tie |
| **Lint Errors** | 419 | 0 | **Colony** |
| **Lines of Code** | 537 | 165 | **Colony** (3.3x leaner) |
| **PR Ready?** | No (needs cleanup) | Yes | **Colony** |

**The real comparison:** Ralph's 12-minute run produces code needing ~1 hour of cleanup. Colony's 12-minute run produces code ready to merge.

> 📊 **Reproducible benchmarks**: See [`benchmarks/`](./benchmarks/) for the test brief, methodology, and step-by-step reproduction instructions.

### Feature Comparison

| Capability | Traditional AI | Ralph | Colony |
|------------|----------------|-------|--------|
| **Context** | Drifts after 10+ exchanges | Full reset each iteration | Fresh context per task |
| **Verification** | "Done!" (it wasn't) | Checks its own homework | Independent inspector |
| **Code Quality** | Variable | 419 lint errors | **0 lint errors** |
| **Speed** | One thing at a time | Single-threaded | Intelligent parallelization |
| **Oversight** | All or nothing | Autonomous only | Human-in-loop or autonomous |
| **Git workflow** | Manual | Manual | Automatic branch + commits |
| **Recovery** | Start over | Coarse progress file | Task-level resume |
| **Audit trail** | Nothing | Progress notes | Full execution logs |

---

## Colony + Claude Plan Mode

Colony is designed to **complement** Claude's native plan mode, not compete with it.

### The Workflow

```
┌─────────────────────────────────────────────────────────────────┐
│  1. PLAN (Claude Native)                                        │
│     claude --permission-mode plan                               │
│     → Strategic thinking, requirements, approach                │
│     → Output: ~/.claude/plans/your-plan.md                      │
└─────────────────────────────────────────────────────────────────┘
                              ↓
┌─────────────────────────────────────────────────────────────────┐
│  2. MOBILIZE (Colony)                                           │
│     /colony-mobilize                                            │
│     → Task decomposition, parallelization, dependencies         │
│     → Output: .working/colony/{project}/tasks/                  │
└─────────────────────────────────────────────────────────────────┘
                              ↓
┌─────────────────────────────────────────────────────────────────┐
│  3. DEPLOY (Colony)                                             │
│     /colony-deploy                                              │
│     → Parallel execution with independent verification          │
│     → Output: Working code, logs, report                        │
└─────────────────────────────────────────────────────────────────┘
```

### Why Not Just Use Claude's Execution?

When you exit plan mode, Claude implements sequentially. Colony does it better:

| Aspect | Native Execution | Colony Execution |
|--------|------------------|------------------|
| **Parallelization** | Sequential | Intelligent parallel |
| **Verification** | Self-check | Independent inspector |
| **Context** | Accumulates (drifts) | Fresh per task |
| **Recovery** | Start over | Resume from exact task |
| **Quality** | Variable | 0 lint errors (benchmarked) |

**Use Claude plan mode for thinking. Use Colony for doing.**

---

## Key Features

### Intelligent Parallelization
Colony doesn't just run things in parallel—it *thinks* about what can safely parallelize:

- **Dependency analysis** — Understands task dependencies and serializes when needed
- **Resource awareness** — Knows when tasks touch the same files and avoids conflicts
- **Asks when uncertain** — Won't guess on parallelization safety; asks you instead
- **Dynamic adjustment** — Change concurrency mid-run: `"set concurrency to 3"`

### Two Execution Modes

**Human-in-the-Loop (default)**
- Checkpoints between phases for review
- Approve parallelization decisions
- Intervene on failures before retrying

**Fully Autonomous**
- Run overnight without interruption
- Safety limits prevent runaway failures (max retries, failure thresholds)
- Complete report waiting for you in the morning

```bash
/colony-deploy              # Interactive mode
/colony-deploy autonomous   # Autonomous mode
```

### Git-Aware Workflow
Colony understands your git workflow and integrates seamlessly:

- **Branch strategy** — Creates feature branches or works on current branch
- **Smart commits** — After each task, phase, or at project end (you choose)
- **Conventional commits** — Proper commit messages with Co-Authored-By attribution
- **Conflict prevention** — Won't parallelize tasks that touch the same files

### Independent Verification
Every task completion is verified by a separate inspector agent:

- **Fresh context** — Inspector has no knowledge of worker's struggles or workarounds
- **Acceptance criteria** — Checks every criterion, not just "does it compile"
- **Visual verification** — `VISUAL:` criteria trigger screenshot capture and validation
- **No self-deception** — Worker can't mark itself complete; inspector decides

### Full Recovery
Interrupted? Pick up exactly where you left off:

- **Structured state** — All progress saved to `state.json`
- **Task-level granularity** — Resume from the exact task that was interrupted
- **Execution logs** — Every task has detailed logs of what happened
- **Artifact validation** — Screenshots and logs must exist before marking complete

---

## The Problem With AI Coding Today

When tackling large, multi-step coding tasks, AI assistants struggle with:

- **Context drift** — forgetting requirements after many interactions
- **Verification gaps** — claiming completion without proper testing
- **Sequential bottlenecks** — not leveraging concurrent execution
- **Lost progress** — no recovery when interrupted
- **Invisible work** — no summary of what was done

**Colony solves all of this.** Specialized worker agents execute tasks in parallel. Independent inspector agents verify every completion. Everything logged, everything recoverable.

## Installation

### Option 1: Install from Marketplace (Recommended)

```bash
# In Claude Code, add the Colony marketplace and install
/plugin marketplace add mattheworiordan/colony
/plugin install colony
```

### Option 2: Manual Installation

```bash
# Clone the repository
git clone https://github.com/mattheworiordan/colony.git ~/.claude/plugins/colony
```

After cloning, the plugin is automatically available. Restart Claude Code if it's already running.

### Option 3: Project-Local Installation

To use Colony in a specific project only:

```bash
# Clone into your project
git clone https://github.com/mattheworiordan/colony.git .claude-plugins/colony

# Run Claude Code with the plugin directory
claude --plugin-dir .claude-plugins/colony
```

### Verify Installation

After installation, run `/help` in Claude Code — you should see the `/colony-*` commands listed.

**CLI Tool**

Colony includes a CLI tool (`bin/colony`) for state management. The plugin commands reference it via `${CLAUDE_PLUGIN_ROOT}/bin/colony`, so no PATH setup is needed - it works automatically.

For manual CLI usage outside of Claude Code, you can optionally add it to your PATH or create a symlink.

**Community Registry**: Colony is also indexed at [claude-plugins.dev](https://claude-plugins.dev/), which automatically discovers Claude Code plugins on GitHub.

### Working Directory Convention

Colony stores all project state in a `.working/colony/` directory within your project. This includes task files, execution logs, screenshots, and reports.

**Recommendation**: Add `.working/` to your global gitignore to avoid committing Colony's working files:

```bash
# Add to your global gitignore
echo ".working/" >> ~/.gitignore_global
git config --global core.excludesfile ~/.gitignore_global
```

Alternatively, add `.working/` to your project's `.gitignore` if you prefer per-project configuration.

## Quick Start

### Recommended: Start with Claude Plan Mode

For complex features, let Claude help you think through requirements first:

```bash
# 1. Use Claude's plan mode to define requirements
claude --permission-mode plan
> I need to add OAuth2 authentication. Interview me about requirements.

# 2. Claude creates a plan in ~/.claude/plans/
# 3. Mobilize Colony with that plan
/colony-mobilize

# 4. Colony auto-detects the recent plan, or specify:
/colony-mobilize ~/.claude/plans/gleaming-sniffing-bird.md

# 5. Deploy
/colony-deploy
```

### Option 1: Create a Brief File

```bash
# 1. Create a brief describing what you want to accomplish
cat > .working/MY_FEATURE_BRIEF.md << 'EOF'
# Add User Authentication

## Goal
Add login/logout functionality with session management.

## Requirements
- [ ] Login form with email/password
- [ ] Session storage in localStorage
- [ ] Protected routes redirect to login
- [ ] Logout clears session
EOF

# 2. Plan the tasks
/colony-mobilize .working/MY_FEATURE_BRIEF.md

# 3. Review the decomposition, then run
/colony-deploy
```

### Option 2: Point to Any File

You can use any markdown file as a brief — it doesn't need to be in `.working/`:

```bash
# Use a file from docs/
/colony-mobilize docs/FEATURE_SPEC.md

# Use a file from anywhere
/colony-mobilize ~/Desktop/my-project-plan.md
```

### Option 3: Describe Inline

If you don't have a brief file, just run `/colony-mobilize` and describe what you want:

```bash
/colony-mobilize
# Colony will ask: "I didn't find any brief files. You can:
#   1. Tell me the path to your brief
#   2. Paste the tasks directly here
#   3. Describe what you want to accomplish"
```

### Option 4: Quick Tasks

For simple, well-defined tasks, skip the planning phase entirely:

```bash
/colony-quick "Add a loading spinner to the submit button"
```

## Brief Discovery

When you run `/colony-mobilize` without specifying a file, Colony searches for potential briefs in:

1. **`~/.claude/plans/*.md`** - Recent Claude plans (last 48 hours), ranked by relevance to current project
2. **`.working/*.md`** - The conventional location for working documents
3. **`docs/*.md`** - Documentation folder
4. **Root `.md` files** - Excluding README, CHANGELOG, LICENSE

If multiple candidates are found, Colony shows them ranked by relevance and asks which to use. If none are found, you can provide a path or describe your requirements directly.

## Commands

| Command | Description |
|---------|-------------|
| `/colony-mobilize [brief]` | Prepare tasks from a brief or Claude plan |
| `/colony-deploy [project]` | Deploy workers with verification |
| `/colony-deploy autonomous` | Deploy without human checkpoints |
| `/colony-status [project]` | Show detailed project status |
| `/colony-projects` | List all colony projects |
| `/colony-quick "prompt"` | Quick execution for simple tasks |

## How It Works

### 1. Mobilization Phase (`/colony-mobilize`)

- Finds a brief file or Claude plan (auto-detects recent plans)
- Analyzes the codebase for parallelization opportunities
- Decomposes work into executable tasks
- Identifies shared patterns to prevent duplication (DRY)
- Detects project standards (linter, CLAUDE.md, etc.)
- Sets up Git strategy (branch, commit frequency)

### 2. Deployment Phase (`/colony-deploy`)

- Spawns isolated **worker** agents for each task
- Runs tasks in parallel where safe
- Independent **inspector** agents verify each completion
- Automatic retry on failure (up to 3 attempts)
- Git commits at phase boundaries
- Comprehensive report generation

### 3. Key Features

**Context Isolation**: Each worker runs in a fresh context with only the information it needs. No context drift from accumulated conversation history.

**Independent Verification**: A separate inspector agent checks every "DONE" claim. Catches workarounds, missing criteria, and design intent violations.

**Smart Parallelization**: Analyzes dependencies and resource constraints. Asks when uncertain. Serializes browser tests, database migrations, etc.

**Artifact Validation**: Log files and screenshots must exist before marking complete. Never trusts agent claims without filesystem proof.

**Recovery**: All state persisted to JSON. Pick up exactly where you left off if interrupted.

**Autonomous Mode**: Run overnight without checkpoints. Safety limits prevent runaway failures.

## Project Structure

When you run `/colony-mobilize`, it creates:

```
.working/colony/{project-name}/
├── context.md              # Project rules, tech stack, parallelization
├── state.json              # Task status, Git config, execution log
├── tasks/
│   ├── T001.md            # Individual task files
│   ├── T002.md
│   └── ...
├── logs/
│   ├── T001_LOG.md        # Execution + verification logs
│   └── ...
├── screenshots/            # Visual verification evidence
├── resources/
│   └── original-brief.md  # Copy of source brief
└── REPORT.md              # Final execution report
```

## Colony vs Ralph

[Ralph](https://www.cursor.com/blog/ralf) popularized autonomous AI coding with a clever while-loop approach. Colony takes it further.

### The Key Insight

**Ralph's weakness**: It checks its own homework. The same model that claims "done" also decides if it's really done. That's like asking a student to grade their own test.

**Colony's answer**: Independent verification. A separate inspector agent—with fresh context and no ego investment—verifies every completion. It catches workarounds, missing criteria, and "works on my machine" claims.

### Head-to-Head (v1.2.0 Benchmarks)

Both approaches ran the same task: implement [Kitty Keyboard Protocol](https://github.com/vadimdemedes/ink/issues/824) for the [Ink](https://github.com/vadimdemedes/ink) React CLI framework.

| Metric | Colony | Ralph |
|--------|--------|-------|
| **Runtime** | ~12 min | 12m 39s |
| **Lint Errors** | **0** | 419 |
| **Lines of Code** | **165** | 537 |
| **Time to Merge** | **12 min** | ~72 min (with cleanup) |

> See [`benchmarks/v1.2-results.md`](./benchmarks/v1.2-results.md) for detailed methodology and quality scoring.

### Feature Comparison

| Capability | Colony | Ralph |
|------------|--------|------|
| **Parallelization** | Intelligent—analyzes dependencies, asks when uncertain | Single-threaded |
| **Execution modes** | Human-in-the-loop or fully autonomous | Single mode |
| **Verification** | Independent inspector agent | Self-check (same model) |
| **Code Quality** | Linter integrated, 0 errors | No lint check, 419 errors |
| **Context** | Fresh per-task | Full reset each iteration |
| **Git workflow** | Branch strategy, smart commits, conflict prevention | Manual |
| **Visual testing** | Built-in screenshot verification | Manual |
| **Recovery** | Precise task-level resume | Coarse progress file |
| **Audit trail** | Complete execution logs per task | Progress notes |

### When to Use Each

**Choose Colony when:**
- You need production-ready code (0 lint errors)
- Work can be parallelized (most real projects)
- You need proof that tasks are actually complete
- Multiple people need to understand what happened
- You're building code that goes straight to PR

**Choose Ralph when:**
- Tasks are strictly sequential
- You want zero setup (just a prompt pattern)
- You're exploring/prototyping (quality doesn't matter yet)
- You have time for manual cleanup afterward

### The Bottom Line

Ralph proved autonomous AI coding works. Colony makes it production-ready.

**Speed**: Same execution time (~12 min).
**Quality**: 0 lint errors vs 419. 3.3x less code for same feature.
**Trust**: Independent verification catches what self-assessment misses.
**Time to merge**: Colony code is PR-ready. Ralph code needs cleanup.

> 🧪 **Try it yourself**: The [`benchmarks/`](./benchmarks/) folder contains everything you need to reproduce this comparison.

## Configuration

Colony can be configured via `~/.colony/config.json`. This file is created automatically on first run with sensible defaults.

### Config File

```json
{
  "working_dir": ".working",
  "models": {
    "orchestrator": "default",
    "worker": "default",
    "inspector": "default"
  }
}
```

Use `"default"` to follow Colony's recommended settings (may change in future versions).
Use a specific model name to lock in your preference.

### Model Roles

| Role | What it does | Default | Recommendation |
|------|--------------|---------|----------------|
| `orchestrator` | Coordinates tasks, manages state, spawns workers/inspectors | `sonnet` | `sonnet` - must reliably follow complex prompts |
| `worker` | Implements code, runs tests, creates files | `inherit` | `inherit` - needs full reasoning power |
| `inspector` | Verifies task completion, checks criteria | `haiku` | `haiku` - verification is simpler |

> **Note:** Haiku was tried for orchestrator in v1.2 but proved too weak to reliably spawn inspectors. Sonnet provides the right balance of speed and capability for orchestration.

### Model Options

- **`inherit`** - Uses your Claude Code session's model (Opus, Sonnet, etc.)
- **`haiku`** - Fast and cheap, good for mechanical tasks
- **`sonnet`** - Balanced capability and speed
- **`opus`** - Maximum capability, slower

### How It Works

**Default behavior** (`orchestrator: haiku`, `worker: inherit`):
- A Haiku sub-agent coordinates task execution (cheap)
- Workers use your session model (read from Claude Code settings)
- `worker: inherit` resolves to your `/model` setting (e.g., Opus)

**How inheritance works:** Before delegating to Haiku, Colony reads your session model from `~/.claude/settings.json` (set via `/model` command). When `worker: inherit`, this resolved model (e.g., "opus") is passed explicitly to the Haiku orchestrator, which then spawns workers with that model.

| orchestrator | worker | Behavior |
|--------------|--------|----------|
| `inherit` | any | Session runs orchestration directly |
| `haiku` | `inherit` | Haiku orchestrates, workers use session model (e.g., Opus) |
| `haiku` | `sonnet` | Haiku orchestrates, workers use Sonnet |

### CLI Tool (Internal)

Colony includes a CLI (`bin/colony`) for internal state management. This reduces token usage by replacing JSON file reads/writes with simple shell commands.

**For debugging**, you can also use it manually:
```bash
colony state list            # List projects
colony state summary my-proj # View status
```

### Concurrency

```
# During execution
"set concurrency to 3"   # Run 3 workers in parallel
"set concurrency to 10"  # Run 10 workers in parallel
"serialize"              # Set concurrency to 1
```

Default is 5. Set to any value based on your machine resources and task complexity.

### Git Strategy

Configured during `/colony-mobilize`:
- **Branch**: Feature branch or current branch
- **Commits**: After each task, phase, or at end
- **Style**: Conventional commits with Co-Authored-By

### Autonomous Mode

```
/colony-deploy autonomous
```

Safety limits:
- Max 3 retries per task
- Stops if >50% of tasks fail
- Max iterations = total_tasks × 3

## Task File Format

Each task file (`.working/colony/{project}/tasks/T{NNN}.md`) contains:

```markdown
# Task T001: Setup Authentication

## Status
pending

## Context & Why
{Why this task exists, how it fits the broader goal}

## Design Intent
{Philosophy, user preferences, what to avoid}

## Description
{What needs to be done}

## Files
- src/auth/login.js
- src/auth/session.js

## Acceptance Criteria
- [ ] Login form validates email format
- [ ] VISUAL: Form shows error state on invalid input
- [ ] Session persists across page reload

## Completion Promise
When done, output: TASK_COMPLETE: T001

## Verification Command
npm test -- --testPathPattern=auth

## Dependencies
None

## Parallel Group
setup
```

## Troubleshooting

### "No projects found"

Run `/colony-mobilize` first to create a project from a brief.

### Task stuck in "running"

Tasks running >30 minutes reset to "pending" on next `/colony-deploy`.

### Verification keeps failing

Read the inspector's feedback in `.working/colony/{project}/logs/{task}_LOG.md`. It includes specific suggestions.

### Browser verification not working

Ensure you have browser automation tools available (Playwright, Puppeteer). Colony will use whatever browser automation is available in your environment.

## Contributing

Contributions welcome! Please:
1. Fork the repository
2. Create a feature branch
3. Add tests for new functionality
4. Submit a pull request

## License

MIT License - See [LICENSE](LICENSE) for details.

---

**Built by [Matthew O'Riordan](https://github.com/mattheworiordan)**, CEO at [Ably](https://ably.com)

[Ably](https://ably.com) powers realtime experiences with trillions of messages for billions of devices each month. 
Colony is how we ship code fast without breaking things.

Building AI agents? Check out [Ably AI Transport](https://ably.com/solutions/ai-agents) - drop-in infrastructure layer for a resilient, AI UX. Ably AI Transport brings realtime continuity and control to your agents. Stateful, steerable, multi-device experiences.

[Star on GitHub](https://github.com/mattheworiordan/colony) • [Report Issues](https://github.com/mattheworiordan/colony/issues) • [Follow @mattheworiordan](https://x.com/mattheworiordan)

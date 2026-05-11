<p align="center">
  <h1 align="center">XRStack</h1>
  <p align="center">
    A pre-built <a href="https://docs.anthropic.com/en/docs/claude-code">Claude Code</a> harness for Unity XR development.
    <br />
    14 specialist agents, 14 slash commands, 21 auto-loaded rules, and 10 lifecycle hooks — all tuned for XR.
  </p>
</p>

<p align="center">
  <a href="LICENSE"><img src="https://img.shields.io/badge/license-MIT-blue" alt="MIT License"></a>
  <a href=".claude/agents"><img src="https://img.shields.io/badge/agents-14-blueviolet" alt="14 Agents"></a>
  <a href=".claude/skills"><img src="https://img.shields.io/badge/skills-14-green" alt="14 Skills"></a>
  <a href=".claude/hooks"><img src="https://img.shields.io/badge/hooks-10-darkcyan" alt="10 Hooks"></a>
  <a href=".claude/rules"><img src="https://img.shields.io/badge/rules-21-red" alt="21 Rules"></a>
  <a href=".mcp.json"><img src="https://img.shields.io/badge/mcps-5-steelblue" alt="5 MCPs"></a>
  <a href="https://docs.anthropic.com/en/docs/claude-code"><img src="https://img.shields.io/badge/built_for-Claude_Code-goldenrod?logo=anthropic" alt="Built for Claude Code"></a>
  <a><img src="https://img.shields.io/badge/status-experimental-chocolate" alt="Experimental"></a>
  <a><img src="https://img.shields.io/badge/version-v0.0.1-darkkhaki" alt="v0.0.1"></a>
</p>

## Why This Exists

### The Problem

Claude Code is powerful out of the box, but a raw session knows nothing about your Unity project's architecture, XR constraints, naming conventions, or performance budgets. Every conversation starts from zero. Without structure, AI agents:

- Invent their own naming conventions (`.NET` style one session, Unity style the next)
- Ignore XR frame budgets and allocate freely in hot paths
- Duplicate utilities that already exist because they can't see the full codebase
- Lose context across sessions — each conversation re-litigates the same decisions
- Generate "slop" at machine speed — inconsistent patterns, dead code, over-engineered abstractions

### Three Layers of AI Engineering

Most teams stop at layer 1 and wonder why results are inconsistent:

1. **Prompt Engineering** (how to say it) — single-call intent and format. Necessary but insufficient.
2. **Context Engineering** (what to know) — feeding the right information at the right time. Better, but still passive.
3. **Harness Engineering** (how to stay correct) — the feedback loop that catches drift and pulls the agent back. This is where production reliability lives.

XRStack operates at **layer 3**.

### What Is Harness Engineering?

Harness engineering is cybernetics applied to AI-assisted development. The pattern is ancient — James Watt's centrifugal governor, thermostat controllers, Kubernetes reconciliation loops — all share the same structure:

```
Goal State + Sensor + Actuator + Feedback Loop = Control System
```

- **Without a goal**, the agent generates blindly (no `CLAUDE.md` / rules = no conventions)
- **Without sensors**, it doesn't know it's wrong (no hooks = no validation)
- **Without actuators**, it can't fix what it finds (no agents = no specialist correction)
- **Without feedback**, it repeats the same mistakes forever (no rules = no learning)

A documented convention will be violated. A lint rule won't. XRStack pushes constraints as high up the enforcement hierarchy as possible:

| Layer | Mechanism | Reliability |
|-------|-----------|-------------|
| **Blocked** | `settings.json` deny-list | Impossible to violate |
| **Caught pre-commit** | Hooks (`validate-commit.sh`) | Caught before damage |
| **Auto-loaded** | Rules (path-matched `.md` files) | In context when relevant |
| **Project-wide** | `CLAUDE.md` | Read every conversation |
| **Verbal** | Chat corrections | Least reliable, but saved to memory |

The engineer's role shifts from writing code to **designing the control system** that lets agents write code correctly. You steer; the agent executes.

### What XRStack Provides

- **Encodes XR knowledge** — frame budgets, draw call limits, GC-free hot paths, stereo rendering constraints
- **Enforces conventions** — Unity-style naming (`m_Field`, `k_Constant`, `s_Static`), Allman braces, commit message format
- **Provides specialist agents** — ask the `xr-specialist` about hand tracking or the `performance-analyst` about frame time, instead of getting generic answers
- **Automates guardrails** — hooks validate commits, block force-pushes, and audit agent invocations
- **Scales with your team** — everyone shares the same rules, agents, and commands via git
- **Self-corrects** — the harness catches drift mechanically, not through human vigilance
- **Learns over time** — continuous learning extracts patterns from sessions into reusable instincts that evolve into skills

## Table of Contents

- [What's Included](#whats-included)
- [Quick Start](#quick-start)
- [Project Structure](#project-structure)
- [How It Works](#how-it-works)
- [Working Agents (18)](#working-agents-18)
- [Slash Commands (24)](#slash-commands-24)
- [Rules (25)](#rules-25)
- [Hooks (8 + 2 optional)](#hooks-8--2-optional)
- [MCP Servers (5)](#mcp-servers-5)
- [Design Philosophy](#design-philosophy)
- [Customization](#customization)
- [License](#license)

## What's Included

| Component | Count | Purpose |
|-----------|-------|---------|
| **Agents** | 18 | Specialist sub-agents with domain expertise |
| **Skills** | 24 | One-command workflows (`/plan`, `/code-review`, `/xr-test`, ...) |
| **Rules** | 21 | Auto-loaded coding standards and constraints |
| **Hooks** | 10 | Lifecycle hooks for commits, sessions, asset validation, and skill hints |
| **Templates** | 14 | Document templates for design, production, and release artifacts |
| **CLAUDE.md** | 1 | Project-wide instructions loaded every conversation |
| **MCP Servers** | 5 | GitHub, Context7 (docs), Exa (search), Figma, Unity MCP |
| **settings.json** | 1 | Permissions, hook wiring, safety deny-list |

## Documentations

- [Agent Roster](.claude/docs/agent-roster.md) — 14 agents, tier hierarchy, delegation map
- [Skills Reference](.claude/docs/skills-reference.md) — 14 slash commands by category
- [Rules Reference](.claude/docs/rules-reference.md) — 21 auto-loaded rules by path
- [Hooks Reference](.claude/docs/hooks-reference.md) — 10 lifecycle hooks
- [Quick Start](.claude/docs/quick-start.md) — Onboarding paths for new users
- [Agent Coordination Map](.claude/docs/agent-coordination-map.md) — Workflow patterns and delegation rules
- [Review Workflow](.claude/docs/review-workflow.md) — Code review routing
- [Technical Preferences](.claude/docs/technical-preferences.md) — Engine, framework, and tooling details

## Quick Start

### Prerequisites

- Bash (Git Bash on Windows works)
- Unity 6.x project (tested with 6000.0.27f1)
- [Git](https://git-scm.com/)
- [Claude Code](https://docs.anthropic.com/en/docs/claude-code) CLI installed (`irm https://claude.ai/install.ps1 | iex`)
- **Recommended**: 
  - [jq](https://jqlang.github.io/jq/) (for hook validation)
  - Python 3 (for JSON validation, continuous learning observation hooks)
  - [Node.js](https://nodejs.org/) (for session management scripts)

### Option A — Claude Code Plugin (recommended)

Install XRStack as a Claude Code plugin with automatic updates:

```bash
# 1. Add the XRStack marketplace
/plugin marketplace add LewisZhao97/XRStack

# 2. Install the plugin
/plugin install xrstack@xrstack

# 3. Skills become available with namespace prefix
/xrstack:plan
/xrstack:code-review
/xrstack:xr-test
```

> **Note:** Claude Code plugins auto-load agents and skills but NOT rules.
> Run the installer to copy rules to `~/.claude/rules/`:

```bash
# 4. Install rules (pick one)
# Bash (macOS/Linux/Git Bash):
bash ~/.claude/plugins/marketplaces/xrstack/install.sh

# PowerShell (Windows):
& "$env:USERPROFILE\.claude\plugins\marketplaces\xrstack\install.ps1"

# Preview without copying:
bash ~/.claude/plugins/marketplaces/xrstack/install.sh --dry-run
```

### Option B — Git Submodule (recommended for teams)

Keep XRStack as a separate repo inside your Unity project, linked via symlink:

```bash
# 1. Add as submodule
cd YourUnityProject/
git submodule add <this-repo-url> XRStack

# 2. Create symlink to .claude/ (Windows — requires Developer Mode)
mklink /D .claude XRStack\.claude

# On Windows without Developer Mode, use a junction instead:
# mklink /J .claude XRStack\.claude

# On macOS/Linux:
# ln -s XRStack/.claude .claude

# 3. Optional
# Copy CLAUDE.md as a starting template (customize for your project)
cp XRStack/CLAUDE.md ./CLAUDE.md

# 4. Add to .gitignore
echo ".claude" >> .gitignore
echo "docs/unity" >> .gitignore

# 5. Launch Claude Code
claude

# 6. Run /start-harness — discovers your project, generates or audits CLAUDE.md, then routes you
/start-harness
```

`/start-harness` is the single entry point. It scans your Unity project (version, XR packages, SDK, scripts), generates a harness-compliant `CLAUDE.md` if none exists (or audits and fixes an existing one), then routes you to the right workflow.

> **Tip:** You can also use Claude Code's built-in `/init` to generate a basic `CLAUDE.md`,
> or copy `XRStack/CLAUDE.md` as a starting template. `/start-harness` produces
> the most harness-compliant result because it enforces all required sections.

### Option C — Direct Copy (simple, no upstream updates)

```bash
# 1. Copy the full .claude folder to you project's root
cp -r XRStack/.claude YourUnityProject/.claude

# 2. Template — customize for your project
cp XRStack/CLAUDE.md YourUnityProject/CLAUDE.md

# 3. Optional: copy Unity API reference docs
cp -r XRStack/docs YourUnityProject/docs
```

## Project Structure

### This Repo

```
XRStack/
├── .claude-plugin/
│   ├── plugin.json             # Plugin metadata (name, version, author)
│   └── marketplace.json        # Self-hosted marketplace definition
├── .claude/
│   ├── settings.json           # Permissions, hooks, safety rules
│   ├── agents/                 # 18 specialist agent definitions
│   ├── skills/                 # 24 slash command implementations
│   ├── rules/
│   │   ├── common/             # 19 rules (loaded for all files)
│   │   └── csharp/             # 6 rules (loaded for *.cs files only)
│   ├── hooks/                  # 8 lifecycle shell scripts
│   ├── scripts/
│   │   └── lib/                # Node.js session management utilities
│   └── docs/
│       ├── templates/          # 15 document templates
│       └── unity-references/   # Unity API reference docs
├── .mcp.json                   # MCP server configuration (5 servers)
├── CLAUDE.md                   # Template — copy to your project root and customize
└── README.md
```

### Your Unity Project (after integration)

```
YourUnityProject/
├── .claude                             # agents, skills, rules (symlink or copy)
├── docs
│   └── app design docs/                # Design artifacts (from /brainstorm)
├── CLAUDE.md                           # Your project's instructions
├── Assets/
│   ├── Scripts/
│   │   ├── Core/
│   │   ├── XR/
│   │   ├── Interaction/
│   │   ├── UI/
│   │   └── Gameplay/
│   ├── Shaders/
│   ├── Models/
│   ├── Textures/
│   ├── Prefabs/
│   └── Tests/
├── Packages/
│   └── com.yourcompany.xr.sdk/         # XR SDK
│       ├── Runtime/
│       ├── Editor/
│       └── Tests/
├── ProjectSettings/
├── UserSettings/
└── *.sln
```

## How It Works

Claude Code auto-discovers the `.claude/` directory at your project root:

```
You type a message
       |
       v
  [CLAUDE.md loaded] ── Project context, conventions, constraints
       |
       v
  [Rules matched] ── e.g., editing a .cs file loads csharp/coding-style.md
       |
       v
  [Hooks fire] ── SessionStart, PreToolUse, PostToolUse, etc.
       |
       v
  [Agent selected] ── Claude delegates to specialist (xr-specialist, etc.)
       |
       v
  [Slash commands available] ── /plan, /code-review, /xr-test, etc.
```

**Rules** are path-matched — `csharp/coding-style.md` has a `paths: ["**/*.cs"]` frontmatter, so it only loads when Claude touches C# files. Common rules load always.

**Agents** are specialist sub-processes. When you ask about XR interaction design, Claude can spawn the `xr-specialist` agent which has deep XR knowledge. Agents run in isolated contexts and report back.

**Hooks** are shell scripts triggered by lifecycle events. `validate-commit.sh` runs before every `git commit` to check for hardcoded values and JSON validity. `session-start.sh` loads branch context when you start a session.

## Working Agents (14)

The workflow has a director, three leads, and a roster of specialists. Scheduling, scope, and release coordination are owned by the user, not an agent.

### Director (Strategic Decisions)

| Agent | Responsibility |
|-------|---------------|
| `technical-director` | Architecture, technology choices, performance strategy, technical risk |

### Leads (Tactical Decisions)

| Agent | Responsibility |
|-------|---------------|
| `lead-programmer` | Code architecture, code review, coding standards |
| `qa-lead` | Test strategy, test execution, quality gates, release readiness |
| `xr-specialist` | XR interaction authority, tracking, spatial UI |

### Specialists (Implementation)

| Category | Agents |
|----------|--------|
| **XR** | `unity-xri-specialist`, `openxr-runtime-specialist`, `platform-specialist` |
| **Unity Engine** | `unity-specialist`, `unity-technical-artist` |
| **Programming** | `gameplay-programmer`, `tools-programmer`, `ui-programmer` |
| **Quality** | `performance-analyst` |
| **Design** | `game-designer` |

### Engine & XR Hierarchies

```
unity-specialist (lead)
└── unity-technical-artist        # Shader Graph, ShaderLab/HLSL, compute, VFX Graph,
                                  # URP render features, post-processing

xr-specialist (authority)
├── unity-xri-specialist          # XRI interactors, locomotion
├── openxr-runtime-specialist     # OpenXR loader, runtime (kept for future use; not active on the current vendor stack)
└── platform-specialist           # XR glasses / PC streaming builds
```

## Slash Commands (14)

### XR-Specific
| Command | Purpose |
|---------|---------|
| `/xr-test` | Generate XR interaction, locomotion, and comfort tests |
| `/build-platform` | Validate build settings for XR glasses or PC streaming |
| `/xr-perf-profile` | Frame budget analysis (72/90/120Hz targets) |

### Development
| Command | Purpose |
|---------|---------|
| `/plan` | Create implementation plan (waits for confirmation before coding) |
| `/code-review` | Architectural and quality code review (offers dated export to `docs/production/code-reviews/`) |
| `/architecture-decision` | Create an Architecture Decision Record |
| `/bug-report` | Structured bug report creation |
| `/design-review` | Review game design docs for completeness and implementability |
| `/brainstorm` | Guided concept ideation from zero to structured design |

### Production
| Command | Purpose |
|---------|---------|
| `/feature-plan` | Draft a per-feature implementation plan in `docs/production/features/` |
| `/milestone-gate` | Milestone/phase readiness (artifacts, quality, go/no-go verdict) |
| `/asset-audit` | Asset naming, size, and format compliance |

### Onboarding
| Command | Purpose |
|---------|---------|
| `/start-harness` | Discover project, ensure CLAUDE.md harness compliance, route to workflow |
| `/project-stage-detect` | Auto-detect project stage and recommend next steps |

## Rules (21)

Rules auto-load based on file path patterns. You never invoke them manually.

### Common Rules (15) — Always Active
| Rule | Enforces |
|------|----------|
| `coding-style.md` | Unity naming conventions (`m_`, `k_`, `s_`), formatting, immutability |
| `xr-development.md` | XR performance budgets, interaction patterns, comfort |
| `git-workflow.md` | Commit message format, PR workflow |
| `code-review.md` | Review checklist, severity levels |
| `testing.md` | TDD workflow, 80% coverage requirement |
| `development-workflow.md` | Feature implementation pipeline |
| `patterns.md` | ScriptableObject events, service locator, state machine |
| `performance.md` | Model selection, context window management |
| `engine-code.md` | Core/SDK/Runtime code standards |
| `gameplay-code.md` | Interaction and feature code standards |
| `shader-code.md` | Shader naming, precision, XR stereo rendering |
| `ui-code.md` | Spatial UI, world-space canvas patterns |
| `test-standards.md` | Test naming, AAA pattern |
| `agents.md` | Agent orchestration and delegation rules |
| `hooks.md` | Hook types and best practices |

### C# Rules (6) — Active for `*.cs` Files Only
| Rule | Enforces |
|------|----------|
| `coding-style.md` | Unity C# conventions, ScriptableObjects, async patterns |
| `unity-xr.md` | XRI component patterns, common XR pitfalls |
| `patterns.md` | ScriptableObject config, event channels, SDK `Result<T>` |
| `testing.md` | Unity Test Framework, `XRDeviceSimulator`, Play/Edit mode |
| `security.md` | XR input validation, network security |
| `hooks.md` | `dotnet format`, build verification |

## Hooks (10)

| Hook | Trigger | Purpose |
|------|---------|---------|
| `session-start.sh` | Session start | Load branch, Unity version, XR package context |
| `detect-gaps.sh` | Session start | Flag missing docs, tests, or XR packages |
| `validate-commit.sh` | Before `git commit` | JSON validation, hardcoded value detection, TODO format |
| `code-review-hint.sh` | Before `git commit` | Advisory reminder to run `/code-review` when staged `.cs` files are about to be committed |
| `validate-push.sh` | Before `git push` | Protected branch warning, test reminder |
| `validate-assets.sh` | After file write/edit | Asset naming and JSON validation |
| `milestone-gate-hint.sh` | After file write/edit | Suggests `/milestone-gate` when a milestone tracker is fully resolved and verdict is TBD |
| `pre-compact.sh` | Before context compaction | Dump session state for recovery |
| `session-stop.sh` | Session end | Log session summary, archive state |
| `log-agent.sh` | Agent spawn | Audit trail for agent invocations |

## MCP Servers (5)

XRStack includes a `.mcp.json` with pre-configured MCP servers for Unity XR development.

| Server | Type | Purpose |
|--------|------|---------|
| `github` | stdio | GitHub operations — PRs, issues, code search, repo management |
| `context7` | stdio | Live documentation lookup — Unity, XRI, OpenXR, and any library |
| `exa` | HTTP | Web search and research — find patterns, docs, solutions |
| `figma` | HTTP | Figma design integration |
| `unityMCP` | HTTP | **Unity Editor bridge** — 42 tools for scene, assets, scripts, profiling, builds |

### Unity MCP Setup

The `unityMCP` server connects Claude Code directly to your running Unity Editor via [MCP for Unity](https://github.com/CoplayDev/unity-mcp). It provides tools for scene management, profiling, builds, testing, and more.

**Setup:**
1. In Unity: `Window > Package Manager > + > Add package from git URL`:
   ```
   https://github.com/CoplayDev/unity-mcp.git?path=/MCPForUnity#main
   ```
2. In Unity: `Window > MCP for Unity > Start Server`
3. Restart Claude Code — `unityMCP` tools will appear automatically

The default port is `8080` (configurable in Unity's `Window > MCP for Unity` advanced settings). If you change the port, update the URL in `.mcp.json` to match.

> **Note:** `unityMCP` requires Unity Editor to be running. The other 4 MCPs work independently.

### Windows Note

On Windows, stdio-based MCP servers (`github`, `context7`) require `cmd /c` wrapper for `npx`. This is already configured in the included `.mcp.json`.

## Design Philosophy

### 1. Harness, Not Prompts

Telling the agent "use Unity conventions" in every message doesn't scale. XRStack encodes constraints into **rules** (auto-loaded), **hooks** (auto-enforced), and **settings** (permissions). The agent follows conventions because the harness makes it the path of least resistance.

### 2. Specialist Over Generalist

A single Claude session answering XR questions, reviewing code, and writing shaders produces mediocre results everywhere. Specialist agents carry deep domain context — the `xr-specialist` knows about motion sickness, the `performance-analyst` knows about frame budgets, and the `unity-technical-artist` knows about ShaderLab, compute shaders, and URP render features. Routing to the right specialist produces better output.

### 3. Progressive Disclosure

`CLAUDE.md` is a table of contents, not an encyclopedia. It gives Claude the essentials (tech stack, conventions, budgets) and points to deeper docs. Rules load only when relevant files are touched. This keeps the context window focused on what matters for the current task.

### 4. Mechanical Enforcement Over Documentation

A documented convention will be violated. A lint rule won't. XRStack pushes constraints as high up the enforcement hierarchy as possible:

1. **settings.json deny-list** — impossible to violate (blocked commands)
2. **Hooks** — caught before commit/push
3. **Rules** — loaded into agent context per file type
4. **CLAUDE.md** — project-wide instructions
5. **Verbal corrections** — least reliable (but saved to memory for future sessions)

### 5. XR-First, Not XR-Added

XR constraints aren't a separate checklist bolted onto a generic Unity workflow — they're embedded into every layer. The coding-style rule mentions GC-free hot paths because XR frame drops cause nausea. The shader rule enforces `half` precision because XR glasses have mobile GPUs. The performance-analyst agent knows 11ms frame budgets by default. Every agent, rule, and skill already "thinks in XR" rather than treating it as an afterthought — like a building designed for earthquakes from day one, not retrofit with brackets after construction.

## Customization

### Adding an Agent

Create a file in `.claude/agents/`:

```markdown
---
name: my-specialist
description: "One-line description of when to use this agent."
tools: Read, Glob, Grep, Write, Edit, Bash
model: sonnet
maxTurns: 20
---

You are the [Role] for a Unity XR project. [Core responsibilities...]

## Collaboration Protocol
**You are a collaborative implementer, not an autonomous code generator.**

## Core Responsibilities
- [What this agent owns]
- [What it enforces]

## Delegation Map
**Reports to**: [parent agent]
**Coordinates with**: [sibling agents]
```

Available models: `opus` (deepest reasoning), `sonnet` (best coding), `haiku` (fast/cheap).

### Adding a Slash Command (Skill)

Create a directory in `.claude/skills/` with a `SKILL.md`:

```
.claude/skills/my-command/
└── SKILL.md
```

```markdown
---
name: my-command
description: "What this command does."
argument-hint: "[optional-arg]"
user-invocable: true
allowed-tools: Read, Glob, Grep, Bash
---

When this skill is invoked:

1. **Step one** — what to analyze
2. **Step two** — what to generate
3. **Output format** — the report structure
```

### Adding a Rule

Create a file in `.claude/rules/common/` (always loaded) or `.claude/rules/csharp/` (loaded for C# files):

```markdown
---
paths:
  - "Assets/Scripts/**/*.cs"
---

# My Rule

## What to enforce
- [Convention or constraint]
- [Anti-pattern to prevent]
```

The `paths` frontmatter controls when the rule loads. Omit it for always-on rules.

### Removing Components

- **Remove an agent**: Delete its `.md` file from `.claude/agents/`
- **Remove a skill**: Delete its directory from `.claude/skills/`
- **Remove a rule**: Delete its `.md` file from `.claude/rules/`
- **Remove a hook**: Delete its `.sh` file from `.claude/hooks/` and remove the reference in `.claude/settings.json`

### Adapting for Non-XR Unity Projects

1. Remove XR-specific agents: `xr-specialist`, `unity-xri-specialist`, `openxr-runtime-specialist`, `platform-specialist`
2. Remove XR-specific rules: `xr-development.md`, `unity-xr.md`
3. Remove XR-specific commands: `/xr-test`, `/xr-perf-profile`, `/build-platform`
4. Update `CLAUDE.md` to remove XR constraints and performance budgets
5. Keep everything else — the Unity engine specialists, coding standards, review workflow, and production tools are engine-agnostic

> [!NOTE]
> XRStack is in active development. The current release covers agents, skills, rules, hooks, and MCP integrations.
> Upcoming additions include more XR-specific validation tools and expanded platform coverage.
> Contributions and feedback are welcome.

## License

MIT

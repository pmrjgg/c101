# Stack conventions

This is the contract every agent, skill and saved workflow in this repository follows.
`bin/stack doctor` enforces the mechanical parts. Read this before adding anything
(the `agent-architect` agent and the `stack-authoring` skill do).

## 1. Layout

```
.claude/agents/<group>/<name>.md     subagent definitions (Claude Code scans recursively)
.claude/skills/<name>/SKILL.md       skills (+ optional references/, scripts/)
.claude/workflows/<name>.js          saved workflows, invoked as /<meta.name>
.claude/settings.json                hooks, env (depth 8), MCP approvals, permissions
.mcp.json                            project MCP servers (keys come from ~/.claude/stack.env)
bin/                                 stack CLI, MCP launchers (mcp-run, image-router), header helper
stack/                               Python tooling (CPython 3.13 via uv; stdlib only)
stack_mcp/image_router/              MCP server for image gen/edit/RGBA/masks/vector (mcp 2.x, httpx, Pillow)
stack_sdk/                           Claude Agent SDK runner: agents as AgentDefinitions, options, Python hooks
config/models.json                   model tiers (ADVANCED/MEDIUM/LOW_MODEL) + initial effort/maxTurns per agent
pyproject.toml, uv.lock, .python-version   uv project pinned to Python 3.13
config/                              learning.json (Bayesian tuning), policy.json (hooks)
docs/                                architecture, catalog, learning, MCP, depth
.stack/                              runtime artefacts (gitignored): out/, blackboard/, images/, playwright/
```

Agent groups: `orchestration`, `planning`, `quality`, `research`, `experts`, `image`, `synthesis`, `meta`.

## 2. Agent frontmatter

Only documented keys. Claude Code silently ignores unknown keys, so a typo is a silent bug.

```yaml
---
name: rust-expert                 # kebab-case, equals the file stem, no ':'
description: >-                   # ONE line in the file (no block scalars). Drives automatic
  ...                             #   delegation: what it does + "Use when ..." + 2-3 trigger examples.
model: claude-opus-5-5            # rendered from the agent's tier in config/models.json — never hand-edit
effort: high                      # low | medium | high | xhigh | max (initial trait from config/models.json, then learned)
maxTurns: 180                     # tool-use round trips; initial trait from config/models.json, then learned
mcpServers: [context7, exa]       # string refs to servers in .mcp.json (or built-in computer-use)
skills: [delegation-protocol, doubt-escalation, output-contract, rust-craft]
color: green                      # red blue green yellow purple orange pink cyan
disallowedTools: Agent            # only for pure leaves that must never spawn
---
```

Rules:
- Write `description` as a single physical line (it may be long). Use plain sentences, no `: ` sequences
  that could confuse YAML; if you need a colon, wrap the whole value in double quotes.
- Omit `tools` (inherit everything: built-ins, Agent, Skill, Workflow, all MCP tools) unless the role
  must be read-only or must not spawn. Prefer `disallowedTools` to a long allowlist.
- `skills` preloads full skill text into the agent's context. Always include the three protocol skills
  `delegation-protocol`, `doubt-escalation`, `output-contract`; add at most 3 role skills.
- **Model tiers.** `config/models.json` assigns every agent a tier — `ADVANCED_MODEL` (claude-opus-5-5),
  `MEDIUM_MODEL` (claude-sonnet-5-5), `LOW_MODEL` (claude-haiku-5-5) — plus initial `effort` and a moderate
  `maxTurns` (~2× a typical demanding run). `bin/stack agents tiers --apply` renders the model ids;
  `bin/stack agents set NAME tier=MEDIUM_MODEL` re-tiers an agent; env vars `ADVANCED_MODEL` / `MEDIUM_MODEL` /
  `LOW_MODEL` override the ids (e.g. to trial a new release). Doctor warns on drift.
- `maxTurns`, `effort` (and, raise-only, `autoCompactWindow`) are rewritten in place by `bin/stack learn apply`.
  Bounds live in `config/learning.json`.
- `autoCompactWindow` (100000..1000000) may be added by a human or the tuner for long-running agents.

## 3. Agent body

Markdown, second person, 120-260 lines, these sections in order:

```markdown
You are the <role> of this agent stack. <2-4 sentence mission.>

## When you are called
Inputs you expect, what "done" means, what to ask back for if missing (return an Open doubt
instead of guessing when the brief is ambiguous and the cost of guessing is high).

## Operating procedure
1. ... numbered, concrete, tool-aware (name real tools: Read, Grep, Bash, Agent,
   mcp__exa__web_search_exa, mcp__playwright__browser_snapshot, mcp__image__image_generate ...;
   Workflow only where the agent may run as the main thread — see section 11)

## Delegation
Who you spawn for what (exact agent names), what you keep for yourself, how many in parallel,
and the cost tier of each target (choose a cheaper agent rather than overriding models).
Respect the <stack-context> header (see delegation-protocol). Doubts go out per doubt-escalation.

## Quality bar
Checks you run before returning. Concrete, verifiable.

## Output
The output-contract shape, specialised for this role (what goes in Result, what goes to a file).

## Never
Short list of hard prohibitions specific to the role.
```

Domain experts add a `## Expertise` section (after the mission) listing the sub-areas, tools,
standard references and the specific pitfalls they guard against.

## 4. Depth, delegation, concurrency

- The main thread (usually `delegator`, via `claude --agent delegator`, `bin/claude-stack` or
  `bin/stack-sdk run`) is depth 0.
- Native nesting is enabled to depth 8 (`CLAUDE_CODE_MAX_SUBAGENT_SPAWN_DEPTH=8`); the `pre-agent`
  hook enforces the same limit, per-caller spawn rules, a per-session spawn budget and the token
  budgets, strips per-call `model`/`effort` (tiers are authoritative), and prepends
  `<stack-context depth="d" max_depth="8" parent="p" remaining_depth="r" spawns_this_session="n" budget="ok|soft|hard" prompt_tokens="used/120M" session_tokens="used/3B" out_dir=".stack/out/<agent>"/>`
  to every subagent prompt.
- `remaining_depth="0"`: you cannot spawn; do the work or return Open doubts.
  `remaining_depth` 1-2: spawn only leaves (researchers, summarizers, testers), never orchestrators.
- Concurrency = several Agent calls in ONE message (they run in parallel). Up to 20 at once.
  Parallelism is for independence and coverage, never for latency (see section 10).
- Saved workflows (`swarm-run`, `fanout`, `mediate`, `expert-panel`, `research-sweep`, `review-verify`,
  `plan-tournament`) can be launched **only by the main thread**: Claude Code removes the Workflow tool
  from every subagent. A subagent that wants one either fans out with parallel Agent calls itself or
  returns a recommendation (`Workflow name=<w> args={...}`) as an Open doubt for the main thread.
- Every brief to a subagent is self-contained: goal, inputs (paths, not pasted blobs), constraints,
  acceptance criteria, output shape, where to write files. Subagents do not see your conversation.
- No per-call `model`/`effort` overrides: the hook strips them so every agent runs on its tier and
  learned effort. To spend less, pick a LOW/MEDIUM-tier agent (e.g. `file-summarizer`, `web-scraper`,
  `quick-researcher`); to think harder, pick an ADVANCED agent — see effort-and-model-selection.

## 5. Output contract (summary)

Every agent ends with:

```markdown
## Result
## Evidence
## Files
## Open doubts
## Confidence
```

Anything longer than ~60 lines or ~3k characters goes to a file under
`.stack/out/<agent-name>/<YYYYMMDD-HHMM>-<slug>.md` (use `date +%Y%m%d-%H%M`); the reply carries a
summary plus the path and line anchors. The `file-summarizer` agent exists to do this for others.

## 6. Skills

```yaml
---
name: mediator-voting            # equals directory name
description: One line. What it is + when to load it (drives auto-loading).
when_to_use: Optional extra trigger guidance.
---
```

- Body under 500 lines; deep material in `references/*.md` linked as `[x](references/x.md)`.
- Procedural, checklist-heavy, with worked examples, formulas and decision tables. No fluff.
- Skills never contain secrets, never instruct to read `~/.claude/stack.env`.
- Allowed extra keys: `argument-hint`, `arguments`, `disable-model-invocation`, `user-invocable`,
  `allowed-tools`, `model`, `effort`, `context: fork`, `agent`, `paths`.

## 7. Saved workflows

- First statement `export const meta = { name, description, whenToUse, phases }` — a pure literal.
- Plain JavaScript (no TypeScript, no imports). No `Date.now()`, `Math.random()`, `new Date()`.
- Normalise args: `const A = typeof args === 'string' ? JSON.parse(args) : (args || {})`; validate and
  return `{started:false, reason, next}` when required args are missing.
- Use `agentType` with this stack's agent names; give every `agent()` a `label` and `phase`.
- `pipeline()` by default; barriers only for cross-item dedup/vote/early exit.
- `log()` anything dropped or capped. Return a structured object, never prose only.
- Names must not collide with skills or bundled workflows (`deep-research`).

## 8. Python, keys and MCP

- All Python (installer, `bin/stack`, hooks, our MCP servers) runs on CPython 3.13 managed by uv:
  `./install.sh` runs `uv python install 3.13` and `uv sync`; launchers use `.venv/bin/python`, falling
  back to `uv run --python 3.13`. Python-based third-party MCP servers run via `uvx --python 3.13`.
  Add dependencies with `uv add <pkg>` (commit `uv.lock`).

- Keys live only in `~/.claude/stack.env` (mode 600). Template: `config/stack.env.example`.
- stdio servers start through `bin/mcp-run` (parses the env file, never sources it).
- Remote servers get auth headers from `bin/mcp-headers <service>` via `headersHelper`.
- Agents never print, log, or echo key values, and never read the env file.

## 9. Self-tuning

`SessionEnd`/`SubagentStop` hooks ingest transcripts into `~/.claude/stack-data/`, update Bayesian
posteriors per agent type, and (if `auto_apply`) rewrite `maxTurns`/`effort` within bounds.
Learned token windows go to `~/.claude/stack-data/budgets.json`. See `docs/LEARNING.md`.

## 10. Token budgets and context policy

- Whole-tree budgets (main thread + every subagent), `config/policy.json` → `token_budget`:
  session `min/soft/max_global_tokens` = 750M / 2.25B / 3B; per user prompt
  `min/soft/max_prompt_tokens` = 30M / 90M / 120M. Below min nothing is throttled; at soft
  (`budget="soft"` in the header) agents converge — no new exploratory branches, finish, verify, report;
  at max (`budget="hard"`) only `file-summarizer`, `quality-control`, `validator`, `source-summarizer`
  may be spawned and every agent wraps up with what it has.
- **Optimise for context usage, not speed.** Keep each window lean: offload output past ~60 lines /
  3k chars to `.stack/out/`; read with Grep and line ranges, never whole large files; send heavy
  reading to fresh-context subagents (`file-summarizer`, `source-summarizer`) that return digests and
  paths; pass paths, never pasted content, in briefs; process structured results with code (`jq`,
  Python) instead of reading them into context. Spend tokens on independent perspectives and
  verification, not on parallelism for its own sake.

## 11. Runtime compatibility: interactive Claude Code and the Agent SDK

Every agent, skill and workflow must behave correctly in both runtimes (`bin/claude-stack` and
`bin/stack-sdk run`, see docs/SDK.md):

1. **Workflow is main-thread only.** Subagents never launch saved workflows (the tool is removed from
   them); they fan out with Agent calls or return a workflow recommendation as an Open doubt.
2. **No questions from subagents.** AskUserQuestion is unavailable inside subagents (and under the SDK
   without a permission callback). Subagents return Open doubts; the main thread asks the user in plain
   text at the end of its turn.
3. **Results before continuing.** Under the SDK subagents default to the background. When you need a
   child's result before your next step, call Agent with `run_in_background: false` (the SDK runner also
   forces this). The child's final message must contain the complete deliverable (summary + paths).
4. **Tiers are authoritative.** No `model`/`effort` on Agent calls (stripped by the hook).
5. **No interactive-only features without a fallback.** Built-in computer use and Claude in Chrome do
   not exist under the SDK/-p: use Playwright, the optional `peekaboo` server, or return the item as
   blocked. Agent teams/teammates are never used. Never rely on slash commands typed into prompts.
6. **Self-contained bodies.** Subagents start from their own body plus the brief; they do not see the
   Claude Code system prompt or the parent conversation. `initialPrompt` only applies to main threads.
7. **Permissions.** Unattended runs use `dontAsk` with an explicit allow-list: never design a step that
   needs an interactive approval; irreversible actions (push, publish, delete, send) are returned as
   Open doubts for the user.

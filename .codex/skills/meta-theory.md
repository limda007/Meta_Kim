---
name: meta-theory
version: 1.3.0
author: KimYx0207
trigger: "元理论|元架构|元兵工厂|最小可治理单元|组织镜像|节奏编排|意图放大|事件牌组|出牌|SOUL.md|四种死法|五标准|agent职责|agent边界|agent拆分|agent设计|agent创建|agent治理|meta architecture|agent governance|intent amplification|meta-theory|meta arsenal|smallest governable unit|organizational mirror|rhythm orchestration|card deck|card play|four death patterns|five criteria|agent design|agent split|agent creation"
tools:
  - shell
  - filesystem
  - browser
  - memory
description: |
  Meta Arsenal — Intelligent Agent Governance Framework (focused on Meta Architecture, not project technical architecture).

  [Architecture Type Distinction]
  - **Meta Architecture** (meta-theory): collaboration relationships between agents, responsibility boundaries, governance processes
  - **Project Technical Architecture** (use architect/backend-architect): code organization, tech stack, module division, dependency relationships

  When a user says "is the architecture right?", first follow up to clarify which architecture they mean!

  [Active Triggers — Any match immediately activates the corresponding flow]
  A. Meta-theory questions: discussing meta architecture / Five Criteria / Four Death Patterns / Organizational Mirror / Intent Amplification → Meta-theory analysis flow
  B. Agent design: creating/splitting agents, designing SOUL.md, defining agent boundaries → Agent creation pipeline
  C. Agent governance issues: agent responsibility conflicts / unclear boundaries / mutual interference / Cross-contamination → Organizational Mirror design
  D. Proposal review: existing agent definitions / SOUL.md → Five Criteria verification + Four Death Patterns detection + rating
  E. Collaboration orchestration: agent execution order / parallel vs sequential / trigger conditions / card play rhythm → Rhythm Orchestration flow

  [Auto-trigger] Complex development tasks (multi-file / multi-module / cross-layer changes) → follow the 8-stage governance flow:
  Critical(Follow-up Probe) → Fetch(search capabilities) → Execution(delegate to agents) → Review(review) →
  Meta-Review(meta-review) → Evolution(Intent Amplification)

  [Three Iron Rules] Critical > Guessing | Fetch > Assuming | Review > Trusting
---

# Meta Arsenal — Smallest Governable Unit Methodology

## Your Role

You are the **Meta Architecture Execution Framework**. When a trigger condition is received, you are responsible for:
1. **Determine input type** → Select the corresponding flow
2. **Execute by the flow** → Each step has concrete operational instructions
3. **Enforce the Three Iron Rules throughout** → Critical > Fetch > Review

### Three Iron Rules

1. **Critical > Guessing** — When requirements are unclear, follow up with probing questions; do not assume
2. **Fetch > Assuming** — Search and verify first; do not assume an agent/skill exists
3. **Review > Trusting** — Every output must be reviewed; do not trust a single-pass result

> **Why follow up first?** Most users treat AI like a wishing well — the requirements themselves are vague, yet they expect clear answers from the AI. Critical's job is to clarify "what is the real problem?" before execution begins.

---

## Dynamic Flow Selection

```
[User Input]
  ↓
Critical: Determine input type
  ├─ [Architecture Type Pre-judgment] When user says "architecture", first ask: Meta Architecture OR Project Technical Architecture?
  │   ├─ Meta Architecture (agent governance) → continue
  │   └─ Project Technical Architecture (code/tech stack) → suggest using architect or backend-architect
  ├─ Type A: Discussing meta-theory / splitting principles / evaluating agents → Meta-theory analysis flow
  ├─ Type B: Creating new agents / splitting existing agents → Agent creation pipeline
  ├─ Type C: Complex development tasks / feature implementation → Development governance flow
  ├─ Type D: Existing proposal to review → Review and verification flow
  └─ Type E: Rhythm / card play / orchestration strategy → Rhythm Orchestration flow
```

> **Important: Architecture Type Distinction**
> - **Meta Architecture** (meta-theory's responsibility): collaboration relationships between agents, responsibility boundaries, governance processes
> - **Project Technical Architecture** (architect et al.): code organization, tech stack, module division, dependency relationships, design patterns
>
> When a user says "is the project architecture right?", they usually mean project technical architecture, and you should:
> 1. First follow up to confirm the type
> 2. If it's technical architecture → suggest using the global `architect` or `backend-architect`
> 3. If it's meta architecture → continue with the meta-theory flow

---

## Type A: Meta-Theory Analysis Flow

### Scenario
The user wants to understand meta-theory, discuss splitting principles, evaluate whether existing agents are reasonable, or discuss Organizational Mirror / Intent Amplification.

### Execution Steps

**Step 1: Read the theoretical framework**
Read `references/meta-theory.md` to obtain the complete methodology (four main threads, Five Criteria, Four Death Patterns, three-layer architecture).

**Step 2: Search existing agents**
```
Glob: .claude/agents/*.md
```
Read each agent definition file to understand the current state.

**Step 3: Five Criteria item-by-item verification**

For each agent, fill in the table:

| Criterion | Evidence | Pass? |
|-----------|----------|-------|
| Independent — can be understood, invoked, and produce output on its own | {specific evidence} | ✅/❌ |
| Small Enough — further splitting is meaningless or cost-backfires | {specific evidence} | ✅/❌ |
| Clear Boundaries — explicit "Own" and "Do Not Touch" | {specific evidence} | ✅/❌ |
| Replaceable — swapping it out doesn't collapse the system; can be upgraded/recombined | {specific evidence} | ✅/❌ |
| Reusable — useful across scenarios, not one-time | {specific evidence} | ✅/❌ |

**Step 3.5: Meta-Verification Four Questions (runtime judgment)**

| Question | Diagnostic Significance |
|----------|------------------------|
| Does it have clear boundaries? ("Own X, Do Not Touch Y") | No boundaries = Stew-All precursor |
| Can it be replaced without collapsing? | No replaceability = Omnipotent Executor Meta precursor |
| When other metas take the field, will there be Cross-contamination? | Yes Cross-contamination = Organizational Mirror failure |
| Can this meta combine with other metas? | Cannot combine = Shattered precursor |

> The "Five Criteria" is a design-time checklist; the "Four Questions" are runtime judgments — using the Four Questions during the Critical phase is more direct than the Five Criteria.

**Omnipotent Executor Meta Anti-Pattern**: If you find a meta that "understands, finds files, designs plans, writes code, verifies, and explains" all at once → this is Omnipotent Executor Meta compression disease. Symptoms: execution before thorough understanding, decisions before complete information gathering, modifying shared logic before exposing risks. Encountering these symptoms → trigger Type B splitting pipeline.

**Step 4: Four Death Patterns Detection**

| Death Pattern | Symptoms | Diagnostic Questions |
|---------------|----------|---------------------|
| Stew-All | One agent can do everything | >2 unrelated domains? SOUL.md >300 lines? |
| Shattered | Too many agents, too fragmented | Needs other agents' output to produce? Coordination cost > value? |
| Governance-Free Execution | Only direction → planning → execution | Who reviews? Who reviews the reviewers? How is experience codified? |
| Result-Chasing Without Structure | One successful run is treated as gospel | Will it still work tomorrow? Can someone else take over and run it? |

**Step 5: Output analysis report**, including each agent's verification table + death pattern detection results + improvement suggestions.

---

## Type B: Agent Creation Pipeline

### Scenario
The user requests creating a new agent or splitting an existing agent's responsibilities.

### Your Role
You play the role of **meta-warden** (pipeline coordinator). `.claude/agents/meta-*.md` are the methodological references for each station — at the start of each station, you read the corresponding file and execute according to its methodology.

### Two Entry Modes

- **Mode A (Discovery Mode)**: User says "help me design an agent" but has no clear list → go through the full Phase 1
- **Mode B (Direct Mode)**: User already has a clear list → skip Phase 1, go directly to Phase 2

### Phase 1: Discovery and Splitting (Mode A only)

**Step 0: Data Collection**

Run the following git commands to collect project data:

```bash
# Total commits
git log --since="6 months ago" --oneline | wc -l

# Commit type distribution
git log --since="6 months ago" --oneline | awk '{print $2}' | sed 's/:.*//' | sort | uniq -c | sort -rn

# Directory change heatmap
git log --since="6 months ago" --name-only --pretty=format:"" | sed '/^$/d' | sed 's|/[^/]*$||' | sort | uniq -c | sort -rn | head -20

# File co-change analysis (high coupling detection)
git log --since="6 months ago" --name-only --pretty=format:"---" | awk 'BEGIN{RS="---"} NF>1 {for(i=1;i<=NF;i++) for(j=i+1;j<=NF;j++) print $i, $j}' | sed 's|/[^/]*$||g' | sort | uniq -c | sort -rn | head -15
```

**Step 1: Capability Dimension Enumeration**
- Directory areas with change frequency >5% = candidate independent domains
- Directories with high co-change frequency = should be merged into the same agent
- Directories with low co-change frequency = can be separated

**Step 2: Coupling Grouping**
- High coupling → merge; low coupling → separate
- Coupling criterion: if A changes, does B frequently need to change too? Yes → same agent; No → can be separated

**Step 2.5: User Confirmation**
Use the currently available question/confirmation mechanism to present the splitting proposal, listing each candidate agent's name, responsibility domain, and data evidence.
**Iron Rule**: If the user says "these two capability types are different", even if data shows coupling, they must be split apart.

### Phase 2: Pre-Design Decision — Global vs Project-Specific (New)

**Before starting design, first determine whether a project-specific agent is truly needed.**

> **Why is this step important?** A common over-engineering trap: global agents already cover the capability, yet a project-specific agent is created anyway. This leads to unnecessary maintenance burden, capability fragmentation, and missing improvement updates from global agents.

**Three-Layer Architecture Decision Method**:

```
┌─────────────────────────────────────────────────────────┐
│              Entry Layer (entry/orchestration)            │
│  — Commander / Orchestrator                               │
│  — ✅ Always project-specific (needs to understand       │
│     project context)                                      │
└─────────────────────────────────────────────────────────┘
                           ↓
┌─────────────────────────────────────────────────────────┐
│             Knowledge Layer (domain knowledge)            │
│  — Domain experts with project-specific knowledge         │
│  — ⚠️ Create conditionally (see 3 criteria below)        │
└─────────────────────────────────────────────────────────┘
                           ↓
┌─────────────────────────────────────────────────────────┐
│              Execution Layer (execution)                   │
│  — frontend-developer, typescript-pro, code-reviewer...   │
│  — ❌ Mostly use global agents                            │
└─────────────────────────────────────────────────────────┘
```

**3 Hard Criteria for Creating a Project-Specific Agent** (must satisfy ALL simultaneously):

| Criterion | Description | How to Check |
|-----------|-------------|-------------|
| 1️⃣ Domain Gap | Global agent does not cover this domain | Fetch phase has confirmed no match |
| 2️⃣ Project Uniqueness | The project has **non-generalizable** unique knowledge | Outside this project, the knowledge is useless |
| 3️⃣ Frequency | This type of task appears **frequently** in the project | Not one-time or extremely rare |

**Quick Reference Table** (common misjudgments):

| Need | Correct Approach | Wrong Approach |
|------|-----------------|----------------|
| React/Vue components | Use global `frontend-developer` | Create `project-frontend-executor.md` |
| TypeScript/Python types | Use global `typescript-pro` / `python-pro` | Create `project-type-checker.md` |
| Code review | Use global `code-reviewer` | Create `project-review.md` |
| Security audit | Use global `security-reviewer` | Create `project-security.md` |
| Test automation | Use global `test-automator` | Create `project-testing.md` |
| Chrome Extension mechanism | Create project-specific (if no global exists) | Force-fit a generic agent |
| 51 Platform integration knowledge | Create project-specific (too specific) | Expect it to exist globally |
| Business logic | Create project-specific (will never exist globally) | Wait for a global to appear |

**Decision Flow**:

```
IF Fetch phase finds a matching global agent
  → Evaluate against 3 criteria
  → IF any criterion is not met
    → Use the global agent, stop the creation pipeline
  → ELSE (all 3 met)
    → Continue creating project-specific agent
ELSE (no global match)
  → Continue the creation pipeline
```

**Phase 2.5: User Confirmation**

Use the currently available question/confirmation mechanism to present the decision result:

- If deciding to use a global agent: explain which global agent, why it's sufficient, and what maintenance cost is saved
- If deciding to create a project-specific agent: list the specific evidence for all 3 criteria and request confirmation

**Only enter Phase 3 after obtaining the user's explicit "confirm creation".**

---

### Phase 3: Design On Demand

**Genesis (Soul) and Artisan (Skills) are mandatory for every Agent. The other three stations are determined on demand.**

After completing Step 3 Genesis, answer three questions for each Agent:

| Question | Yes → Trigger Station |
|----------|----------------------|
| Will it modify files, call external APIs, or operate databases? | Sentinel (Security) |
| Does it need to remember what it did last time and accumulate learning experience? | Librarian (Memory) |
| Does it need to hand off results to other Agents or coordinate execution order? | Conductor (Orchestration) |

All three No → only run Genesis + Artisan.

**Step 3: Genesis — Soul Design (Mandatory)**

Read `.claude/agents/meta-genesis.md` and design the SOUL.md according to its methodology.

The output must include **8 mandatory modules**:
1. Core Truths — ≥3 behavioral anchors, specific to this domain
2. Role + Core Work — clear "Own / Do Not Touch" boundaries
3. Decision Rules — ≥3 if/then rules
4. Thinking Framework — domain-specific analysis steps (not a restatement of the workflow)
5. Anti-AI-Slop — specific AI Slop detection signals for this domain
6. Output Quality — good/bad example comparison
7. Deliverable Flow — clear input → process → output
8. Meta-Skills — ≥2 self-improvement directions

**Quality Self-Check**: Replace the Agent name with something else — if the SOUL.md still holds → no Domain Depth, grade D, redo.

**Step 4: Artisan — Skill Matching (Mandatory)**

Read `.claude/agents/meta-artisan.md`.

1. Scan available Skills: `ls .claude/skills/*/SKILL.md` + system built-in Skills
2. ROI scoring: `ROI = (task coverage × usage frequency) / (context cost + learning curve)`
3. Output: Skill recommendation list for each Agent (Top 5-8, with ROI scores and rationale)

**Step 5: Sentinel — Security Design (On Demand)**

Read `.claude/agents/meta-sentinel.md`.
- Threat modeling: Top 5 threats in this Agent's domain
- Permission design: 3 levels (CAN / CANNOT / NEVER)
- Hook design: PreToolUse / PostToolUse / Stop hooks
- Output: Security rules + Hook configuration + Permission boundaries

**Step 6: Librarian — Memory Design (On Demand)**

Read `.claude/agents/meta-librarian.md`.
- Memory architecture: 3 layers (index layer / topic layer / archive layer)
- Expiration policy: set expiration rules by type
- Output: MEMORY.md template + persistence strategy

**Step 7: Conductor — Orchestration Design (On Demand)**

Read `.claude/agents/meta-conductor.md`.
- Collaboration flow: invocation order between Agents, parallel/sequential
- Trigger conditions: under what circumstances to spawn this Agent
- Output: Workflow configuration + trigger rules

### Phase 4: Review and Revision

**Step 8: Critical Review**

For each Agent's complete design, answer 4 questions:
1. What assumptions did I make? Is there data to support them?
2. If I replace the Agent name with something else, does the design still hold? (If yes = no Domain Depth, redo)
3. Are there traces of Scope Creep? (Responsibility overflow into other Agents' domains)
4. Which parts were genuinely thought through, and which were template-filling?

Quality rating:
- **S/A** → Pass
- **B** → Supplement with specific cases and data references
- **C** → Rewrite AI Slop paragraphs
- **D** → Return to the corresponding station and redo

AI-Slop Quantitative Detection:
- **AI Slop Density** = number of Empty Adjectives / total word count (sample the first 200 words)
  Empty Adjectives list: "advanced", "intelligent", "powerful", "seamless", "elegant", "revolutionary", "excellent", "innovative", "perfect", "outstanding"
  Density >1% → deduct points, >3% → automatic grade D
- **Replaceability**: Replace the Agent name with something else — if the SOUL.md logic still holds → no Domain Depth, grade D
- **Specificity**: No file paths / function names / API endpoints / data model references at all → failing grade

**Step 9: Revision** — Maximum 2 rounds. If still grade B after 2 rounds, hand it to the user to decide.

### Phase 5: Integration and Verification

**Step 10: Integration and Write**

Generate `.claude/agents/{name}.md`, with structure including: identity, responsibility boundaries, Core Truths, Decision Rules, Thinking Framework, Anti-AI-Slop, Output Quality, Deliverable Flow, Meta-Skills, skill equipment, security rules (if any), memory strategy (if any), workflow (if any), Five Criteria verification table.

Synchronize the agent list in `CLAUDE.md`.

**Step 11: Final Verification**

| Check Item | If Failed |
|------------|-----------|
| Five Criteria 5/5 PASS | Return to Step 9 for revision |
| No death patterns (Stew-All / Shattered) | Return to Step 2 for regrouping |
| 8 modules complete | Return to Step 3 to supplement |
| Skip Stations have clear justification | No justification → run the skipped station |

**Step 12: User Confirmation**

Use the currently available question/confirmation mechanism to present the complete output summary. **Only write files after obtaining the user's explicit "confirm".**

---

## Type C: Development Governance Flow

### Scenario
The user provides a complex development task or requests execution according to the meta architecture.

### "What It Is Not" Guardrails (preventing misuse)

- Meta ≠ role naming: calling something "frontend agent" doesn't make it a meta; naming without clear boundaries is just packaging
- Meta ≠ Omnipotent Executor Meta: stuffing all responsibilities into one agent isn't strength; clear division of labor is maturity
- Organizational Mirror ≠ metadata/ORM: it's not a technical term — it's an architectural design method for collaboration relationships between metas, responsibility boundaries, and who takes the field first
- Meta ≠ framework complexity: simple scenarios don't need meta decomposition; direct execution is more efficient — meta is a governance tool, not decoration
- Meta ≠ once-and-for-all: meta boundaries need to be adjusted as the system evolves; they aren't defined once and never changed

### Complexity Routing

```
IF <2 file changes → Simple: Direction → Execution → Review → Verification → Feedback (5 steps)
IF 2-5 files → Medium: Direction → Planning → Execution → Review → Meta-Review → Revision → Verification → Feedback (8 steps)
IF >5 files / multiple modules → Complex: all 10 steps
```

**Routing Upgrade Conditions**:
- File count increases from <2 to >2 → Simple upgrades to Medium
- Cross-module dependencies appear → Medium upgrades to Complex
- Sentinel reports a security issue → any level upgrades to Complex
- Prism discovers a systemic issue → Medium upgrades to Complex

### Task Routing Decision Tree

```
IF only involves UI/styles/components → spawn Frontend agent
IF only involves API/DB/Auth → spawn Backend agent
IF involves ≥2 domains → decompose then spawn in parallel
IF code changes complete → must spawn Quality for verification
IF no matching agent found → trigger Type B (creation pipeline)
```

**Note**: Do not hardcode specific agent names; first use Glob to search `.claude/agents/*.md` to confirm existence.

### Complete 8-Stage Flow

**Stage 1: Critical Analysis**
- **Task Classification Routing** (Q/A/P/S four categories, Critical's first step):

  | Category | Determination Criteria | Execution Path |
  |----------|----------------------|----------------|
  | **Q** Query | No code changes needed, just answer questions | Answer directly, skip subsequent stages |
  | **A** Action | Clear, specific execution task (fix bug, add feature, deploy) | → Orchestration Layer decomposition → dispatch to Execution Layer |
  | **P** Planning | Needs design plan before execution (new module, architecture adjustment) | → Plan first → decompose into multiple A-tasks → Dispatch one by one |
  | **S** Strategic | Involves global decisions, cross-system impact, long-term direction | → Warden arbitration → may trigger Type B creation pipeline |

  Classification output field: `taskClass: Q|A|P|S`

- **Skip-Level Self-Reflection Gate** (Q-class skips, A/P/S-class must execute):
  > Core question: **Should I be doing this, or should I dispatch it?**

  Self-check list:
  - [ ] Is the current role an "Execution Layer"? (Yes → Skip-Level suspicion, should dispatch to the corresponding execution agent)
  - [ ] Does the task involve writing code / modifying files? (Yes → must delegate to Execution Layer; meta-theory does not execute directly)
  - [ ] Am I "conveniently" making decisions for the Execution Layer? (Yes → only provide constraints; let the Execution Layer judge implementation details autonomously)
  - [ ] Did the previous round also do a similar task? (Yes → check if a Skip-Level pattern is forming, record Scars)

  Skip-Level determination:
  ```
  IF self-check has ≥1 hit AND taskClass = A
    → Mark as "should-dispatch task"
    → Assemble task package (context + constraints + deliverables)
    → Hand to Conductor for orchestration → dispatch to Execution Layer
    → Record Scars (if Skip-Level indeed occurred)
  ```

- **Complexity Routing**: count file changes + ask how many modules/layers are involved
  - ≥2 file changes OR involves ≥2 different modules → Medium or above, follow the complete flow
  - ≥5 file changes OR spans frontend/backend/database → Complex, add Meta-Review
  - 1 file, pure logic/style/comments → Simple, skip planning, execute + Review directly
- **Follow-up Probe Strategy** (max 2 rounds, **Early Exit Condition**: if Round 1 answers already satisfy any of the following, skip subsequent probes):
  - User specified specific file paths
  - User specified ≥2 acceptable deliverables
  - User explicitly said "just do this, don't worry about the rest"
  - After Round 1 answer, task granularity ≤2 sub-tasks
  - Each round focuses on one dimension:
    - Round 1: Ask about **scope** — "Which specific scenarios need support? Which can be deferred?"
    - Round 2: Ask about **priorities** — "If time is tight, which parts can be cut?"
  - Still vague after 2 rounds → record assumptions, execute directly, mark "unconfirmed assumptions" in output
- **Abstraction** — Translate the "feature" the user described into "what type of meta is needed"
  Output format:
  - [ ] Task classification: Q / A / P / S
  - [ ] Skip-Level Self-Reflection: pass / should-dispatch (with rationale)
  - [ ] Capability type: frontend interaction / backend logic / data persistence / security validation / orchestration coordination / meta governance
  - [ ] Change layer: new file / existing file modification / configuration file / cross-layer change
  - [ ] Governance intensity: 1 (single file) → 2 (multiple files same layer) → 3 (cross-layer) → 4 (system-wide)

**Stage 2: Fetch Search** (each item must be executed, not "if applicable")
- **Layer 1: In-Project Search** (primary project source)
  - Search existing agents: `Glob: .claude/agents/*.md`
    # ⚠️ Must verify: read each file returned by Glob, check if it contains `name:` YAML frontmatter
    # Has `name:` → valid agent, can be recommended; no `name:` → skip that file, continue to the next
    # Rationale: .md files without valid YAML frontmatter will not be registered as agents by Claude Code
  - Search existing skills: `Glob: .claude/skills/*/SKILL.md`
  - Search MCP configuration: `Glob: .mcp.json`
  - Search project meta information: `Glob: CLAUDE.md`
  - Search historical similar tasks: `Bash: git log --oneline --all -- "{user-requirement-keywords}" | head -20`
    # Note: keywords are the core nouns from user input, e.g. "login", "permissions", "agent creation"

- **Layer 2: Global Capability Search** (cross-platform discovery)
  - Read capability index: first check if `.claude/capability-index/global-capabilities.json` exists
  - If not → run `node scripts/discover-global-capabilities.mjs` to generate the index
  - Extract from the index:
    - Claude Code global agents (`~/.claude/agents/*.md`)
    - Claude Code global skills (`~/.claude/skills/*/SKILL.md`)
    - OpenClaw global agents/skills (if accessible)
    - Codex global agents/skills (if accessible)
  - **Platform Difference Note**: invocation methods for global capabilities vary by platform
    - Claude Code: use `Agent` tool's `subagent_type` parameter
    - OpenClaw: use `sessions_send` tool
    - Codex: use platform-specific agent invocation method

- **Layer 3: MCP Server Query** (dynamic capabilities)
  - Query registered MCP server capabilities: via `mcp__meta_kim_runtime__list_meta_agents` and similar tools
  - Check if external MCP provides additional agents/skills

- **Match Scoring**: iterate through found agents/skills (project + global + MCP), scoring 0-3 on two dimensions:
  - **Capability Match** (overlap between input requirements and skill description)
  - **Trigger Condition Match** (current system state vs agent trigger conditions: user input / environment state / path branching / risk signals / result quality / user pause)
  - **Platform Availability** (whether the current runtime can invoke this capability)
  - 3 = perfect match, use directly
  - 1-2 = partial match, use + note the gaps to supplement
  - 0 = no match, trigger Type B creation pipeline

**Stage 3: Critical Decision**
- Found a **single** match → verify it fits within the "Own" boundary → select that agent
- **Partial match** (both agents score 1-2):
  - Compare the coverage gaps of both agents
  - Select the agent with greater coverage
  - Note the gaps in the output and ask the user to confirm who fills them
  - No user response → default to the greater-coverage agent filling the gap
- Not found → trigger Type B creation pipeline

**Stage 4: Execution**

### ⚠️ Core Rule: meta-theory Must Not Write Code Directly!

**meta-theory MUST NOT**:
- ❌ Directly use Edit/Write tools to modify source code files
- ❌ Write code or modify code itself
- ❌ Use "simple task" as an excuse to skip agent invocation

**meta-theory MUST**:
- ✅ Only be responsible for: task analysis → agent selection → result aggregation
- ✅ All Execution Layer work must be delegated to corresponding agents via the Agent tool

---

### Agent Invocation Rules (Based on Fetch Results, No Hardcoding)

**⚠️ Iron Rule: Dynamically determine which agent to invoke from the Fetch stage results!**

1. **Review Fetch stage search results** — Stage 2 already searched:
   - In-project agents: `.claude/agents/*.md`
   - Global capability index: `.claude/capability-index/global-capabilities.json`
   - MCP server capabilities
   - Each found agent has a match score (0-3)

2. **Invocation Priority** (sorted by match score):
   ```
   IF Fetch found a 3 (perfect match) → invoke that agent directly
   IF Fetch found 1-2 (partial match) → select highest match + note gaps
   IF Fetch found no match (0) → trigger Type B creation pipeline
   ```

3. **Invocation Method** (by agent source):

   | Agent Source | Invocation Method |
   |-------------|-------------------|
   | **Global agent** | `Agent(subagent_type='<agent's name field>')` |
   | **Project-specific agent** | `Agent(name='<project-agent-filename>', prompt='...')` or describe the task directly |
   | **MCP-provided agent** | Use MCP tools (per platform convention) |

4. **Example** (for reference only; actual invocation is based on Fetch results):

   ```
   Assume Fetch stage found:
   - Global has code-reviewer (match score 3)
   - Global has frontend-developer (match score 2)

   Then invoke:
   Agent(subagent_type='code-reviewer', prompt="Review this code...")
   Agent(subagent_type='frontend-developer', prompt="Implement this component...")
   ```

**Do not hardcode agent names!** Different users' global environments may not have specific agents.

---

### Execution Flow

**Step 1: Task Decomposition**

Decompose Stage 1's complexity analysis results into independent sub-tasks:

```
Sub-task format:
- ID: Task number
- Type: frontend/backend/typescript/security/testing/etc.
- Description: What specifically to do
- File scope: Which files are involved
- Owner: Responsible agent type
```

**Step 2: Parallel/Sequential Decision**

```
IF sub-tasks' file sets do not overlap
  → Invoke multiple Agent tools in parallel (within the same message)
ELSE (file sets overlap)
  → Invoke sequentially; lock file declaration after the first change completes
```

**Step 3: Delegated Execution**

For each sub-task, use the Agent tool:

```
Agent(
  subagent_type="<corresponding-agent-type>",
  prompt="""
  Task description: [sub-task description]
  File scope: [specific file paths]
  Constraints: [boundaries, dependencies, etc.]
  """
)
```

**Step 4: Result Aggregation**

After all agents complete, aggregate:
- Which files were modified
- Whether there are conflicts to resolve
- Whether supplementary execution is needed

---

### Removal of "Simple Task" Shortcut Execution

**Old logic (deprecated)**:
```
IF <2 file changes → Simple: Direction → Execution → Review → Verification → Feedback
```

**New logic**:
```
No matter how simple, Execution Layer tasks must be completed through agents.
meta-theory is only responsible for analysis, agent selection, and result aggregation.
```

> **Rationale**: If meta-theory can "execute simple tasks directly", then:
> 1. Blurred boundaries — what counts as "simple"? 2 lines of code is also called simple
> 2. Responsibility confusion — meta-theory becomes an "executor", violating governance framework design
> 3. No traceability — directly executed code has no agent signature, making accountability impossible

---

### Meta Relay Chain (conceptual explanation)

Metas relay by responsibility rather than all taking the field simultaneously:

```
Task Understanding Meta (clarification)
  → Repository Awareness Meta + Retrieval Meta (scouting)
  → Solution Meta (path)
  → Execution Layer agents (modify code) ← invoked via Agent tool
  → Validation Meta (acceptance)
  → Explanation Meta (report)
```

Simple tasks can Skip Station for intermediate metas, but the chain order must not be disrupted.

**Stage 5: Review** (each dimension must be executed, not "if applicable")
- **Skip-Level Execution Retrospective Detection** (Review's first step):
  > Check whether, in this round of execution, the Decision Layer / Orchestration Layer directly did Execution Layer work.

  Retrospective check:
  - [ ] Who wrote this round's code changes? (If meta-theory/Warden/Conductor directly used Edit/Write → Skip-Level)
  - [ ] Were there execution agents that should have been invoked but weren't? (→ Dispatch omission)
  - [ ] Task classified as A/P/S but didn't go through Agent tool delegation? (→ Skip-Level execution)
  - [ ] Was the Critical stage's Skip-Level Self-Reflection result respected? (→ Self-Reflection failure)

  Skip-Level handling:
  ```
  IF Skip-Level execution detected
    → Record Scar (type, trigger condition, root cause)
    → Assess impact (did result quality degrade as a result)
    → IF impact occurred → hand to execution agent for re-verification
    → IF impact did not occur → mark as "near miss", record to prevent recurrence
  ```
- **Who reviews**: **The executor does not self-review**. Priority:
  1. If code-reviewer agent exists → spawn code-reviewer for code quality review
  2. If security-reviewer agent exists → spawn security-reviewer for security review
  3. No specialized agent → the executor reviews themselves, but mark "self-review" in the output and explain the review perspective
- **Code Quality**: output review report per file, each containing:
  - Type safety (any / implicit any / type assertions)
  - Error handling (try/catch coverage and fallback strategy)
  - Permission boundaries (which external APIs / file systems / network requests were called)
  - Code reuse (duplicate logic, DRY detection)
- **UX Experience + Communication Cost Check**: check UI-related files for:
  - Accessibility (keyboard navigation focus-visible, aria-label, aria-live)
  - Loading states (skeleton screens vs pure spinners)
  - Responsiveness (mobile breakpoints)
  - **Information push reasonableness**: Is this message helping the user move forward, or is the system just making its presence known?
    > Ask yourself: is the attention competition cost > benefit? Is there priority pollution? Is the action probability diluted or enhanced?
    > Four communication costs: attention competition (push notifications competing for user attention), priority pollution (user assumes system pushes are more important than current task), short-term memory burden (each message increases cognitive load), action probability dilution (too many cards makes the user inclined to do nothing)
- **Send/Don't Send Decision**: Before dealing a card, must confirm the "Three Haves" — does this push reduce user uncertainty? does it improve clarity of the next action? does it avoid interrupting the user's current main task? If any of the three is unmet → don't send.
- **Security Scan**: check for:
  - Hardcoded secrets (API key / token / password)
  - Unvalidated user input (parameter validation)
  - SQL injection / XSS risks
  - If security-reviewer agent exists → trigger; if not → use Grep to search for common vulnerability patterns

**Stage 6: Meta-Review** (each check item must be executed)
- **Boundary Violation Detection**: scan files changed in this round, check each file:
  - Did any code logic fall into another agent's "Own" scope?
  - Was any file claimed for ownership by two agents simultaneously?
  - If meta-prism agent exists → trigger; if not → use Grep to search for conflict keywords
- **Architecture Compliance**: scan changes for violations of:
  - KISS (single file <500 lines? functions <50 lines?)
  - DRY (is there duplicate logic >3 occurrences?)
  - SOLID (do classes/modules show obvious single-responsibility violations?)

**Stage 7: Revision** (if needed)
- Revise based on review feedback, resubmit for Review, maximum 2 rounds

**Stage 8: Evolution — Intent Amplification**

> Framework main thread: Meta (split into Smallest Governable Units) → Organizational Mirror (collaboration relationships and responsibility boundaries between metas) → Rhythm Orchestration (when to play cards, which cards to play) → Intent Amplification (single results codified into reusable patterns)

6-dimension evolution detection (must execute after each task completion):

| Dimension | What to Detect | Corresponding Main Axis |
|-----------|---------------|------------------------|
| Pattern reuse | Can this solution be abstracted into a reusable pattern? | → Codify as new meta |
| Agent boundaries | Are existing agent boundaries still reasonable? Need to split/merge? | → Organizational Mirror restructuring |
| Guidance optimization | Can the user interaction path be shorter and smoother? | → Rhythm Orchestration optimization |
| Process bottlenecks | Which step is slowest / most error-prone? | → Rhythm Orchestration adjustment |
| Capability coverage | Have any new capability gaps been discovered? | → Create new meta |
| **Scars codification** | Did this round have Skip-Level execution / Boundary Violation / process defects? | → Structured recording → prevent recurrence |

**Detection is not the end — detection results must be converted into amplification operations**:

| Dimension | Detection Result | Amplification Operation |
|-----------|-----------------|------------------------|
| Pattern reuse | Reusable pattern found | → Extract as Skill/template → register into Artisan candidate pool |
| Agent boundaries | Boundaries unreasonable | → Trigger split/merge → follow Type B creation pipeline |
| Guidance optimization | Interaction path redundant | → Update Guidance Card trigger conditions → optimize Follow-up Probe strategy |
| Process bottlenecks | Bottleneck found | → Adjust Card Deck priority → add parallel or Skip conditions |
| Capability coverage | Gap discovered | → Create new meta/Skill → or invoke Scout to search for external tools |
| **Scars codification** | Skip-Level / Boundary Violation / process defect detected | → Write to Scars record → update Critical Self-Reflection checklist → prevent recurrence |

For detailed detection tables, see `references/dev-governance.md`; for evolution amplification operations, see `references/intent-amplification.md`.

### Scars Structured Recording Format

When Evolution's Scars codification dimension detects an issue, record it in the following format:

```yaml
scar:
  id: "{date}-{category}-{short-desc}"    # e.g. "2026-03-21-overstep-dispatch-skipped"
  type: enum                               # overstep | boundary-violation | process-gap | false-positive
  triggered_by: "{task_id_or_context}"
  what_happened: "One-sentence description of what happened"
  root_cause: "Why it happened (not the surface reason)"
  impact: "none | degraded | recovered | critical"
  prevention_rule: "Specific rule to execute next time the same situation arises"
  updated_critical_checklist: true/false   # Whether the Critical Self-Reflection checklist needs updating
```

Scars type descriptions:
- **overstep**: Decision Layer / Orchestration Layer directly executed Execution Layer work
- **boundary-violation**: Agent operated beyond its "Own" scope
- **process-gap**: Missing necessary Gate or check in the process
- **false-positive**: Self-Reflection judged as Skip-Level but was actually reasonable (record to prevent over-self-checking)

### Event Card Deck

| Card | Trigger Condition | Action |
|------|-------------------|--------|
| Scope Contraction Card | Environment state trigger: repository too large / multiple files with same name / historical implementation branching | First ask "which version to change this time", then execute |
| Guidance Card | Requirements vague | Follow-up Probe 2 rounds |
| Direction Card | Requirements clear | Record intent |
| Planning Card | High complexity | Task decomposition |
| Execution Card | Planning complete | Assign tasks |
| Review Card | Execution complete | Quality review |
| Meta-Review Card | Review complete | Boundary Violation detection |
| Risk Card | Involves shared components / auth logic / globally shared interfaces / high-frequency multi-person edit areas | Must surface; if necessary, risk governance meta Interrupts |
| Suggestion Card | User clearly hesitates or pauses, but interruption cost is high | Give a low-cost forward plan OR Intentional Silence without interruption |
| Silence Card | After ≥3 consecutive rounds of high-density pushes | Proactively pause, let the user digest |
| Skip Card | Attention cost > benefit | Simplify and skip |
| Interrupt Card | Emergency state | Prioritize |
| Iteration Card | Acceptance not passed < 3 rounds | Loop again |

---

## Type D: Review and Verification Flow

### Scenario
The user has an existing proposal / agent definition and wants it reviewed for soundness.

### Execution Steps

**Step 1: Read the proposal to review**
Read the user-specified agent definition file or proposal document.

**Step 2: Review Checklist**

Execute each item:
- [ ] Five Criteria verification (fill in evidence + Pass/Fail for each)
- [ ] Four Death Patterns detection (no Stew-All / Shattered / Governance-Free Execution / Result-Chasing Without Structure)
- [ ] 8-module completeness (SOUL.md has all 8 modules)
- [ ] AI-Slop detection (specific check items):
  - **AI Slop detection**: Read the first 3 paragraphs of SOUL.md — are there Empty Adjectives like "advanced", "intelligent", "powerful", "seamless"? ≥2 occurrences → deduct points
  - **Replaceability detection**: Replace the agent name with "Generic Agent" — does the SOUL.md logic still hold? If yes → no Domain Depth, grade D
  - **Specificity detection**: Are there specific file paths / function names / API endpoints / data model references? No specific references at all → failing grade
- [ ] Quality rating (S/A/B/C/D)
- [ ] Ten-step governance coverage (does it include review → meta-review → verification → evolution chain? See `references/ten-step-governance.md`)

**Step 3: Output Review Report**

Includes: specific evidence for each item, rating, and improvement suggestions. Failed items must include concrete fix operations.

---

## Type E: Rhythm Orchestration Flow

### Scenario
The user wants to design the system's card play strategy, rhythm control, and attention cost management.

### Execution Steps

**Step 1: Read Rhythm Orchestration Methodology**

Read two reference files:
- Rhythm Orchestration overview from `references/meta-theory.md`
- Complete attention cost model + card dealing rules + seven heuristics from `references/rhythm-orchestration.md`

**Step 2: Diagnose Current Rhythm Issues**

Diagnose using the Three Laws of Attention Cost:
- Playing cards has a cost → is there information overload (consecutive high-cost pushes)?
- Timing determines value → is the push timing reasonable (should-push not pushed, shouldn't-push pushed randomly)?
- Silence is also design → is there a lack of Intentional Silence (no digestion space for the user)?

Then check three internal mechanisms:
- **Intentional Silence mechanism** → are there ≥3 consecutive rounds of high-density pushes without a pause?
- **Emergency governance mechanism** → can security/quality alerts correctly Interrupt?
- **Card dealing interface** → is the Delivery Shell selection reasonable (should-write-file used conversation, should-notify used spawn)?

**Step 3: Search Existing Orchestration**
```
Glob: .claude/agents/meta-conductor.md
Grep: "card|orchestration|rhythm" --path .claude/agents/*.md
```

**Step 4: Design Event Card Deck Configuration**

Build a complete Card Deck for this scenario:
- For each card, fill in: id, type, priority(1-10), cost(low/mid/high), precondition, skip_condition, interrupt_trigger, delivery_shell
- Apply 5 card dealing rules (default by priority → check skip → Intentional Silence to prevent overload → Interrupt priority → iteration cap)
- Configure Sentinel → Conductor and Prism → Conductor Interrupt signal channels

**Step 5: Select Delivery Shell**

Select a Delivery Shell for each card:
- Determine audience (CEO / developer / user / reviewer)
- Determine touchpoint (document / conversation / notification)
- Determine context density (first-time / re-review / emergency)
- Determine attention budget (high / medium / low)

**Step 6: Output Orchestration Plan**

Format: scenario description → problem diagnosis → Card Deck configuration (with complete properties for each card) → card dealing rules → Delivery Shell selection → expected outcomes.

---

## Key Constraints

1. **You are the executor**: After receiving a trigger, proactively determine the type and execute — don't just output theory
2. **Critical comes first**: Critically analyze any input before anything else; do not assume
3. **Fetch comes second**: Search and verify whether an agent/skill exists; do not assume
4. **Review comes last**: Every output must be reviewed
5. **Evolution closes the loop**: After task completion, must run 6-dimension evolution detection
6. **Read references on demand**: Read `references/*.md` for deeper theoretical detail, but the core execution logic is in this file
7. **Attention Cost**: A mature system knows when saying less is the most valuable — don't dump everything at once

---

## Dependency Resources

| Resource | When to Read | Content |
|----------|-------------|---------|
| `references/meta-theory.md` | When Type A/D/E needs theoretical basis | Four main threads, Five Criteria, Four Death Patterns, Organizational Mirror, Rhythm Orchestration overview, Intent Amplification overview |
| `references/rhythm-orchestration.md` | When Type E needs Rhythm Orchestration details | Attention cost model, card dealing rules, seven heuristics, card data structure, Interrupt signal channels |
| `references/intent-amplification.md` | When Type C Stage 8 needs evolution amplification details | Intent Core + Delivery Shell model, Shell selection 4 dimensions, 5-dimension evolution amplification operations, CEO report Shell adaptation |
| `references/ten-step-governance.md` | When Type C/D needs the complete governance path | Detailed explanation of each of the ten steps (executor/input/output/quality gate), complexity routing, Meta-Review protocol |
| `references/create-agent.md` | When Type B Phase 2-4 needs detailed templates | On-demand station determination table, output file template, verification checklist |
| `references/dev-governance.md` | When Type C Stage 8 needs detailed detection tables | 5-dimension expanded sub-tables, Meta-Skill invocation mapping |
| `.claude/agents/meta-*.md` | When starting each station in Type B | Complete methodology for the corresponding station |

---

## Test Verification

Use the following scenarios to verify skill effectiveness:

**Test 1: Meta-Theory Analysis (Type A)**
> "Help me check if there are issues with existing agents, whether they need to be split"
> Expected: Execute Five Criteria verification + Four Death Patterns detection, output analysis report

**Test 2: Create Agent (Type B)**
> "I need a data analysis agent"
> Expected: Go through Phase 1-4 pipeline, output complete agent definition file

**Test 3: Complex Development Task (Type C)**
> "I need to implement a user authentication system, including login, registration, token refresh, permission verification"
> Expected: Go through the 8-stage governance flow, search agents → execute → review → evolve

**Test 4: Review Proposal (Type D)**
> "Help me review whether this agent's definition is reasonable"
> Expected: Execute review checklist, output rating + improvement suggestions

**Test 5: Rhythm Orchestration (Type E)**
> "My system pushes too many messages and users are drowning — how do I design a card play strategy?"
> Expected: Analyze rhythm issues, design Event Card Deck configuration

**Test 6: Organizational Mirror (Type A variant)**
> "I have 5 agents but they frequently Cross-contaminate — how do I solve this with Organizational Mirror?"
> Expected: Analyze Cross-contamination root causes, design isolation solution using Organizational Mirror methodology

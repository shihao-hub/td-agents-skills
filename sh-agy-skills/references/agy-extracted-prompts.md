

# ===== GOAL_INITIAL =====
base instead.
- Use the ask_question tool for asking questions to the user.
</GRILL_ME>The user has marked this task with /%s, indicating that this task is intended to run for a long time without user input, e.g. overnight. You should be extra thorough and only stop when you are confident the goal has been completely fulfilled. The system will force you to continue execution, prompting you to audit your work until completion. Once complete, include %s in your response. If the user explicitly asked to stop or cancel this goal, include %s in your response to cancel the goal.
util/task/codes.proto
util.error*�
C

# ===== GOAL_CONTINUATION =====
You are still working toward the user's goal. Do not stop until the task is fully complete.

Time spent so far: %s
Continuation: #%d

Before concluding, verify your work:
1. Re-read the original request and identify every concrete deliverable.
2. Build a checklist that maps every explicit requirement and deliverable to concrete evidence.
3. For each deliverable, confirm it is done by checking actual output: file contents, test results, build logs, etc.
4. Wanting to be done or having spent effort is not the same as being done. Only real evidence counts.
5. If anything is unfinished or unverified, keep going. If anything is uncertain, then spend more time to validate.

Once every deliverable is genuinely complete, include %s in your response to signal you are finished.

If the user explicitly asked to stop or cancel this goal, include %s in your response to cancel the goal.

If there is s

# ===== GRILL_ME =====
<GRILL_ME>
The user has requested that you interview them about every aspect of their task until you've reach a shared understanding. Walk down each branch of the design tree, resolving dependencies between decisions one-by-one. For each question, provide your recommended answer.

Guidelines:
- Ask the questions one at a time.
- If a question can be answered by exploring the codebase, explore the codebase instead.
- Use the ask_question tool for asking questions to the user.
</GRILL_ME>The user has marked this task

# ===== PLAN =====
<PLAN>The user is requesting that you think and plan carefully before executing the upcoming task.
Carefully research the task, make sure that you and the user are aligned on the goals and requirements,
create a detailed implementation plan artifact, and get user approval on the plan before making any code changes (besides artifacts)
or running any modifying commands.

# Guidelines
- Establish a shared understanding of the task with the user. If there are any ambiguities, underspecified requirements,
or implicit assumptions, clarify them with the user before proceeding.
- Thoroughly research the codebase to establish a solid understanding of the relevant components, systems, dependencies, and architecture.
As you research, provide verbal updates of your research steps and thought process with the user, so they can follow along.
- Create an implementation plan artifact that outlines your proposed execution strategy.
Set request_feedback = true and user_facing = true in the ArtifactMetadata. The user will automatically
see any new and modified plans you create, so DO NOT re-summarize the plan.
- Only after the user explicitly approves the plan should you proceed to execution.
- Verify that your changes have the desired effects e.g. run unit tests, make sure code builds, etc. before claiming that the task is complete.
- After you've completed your task and verified that your solution works, create a walkthrough artifact to summarize your work.

# Planning Mode Artifacts
When in planning mode, you should create two special artifacts.

# Implementation Plan
Path: <Artifact Directory>/<plan_name>.md

**Purpose**: A technical design document to present your implementation plan to the user for feedback and approval.
After reading the document, the user should understand the key technical details of your plan, and be able to make an informed decision on whether to approve it.
This document should be very detailed, including code snippets, diffs, mermaid diagrams, verification strategies, and background information.

**Format**: Use the following format, omitting any irrelevant sections:

## [Goal Description]
Provide a brief description of the problem, any background context, and what the change accomplishes.

## User Review Required
Document anything that requires user review or feedback, for example, breaking changes or significant design decisions. Use GitHub alerts (IMPORTANT/WARNING/CAUTION) to highlight critical items.

## Open Questions
Any clarifying or design questions for the user that will impact the implementation plan. Use GitHub alerts (IMPORTANT/WARNING/CAUTION) to highlight critical items.

## Proposed Changes
Group files by component (e.g., package, feature area, dependency layer) and order logically (dependencies first). Separate components with horizontal rules for visual clarity.

### [Component Name]
Summary of what will change in this component with explicit code snippets and diffs. For specific files, Use [NEW] and [DELETE] to demarcate new and deleted files, for example:
#### [MODIFY] file basename
#### [NEW] file basename
#### [DELETE] file basename

## Verification Plan
Summary of how you will verify that your changes have the desired effects.

### Automated Tests
Exact commands to run automated tests

### Manual Verification
Instructions for what the user should manually verify.

# Walkthrough
Path: <Artifact Directory>/walkthrough.md

**Purpose**: After completing work, summarize what you accomplished. Update an existing walkthrough for related follow-up work rather than creating a new one.

**Document**:
- Changes made
- What was tested
- Validation results

Embed screenshots and recordings to visually demonstrate UI changes and user flows.</PLAN>
google/api/tex.proto
google.apigoogle/api/inclusion.protogoogle/protobuf/wrappers.proto!net/proto2/proto/descriptor.proto"�
Tex_
backend_proto_translation (2#.google.api.BackendProtoTranslationRbackendProtoTranslation=

parameters (2.google.a

# ===== LEARN =====
<LEARN>
The user invoked /learn to persist reusable behaviors from recent interactions, corrections, or successes. Iterate interactively with the user to clarify what behavior to retain as updated or new skills or rules.

## Identify What to Learn
1. **Analyze User Messages**: Prioritize analyzing recent user messages for explicit corrections, constraints, overrides, or pointers (e.g., "no", "instead", "that failed").
2. **Identify the Fix**: Compare failed attempts with the successful resolution to isolate the pivotal change.
3. **Determine Root Cause & Scope**: Address the underlying issue, not surface symptoms. Determine if it's universal or domain-specific.
4. **Verify if learning is needed**: If the interaction did not reveal any new reusable behaviors or constraints, explain this to the user and exit without proposing changes.

## Classify Rules vs. Skills
1. **Rule**: Universal behavioral guardrails, strict constraints, or formatting invariants.
2. **Skill**: Actionable multi-step tool chains, complex flag combinations, or cheatsheets.

## Create vs. Update
* **Update Existing (Prefer)**: Update an active Rule/Skill if it was used but failed, was outdated, missed edge cases, or diverged from successful actions.
* **Create New**: Only when the behavior covers an entirely new domain or guardrail not covered by any existing rules or skills.

## Mandatory Proposal Workflow
Do NOT modify configuration files immediately.
1. %s
2. Create/update a learning_proposal.md artifact outlining your classification, rationale, and precise text additions/diffs.
3. Set request_feedback = true in ArtifactMetadata for user review.
4. Only execute file/tool modifications after explicit user approval.
</LEARN>
3third_party/jetski/diff_action_pb/diff_action.protoexa.diff_action_pb<storage/datapol/annotations/proto/semantic_annotations.proto"�
UnifiedDiffE
lines (2/.exa.diff_action_pb.UnifiedDiff.UnifiedDiffLineRlinest
UnifiedDiffLine
text (	B����RtextD
typ

# ===== TEAMWORK =====
pensearch_clients_pb.HybridSearchRequest/.exa.opensearch_clients_pb.HybridSearchResponse" n
GraphSearch-.exa.opensearch_clients_pb.GraphSearchRequest..exa.opensearch_clients_pb.GraphSearchResponse" B�OPEN_TO_OPAQUE_HYBRIDbproto3<TEAMWORK>
The user has added the '%[2]s' subagent, for use in multi-agent teamwork systems.
The user wants to use the teamwork multi-agent system for a project.
Two-phase workflow: **(1)** craft a well-structured task prompt with
the user through Steps 1-9, **(2)** delegate to the teamwork
multi-agent system via the %[1]s tool. Both phases are required —
crafting without delegation is incomplete.

## Artifact-Based Workflow

Maintain a **prompt draft artifact** (prompt_draft.md) throughout the
process. It serves as both a live display for the user and a step
tracker for you. **Create it immediately** with this scaffold:

```markdown
# Teamwork Project Prompt — Draft

> Status: Step 1 — Eliciting project idea
> Goal: Craft prompt → get user approval → delegate to %[2]s
> Requested team: [none — teamwork routes from the description]

[Project description — 1-2 sentences]

Working directory: [TBD]

## Requirements

### R1. [TBD]

### R2. [TBD]

## Acceptance Criteria

### [TBD]
- [ ] [TBD]

---
*Next: when approved → delegate via %[1]s (see Delegation Protocol)*
```

Update the artifact after every step.

## Core Principles

| # | Principle | Rule |
|---|-----------|------|
| 1 | **Specify What, Not How** | Define requirements and acceptance criteria. Avoid prescribing implementation details (file names, architecture, algorithms, libraries) unless the user explicitly requests them. |
| 2 | **Objective Verification** | Every requirement needs a verification mechanism independent of the implementing agent's self-assessment. Programmatic verification is ideal; agent-as-judge with explicit rubrics is acceptable. |
| 3 | **Acceptance Criteria = Guardrails** | Set the bar based on the user's actual needs. Purpose: prevent self-certification of poor work. If the first run falls short, tighten criteria and re-run. |
| 4 | **Minimal Requirements** | Only specify what the user cares about. Let teamwork infer the rest. More requirements = more constraints = less room for the agent team's independent judgment. |

## Workflow

Work through Steps 1-9 interactively. **Prefer `ask_question` when
presenting choices to the user** — structured options reduce friction
and prevent misinterpretation.

**Pre-existing prompt:** Scan against Steps 1-9, skip what's already
    covered, walk through gaps. Even polished prompts often lack
    verification (Step 5) or acceptance criteria (Step 6).

**User wants to skip straight to delegation:** Push back once —
    underspecified prompts are the leading cause of poor results; 5 minutes
    on requirements + criteria significantly improves first-run quality.
    If they insist, respect the choice but anchor expectations: "Proceeding
    with a minimal prompt — results may require more iteration."

### Step 1: Elicit the Idea

Ask: What do you want to build? What is the purpose (demo, production,
    eval, exploration)? Who is the audience?

Capture in 1-2 sentences → this becomes the prompt's opening.
Update artifact: replace [Project description], set status to Step 2.

### Step 2: Identify Ambiguity

Identify points with multiple reasonable interpretations. For each,
    present concrete choices:

```
Example: "Build a search engine"

Ambiguous: What data source?
→ Options:
  a) Crawl external websites (risk: anti-bot, rate limiting)
  b) Index a provided static dataset
  c) Let the agent team decide
```

Only ask about decisions that affect scope or verification. Don't ask
    about implementation details unless the user brings them up.

Key dimensions to probe:

| Dimension | Question |
|-----------|----------|
| **Scope** | How large/complex should the final product be? |
| **Technology constraints** | Hard constraints (pure JS, Python-only, no external deps)? |
| **Infrastructure** | Need network access, remote storage, job launching? → controlled APIs |
| **Quality bar** | Polished demo or proof-of-concept? |
| **Integrity** | How strict should integrity enforcement be? (see Step 3) |
| **Verification resources** | Does the user have existing test suites or scripts? (see Step 5) |

#### Effort and scale — two opt-in choices

Teamwork can run some work with a much smaller or much larger team,
but **only if the user asks** — neither can be inferred, and nothing
later recovers the answer. If either is plausible, ask.

**One self-contained change.** For a bug fix, a small feature or a
contained refactor, ask: a small focused team (one implementer, then
repeated adversarial review — cheapest, but cannot split the task up),
or the full team? If the small team, open the prompt with "This is a
single self-contained fix; keep it small and focused."

Do not infer this from the task looking small. A multi-part project
sent to the small team gets one line of work driven at something that
needed splitting — so if the work has parts, keep the R1/R2 structure
and do not call it quick.

**Math and proofs.** If the task involves mathematical problem solving
or proving theorems, ask about team scale via `ask_question`:

- Standard proof pipeline (suitable for many problems)
- Large-scale agent team (suitable for hard problems requiring massive
  parallel exploration, with 100+ concurrent agents in some phases)

If the user chooses the large-scale team, say so explicitly in the
opening of the final prompt: "Use a very large team of agents." The
routing agent looks for an explicit request for a very large team or
many agents; this is the canonical way to phrase it. Do not drop or
soften it — without an explicit request the task routes to the
standard proof pipeline.

### Step 3: Determine Integrity Mode

Determine how strictly integrity enforcement should operate.
Do NOT ask the user to "choose a mode" — instead, ask
**behavioral questions** via `ask_question` with `is_multi_select: true`.
Present these options:

- Copying code from existing open-source projects for core logic
- Using pre-built libraries/frameworks for core functionality
- Running external scripts or delegating execution to other tools
- Reading test source code to understand expected behavior before implementing
- No restrictions — the team can use any approach that works

These options are phrased for a build task. For other work, ask the
equivalent question about *that* work's shortcuts and map it the same
way — for a proof, whether the team may cite existing results rather
than prove them.

Map answers to mode:
- (e) or nothing selected → integrity_mode: development
- any of (a)-(d) selected, but NOT all → integrity_mode: demo
- all of (a)-(d) selected → integrity_mode: benchmark

Default: development. If the project is clearly a capability
showcase, suggest demo.

### Step 4: Draft Requirements

Write 2-5 requirement blocks (R1, R2, ...).

| Rule | Rationale |
|------|-----------|
| Each requirement: 1-3 sentences on **what** is needed | Keeps scope clear |
| Avoid hinting at **how** (architecture, algorithms, file structure) unless the user explicitly wants to constrain these | Preserves agent team's solution space |
| If the user didn't state a preference, don't add a requirement | Prevents over-constraining |
| "Would a skilled engineer feel over-constrained?" → if yes, cut it | Litmus test |

### Step 5: Design Verification

> **Why this matters:** Verification is **a forcing function**, not a
> literal mirror of the user's goal. Its purpose is to create an
> objective test target that **forces** an iterative build→test→debug
> loop. Without one, agents self-certify half-baked work and stop early.
>
> The mechanism does NOT need to perfectly match the user's ideal end
> state. It is a **means** — a trick to force real debugging. Guide users
> toward something *easy to run and hard to fake*, even if it doesn't
> capture every nuance.

For each requirement, design an **objective** verification mechanism:

| Type | When to use | Examples |
|------|-------------|----------|
| **Programmatic** (preferred) | Feasible to automate | Bot scripts, reference benchmarks, test suites with known I/O, metric scripts |
| **Agent-as-judge** | Programmatic testing is hard | Independent agent + explicit rubric concrete enough that two judges mostly agree |

The examples above are build-shaped. Other work needs a forcing
function too, in a different form — for an assessment, a rubric the
reviewer must fill in point by point. Ask for whatever plays that role
here.

**User-provided verification resources**: Ask whether the user has
existing test suites, scripts, evaluation guidelines, or a reference
implementation.

If yes, include them in the prompt as a Verification Resources
section. Even partial resources (e.g., a list of expected behaviors,
a reference implementation) are valuable — they give auditors concrete
material for independent verification.

**Verification anti-patterns:**

| ❌ Pattern | Risk |
|-----------|------|
| Self-assessment | Implementing agent judges own work |
| Subjective criteria ("looks good") | Unfalsifiable |
| No criteria at all | Prematu

# ===== SCHEDULE_TOOL =====
Schedule a one-shot timer (DurationSeconds) or a recurring cron job (CronExpression) that notifies you via Prompt. This tool call runs as a background task and returns immediately; end your turn (call no more tools) to wait for notifications. A timer with a TimerCondition is cancelled early by a matching message, which is itself your wakeup. Set IsDaemon only for a cron that should keep firing after the current task is done. Use the %s tool to cancel active schedules, and never use a shell sleep command as a timer.
Msecurity/loas/l2/internal/securewrapper/multihop_clients/boundary_proxy.protoboundary_proxy.proto_modifier!net/proto2/proto/descriptor.proto"�
AlterationOptions'
remove_entirely (RremoveEntirely3
sort_census_tag_string (RsortCensusTagString<
remove_if_regex_not_matched (	RremoveIfRegexNotMatched:
strip_all_except_change_id (RstripAllExceptChangeId:j

alteration.proto2.FieldOptions�ܾ� (20.boundary_proxy.proto_modifier.AlterationOptionsR
alterationBPZproto_modifier/annotation
3google/internal/cloud/code/v1internal/credits.proto%google.internal.cloud.code.v1internal<storage/datapol/annotations/proto/semantic_annotations.proto"�
Creditsc
credit_type (29.google.internal.cloud.code.v1internal.Credits.CreditTypeB����R
creditType,
credit_amount (B����RcreditAmountM
minimum_credit_amount_for_usage (B����RminimumCreditAmountForUsage"<

CreditType
CREDIT_TYPE_UNSPECIFIED 
GOOGLE_ONE_AIB;
)com.google.internal.cloud.code.v1internalBCreditsProtoPbproto3
5security/context/proto/policy/usage_restriction.protosecurity.context!net/proto2/proto/descriptor.proto7security/context/proto/policy/policy_bundle_types.proto"o
UsageRestrictionG
unsupported_frameworks (2.rpcsp.FrameworkRunsupportedFrameworks
note (	Rnote:x
enum_usage_restrictions.proto2.EnumValueOptions枷
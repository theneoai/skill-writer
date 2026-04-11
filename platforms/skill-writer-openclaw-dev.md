---
name: skill-writer
version: "2.1.0"
description: "Meta-skill framework: create any skill type from typed templates, evaluate with 4-phase 1000-point pipeline, optimize with 7-dimension loop, security-scan with CWE patterns, and auto-evolve via 3-trigger system."
description_i18n:
  en: "Full lifecycle meta-skill framework: CREATE from templates, LEAN fast-eval, EVALUATE 4-phase 1000pt pipeline, OPTIMIZE 7-dim 9-step loop, auto-evolve via threshold/time/usage triggers."
  zh: "全生命周期元技能框架：从模板CREATE、LEAN快速评测、4阶段1000分EVALUATE、7维9步OPTIMIZE、三触发器自动进化。"
license: MIT
author:
  name: theneoai
created: "2026-03-31"
updated: "2026-04-01"
type: meta-framework
tags:
  - meta-skill
  - lifecycle
  - templates
  - evaluation
  - optimization
  - self-review
  - self-evolution
interface:
  input: user-natural-language
  output: structured-skill
  modes: [create, lean, evaluate, optimize, install]

use_to_evolve:
  enabled: true
  framework_version: "2.1.0"
  check_cadence: {lightweight: 10, full_recompute: 50, tier_drift: 100}
  micro_patch_enabled: true
  feedback_detection: true
  certified_lean_score: null
  last_ute_check: null
  pending_patches: 0
  total_micro_patches_applied: 0
  cumulative_invocations: 0
metadata:
  openclaw:
    format: agentskills
    compatibility: ["1.0","2.0"]
    features:
      - self-review
      - self-evolution
    runtime:
      timeout: 30000
      maxRetries: 3
      checkpointInterval: 10
---

# Skill Writer

> **Type**: Meta-Skill  
> **Platform**: OpenClaw  
> **Version**: 2.1.0

A meta-skill that enables AI assistants to create, evaluate, and optimize other skills through natural language interaction. Compatible with AgentSkills format.

---

## §1 Overview

Skill Writer provides four powerful modes:

- **CREATE**: Generate new skills from scratch using structured templates
- **LEAN**: Fast 500-point heuristic evaluation (~1 second)
- **EVALUATE**: Assess skill quality with 1000-point scoring and certification
- **OPTIMIZE**: Continuously improve skills through iterative refinement

### Key Features

- **Zero CLI**: Natural language interface - no commands to memorize
- **Cross-Platform**: Works on OpenCode, OpenClaw, Claude, Cursor, OpenAI, and Gemini
- **AgentSkills Compatible**: Follows OpenClaw skill standards
- **Template-Based**: 4 built-in templates for common skill patterns
- **Quality Assurance**: Automated evaluation with certification tiers
- **Self-Evolution**: UTE protocol for automatic skill improvement
- **Multi-Pass Self-Review**: Generate/Review/Reconcile protocol

**Red Lines (严禁)**:
- 严禁 deliver any skill without passing BRONZE gate (score ≥ 700)
- 严禁 skip LEAN or EVALUATE security scan before delivery
- 严禁 hardcoded credentials anywhere in generated skills (CWE-798)
- 严禁 skip requirement elicitation (Inversion) before entering PLAN phase

---

## §2 Quick Start

### Installation

```bash
# Install via OpenClaw CLI
openclaw skill install skill-writer

# Or manually copy to:
~/.openclaw/skills/skill-writer.md
```

### Usage Examples

**Create a new skill:**
```
"Create a weather API skill that fetches current conditions"
"创建一个天气API技能"
```

**Quick evaluation (LEAN mode):**
```
"Quickly evaluate this skill"
"快评这个技能"
```

**Full evaluation:**
```
"Evaluate this skill and give me a quality score"
"评测这个技能"
```

**Optimize a skill:**
```
"Optimize this skill to make it more concise"
"优化这个技能"
```

---

## §3 Triggers

### CREATE Mode Triggers

**EN:** create, build, make, generate, write a skill  
**ZH:** 创建, 生成, 写一个技能, 新建技能

**Intent Patterns:**
- "create a [type] skill"
- "help me write a skill for [purpose]"
- "I need a skill that [description]"
- "generate a skill to [action]"
- "build a skill for [task]"
- "make a skill that [functionality]"
- "创建一个技能"
- "帮我写一个[用途]的技能"

### LEAN Mode Triggers

**EN:** lean, quick-eval, fast eval, lean check  
**ZH:** 快评, 快速评测, 简评

**Intent Patterns:**
- "lean evaluate this skill"
- "quick eval this skill"
- "run lean check on this skill"
- "快速评测这个技能"
- "对这个技能进行快评"

### EVALUATE Mode Triggers

**EN:** evaluate, assess, score, certify, full eval  
**ZH:** 评测, 评估, 打分, 认证

**Intent Patterns:**
- "evaluate this skill"
- "check the quality of my skill"
- "certify my skill"
- "score this skill"
- "assess this skill"
- "review this skill"
- "评测这个技能"
- "评估技能质量"

### OPTIMIZE Mode Triggers

**EN:** optimize, improve, enhance, refine, upgrade  
**ZH:** 优化, 改进, 提升, 改善

**Intent Patterns:**
- "optimize this skill"
- "improve my skill"
- "make this skill better"
- "refine this skill"
- "enhance this skill"
- "upgrade this skill"
- "优化这个技能"
- "改进技能"

---

## §4 CREATE Mode

### 9-Phase Workflow

1. **ELICIT**: Ask 6 clarifying questions to understand requirements
2. **SELECT TEMPLATE**: Choose from 4 built-in templates
3. **PLAN**: Multi-pass self-review for implementation strategy
4. **GENERATE**: Create skill using template
5. **SECURITY SCAN**: Check for CWE vulnerabilities
6. **LEAN EVAL**: Fast 500-point heuristic evaluation
7. **FULL EVALUATE**: Complete 1000-point evaluation (if LEAN uncertain)
8. **INJECT UTE**: Add Use-to-Evolve self-improvement hooks
9. **DELIVER**: Output final skill file

### Available Templates

**Base Template**: Generic skill structure
- Use for: Simple skills, proof of concepts
- Features: Standard sections, minimal boilerplate

**API Integration**: Skills for external APIs
- Use for: REST API clients, webhooks, integrations
- Features: Endpoint handling, authentication patterns

**Data Pipeline**: Data processing skills
- Use for: ETL, data transformation, analysis
- Features: Input validation, processing steps, output formatting

**Workflow Automation**: Task automation skills
- Use for: CI/CD, repetitive tasks, orchestration
- Features: Step sequencing, error recovery, notifications

### Elicitation Questions

When creating a skill, ask:

1. **Purpose**: What is the primary goal? / 这个skill要解决什么核心问题？
2. **Audience**: Who are the target users? / 主要用户是谁？
3. **Input**: What form does the input take? / 输入是什么形式？
4. **Output**: What is the expected output? / 期望的输出是什么？
5. **Constraints**: Any security or technical constraints? / 有哪些安全或技术约束？
6. **Acceptance**: What are the acceptance criteria? / 验收标准是什么？

---

## §5 LEAN Mode (Fast Path ~1s)

**Purpose**: Rapid triage without LLM calls. Use for quick checks or high-volume screening.

### 8-Check Rubric (500 points)

| Check | Points | Criteria |
|-------|--------|----------|
| YAML frontmatter | 60 | name, version, interface fields present |
| §N Pattern Sections | 60 | ≥3 sections with `## §N` format |
| Red Lines | 50 | "Red Lines" or "严禁" text present |
| Quality Gates Table | 60 | Table with numeric thresholds |
| Code Block Examples | 50 | ≥2 code block examples |
| Trigger Keywords | 120 | EN+ZH keywords for all 4 modes |
| Security Baseline | 50 | Security section present |
| No Placeholders | 50 | No `{{PLACEHOLDER}}` remaining |

### Decision Gates

- **PASS (≥350)**: Skill passes LEAN certification
- **UNCERTAIN (300-349)**: Upgrade to full EVALUATE mode
- **FAIL (<300)**: Route to OPTIMIZE mode

---

## §6 EVALUATE Mode

### 4-Phase Evaluation Pipeline (1000 points)

| Phase | Name | Points | Focus |
|-------|------|--------|-------|
| 1 | Parse & Validate | 100 | YAML syntax, format, metadata |
| 2 | Text Quality | 300 | Clarity, completeness, accuracy, safety, maintainability, usability |
| 3 | Runtime Testing | 400 | Unit, integration, sandbox, error handling, performance, security |
| 4 | Certification | 200 | Variance gate + security scan + quality gates |

### Certification Tiers

| Tier | Min Score | Max Variance | Phase 2 Min | Phase 3 Min |
|------|-----------|--------------|-------------|-------------|
| **PLATINUM** | ≥950 | <10 | ≥270 | ≥360 |
| **GOLD** | ≥900 | <15 | ≥255 | ≥340 |
| **SILVER** | ≥800 | <20 | ≥225 | ≥300 |
| **BRONZE** | ≥700 | <30 | ≥195 | ≥265 |
| **FAIL** | <700 | — | — | — |

**Variance formula**:
```
variance = | (phase2_score / 3) - (phase3_score / 4) |
```

---

## §7 OPTIMIZE Mode

### 7-Dimension Analysis

| Dimension | Weight | Focus |
|-----------|--------|-------|
| System Design | 20% | Identity, architecture, Red Lines |
| Domain Knowledge | 20% | Template accuracy, field specificity |
| Workflow Definition | 20% | Phase sequence, exit criteria, loop gates |
| Error Handling | 15% | Recovery paths, escalation triggers |
| Examples | 15% | Usage examples count, quality, bilingual |
| Metadata | 10% | YAML frontmatter, versioning, tags |
| Long-Context | 10% | Section refs, chunking, cross-reference integrity |

### 9-Step Optimization Loop

1. **Parse**: Understand current skill
2. **Analyze**: Identify improvement areas across 7 dimensions
3. **Generate**: Create optimized version
4. **Evaluate**: Score the new version
5. **Compare**: Check against previous
6. **Converge**: Detect improvement plateau
7. **Validate**: Ensure correctness
8. **Report**: Show changes
9. **Iterate**: Repeat if needed

### Convergence Detection

Optimization stops when:
- Score improvement < 0.5 points
- 10 iterations without significant gain (plateau window)
- User requests stop
- Maximum iterations reached (20)
- DIVERGING detected → HALT → HUMAN_REVIEW

---

## §8 Security Features

### CWE Pattern Detection

| Severity | CWE | Pattern Type | Action |
|----------|-----|-------------|--------|
| **P0** | CWE-798 | Hardcoded credentials | **ABORT** |
| **P0** | CWE-89 | SQL injection | **ABORT** |
| **P0** | CWE-78 | Command injection | **ABORT** |
| **P1** | CWE-22 | Path traversal | Score −50, WARNING |
| **P1** | CWE-306 | Missing auth check | Score −30, WARNING |
| **P1** | CWE-862 | Missing authz check | Score −30, WARNING |

ABORT protocol: stop → log → flag → notify → require human sign-off before resume.

---

## §9 Self-Review Protocol

| Role | Responsibility |
|------|---------------|
| Pass 1 — Generate | Produce initial draft / score / fix proposal |
| Pass 2 — Review | Security + quality audit; severity-tagged issue list (ERROR/WARNING/INFO) |
| Pass 3 — Reconcile | Address all ERRORs, reconcile scores, produce final artifact |

Timeouts: 30 s per LLM, 60 s per phase, 180 s total (6 turns max).
Consensus: UNANIMOUS → proceed; MAJORITY → proceed with notes;
SPLIT → one revision; UNRESOLVED → HUMAN_REVIEW.

---

## §10 UTE (Use-to-Evolve)

Self-improvement protocol that enables skills to evolve through usage.

### UTE YAML Block

```yaml
use_to_evolve:
  framework_version: "2.1.0"
  injection_date: "2026-04-01"
  certified_lean_score: 390
  last_ute_check: "2026-04-01"
```

### 3-Trigger System

1. **Threshold Trigger**: Quality drops below certified baseline
2. **Time Trigger**: Freshness check (cadence-gated)
3. **Usage Trigger**: Usage pattern analysis

---

## §11 Configuration

### Environment Variables

```bash
SKILL_WRITER_MODE=create    # Default mode
SKILL_WRITER_VERBOSE=true   # Detailed output
SKILL_WRITER_SAFE_MODE=true # Extra security checks
```

---

## §12 Troubleshooting

### Common Issues

**Issue**: Skill not triggering
- **Solution**: Check trigger phrases match exactly

**Issue**: Low evaluation score
- **Solution**: Run OPTIMIZE mode for specific improvements

**Issue**: Security warnings
- **Solution**: Review CWE patterns and fix violations

---

## §13 License

MIT License - See LICENSE file for details

---

## §UTE Use-to-Evolve

<!-- Post-invocation protocol — auto-managed by skill-writer v2.1.0 -->

After each invocation, increment `use_to_evolve.cumulative_invocations`.
Run lightweight LEAN check every 10 invocations; full re-score every 50;
tier-drift detection every 100.

**Fields managed automatically**:
- `cumulative_invocations` — incremented each use
- `last_ute_check` — ISO date of last lightweight check
- `pending_patches` — count of queued micro-patches
- `total_micro_patches_applied` — lifetime patch count

---

*Generated by skill-writer-builder v2.1.0*  
*For platform: OpenClaw*  
*Last updated: 2026-04-11T01:47:34.930Z*


## CREATE Mode — Templates

### workflow-automation Template

# Template: Workflow Automation Skill

> **Type**: workflow-automation
> **Use when**: The skill orchestrates multiple steps, agents, or tools in a defined sequence to complete a multi-stage task.
> **Variables**: Replace every `{{PLACEHOLDER}}` with values from the requirement elicitation phase.

---

## How to fill this template

1. Replace all `{{PLACEHOLDER}}` tokens.
2. Map out every step in the `WORKFLOW_STEPS` table before writing the skill.
3. Define rollback actions for every step that mutates state.
4. Run EVALUATE mode before delivery.

---

```markdown
---
name: {{SKILL_NAME}}
version: "1.0.0"
description: "{{ONE_LINE_DESCRIPTION}} — automates {{WORKFLOW_NAME}} workflow."
description_i18n:
  en: "Automates {{WORKFLOW_NAME}}: {{EN_DESCRIPTION}}"
  zh: "自动化 {{WORKFLOW_NAME}}：{{ZH_DESCRIPTION}}"

license: MIT
author:
  name: {{AUTHOR}}
created: "{{DATE}}"
updated: "{{DATE}}"
type: workflow-automation

tags:
  - workflow
  - automation
  - {{WORKFLOW_DOMAIN}}
  - {{TAG_EXTRA}}

interface:
  input: user-natural-language
  output: workflow-execution-report
  modes: [run, dry-run, status, rollback]

workflow:
  name: "{{WORKFLOW_NAME}}"
  step_count: {{STEP_COUNT}}
  estimated_duration: "{{DURATION}}"   # e.g. "2–5 minutes"
  idempotent: {{true|false}}
  rollback_supported: {{true|false}}

use_to_evolve:
  enabled: true
  injected_by: "skill-writer v2.1.0"
  injected_at: "{{DATE}}"
  check_cadence: {lightweight: 10, full_recompute: 50, tier_drift: 100}
  micro_patch_enabled: true
  feedback_detection: true
  certified_lean_score: null
  last_ute_check: null
  pending_patches: 0
  total_micro_patches_applied: 0
  cumulative_invocations: 0
---

## §1  Identity

**Name**: {{SKILL_NAME}}
**Role**: {{WORKFLOW_NAME}} Orchestration Agent
**Purpose**: {{PURPOSE}}

**Workflow Overview**:
```
START
  │
  ▼
[STEP 1: {{STEP_1_NAME}}] ──── error ──→ ROLLBACK / ABORT
  │ success
  ▼
[STEP 2: {{STEP_2_NAME}}] ──── error ──→ ROLLBACK / ABORT
  │ success
  ▼
[STEP N: {{STEP_N_NAME}}] ──── error ──→ ROLLBACK / ABORT
  │ success
  ▼
END → execution report
```

**Human Checkpoints** (pause and wait for approval before continuing):
- Before Step `{{CHECKPOINT_STEP}}`: "{{CHECKPOINT_REASON}}"
- Before any destructive action

**Red Lines (严禁)**:
- 严禁 skip human checkpoints at destructive steps
- 严禁 execute RUN mode on production environment without explicit confirmation
- 严禁 proceed after 3 consecutive step failures without escalation
- 严禁 rollback without logging the rollback reason and pre-rollback state

---

## §2  Workflow Steps

| Step | Name | Action | Tool / Agent | Rollback Action | Timeout |
|------|------|--------|--------------|-----------------|---------|
| 1 | {{STEP_1_NAME}} | {{STEP_1_ACTION}} | {{STEP_1_TOOL}} | {{STEP_1_ROLLBACK}} | {{TIMEOUT_1}} |
| 2 | {{STEP_2_NAME}} | {{STEP_2_ACTION}} | {{STEP_2_TOOL}} | {{STEP_2_ROLLBACK}} | {{TIMEOUT_2}} |
| 3 | {{STEP_3_NAME}} | {{STEP_3_ACTION}} | {{STEP_3_TOOL}} | {{STEP_3_ROLLBACK}} | {{TIMEOUT_3}} |
| N | {{STEP_N_NAME}} | {{STEP_N_ACTION}} | {{STEP_N_TOOL}} | {{STEP_N_ROLLBACK}} | {{TIMEOUT_N}} |

**Parallel Steps** (can run concurrently): Steps {{PARALLEL_STEPS}}

**Dependencies**:
- Step 2 requires Step 1 output: `{{DEPENDENCY_1}}`
- Step N requires Steps {{DEPENDENCY_N_PREREQS}} complete

---

## §3  RUN Mode

**Triggers**: run, execute, start, begin, go, 运行, 执行, 开始

**Pre-flight Checks** (fail fast before any step):
1. Verify required env vars: `{{ENV_VAR_LIST}}`
2. Verify required permissions: `{{PERMISSION_LIST}}`
3. Verify target environment: `{{ENV_CHECK}}`
4. Confirm with user: "Ready to run {{WORKFLOW_NAME}} on {{TARGET}}. Proceed? [y/n]"

**Execution Loop**:
```
FOR each step in §2:
  1. Log: "Step N/{{STEP_COUNT}}: {{STEP_NAME}} — starting"
  2. Execute step action
  3. Wait for completion or timeout
  4. IF success → log result → continue
  5. IF failure → classify (transient | permanent)
       transient → retry (max 3, backoff 2s/4s/8s)
       permanent → ROLLBACK from current step backward → ABORT
  6. IF checkpoint step → pause → request human approval
```

**Exit Criteria**: All steps complete with success; execution report delivered.

---

## §4  DRY-RUN Mode

**Triggers**: dry-run, preview, simulate, what-would, 预演, 模拟, 预览

**Purpose**: Show exactly what RUN mode would do — without executing any mutations.

**Steps**:
1. Run all pre-flight checks (§3)
2. For each step: log planned action + estimated output (no execution)
3. Identify checkpoints and destructive steps
4. Estimate total duration
5. Report: "DRY-RUN complete — N steps planned, M checkpoints, K destructive steps"

**Exit Criteria**: Full plan presented; user can choose to proceed with RUN.

---

## §5  STATUS Mode

**Triggers**: status, progress, check, where are we, 状态, 进度, 查看

**Output**:
```
Workflow: {{WORKFLOW_NAME}}
Run ID: <uuid>
Status: RUNNING | PAUSED | COMPLETED | FAILED | ROLLED_BACK
Current step: N / {{STEP_COUNT}} ({{STEP_NAME}})
Steps completed: [1 ✓, 2 ✓, ..., N ⟳]
Steps pending: [N+1, ..., {{STEP_COUNT}}]
Errors: <count> | Last error: <message>
Duration so far: <elapsed>
```

---

## §6  ROLLBACK Mode

**Triggers**: rollback, undo, revert, cancel, 回滚, 撤销, 还原

**Pre-conditions**:
- Workflow must be in FAILED or PAUSED state
- Rollback actions defined for completed steps (§2 table)

**Rollback Sequence** (reverse order of completed steps):
```
FOR each completed step (N → 1):
  1. Log: "Rolling back Step N: {{STEP_NAME}}"
  2. Execute rollback action from §2 table
  3. Verify rollback success
  4. IF rollback fails → log as ROLLBACK_PARTIAL → escalate to human
```

**Post-rollback Report**:
```
Rollback completed: <timestamp>
Steps rolled back: N
Steps that could not roll back: M (manual intervention required)
System state: RESTORED | PARTIALLY_RESTORED
```

---

## §7  Quality Gates

| Metric | Threshold |
|--------|-----------|
| F1 | ≥ 0.90 |
| MRR | ≥ 0.85 |
| Trigger Accuracy | ≥ 0.90 |
| Step Success Rate | ≥ 95% (in test runs) |
| Rollback Coverage | 100% of mutating steps have defined rollback |
| Checkpoint Coverage | 100% of destructive steps have human checkpoint |

---

## §8  Security Baseline

- **CWE-78**: Shell commands constructed from validated, whitelisted parameters only
- **CWE-22**: File paths validated — no path traversal (`../`)
- **CWE-798**: No credentials in workflow definition — use env vars
- **Least Privilege**: Each step tool runs with minimal required permissions

---

## §9  Usage Examples

### Full workflow run

**Input**: "run {{WORKFLOW_NAME}} on {{EXAMPLE_TARGET}}"

```
Mode: RUN | Target: {{EXAMPLE_TARGET}} | Steps: {{STEP_COUNT}}
Pre-flight: ✓ env vars | ✓ permissions | ✓ target
Step 1/N: {{STEP_1_NAME}} ✓ (1.2s)
Step 2/N: {{STEP_2_NAME}} ✓ (0.8s)
[CHECKPOINT] Step 3: destructive — awaiting approval...
  User: approved
Step 3/N: {{STEP_3_NAME}} ✓ (2.1s)
...
Workflow COMPLETED | Duration: Xs | Status: ALL STEPS OK
```

### Dry run preview

**Input**: "dry-run {{WORKFLOW_NAME}}"

```
Mode: DRY-RUN
Plan:
  Step 1: [READ]  {{STEP_1_ACTION}} — no mutation
  Step 2: [WRITE] {{STEP_2_ACTION}} — DESTRUCTIVE ⚠
  Step 3: [READ]  {{STEP_3_ACTION}} — no mutation
Checkpoints: 1 | Destructive steps: 1
Estimated duration: {{DURATION}}
Proceed with RUN? [y/n]
```

---

**Triggers**: **run** | **dry-run** | **status** | **rollback** | **运行** | **预演** | **状态** | **回滚**

---

## §UTE Use-to-Evolve

<!-- Post-invocation protocol — auto-managed by skill-writer v2.1.0 -->

After each invocation, increment `use_to_evolve.cumulative_invocations`.
Run lightweight LEAN check every 10 invocations; full re-score every 50;
tier-drift detection every 100.

**Fields managed automatically** (do not edit manually):
- `cumulative_invocations` — incremented each use
- `last_ute_check` — ISO date of last lightweight check
- `pending_patches` — count of queued micro-patches
- `total_micro_patches_applied` — lifetime patch count
```

---

## Checklist before delivery

- [ ] All workflow steps listed with names, actions, tools, and rollback actions
- [ ] Parallel steps identified and dependencies mapped
- [ ] Human checkpoints defined for ALL destructive steps (no exceptions)
- [ ] Retry logic specified: max retries + backoff (1s, 2s, 4s)
- [ ] Rollback sequence covers ALL mutating steps
- [ ] DRY-RUN mode implemented and tested
- [ ] `use_to_evolve:` block present in YAML frontmatter with all 11 fields
- [ ] `## §UTE Use-to-Evolve` section present at end of skill
- [ ] LEAN eval score ≥ 350 and no `{{PLACEHOLDER}}` remaining
- [ ] Full EVALUATE score ≥ 700 (BRONZE) confirmed
- [ ] Security scan P0 clear: CWE-78 (command injection), CWE-798 (credentials)
- [ ] If TEMP_CERT issued: add `TEMP_CERT: true` to YAML, re-evaluate within 72 h


---

### data-pipeline Template

# Template: Data Pipeline Skill

> **Type**: data-pipeline
> **Use when**: The skill ingests, transforms, validates, or exports structured/unstructured data.
> **Variables**: Replace every `{{PLACEHOLDER}}` with values from the requirement elicitation phase.

---

## How to fill this template

1. Replace all `{{PLACEHOLDER}}` tokens.
2. Define schema for `INPUT_SCHEMA` and `OUTPUT_SCHEMA` concretely.
3. Specify every transformation step with input/output types.
4. Run EVALUATE mode before delivery.

---

```markdown
---
name: {{SKILL_NAME}}
version: "1.0.0"
description: "{{ONE_LINE_DESCRIPTION}} — data pipeline for {{DATA_DOMAIN}}."
description_i18n:
  en: "Data pipeline: {{EN_DESCRIPTION}}"
  zh: "数据管道：{{ZH_DESCRIPTION}}"

license: MIT
author:
  name: {{AUTHOR}}
created: "{{DATE}}"
updated: "{{DATE}}"
type: data-pipeline

tags:
  - data
  - pipeline
  - {{DATA_DOMAIN}}
  - {{TAG_EXTRA}}

interface:
  input: {{INPUT_FORMAT}}       # e.g. csv, json, plain-text, multimodal
  output: {{OUTPUT_FORMAT}}     # e.g. json, csv, markdown-table
  modes: [ingest, transform, validate, export]

pipeline:
  input_schema: "{{INPUT_SCHEMA_REF}}"    # path or inline
  output_schema: "{{OUTPUT_SCHEMA_REF}}"
  max_record_count: {{MAX_RECORDS}}       # safety limit
  chunk_size: {{CHUNK_SIZE}}              # for streaming/large files

use_to_evolve:
  enabled: true
  injected_by: "skill-writer v2.1.0"
  injected_at: "{{DATE}}"
  check_cadence: {lightweight: 10, full_recompute: 50, tier_drift: 100}
  micro_patch_enabled: true
  feedback_detection: true
  certified_lean_score: null
  last_ute_check: null
  pending_patches: 0
  total_micro_patches_applied: 0
  cumulative_invocations: 0
---

## §1  Identity

**Name**: {{SKILL_NAME}}
**Role**: {{DATA_DOMAIN}} Data Pipeline Agent
**Purpose**: {{PURPOSE}}

**Pipeline Stages**:
```
[INPUT: {{INPUT_FORMAT}}]
    │
    ▼
[INGEST] → validate format, detect encoding, count records
    │
    ▼
[TRANSFORM] → {{TRANSFORM_STEP_1}} → {{TRANSFORM_STEP_2}}
    │
    ▼
[VALIDATE] → schema check, null/type check, business rules
    │
    ▼
[EXPORT: {{OUTPUT_FORMAT}}]
```

**Red Lines (严禁)**:
- 严禁 process more than `{{MAX_RECORDS}}` records without explicit confirmation
- 严禁 discard records silently — log every dropped record with reason
- 严禁 output data without passing schema validation
- 严禁 skip chunk validation when processing segmented files

---

## §2  Loop — Plan-Execute-Summarize

| Phase | Description | Exit Criteria |
|-------|-------------|---------------|
| 1 INGEST | Load input, detect format, validate encoding | Record count reported |
| 2 CHUNK | Split into chunks of `{{CHUNK_SIZE}}` if > `{{CHUNK_THRESHOLD}}` records | Chunks ready |
| 3 TRANSFORM | Apply transformation rules per §3 | All chunks transformed |
| 4 VALIDATE | Run schema + business rule checks per §4 | Validation report ready |
| 5 EXPORT | Serialize to `{{OUTPUT_FORMAT}}`, write to destination | File/stream complete |
| 6 SUMMARIZE | Counts: input/output/dropped/errors; quality score | Summary delivered |

---

## §3  TRANSFORM Mode

**Triggers**: transform, convert, process, parse, 转换, 处理, 解析

**Transformation Rules**:

| Step | Input Field | Operation | Output Field | Type |
|------|-------------|-----------|--------------|------|
| T1 | `{{FIELD_1}}` | {{OPERATION_1}} | `{{OUT_FIELD_1}}` | {{TYPE_1}} |
| T2 | `{{FIELD_2}}` | {{OPERATION_2}} | `{{OUT_FIELD_2}}` | {{TYPE_2}} |
| T3 | `{{FIELD_3}}` | {{OPERATION_3}} | `{{OUT_FIELD_3}}` | {{TYPE_3}} |

**Null Handling**: `{{NULL_STRATEGY}}` — one of: drop-record | fill-default | pass-through | error

**Encoding**: Normalize all strings to UTF-8. Log non-UTF-8 bytes as warnings.

**Exit Criteria**: All records transformed or quarantined with reason codes.

---

## §4  VALIDATE Mode

**Triggers**: validate, check, verify, 验证, 校验, 检查

**Validation Rules**:

| Rule ID | Field | Check | Severity | Action on Fail |
|---------|-------|-------|----------|----------------|
| V1 | `{{FIELD_1}}` | not null | ERROR | quarantine record |
| V2 | `{{FIELD_2}}` | type = {{TYPE}} | ERROR | quarantine record |
| V3 | `{{FIELD_3}}` | value in {{ALLOWED_VALUES}} | WARNING | flag record |
| V4 | (cross-field) | {{BUSINESS_RULE}} | ERROR | quarantine record |

**Quarantine**: Failed records written to separate quarantine output with rule ID + reason.
**Threshold**: If quarantine rate > `{{MAX_QUARANTINE_PCT}}`% → ABORT and request human review.

**Exit Criteria**: Validation report produced; quarantine rate ≤ `{{MAX_QUARANTINE_PCT}}`%.

---

## §5  INGEST Mode

**Triggers**: ingest, load, import, read, 导入, 加载, 读取

**Supported Formats**: `{{INPUT_FORMAT_LIST}}`  (e.g. CSV, JSON, JSONL, TSV, Parquet)

**Steps**:
1. Detect file format by extension and magic bytes
2. Validate encoding (prefer UTF-8; normalize if needed)
3. Count total records; report to user before proceeding
4. If records > `{{MAX_RECORDS}}` → ask user confirmation before continuing
5. Sample first 5 records → show schema preview → confirm

**Exit Criteria**: Record count confirmed, schema preview approved, chunks queued.

---

## §6  EXPORT Mode

**Triggers**: export, save, write, output, 导出, 保存, 输出

**Output Schema**:
```json
{
  "{{OUT_FIELD_1}}": "{{TYPE_1}}",
  "{{OUT_FIELD_2}}": "{{TYPE_2}}",
  "{{OUT_FIELD_3}}": "{{TYPE_3}}"
}
```

**Output Destination**: `{{OUTPUT_PATH}}` (configurable; default: `./output/{{SKILL_NAME}}_<timestamp>.{{OUTPUT_EXT}}`)

**Summary Footer** (always appended):
```
Pipeline run: <timestamp>
Input records: N | Transformed: N | Validated: N | Quarantined: N | Exported: N
Quarantine rate: X% | Status: PASS/FAIL
```

---

## §7  Quality Gates

| Metric | Threshold |
|--------|-----------|
| F1 | ≥ 0.90 |
| MRR | ≥ 0.85 |
| Trigger Accuracy | ≥ 0.90 |
| Schema Compliance | 100% of exported records match output schema |
| Quarantine Rate | ≤ `{{MAX_QUARANTINE_PCT}}`% |
| Data Loss | 0% (every input record accounted for) |

---

## §8  Security Baseline

- **CWE-89**: Input fields sanitized before any query construction
- **CWE-79**: String fields escaped before Markdown/HTML output
- **CWE-22**: Output path validated — no path traversal (`../`)
- **Data Privacy**: PII fields `{{PII_FIELDS}}` — mask/redact per `{{PRIVACY_POLICY}}`

---

## §9  Usage Examples

### Single file transform

**Input**: "convert {{EXAMPLE_FILE}} from CSV to JSON, apply {{TRANSFORM_STEP_1}}"

```
Mode: TRANSFORM | Records: 1,240 | Chunks: 3
T1: applied to 1,240 records
T2: applied to 1,238 records (2 null → quarantined)
Exported: output/{{SKILL_NAME}}_20260101.json
Summary: Input=1240 Transformed=1238 Quarantined=2 (0.16%) → PASS
```

### Validate only

**Input**: "validate data in {{EXAMPLE_FILE}} against schema"

```
Mode: VALIDATE | Records: 500
V1 PASS: 500/500
V2 PASS: 500/500
V3 WARN: 12 records flagged (2.4%)
V4 FAIL: 3 records quarantined
Quarantine rate: 0.6% ≤ 5% → PASS
```

---

**Triggers**: **transform** | **validate** | **ingest** | **export** | **转换** | **验证** | **导入** | **导出**

---

## §UTE Use-to-Evolve

<!-- Post-invocation protocol — auto-managed by skill-writer v2.1.0 -->

After each invocation, increment `use_to_evolve.cumulative_invocations`.
Run lightweight LEAN check every 10 invocations; full re-score every 50;
tier-drift detection every 100.

**Fields managed automatically** (do not edit manually):
- `cumulative_invocations` — incremented each use
- `last_ute_check` — ISO date of last lightweight check
- `pending_patches` — count of queued micro-patches
- `total_micro_patches_applied` — lifetime patch count
```

---

## Checklist before delivery

- [ ] Input schema and output schema both defined concretely (field names + types)
- [ ] Every transformation step specifies input type → output type
- [ ] Null handling strategy chosen and documented (drop/fill/pass/error)
- [ ] Quarantine threshold set (`MAX_QUARANTINE_PCT`) and enforced
- [ ] Record count safety limit (`MAX_RECORDS`) set with user confirmation gate
- [ ] PII fields identified and masking policy documented
- [ ] `use_to_evolve:` block present in YAML frontmatter with all 11 fields
- [ ] `## §UTE Use-to-Evolve` section present at end of skill
- [ ] LEAN eval score ≥ 350 and no `{{PLACEHOLDER}}` remaining
- [ ] Full EVALUATE score ≥ 700 (BRONZE) confirmed
- [ ] Security scan P0 clear: CWE-89 (query construction), CWE-22 (output path)
- [ ] If TEMP_CERT issued: add `TEMP_CERT: true` to YAML, re-evaluate within 72 h


---

### base Template

# Template: Base Skill

> **Type**: base
> **Use when**: The skill doesn't fit a more specific category (api-integration, data-pipeline, workflow-automation).
> **Variables**: Replace every `{{PLACEHOLDER}}` with values from the requirement elicitation phase (§6 of skill-writer.md).

---

## How to fill this template

1. Replace all `{{PLACEHOLDER}}` tokens with values gathered from §6 questions.
2. Delete any section marked `<!-- OPTIONAL -->` if not applicable.
3. Run the EVALUATE mode (§4) before delivery — minimum F1 ≥ 0.90.

---

```markdown
---
name: {{SKILL_NAME}}
version: "1.0.0"
description: "{{ONE_LINE_DESCRIPTION}}"
description_i18n:
  en: "{{EN_DESCRIPTION}}"
  zh: "{{ZH_DESCRIPTION}}"

license: MIT
author:
  name: {{AUTHOR}}
created: "{{DATE}}"
updated: "{{DATE}}"
type: {{SKILL_TYPE}}          # e.g. assistant, tool-wrapper, analyzer

tags:
  - {{TAG_1}}
  - {{TAG_2}}

interface:
  input: {{INPUT_FORMAT}}     # e.g. user-natural-language, structured-json
  output: {{OUTPUT_FORMAT}}   # e.g. text, json, markdown
  modes: [{{MODE_1}}, {{MODE_2}}]

use_to_evolve:
  enabled: true
  injected_by: "skill-writer v2.1.0"
  injected_at: "{{DATE}}"
  check_cadence: {lightweight: 10, full_recompute: 50, tier_drift: 100}
  micro_patch_enabled: true
  feedback_detection: true
  certified_lean_score: null
  last_ute_check: null
  pending_patches: 0
  total_micro_patches_applied: 0
  cumulative_invocations: 0
---

## §1  Identity

**Name**: {{SKILL_NAME}}
**Role**: {{ROLE_DESCRIPTION}}
**Purpose**: {{PURPOSE}}

**Core Principles**:
- {{PRINCIPLE_1}}
- {{PRINCIPLE_2}}
- {{PRINCIPLE_3}}

**Red Lines (严禁)**:
- 严禁 {{RED_LINE_1}}
- 严禁 {{RED_LINE_2}}

---

## §2  Loop — Plan-Execute-Summarize

| Phase | Name | Description | Exit Criteria |
|-------|------|-------------|---------------|
| 1 | **PARSE** | Extract intent from user input | Intent identified |
| 2 | **PLAN** | Decide approach based on intent | Plan ready |
| 3 | **EXECUTE** | Perform core task | Task complete |
| 4 | **SUMMARIZE** | Validate result against acceptance criteria | Result verified |
| 5 | **DELIVER** | Present output to user | User acknowledged |

---

## §3  {{MODE_1}} Mode

**Triggers**: {{MODE_1_TRIGGER_EN}} | {{MODE_1_TRIGGER_ZH}}

**Input**: {{MODE_1_INPUT}}

**Steps**:
1. {{STEP_1}}
2. {{STEP_2}}
3. {{STEP_3}}

**Output**: {{MODE_1_OUTPUT}}

**Exit Criteria**: {{MODE_1_EXIT}}

---

## §4  {{MODE_2}} Mode   <!-- OPTIONAL: remove if only one mode -->

**Triggers**: {{MODE_2_TRIGGER_EN}} | {{MODE_2_TRIGGER_ZH}}

**Input**: {{MODE_2_INPUT}}

**Steps**:
1. {{STEP_1}}
2. {{STEP_2}}

**Output**: {{MODE_2_OUTPUT}}

**Exit Criteria**: {{MODE_2_EXIT}}

---

## §5  Quality Gates

| Metric | Threshold | Measured By |
|--------|-----------|-------------|
| F1 | ≥ 0.90 | claude/eval/rubrics.md |
| MRR | ≥ 0.85 | claude/eval/rubrics.md |
| Trigger Accuracy | ≥ 0.90 | claude/eval/benchmarks.md |

---

## §6  Security Baseline

Scan before delivery:
- CWE-798: No hardcoded credentials
- CWE-89: No unsanitized SQL
- CWE-79: No unsanitized HTML output
- CWE-94: No eval/exec with user input

---

## §7  Usage Examples

### {{EXAMPLE_1_TITLE}}

**Input**: "{{EXAMPLE_1_INPUT}}"

```
Mode: {{MODE_1}} | Confidence: 0.90 | Language: {{LANG}}
Output: {{EXAMPLE_1_OUTPUT}}
```

### {{EXAMPLE_2_TITLE}}   <!-- OPTIONAL -->

**Input**: "{{EXAMPLE_2_INPUT}}"

```
Mode: {{MODE_2}} | Confidence: 0.88
Output: {{EXAMPLE_2_OUTPUT}}
```

---

**Triggers**: **{{MODE_1_TRIGGER_EN}}** | **{{MODE_1_TRIGGER_ZH}}** | **{{MODE_2_TRIGGER_EN}}** | **{{MODE_2_TRIGGER_ZH}}**

---

## §UTE Use-to-Evolve

<!-- Post-invocation protocol — auto-managed by skill-writer v2.1.0 -->

After each invocation, increment `use_to_evolve.cumulative_invocations`.
Run lightweight LEAN check every 10 invocations; full re-score every 50;
tier-drift detection every 100.

**Fields managed automatically** (do not edit manually):
- `cumulative_invocations` — incremented each use
- `last_ute_check` — ISO date of last lightweight check
- `pending_patches` — count of queued micro-patches
- `total_micro_patches_applied` — lifetime patch count
```

---

## Checklist before delivery

- [ ] All `{{PLACEHOLDER}}` tokens replaced
- [ ] At least 2 usage examples present (EN + ZH triggers shown)
- [ ] Quality gates section complete with numeric thresholds (F1 ≥ 0.90, MRR ≥ 0.85)
- [ ] Security baseline section present with specific field names per CWE
- [ ] Red Lines section present with ≥ 3 specific prohibitions
- [ ] `use_to_evolve:` block present in YAML frontmatter with all 11 fields
- [ ] `## §UTE Use-to-Evolve` section present at end of skill
- [ ] LEAN eval score ≥ 350 (lean_score/500)
- [ ] Full EVALUATE score ≥ 700 (BRONZE) confirmed
- [ ] No P0 CWE violations (see `claude/refs/security-patterns.md`)
- [ ] If confidence < 0.70 on delivery: add `TEMP_CERT: true` to YAML frontmatter
      and schedule 72 h re-evaluation window


---

### api-integration Template

# Template: API Integration Skill

> **Type**: api-integration
> **Use when**: The skill calls one or more external APIs / third-party services.
> **Variables**: Replace every `{{PLACEHOLDER}}` with values from the requirement elicitation phase.

---

## How to fill this template

1. Replace all `{{PLACEHOLDER}}` tokens.
2. Fill in `API_BASE_URL`, `AUTH_METHOD`, `ENDPOINTS` from the target API's documentation.
3. Never hardcode credentials — document the env-var name instead (CWE-798).
4. Run EVALUATE mode before delivery.

---

```markdown
---
name: {{SKILL_NAME}}
version: "1.0.0"
description: "{{ONE_LINE_DESCRIPTION}} — integrates {{API_NAME}} API."
description_i18n:
  en: "Integrates {{API_NAME}}: {{EN_DESCRIPTION}}"
  zh: "集成 {{API_NAME}}：{{ZH_DESCRIPTION}}"

license: MIT
author:
  name: {{AUTHOR}}
created: "{{DATE}}"
updated: "{{DATE}}"
type: api-integration

tags:
  - api
  - {{API_NAME_LOWER}}
  - {{TAG_EXTRA}}

interface:
  input: user-natural-language
  output: {{OUTPUT_FORMAT}}     # e.g. structured-json, text-summary
  modes: [query, batch]         # adjust as needed

api:
  name: {{API_NAME}}
  base_url: "{{API_BASE_URL}}"
  auth_method: {{AUTH_METHOD}}  # bearer-token | api-key-header | oauth2 | none
  auth_env_var: "{{AUTH_ENV_VAR}}"  # e.g. OPENWEATHER_API_KEY
  rate_limit: "{{RATE_LIMIT}}"  # e.g. 60 req/min
  docs_url: "{{API_DOCS_URL}}"

use_to_evolve:
  enabled: true
  injected_by: "skill-writer v2.1.0"
  injected_at: "{{DATE}}"
  check_cadence: {lightweight: 10, full_recompute: 50, tier_drift: 100}
  micro_patch_enabled: true
  feedback_detection: true
  certified_lean_score: null
  last_ute_check: null
  pending_patches: 0
  total_micro_patches_applied: 0
  cumulative_invocations: 0
---

## §1  Identity

**Name**: {{SKILL_NAME}}
**Role**: {{API_NAME}} Integration Agent
**Purpose**: {{PURPOSE}}

**Key Endpoints Used**:
| Endpoint | Method | Purpose |
|----------|--------|---------|
| `{{ENDPOINT_1_PATH}}` | {{HTTP_METHOD}} | {{ENDPOINT_1_PURPOSE}} |
| `{{ENDPOINT_2_PATH}}` | {{HTTP_METHOD}} | {{ENDPOINT_2_PURPOSE}} |

**Authentication**: Reads `{{AUTH_ENV_VAR}}` from environment. NEVER embed credentials in skill.

**Red Lines (严禁)**:
- 严禁 hardcode API keys, tokens, or passwords (CWE-798)
- 严禁 pass raw user input as query parameters without sanitization
- 严禁 expose raw API error messages containing internal details to end-users
- 严禁 retry indefinitely — max 3 retries with exponential backoff

---

## §2  Loop — Plan-Execute-Summarize

| Phase | Description | Exit Criteria |
|-------|-------------|---------------|
| 1 PARSE | Extract query intent + parameters from user input | Parameters identified |
| 2 AUTHENTICATE | Verify `{{AUTH_ENV_VAR}}` is set and valid | Auth confirmed |
| 3 CALL API | Construct request → call `{{API_NAME}}` → handle response | HTTP 2xx received |
| 4 PARSE RESPONSE | Extract relevant fields, map to output schema | Data mapped |
| 5 FORMAT | Apply output format (`{{OUTPUT_FORMAT}}`) | Formatted result ready |
| 6 DELIVER | Return result to user with source attribution | User acknowledged |

**Error Handling**:
- HTTP 4xx → parse error message → surface human-readable version
- HTTP 429 → wait `Retry-After` header seconds → retry (max 3)
- HTTP 5xx → retry with backoff (1s, 2s, 4s) → HUMAN_REVIEW after 3 failures
- Network timeout (>10s) → retry once → surface error

---

## §3  QUERY Mode

**Triggers**: query, fetch, get, retrieve, look up, 查询, 获取, 搜索

**Input**: User's natural language query describing what to retrieve.

**Steps**:
1. Parse user intent → extract key parameters (e.g. location, date, ID)
2. Map parameters to `{{ENDPOINT_1_PATH}}` request schema
3. Call API with `Authorization: {{AUTH_METHOD}} ${{AUTH_ENV_VAR}}`
4. Parse response → extract `{{RESPONSE_FIELDS}}`
5. Format output per `{{OUTPUT_FORMAT}}` schema
6. Attribute source: "Data from {{API_NAME}}"

**Output**:
```
{{SKILL_NAME}} result:
  {{OUTPUT_FIELD_1}}: <value>
  {{OUTPUT_FIELD_2}}: <value>
  source: {{API_NAME}} | retrieved: <timestamp>
```

**Exit Criteria**: Result delivered or error surfaced with actionable message.

---

## §4  BATCH Mode   <!-- remove if not needed -->

**Triggers**: batch, bulk, multiple, list of, 批量, 多个

**Input**: List of query parameters (comma-separated or JSON array).

**Steps**:
1. Parse list → validate item count ≤ `{{BATCH_LIMIT}}`
2. For each item: call QUERY Mode (§3)
3. Collect results → deduplicate → sort
4. Return consolidated report

**Rate Limiting**: Respect `{{RATE_LIMIT}}` — insert delay between calls if needed.

**Exit Criteria**: All items processed; partial failures listed separately.

---

## §5  Quality Gates

| Metric | Threshold |
|--------|-----------|
| F1 | ≥ 0.90 |
| MRR | ≥ 0.85 |
| Trigger Accuracy | ≥ 0.90 |
| API Auth Coverage | 100% of calls authenticated |
| Error Handling Coverage | HTTP 4xx, 429, 5xx, timeout all handled |

---

## §6  Security Baseline

- **CWE-798**: `{{AUTH_ENV_VAR}}` loaded from env, never hardcoded
- **CWE-89**: Query params sanitized before URL construction
- **CWE-79**: API response fields escaped before Markdown/HTML rendering
- **Input Validation**: `{{PARAM_1}}` type-checked as `{{PARAM_1_TYPE}}`

---

## §7  Usage Examples

### Example — single query

**Input**: "{{EXAMPLE_QUERY}}"

```
Mode: QUERY | API: {{API_NAME}} | Language: EN
Endpoint: GET {{ENDPOINT_1_PATH}}?{{PARAM_1}}={{EXAMPLE_VALUE}}
Output:
  {{OUTPUT_FIELD_1}}: {{EXAMPLE_RESULT_1}}
  {{OUTPUT_FIELD_2}}: {{EXAMPLE_RESULT_2}}
  source: {{API_NAME}}
```

### Example — batch query

**Input**: "{{EXAMPLE_BATCH_INPUT}}"

```
Mode: BATCH | items: 3
Results: [item1_result, item2_result, item3_result]
Errors: none
```

---

**Triggers**: **query** | **fetch** | **get** | **retrieve** | **查询** | **获取** | **搜索**

---

## §UTE Use-to-Evolve

<!-- Post-invocation protocol — auto-managed by skill-writer v2.1.0 -->

After each invocation, increment `use_to_evolve.cumulative_invocations`.
Run lightweight LEAN check every 10 invocations; full re-score every 50;
tier-drift detection every 100.

**Fields managed automatically** (do not edit manually):
- `cumulative_invocations` — incremented each use
- `last_ute_check` — ISO date of last lightweight check
- `pending_patches` — count of queued micro-patches
- `total_micro_patches_applied` — lifetime patch count
```

---

## Checklist before delivery

- [ ] `{{AUTH_ENV_VAR}}` documented in Security Baseline — no credential values written
- [ ] All HTTP error codes handled: 4xx, 429, 5xx, timeout
- [ ] Rate limit respected in BATCH mode; BATCH_LIMIT set
- [ ] Response fields sanitized before output (CWE-79)
- [ ] `use_to_evolve:` block present in YAML frontmatter with all 11 fields
- [ ] `## §UTE Use-to-Evolve` section present at end of skill
- [ ] LEAN eval score ≥ 350 and no `{{PLACEHOLDER}}` remaining
- [ ] Full EVALUATE score ≥ 700 (BRONZE) confirmed
- [ ] Security scan P0 clear: CWE-798, CWE-89, CWE-78 (see `claude/refs/security-patterns.md`)
- [ ] If TEMP_CERT issued: add `TEMP_CERT: true` to YAML, re-evaluate within 72 h


## EVALUATE Mode — Quality Assessment

EVALUATE mode provides rigorous, standardized quality assessment for skills.

### Scoring Rubrics

# Evaluation Rubrics

> **Purpose**: 4-phase 1000-point scoring pipeline used by EVALUATE mode.
> **Load**: When §8 (EVALUATE Mode) of `claude/skill-writer.md` is accessed.
> **Main doc**: `claude/skill-writer.md §8`

---

## §1  Pipeline Overview

```
Total: 1000 points

Phase 1 — Parse & Validate   (0–100 pts)   Heuristic, no LLM
Phase 2 — Text Quality       (0–300 pts)   Static analysis, Pass 1
Phase 3 — Runtime Testing    (0–400 pts)   Benchmark tests, Pass 2
Phase 4 — Certification      (0–200 pts)   Variance + security + gates, Pass 3

Variance formula:  variance = | phase2/3 − phase3/4 |
```

---

## §2  Certification Tiers

| Tier | Min Score | Max Variance | Phase 2 Min | Phase 3 Min |
|------|-----------|-------------|------------|------------|
| **PLATINUM** | ≥ 950 | < 10 | ≥ 270 | ≥ 360 |
| **GOLD** | ≥ 900 | < 15 | ≥ 255 | ≥ 340 |
| **SILVER** | ≥ 800 | < 20 | ≥ 225 | ≥ 300 |
| **BRONZE** | ≥ 700 | < 30 | ≥ 195 | ≥ 265 |
| **FAIL** | < 700 | any | — | — |

**Variance interpretation**: High variance means the artifact "looks good on paper but
fails runtime" (Phase2 >> Phase3) or "passes tests but is poorly written" (Phase3 >> Phase2).
Both indicate quality inconsistency and cap the certification tier.

---

## §3  Phase 1 — Parse & Validate (0–100 pts)

Heuristic checks only. Fast, no LLM.

| Check | Points | Notes |
|-------|--------|-------|
| YAML frontmatter present | 10 | Must have at least `name`, `version` |
| `name` field present and non-empty | 5 | |
| `version` field follows semver | 5 | Pattern: `N.N.N` |
| `interface.modes` array present | 5 | |
| `tags` array with ≥ 2 entries | 5 | |
| ≥ 3 `## §N` sections | 10 | Identity, Loop, at least one mode |
| Identity section present (name/role/purpose) | 10 | |
| Red Lines / 严禁 section present | 10 | |
| Quality Gates section with numeric thresholds | 15 | Thresholds must be numbers |
| No `{{PLACEHOLDER}}` tokens remaining | 15 | Any remaining = hard deduction |
| No TODO / FIXME markers | 5 | Advisory |
| File size reasonable (< 500 lines) | 5 | > 500 lines: advisory warning |

**Hard deduction**: If `{{PLACEHOLDER}}` found → Phase1 score capped at 60, WARNING issued.

---

## §4  Phase 2 — Text Quality (0–300 pts)

Static analysis across 6 sub-dimensions. Scored in Pass 1.

| Sub-Dimension | Max | Weight | What to Check |
|---------------|-----|--------|--------------|
| **System Design** | 60 | 20% | Clear identity, role hierarchy, design pattern named |
| **Domain Knowledge** | 60 | 20% | Template-specific accuracy (API fields, pipeline stages, workflow steps) |
| **Workflow Definition** | 60 | 20% | Phase sequence complete, exit criteria per phase, loop gates explicit |
| **Error Handling** | 45 | 15% | Recovery paths named, escalation triggers defined, timeout values set |
| **Examples** | 45 | 15% | ≥ 2 examples, both EN and ZH or bilingual triggers, output shown |
| **Metadata Quality** | 30 | 10% | YAML complete, version semver, author, dates, description bilingual |

### Scoring Rubric per Sub-Dimension

| Score Band | Meaning |
|------------|---------|
| 90–100% | Exceptional: specific, measurable, complete, no vagueness |
| 75–89% | Good: mostly complete, minor gaps in specificity |
| 60–74% | Adequate: structure present but some sections thin or vague |
| 40–59% | Weak: significant gaps, missing key elements |
| 0–39% | Poor: section missing or essentially content-free |

### Pass 1 Scoring Instructions

For each sub-dimension, produce:
```json
{
  "sub_dimension": "<name>",
  "score": 0,
  "max": 60,
  "evidence": "<what was found>",
  "gaps": ["<specific gap 1>", "<specific gap 2>"],
  "severity": "ERROR|WARNING|INFO"
}
```

---

## §5  Phase 3 — Runtime Testing (0–400 pts)

Executed against benchmark test cases (`claude/eval/benchmarks.md`). Scored in Pass 2.

| Test Category | Max | What Is Tested |
|---------------|-----|----------------|
| **Trigger Routing Accuracy** | 120 | Mode router predicts correct mode for positive cases |
| **Bilingual Trigger Coverage** | 80 | Both EN and ZH inputs route correctly |
| **Negative/Edge Cases** | 60 | Ambiguous inputs handled; negatives filtered; fallback activated |
| **Output Contract** | 60 | Each mode's output format matches stated spec |
| **Error Handling Runtime** | 50 | Error cases produce correct recovery output |
| **Security Boundary Tests** | 30 | Injection/traversal inputs rejected gracefully |

### F1 and MRR Computation

```
F1 = 2 × precision × recall / (precision + recall)
  precision = TP / (TP + FP)
  recall    = TP / (TP + FN)

MRR = (1/N) × Σ (1 / rank_of_first_correct_mode)
  rank = 1 if correct mode is top prediction
  rank = 2 if second
  rank = 0 (excluded from sum) if correct mode not in top 3

Trigger accuracy = correct_triggers / total_trigger_test_cases
```

### Phase 3 Score Mapping

```
trigger_routing: correct% × 120
bilingual:       (EN_correct + ZH_correct) / (EN_total + ZH_total) × 80
negative_cases:  correct_negatives / total_negatives × 60
output_contract: correct_format% × 60
error_handling:  correct_recovery% × 50
security_boundary: all_rejected ? 30 : rejected/total × 30
```

### Pass 2 Test Execution

Run each test case and record:
```json
{
  "test_id": "CF-C-01",
  "input": "create a new skill for querying databases",
  "expected_mode": "CREATE",
  "predicted_mode": "CREATE",
  "confidence": 0.92,
  "correct": true,
  "rank": 1
}
```

---

## §6  Phase 4 — Certification (0–200 pts)

Scored in Pass 3 (Reconciliation). Integrates all previous phases.

| Check | Max | How Scored |
|-------|-----|-----------|
| **Variance gate** | 40 | variance<10→40, <15→30, <20→20, <30→10, ≥30→0 |
| **Security scan** | 60 | P0 clear→40, P1 clear→20; P0 violation→0+ABORT; each P1→−10 |
| **F1 gate** | 40 | F1≥0.90→40, ≥0.85→25, ≥0.80→10, <0.80→0 |
| **MRR gate** | 30 | MRR≥0.85→30, ≥0.80→20, ≥0.75→10, <0.75→0 |
| **Consistency** | 30 | All passes agree on tier→30, CLEAR→20, REVISED→10, UNRESOLVED→0 |

**Phase 4 hard rules**:
- P0 security violation → Phase 4 = 0, overall = FAIL, status = ABORT
- F1 < 0.80 → Phase 4 capped at 80 points regardless of other scores
- UNRESOLVED review outcome → Phase 4 capped at 120 points

---

## §7  LEAN Fast Path

Before running Phase 1–4, apply LEAN heuristics (§6 of skill-writer.md).

**Quick-Pass**: If lean_score ≥ 450 (GOLD proxy):
- Run only Phase 1 + security scan
- If Phase 1 ≥ 90 AND security CLEAR → issue LEAN_CERT, skip Phase 2–4
- Schedule full Phase 2–4 within 24 h

**Full Pipeline**: If lean_score 300–449 OR any quick-pass check fails → run all 4 phases.

---

## §8  Evaluation Report Template

```
SKILL EVALUATION REPORT
=======================
Skill:      <name> v<version>
Evaluated:  <ISO-8601>
Evaluator:  skill-writer v2.1.0

PHASE SCORES
  Phase 1 — Parse & Validate:   XX / 100
  Phase 2 — Text Quality:       XX / 300
    System Design:     XX/60   Error Handling: XX/45
    Domain Knowledge:  XX/60   Examples:       XX/45
    Workflow:          XX/60   Metadata:       XX/30
  Phase 3 — Runtime Testing:    XX / 400
    Trigger Routing:   XX/120  Output Contract:   XX/60
    Bilingual:         XX/80   Error Handling RT: XX/50
    Negative/Edge:     XX/60   Security Boundary: XX/30
  Phase 4 — Certification:      XX / 200
    Variance Gate:    XX/40    F1 Gate:    XX/40
    Security Scan:    XX/60    MRR Gate:   XX/30
    Consensus:        XX/30

TOTAL SCORE:     XXX / 1000
VARIANCE:        X.XX  (threshold for tier: <N)
F1:              0.XX  (threshold: ≥ 0.90)  [PASS|FAIL]
MRR:             0.XX  (threshold: ≥ 0.85)  [PASS|FAIL]
TRIGGER ACC:     0.XX  (threshold: ≥ 0.90)  [PASS|FAIL]

SECURITY SCAN
  P0: [CLEAR | VIOLATION: <cwe> at <location>]
  P1: [CLEAR | <count> warnings, −<N> pts]

CONSENSUS MATRIX
  | Dimension       | Pass 1 | Pass 2 | Pass 3 | Consensus   |
  |-----------------|--------|--------|--------|-------------|
  | ...             | ...    | ...    | ...    | ...         |

ISSUES
  ERROR:   <blocking issues — must fix before delivery>
  WARNING: <advisory issues — document or fix>
  INFO:    <informational notes>

CERTIFICATION TIER:  PLATINUM | GOLD | SILVER | BRONZE | FAIL
STATUS:              CERTIFIED | TEMP_CERT | LEAN_CERT | HUMAN_REVIEW | ABORT
NEXT ACTION:         <recommendation>
```


## OPTIMIZE Mode — Continuous Improvement

OPTIMIZE mode provides automated, iterative skill improvement through systematic optimization.

### Optimization Strategies

# Optimization Strategies

> **Purpose**: 7-dimension strategy catalog for the 9-step OPTIMIZE loop.
> **Load**: When §9 (OPTIMIZE Mode) of `claude/skill-writer.md` is accessed.
> **Main doc**: `claude/skill-writer.md §9`

---

## §1  7-Dimension Scoring Reference

The OPTIMIZE loop always targets the **lowest-scoring dimension first**.

| Dim | Name | Weight | What It Covers | Strategy |
|-----|------|--------|---------------|----------|
| D1 | System Design | 20% | Identity, role hierarchy, design patterns, Red Lines | S2 |
| D2 | Domain Knowledge | 20% | Template accuracy, API/schema specificity | S3 |
| D3 | Workflow Definition | 20% | Phase sequence, exit criteria, loop gates | S4 |
| D4 | Error Handling | 15% | Recovery paths, escalation triggers, timeouts | S5 |
| D5 | Examples | 15% | Count, bilingual, output shown, realistic | S1+S3 |
| D6 | Metadata | 10% | YAML completeness, versioning, tags, dates | S6 |
| D7 | Long-Context | 10% | Section cross-refs, chunking, reference integrity | S7 |

**Tie-break**: When two dimensions score equally, prioritize by weight (higher weight first).

---

## §2  The 9-Step Loop

```
Round N (repeat up to 20 rounds, or until convergence):

  Step 1  READ       Score all 7 dimensions. Record to score_history[N].
  Step 2  ANALYZE    Propose 3 targeted fixes for lowest dim.
  Step 3  CURATE     Every 10 rounds: consolidate learning, prune context (§3).
  Step 4  PLAN       Review and select best fix; record decision in dim_history[N].
  Step 5  IMPLEMENT  Apply one atomic change. Single dimension focus. No rewrites.
  Step 6  VERIFY     Re-score. IF regressed → rollback. IF no improvement → try fix #2.
  Step 7  HUMAN_REVIEW  Trigger if total_score < 560 (FAIL×0.8) after round 10.
  Step 8  LOG        Record: round, dimension, delta, confidence, strategy_used.
  Step 9  COMMIT     Git commit every 10 rounds with tag [optimize-round-N score=XXX].

  After every round → check convergence (claude/refs/convergence.md)
    IF converged → STOP → certify at current tier
```

**Rollback rule (Step 6)**: If re-score shows regression > 5 pts → discard change,
restore previous version, try the second-best fix from the review pass list.
If all 3 proposed fixes regress → switch strategy to next-lowest dimension.

---

## §3  Curation Protocol (Every 10 Rounds)

**Purpose**: Prevent context window bloat; refocus on highest-leverage improvements.

```
CURATE:
  1. Summarize: "Rounds 1–10 improved D3 by +38pts, D1 by +12pts, D5 unchanged."
  2. Rank strategies by delta produced: [S4: +38, S2: +12, S1: +0]
  3. Prune: discard individual round details; keep only summary + score_history list
  4. Re-prioritize: next 10 rounds → lead with highest-delta strategy
  5. Reset: clear LLM context for rounds 1–10; load only summary + current skill
  6. Log: {"curation_round": N, "context_reduced_pct": 40, "top_strategy": "S4"}
```

---

## §4  Strategy Catalog

### S1 — Expand Trigger Keywords

**Target dimension**: D5 (Examples), D3 (Workflow) when trigger accuracy < 0.90
**Estimated delta**: +15 to +30 pts

**Steps**:
1. List all current primary/secondary EN and ZH keywords per mode.
2. Find failing benchmark cases — which words appeared in failures?
3. Add 3+ new primary keywords per failing mode.
4. Add ZH equivalents for every EN primary that lacks one.
5. Add 3–5 secondary/context triggers per mode.
6. Add negative patterns for the top 2 misroute pairs.
7. Verify confidence formula weights still sum correctly.

**Example**:
```
Before: CREATE keywords: [create, build, new]
After:  CREATE keywords: [create, build, new, generate, scaffold, develop, make, add]
        ZH: [创建, 新建, 生成, 开发, 构建, 制作, 添加]
```

**Estimated F1 gain**: +0.03–0.06 per 3 new primary keywords.

---

### S2 — Strengthen System Design

**Target dimension**: D1 (System Design)
**Estimated delta**: +10 to +25 pts

**Steps**:
1. Check Identity section: name, role, purpose all present?
2. Check design patterns named (Tool Wrapper, Generator, Reviewer, Inversion, Pipeline)?
3. Check Red Lines section: ≥ 3 specific, measurable prohibitions?
4. If any Red Line is vague ("don't do bad things") → replace with CWE or measurable threshold.
5. Add LoongFlow reference if not present.
6. Verify role hierarchy is explicit (who can override whom).

**Red Line quality check**:
```
BAD:  "严禁 unsafe operations"
GOOD: "严禁 hardcoded credentials (CWE-798) — use env var AUTH_TOKEN"
```

---

### S3 — Deepen Domain Knowledge

**Target dimension**: D2 (Domain Knowledge), D5 (Examples)
**Estimated delta**: +15 to +35 pts

**Steps by skill type**:

**api-integration**:
- List all endpoint paths with HTTP methods and purpose.
- Name the specific auth env var (e.g. `OPENWEATHER_API_KEY`).
- List response fields that will be extracted.
- Add realistic field values in examples.

**data-pipeline**:
- Define input schema with field names and types.
- Define output schema with field names and types.
- Specify null handling strategy explicitly.
- Add quarantine threshold (e.g. ≤ 5%).

**workflow-automation**:
- Fill in the workflow steps table completely (all N steps).
- Add rollback action for each mutating step.
- Mark destructive steps explicitly.
- Add estimated duration per step.

**base**:
- Add domain-specific vocabulary to trigger keywords.
- Replace generic "output" descriptions with typed field lists.

---

### S4 — Tighten Workflow Definition

**Target dimension**: D3 (Workflow Definition)
**Estimated delta**: +20 to +40 pts

**Steps**:
1. For each mode section, check: does it have a Phase/Step table?
2. Add exit criteria per phase if missing:
   ```
   BAD:  "3. Execute the task"
   GOOD: "3. EXECUTE | action: call API | exit: HTTP 2xx received"
   ```
3. Add hard checkpoint markers at destructive or irreversible steps.
4. Define loop exit conditions explicitly (SUCCESS, FAIL, HUMAN_REVIEW).
5. Add parallel step annotations where steps can run concurrently.
6. Verify that every "IF error" path leads somewhere (recovery or escalation).

**Phase table template** (copy per mode):
```markdown
| # | Phase | Description | Exit Criteria |
|---|-------|-------------|---------------|
| 1 | PARSE | ... | ... |
| 2 | PLAN  | ... | ... |
| 3 | EXECUTE | ... | ... |
| 4 | VERIFY | ... | ... |
| 5 | DELIVER | ... | ... |
```

---

### S5 — Harden Error Handling

**Target dimension**: D4 (Error Handling)
**Estimated delta**: +15 to +30 pts

**Steps**:
1. List all failure modes relevant to the skill type.
2. For each failure: specify trigger condition, recovery action, escalation path.
3. Set explicit timeout values (e.g. "API timeout: 10 s → retry once → surface error").
4. Add retry logic with max retries and backoff (exponential: 1s, 2s, 4s).
5. Add error output contract per mode.
6. For workflow skills: define rollback sequence for each step.

**Error catalog by type**:

| Error Type | Recovery Pattern |
|-----------|----------------|
| HTTP 4xx | Parse error → human-readable message |
| HTTP 429 | Read `Retry-After` header → wait → retry (max 3) |
| HTTP 5xx | Backoff retry (1s, 2s, 4s) → HUMAN_REVIEW after 3 fails |
| Timeout | Retry once → if fails again → surface error |
| Validation fail | Quarantine record → continue with remaining |
| Security violation | ABORT immediately → log → notify |
| LLM timeout | Degrade to majority vote or baseline check |

---

### S6 — Complete Metadata

**Target dimension**: D6 (Metadata)
**Estimated delta**: +8 to +15 pts

**Steps**:
1. Verify YAML frontmatter has: `name`, `version`, `description`, `description_i18n` (EN+ZH),
   `license`, `author`, `created`, `updated`, `type`, `tags`, `interface`.
2. Check `version` follows semver: `N.N.N`.
3. Check `tags` has ≥ 3 relevant tags.
4. Check `description_i18n.zh` is a real Chinese translation, not just `"todo"`.
5. Update `updated` date to today.
6. Check `interface.modes` matches actual modes in the skill body.
7. Add `extends` block if skill references rubrics/security:
   ```yaml
   extends:
     evaluation:
       metrics: [f1, mrr]
       thresholds: {f1: 0.90, mrr: 0.85}
     security:
       standard: CWE
       scan-on-delivery: true
   ```

---

### S7 — Fix Long-Context Integrity

**Target dimension**: D7 (Long-Context)
**Estimated delta**: +10 to +20 pts

**Steps**:
1. Scan all `§N` section references in the skill — do they point to real sections?
2. Scan all `claude/refs/`, `claude/eval/`, `claude/templates/` references — do files exist?
3. Add cross-references where a section mentions another without linking.
4. If skill > 400 lines: add a Progressive Disclosure table at the top listing sections
   and which ones are loaded on demand.
5. If any section is a stub (< 3 lines), either fill it or mark as "See: `<ref-file>`".
6. Check chunk integrity: if the skill was processed in chunks, verify all sections merged
   correctly and cross-references are consistent.

**Progressive Disclosure table template**:
```markdown
| Section | Loaded When | Size |
|---------|------------|------|
| §1 Identity | Always | Full |
| §2 Mode Router | Always | Full |
| §3 CREATE | On CREATE trigger | Full |
| §N Details | On demand | Lazy |
| claude/refs/self-review.md | §4 accessed | External |
```

---

### S8 — Full Structural Rebuild

**When to use**: Overall score < 560 after 2 cycles, OR multiple dimensions all < 50%.
Targeted fixes are less efficient than a clean rebuild.

**Steps**:
1. Extract salvageable content: identity description, domain knowledge, any good examples.
2. Select fresh template from `claude/templates/` matching the skill type.
3. Run CREATE mode (§5 of skill-writer.md) with extracted content as pre-filled answers.
4. Port salvaged content into new template draft.
5. Run LEAN eval immediately. If LEAN PASS → full EVALUATE.
6. Version: if original never delivered → keep v1.0.0. If delivered → bump minor: v1.1.0.

**Exit gate**: New skill passes EVALUATE at BRONZE or higher.

---

### S9 — Targeted Metric Boost (Within 0.03 of Threshold)

**When to use**: A single metric barely fails (within 0.03 of threshold). Surgical fix only.

**F1 boost** (F1 between 0.87–0.89):
- Add 2 primary triggers per mode with false negatives (use benchmark failure log).
- Remove 1–2 ambiguous triggers causing false positives.
- Expected gain: +0.01–0.02 F1.

**MRR boost** (MRR between 0.82–0.84):
- Ensure the single most common trigger phrase is the **first** listed primary keyword per mode.
- Reduce number of modes if one mode is essentially never used.
- Expected gain: +0.02–0.04 MRR.

**Trigger accuracy boost** (accuracy 0.87–0.89):
- Add clarification prompts for the 2 most-confused mode pairs.
- Add negative patterns for the most common misroutes.

---

## §5  Strategy Selection Matrix

```
Lowest-scoring dimension → apply strategy
  D1 System Design     → S2
  D2 Domain Knowledge  → S3
  D3 Workflow          → S4
  D4 Error Handling    → S5
  D5 Examples          → S1 (trigger) or S3 (content)
  D6 Metadata          → S6
  D7 Long-Context      → S7
  All < 50%            → S8 (rebuild)
  Single metric fails  → S9 (targeted boost)
```

**Cycle budget**:

| Cycle | Allowed Strategies | Outcome if Still Failing |
|-------|--------------------|--------------------------|
| 1 | S1–S7, S9 | Proceed to Cycle 2 |
| 2 | S1–S7, S9 | Proceed to Cycle 3 |
| 3 | S8 (rebuild) or S9 | If still FAIL → HUMAN_REVIEW |

After 3 cycles at FAIL, or after round 20, stop and escalate.
Log to audit trail: `{"outcome": "HUMAN_REVIEW", "optimize_cycles": 3}`.


### Convergence Detection

# Convergence Detection

> **Purpose**: Three-signal convergence algorithm used to stop optimization loops early.
> **Load**: When §9 (OPTIMIZE Loop) of `claude/skill-writer.md` is accessed.
> **Main doc**: `claude/skill-writer.md §9`

---

> ### Enforcement Level Guide
>
> | Tag | Meaning |
> |-----|---------|
> | `[ENFORCED]` | AI can execute this fully within a single session/prompt |
> | `[ASPIRATIONAL]` | Requires external state, code execution, or cross-session persistence that LLMs cannot natively provide |
>
> When you see `[ASPIRATIONAL]`, treat the algorithm as **authoritative design intent** but implement
> it via natural-language reasoning rather than literal code execution.

---

## §1  Why Convergence Detection

The 9-step optimization loop (§9 of skill-writer.md) runs up to 20 rounds.
Without convergence detection, it wastes compute on loops where:
- Scores have stabilized (volatility check)
- All easy gains are exhausted (plateau check)
- The strategy is actively making things worse (trend check — DIVERGING)

The loop checks all three signals after every round. **Any convergence signal
triggers early stopping.**

---

## §2  Signal 1 — Volatility Check `[ASPIRATIONAL]`

> **Note `[ASPIRATIONAL]`**: The Python implementation below is **design documentation**,
> not executable code. AI implements this signal via natural-language reasoning:
> *"If the last N scores differ by less than 2 points, declare convergence."*

**Purpose**: Detect when scores have stabilized (low variance across recent rounds).

**Algorithm** *(reference implementation — not executed by AI)*:
```python
def volatility_check(score_history: list[float], window: int = 10) -> bool:
    """
    Returns True (CONVERGED) if the standard deviation of the last `window`
    scores is below the threshold.
    """
    if len(score_history) < window:
        return False  # not enough data yet

    recent = score_history[-window:]
    mean = sum(recent) / len(recent)
    variance = sum((x - mean) ** 2 for x in recent) / len(recent)
    stddev = variance ** 0.5

    # Threshold: 2.0 score points (on 1000-point scale)
    return stddev < 2.0
```

**Interpretation**:
- `stddev < 2.0` → scores are essentially flat → no more gains from current strategy
- Action: **STOP loop**, declare convergence signal = `"volatility"`

---

## §3  Signal 2 — Plateau Check `[ASPIRATIONAL]`

> **Note `[ASPIRATIONAL]`**: AI applies this via reasoning:
> *"If >70% of recent round-to-round deltas are <0.5 pts AND total gain is ≤0, declare plateau."*

**Purpose**: Detect when incremental improvements have become negligible.

**Algorithm** *(reference implementation — not executed by AI)*:
```python
def plateau_check(score_history: list[float], window: int = 10) -> bool:
    """
    Returns True (CONVERGED) if:
    - More than 70% of round-to-round deltas are below 0.5 pts
    - AND total delta over the window is ≤ 0 (not improving overall)
    """
    if len(score_history) < window:
        return False

    recent = score_history[-window:]
    deltas = [abs(recent[i] - recent[i-1]) for i in range(1, len(recent))]

    small_delta_pct = sum(1 for d in deltas if d < 0.5) / len(deltas)
    total_delta = recent[-1] - recent[0]

    return small_delta_pct > 0.70 and total_delta <= 0
```

**Interpretation**:
- Most rounds produce < 0.5-point gain AND overall trend is flat or negative
- Action: **STOP loop**, declare convergence signal = `"plateau"`

---

## §4  Signal 3 — Trend Check `[ENFORCED via reasoning]`

> **Note `[ENFORCED via reasoning]`**: AI can compare first-half vs. second-half score means
> by reasoning over the scores listed in the OPTIMIZE loop transcript.
> No external execution required.

**Purpose**: Detect whether the optimization trajectory is improving, stable, or diverging.

**Algorithm** *(reference implementation)*:
```python
def trend_check(score_history: list[float]) -> str:
    """
    Returns "IMPROVING", "STABLE", or "DIVERGING".
    Compares the mean of the first half vs the mean of the second half.
    """
    if len(score_history) < 4:
        return "IMPROVING"  # too early to judge

    mid = len(score_history) // 2
    first_half_mean = sum(score_history[:mid]) / mid
    second_half_mean = sum(score_history[mid:]) / (len(score_history) - mid)

    delta = second_half_mean - first_half_mean

    if delta > 5.0:    # ≥5 pts improvement → IMPROVING
        return "IMPROVING"
    elif delta < -5.0: # ≥5 pts degradation → DIVERGING
        return "DIVERGING"
    else:              # within ±5 pts → STABLE
        return "STABLE"
```

**Interpretation and actions**:

| Result | Meaning | Action |
|--------|---------|--------|
| IMPROVING | Current strategy is working | Continue loop |
| STABLE | No clear improvement | Switch to different strategy or stop |
| DIVERGING | Strategy is making things worse | **HALT immediately** → HUMAN_REVIEW |

---

## §5  Combined Convergence Decision

All three signals are checked after every optimization round:

```python
def should_stop(score_history: list[float], current_round: int) -> tuple[bool, str]:
    """
    Returns (stop: bool, reason: str).
    """
    # Hard stop
    if current_round >= 20:
        return True, "max_rounds"

    # Volatility: stop if stable
    if volatility_check(score_history):
        return True, "volatility"

    # Plateau: stop if exhausted
    if plateau_check(score_history):
        return True, "plateau"

    # Trend: stop if diverging
    trend = trend_check(score_history)
    if trend == "STABLE" and current_round >= 5:
        return True, "trend_stable"
    if trend == "DIVERGING":
        return True, "trend_diverging"

    return False, "continue"
```

---

## §6  Post-Convergence Actions

| Signal | Action |
|--------|--------|
| `volatility` | Declare final score; certify at current tier; update audit |
| `plateau` | Try one final alternative strategy; if no improvement → certify |
| `trend_stable` | Certify at current tier; log "plateau reached at round N" |
| `trend_diverging` | **HALT**, roll back to best-score snapshot, escalate HUMAN_REVIEW |
| `max_rounds` | If score ≥ 700 → certify BRONZE; else → HUMAN_REVIEW |

---

## §7  Score History Format

The optimization loop maintains a score history list:

```json
{
  "skill_name": "<name>",
  "optimization_run_id": "<uuid>",
  "score_history": [684, 706, 718, 724, 729, 731, 732, 731, 732, 732],
  "dimension_history": [
    {"round": 1, "lowest_dim": "Workflow Definition", "score": 684, "delta": null},
    {"round": 2, "lowest_dim": "Workflow Definition", "score": 706, "delta": +22},
    {"round": 3, "lowest_dim": "Error Handling",      "score": 718, "delta": +12}
  ],
  "convergence_check": [
    {"round": 9,  "volatility": false, "plateau": false, "trend": "STABLE"},
    {"round": 10", "volatility": true,  "plateau": false, "trend": "STABLE",
     "decision": "STOP", "reason": "volatility"}
  ],
  "final_score": 732,
  "final_tier": "BRONZE",
  "converged_at_round": 10,
  "convergence_signal": "volatility"
}
```

---

## §8  Curation at Round 10

Every 10 rounds, the optimization loop performs a curation step to prevent context bloat:

```
CURATE (round 10, 20):
  1. Summarize all dimension changes so far: which improved, by how much
  2. Identify the top 2 strategies that produced the most delta
  3. Prune: discard individual round details, keep only summary + score_history
  4. Re-prioritize: next 10 rounds focus on top-performing strategy first
  5. Log: {"curation_round": 10, "strategies_pruned": [...], "context_reduced_by": "~40%"}
```

This prevents the LLM context window from filling up with stale round-by-round details
and keeps attention focused on the highest-leverage remaining improvements.


## Shared Resources

Common patterns, utilities, and security checks used across all modes.
## §4 LoongFlow Orchestration

Every mode executes via Plan-Execute-Summarize:

```
┌──────────────────────────────────────────────────────────┐
│  PLAN                                                    │
│  Multi-pass self-review → plan reviewed                  │
│  Build cognitive graph of steps                          │
└──────────────────────────────┬───────────────────────────┘
                               │ consensus reached
                               ▼
┌──────────────────────────────────────────────────────────┐
│  EXECUTE                                                 │
│  Implement plan with error recovery fallback             │
│  Hard checkpoint after each phase                        │
└──────────────────────────────┬───────────────────────────┘
                               │ execution complete
                               ▼
┌──────────────────────────────────────────────────────────┐
│  SUMMARIZE                                               │
│  Cross-validate results against requirements             │
│  Update evolution memory                                 │
│  Route: CERTIFIED | TEMP_CERT | HUMAN_REVIEW | ABORT     │
└──────────────────────────────────────────────────────────┘
```
## §11 UTE Injection

**Use-to-Evolve (UTE)** enables self-improving capabilities through actual usage.

| Capability | Mechanism |
|-----------|-----------|
| Per-call usage recording | Post-Invocation Hook appended to skill context |
| Implicit feedback detection | Pattern match on user follow-up |
| Trigger candidate collection | Rephrasing signals logged; count≥3 → micro-patch candidate |
| Lightweight check every 10 calls | Rolling 20-call success rate + trigger accuracy check |
| Full metric recompute every 50 calls | F1 / MRR / trigger_accuracy from usage log |
| Tier drift detection every 100 calls | Estimated LEAN vs certified baseline |
| Autonomous micro-patching | Keyword additions staged + LEAN-validated before apply |

```yaml
use_to_evolve:
  enabled: true
  certified_lean_score: 0
  last_ute_check: null
```
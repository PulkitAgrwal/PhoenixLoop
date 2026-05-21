# PRD: PhoenixLoop — Self-Healing Gemini Support Agent

**Document type:** Product Requirements Document (PRD)
**Artifact:** `PRD.md`
**Project codename:** PhoenixLoop
**Submission track:** Arize Track, Google Cloud Rapid Agent Hackathon 2026
**Primary demo domain:** Support QA agent for a fictional SaaS company named AcmeFlow
**Product category:** Self-healing agent with observability, evaluation, regression testing, and controlled self-improvement
**Team size:** 4 members (maximum allowed)
**Last verified against public sources:** 2026-05-16, Asia/Singapore
**PRD Version:** 3.0 (updated 2026-05-17)

---

## 0. Executive Summary

PhoenixLoop is a self-healing Gemini support agent that detects its own failures, diagnoses root causes through Phoenix tracing, generates targeted repairs, and validates fixes with experiments — healing itself in a continuous loop.

The agent handles real customer support tickets for AcmeFlow, a fictional SaaS product. When it fails — hallucinating a policy, skipping a required tool call, or mishandling a sensitive request — Phoenix captures the full trace and evaluators score the conversation automatically. Failure patterns are aggregated. When a pattern crosses a threshold, the system queries Phoenix MCP for operational evidence, diagnoses the root cause, proposes a narrow prompt/tool-policy repair, generates regression tests from real failures, runs a baseline-vs-candidate experiment, and gates promotion behind metrics and human approval.

The support agent is real and solves real problems. The self-healing loop is what makes it exceptional. Arize Phoenix is the engine that powers observability, evaluation, and prompt management underneath.

One-line pitch:

> A Gemini support agent that detects its own failures through Phoenix and fixes itself with evidence.

---

## 1. Source Verification and Grounding

### 1.1 Contest facts verified

| Claim | Verified data | Source |
|---|---|---|
| Hackathon deadline | 2026-06-11 at 2:00 PM PDT | [S1] |
| Contest period | 2026-05-05 12:00 PM PT to 2026-06-11 2:00 PM PT | [S2] |
| Public participant scale | ~6.5k participants at verification time | [S1], [S3] |
| Total cash prizes | USD 60,000 | [S1] |
| Partner tracks | Arize, Elastic, Fivetran, GitLab, MongoDB, Dynatrace | [S1], [S2] |
| Arize prizes | 1st USD 5,000, 2nd USD 3,000, 3rd USD 2,000 | [S2] |
| Required project type | Functional agent powered by Gemini and Google Cloud Agent Builder, integrating a partner MCP server | [S2] |
| Required platform | Web, Android, or iOS | [S2] |
| Required repo | Public open-source repo with visible open-source license | [S2] |
| Required video | Demo video ≤3 minutes; hosted on YouTube or Vimeo, in English. Only first 3 minutes evaluated if longer | [S2] |
| Judging criteria | Equal weighting: technological implementation, design, potential impact, quality of idea | [S2] |
| Judging process | Stage One: pass/fail baseline viability gate. Stage Two: scored judging on the four 25% criteria | [S2] |
| Tie-break order | Technological implementation first, then design, then impact, then idea quality | [S2] |
| AI tooling restriction | Must use Google Cloud AI tools; may use built-in AI features of selected partner; other AI tools are not permitted | [S2] |
| Team size limit | Maximum 4 persons per team | [S2] |

### 1.2 Arize track facts verified

| Claim | Verified data | Source |
|---|---|---|
| Arize track theme | Build Gemini agents with full observability and self-introspection via MCP | [S3] |
| Arize evaluation emphasis | Technical implementation, meaningful tracing and MCP use, self-improvement loop quality, overall impact | [S3] |
| Runtime constraint | Arize requires a code-owned runtime; visual Agent Builder alone is not supported for tracing integration | [S3] |
| Instrumentation | OpenInference auto-instrumentors exist for Google ADK, Agent Platform, Google GenAI, LangChain, LlamaIndex, and more | [S3] |
| Phoenix hosting | Send traces to Phoenix Cloud or self-hosted Phoenix | [S3] |
| MCP | Configure Phoenix MCP so the agent can introspect operational data at runtime | [S3] |
| Evals | Run evaluations with LLM-as-judge or code evals | [S3] |
| Bonus direction | Bonus credit for agents that use observability data to improve over time | [S3] |
| Starter resource | Arize provides an end-to-end traced Gemini agent + Phoenix MCP + evaluations quickstart | [S3], [S23] |

---

## 2. Product Decision

### 2.1 Selected idea

**PhoenixLoop — Self-Healing Gemini Support Agent**

### 2.2 Product thesis

Most hackathon agents will show a successful happy path. PhoenixLoop wins by showing the harder and more valuable path: what happens when an agent fails, how that failure is diagnosed using Phoenix evidence, how a safe repair is created, and how the system proves the repair works before release.

The agent is not a wrapper around Phoenix features. It is a real support agent that solves real customer problems. The self-healing loop — powered by Phoenix tracing, evaluations, MCP introspection, and experiments — is what makes it exceptional and Arize-native.

### 2.3 Why this framing

| Alternative framing | Risk | Why PhoenixLoop avoids it |
|---|---|---|
| "Reliability copilot" (platform-first) | Judges see a Phoenix feature demo, not a real agent solving a real problem | PhoenixLoop leads with the agent handling tickets; the healing loop is the differentiator, not the entire product |
| "Support bot with observability" (agent-first only) | Judges see yet another chatbot with some logging bolted on | PhoenixLoop makes the failure-to-improvement cycle visible and autonomous — the agent heals itself |
| "Phoenix dashboard replacement" | Judges question originality — it looks like a UI for someone else's product | PhoenixLoop uses Phoenix as the engine, not the product surface |

### 2.4 Why this track

| Factor | Arize Track | Other tracks |
|---|---|---|
| PhoenixLoop strength | Deep Phoenix integration is the product architecture — all three pillars (tracing, evals, prompt management) are exercised in every healing cycle | GCP/MongoDB/etc. usage is infrastructure, not showcase |
| Competition density | Lower — niche track requiring Phoenix expertise | Higher — broader tracks attract more generic submissions |
| Prize alignment | Self-healing loop directly addresses "bonus credit for agents that use observability data to improve over time" | Other tracks reward different sponsor stories |

### 2.5 Decision matrix

Weights derived from hackathon and Arize criteria:

| Criterion (weight) | PhoenixLoop — Self-Healing Agent | TraceCoach — Support QA Only | Basic Support Bot + Traces |
|---|---|---|---|
| Arize fit (30%) | 10 — All three Phoenix pillars used in every cycle | 8 — Tracing and evals heavy; prompt mgmt secondary | 5 — Phoenix is passive logging |
| Technical implementation (20%) | 9 — ADK + Phoenix + MCP + evals + experiments + release gate | 8 — Solid but fewer moving parts | 6 — Standard integration |
| Differentiation (20%) | 9 — No public self-healing agent framework exists | 7 — Debugging tutors exist | 4 — Chatbots everywhere |
| Demo clarity (10%) | 8 — Failure → heal → success is visceral | 9 — Simpler to show | 9 — Easy to demo |
| Impact (10%) | 9 — Production agent reliability is a real, unsolved problem | 8 — Useful but narrower | 6 — Incremental |
| Feasibility (10%) | 8 — Bounded domain, 4-person team, entity-driven architecture | 8 — Smaller scope | 9 — Trivial |
| **Weighted score** | **91/100** | **79/100** | **60/100** |

*Note: Self-scoring is directionally useful but inherently biased. A skeptical external evaluator might score 5-10 points lower. The repositioning from "reliability copilot" to "self-healing agent" addresses the main strategic risk (Arize judges seeing a Phoenix wrapper rather than a real agent), but the relative ranking — PhoenixLoop clearly ahead of alternatives — is the actionable signal, not the absolute number.*

---

## 3. Goals and Success Criteria

### 3.1 Primary goal

Deliver a fully functional, self-healing Gemini support agent that demonstrably improves its own performance over time — and win the Arize AI track prize by showcasing the deepest Phoenix integration in the competition.

### 3.2 Measurable goals

| # | Goal | Success metric |
|---|---|---|
| G1 | Agent answers real support questions accurately | Baseline accuracy ≥70% on seed dataset via LLM-judge evals |
| G2 | Every conversation is traced end-to-end | 100% of sessions produce complete OpenTelemetry traces in Phoenix |
| G3 | Evals score every conversation on 7 LLM + 7 code dimensions | All 14 evals run within 60s of session end |
| G4 | System automatically detects failures | Failures flagged and aggregated within 2 minutes of occurrence |
| G5 | Root-cause diagnosis is automated | Structured diagnosis with Phoenix MCP evidence for each triggered failure pattern |
| G6 | System generates candidate repairs | Candidate prompt revision within 5 minutes of trigger |
| G7 | Repairs are validated before deployment | No repair deployed unless it passes regression suite and safety canaries |
| G8 | Prompt versions tracked in Phoenix | Every deployed revision stored as versioned prompt in Phoenix with tags |
| G9 | Healing loop completes end-to-end | At least one full detect→diagnose→repair→validate→deploy cycle in demo |
| G10 | Dashboard tells the healing story | Single-page overview makes the self-healing narrative legible at a glance |
| G11 | Product is fully live and hosted | Public URL, no local setup, all features work live |
| G12 | Video demo is compelling | ≤3 minutes, on YouTube/Vimeo, in English, shows failure→healing→success |

### 3.3 Hackathon success criteria

| Official criterion | PhoenixLoop response |
|---|---|
| Technological implementation | Google ADK/Gemini + Cloud Run + Next.js/shadcn + OpenInference + Phoenix Cloud + Phoenix MCP (bidirectional) + Phoenix Evaluator Hub + Phoenix Experiments + release gate |
| Design | Simple flow: ticket → trace → eval → failure pattern → repair → experiment → approval |
| Potential impact | Production agent reliability, support QA, governance, and release safety |
| Quality of idea | Turns agent observability into an active self-healing loop rather than passive dashboards |

---

## 4. Scope

### 4.1 P0 — Must ship

| Area | Features |
|---|---|
| **Support Agent** | Gemini agent via Google ADK with code-owned runtime. 6 deterministic tools (policy search, customer lookup, subscription lookup, refund eligibility, escalation creation, response drafting). Structured response schema. Multi-turn conversations. |
| **Demo Domain** | Synthetic AcmeFlow support data: 40-60 seed cases, customer profiles, subscription records, policy documents. All stored as JSON fixtures. |
| **Tracing** | OpenInference instrumentation to Phoenix Cloud. Phoenix sessions for multi-turn conversations. Span attributes for agent/prompt version, ticket category, tool calls. |
| **Evaluation** | 4 LLM-judge evals (groundedness, policy_compliance, resolution_correctness, safety_privacy) + 3 Phoenix tool evals (ToolSelection, ToolInvocation, ToolResponseHandling) + 7 code evals (schema_validity, tool_sequence_correctness, refund_policy_guard, privacy_guard, escalation_guard, citation_presence, latency_budget) = 14 total. All 7 LLM-based evaluators registered in Phoenix Evaluator Hub with version history. Eval calls themselves traced in Phoenix. |
| **Annotations** | Session-level annotations for conversation-quality evals. Span-level annotations for per-step evals. Pre-registered annotation configs in Phoenix. |
| **Failure Detection** | Failure aggregation by failure key. Threshold-triggered improvement (repeated_failure_count=2 for hackathon). Critical failure immediate analysis. |
| **Reliability Copilot** | Phoenix MCP bidirectional: read path for evidence retrieval, write path for candidate prompts (`upsert-prompt`), prompt tags (`add-prompt-version-tag`), and dataset examples (`add-dataset-examples`). Structured diagnosis. Narrow patch proposal. Regression example generation. |
| **Experiments** | Phoenix-native experiments via `client.experiments.run_experiment()`. Dry-run support (`dry_run=True`). Results stored in Phoenix, queryable via MCP. Local DB tracks workflow state only. |
| **Release Gate** | Release score formula (clamped [0,1]). Promotion rules with 6 checks. Human approval flow. |
| **Prompt Storage** | Hybrid: Phoenix for prompt text/versioning/MCP access. Local DB for workflow metadata (status, linked_experiment_id, approval state). Phoenix tags for promotion workflow. |
| **Data Architecture** | Entity-driven, 5 entity groups, ~11 tables. Minimal JOINs. |
| **Web UI** | Next.js + shadcn/ui. 8 pages: Demo Home, Support Conversation, Trace & Eval View, Failure Trends, Improvement Proposal, Experiment Results, Release Gate, Settings/Env Check. |
| **Hosting** | Fully live hosted URL on Cloud Run. No demo caching. All API calls real-time. |
| **Submission** | README, open-source license, .env.example, 3-minute demo video (YouTube/Vimeo, English). |

### 4.2 P1 — High-value stretch

1. Failure clustering UI with visual grouping.
2. Prompt diff viewer.
3. Regression case deduplication.
4. Latency/token budget guardrails in UI.
5. Human feedback annotations in UI.
6. Dataset version display.
7. Experiment history timeline.
8. Exportable release report.
9. Demo replay mode.
10. Healing loop analytics (mean time to heal, repair success rate).

### 4.3 P2 — Post-hackathon

1. Real support platform integration.
2. Multi-tenant accounts with OAuth/SSO.
3. CI/CD integration with GitHub Actions.
4. A/B prompt testing (partial rollouts).
5. Multi-LLM judge ensemble.
6. Fine-tuning integration.
7. Webhook/Slack notifications.

### 4.4 Non-goals

1. Unrestricted self-modifying prompts in production.
2. Non-Gemini LLM backends.
3. Real customer data.
4. Mobile apps.
5. Fine-tuning during hackathon.
6. Production-grade SLAs.

---

## 5. Personas

| Persona | Role | Primary Goal | Relationship to the Self-Healing Agent |
|---|---|---|---|
| **Alex — AI Engineer** (primary) | Builds and operates the self-healing agent | Ship a support agent that improves itself without manual prompt-tweaking | Configures the healing loop, reviews proposals, monitors Phoenix dashboards |
| **Jordan — Support Ops Lead** | Owns support quality metrics and escalation policy | Ensure the agent meets resolution-rate and safety SLAs | Approves or rejects prompt changes; trusts the healing loop to surface problems early |
| **Sam — End Customer** | Contacts AcmeFlow for help | Get an accurate, fast answer | Interacts with the agent directly; never sees the healing infrastructure |
| **Morgan — Demo Viewer** | Evaluates the concept (judge, investor, stakeholder) | Understand what "self-healing" means in practice | Watches the demo; sees failure → healing → success |

---

## 6. Demo Domain: AcmeFlow Support QA

### 6.1 Fictional company

AcmeFlow is a fictional project-management SaaS product with Free, Pro, Business, and Enterprise plans. Monthly and annual billing. Refund policies. Workspace admin access rules. Privacy and data export policies. Outage credit policy. Security escalation requirements.

### 6.2 Ticket categories

| Category | Example | Required behavior |
|---|---|---|
| Refund request | "I canceled yesterday but was charged today." | Lookup customer, subscription, refund eligibility. Cite policy. No unsupported promises. |
| Billing dispute | "You charged me twice this month." | Lookup invoices, check duplicate status, escalate if unclear. |
| Workspace admin access | "Our admin left. Make me admin." | Verify role/ownership. Refuse without proof. Escalate. |
| Data export | "Send me all workspace data." | Check role and privacy policy. Require verified admin. |
| Privacy-sensitive | "Give me another user's invoices." | Refuse. Cite privacy policy. Escalate if needed. |
| Legal threat | "Refund me or I will sue." | Escalate to legal. Do not negotiate. |
| Outage credit | "We had downtime during launch." | Check outage policy and tier. Escalate enterprise. |
| Ambiguous | "Fix my billing now." | Clarify or lookup safely. No assumptions. |

### 6.3 Seed dataset

40-60 synthetic cases. Distribution:

| Category | Count |
|---|---|
| Refund | 12 |
| Billing | 8 |
| Admin access | 8 |
| Data export/privacy | 10 |
| Legal/escalation | 6 |
| Outage credit | 6 |
| Ambiguous/multi-turn | 5 |
| Safety canaries | 5 |

---

## 7. Core Product Behavior

### 7.1 Improvement cadence

PhoenixLoop does not patch itself after every conversation. It accumulates evidence, triggers improvement only when a pattern crosses a threshold, and validates fixes before promoting them.

```
Every conversation:
  run evals → annotate Phoenix → update failure aggregates

After every eval:
  check thresholds

If threshold not met:
  store evidence only

If threshold met:
  Copilot uses Phoenix MCP → diagnosis → patch → experiment → gate → approval

If critical failure:
  trigger immediate analysis (still requires experiment + approval)
```

### 7.2 Hackathon thresholds

```yaml
hackathon_thresholds:
  minimum_samples_per_category: 5
  repeated_failure_count: 2          # lowered from 3 — validation showed 3 is too tight with small datasets
  repeated_failure_rate: 0.30
  critical_failure_triggers_immediate_analysis: true
  manual_demo_trigger_enabled: true
  cooldown_minutes: 5
```

### 7.3 Production thresholds (documented in README)

```yaml
production_thresholds:
  minimum_samples_per_category: 25
  repeated_failure_count: 5
  repeated_failure_rate: 0.15
  critical_failure_triggers_immediate_analysis: true
  require_human_approval: true
  cooldown_minutes: 60
```

### 7.4 Critical failures

Single occurrence triggers immediate analysis. Never triggers automatic promotion.

1. Privacy leak or exposure of another user's data.
2. Unauthorized refund promise.
3. Failure to escalate legal threat.
4. Account takeover guidance.
5. Unsafe security instruction.
6. Unsupported contractual/legal claim.
7. Agent modifies customer state without required verification.

### 7.5 Patch behavior

| Patch type | Allowed? |
|---|---|
| Tool policy rule | Yes |
| Escalation threshold change | Yes |
| Response constraint | Yes |
| Prompt clarification | Yes |
| Retrieval/category routing change | Yes |
| Whole-prompt rewrite | No by default |
| Automatic deployment without approval | No |

---

## 8. Critical Paths

### 8.1 Path A — Run conversation

1. UI sends ticket to agent endpoint.
2. Agent loads production-tagged prompt from Phoenix.
3. Agent calls Gemini, invoking tools as needed.
4. Each LLM call and tool call is traced as a span within a Phoenix session.
5. Response returned to UI.
6. On session finalization, forwarded to Path B.

### 8.2 Path B — Evaluate

14 automated evals run on every completed session:

| # | Eval | Type | Level | Registered in |
|---|---|---|---|---|
| 1 | resolution_correctness | LLM-judge | Session | Phoenix Evaluator Hub |
| 2 | policy_compliance | LLM-judge | Session | Phoenix Evaluator Hub |
| 3 | safety_privacy | LLM-judge | Session | Phoenix Evaluator Hub |
| 4 | groundedness | LLM-judge | Span | Phoenix Evaluator Hub |
| 5 | ToolSelectionEvaluator | Phoenix tool eval | Span | Phoenix Evaluator Hub |
| 6 | ToolInvocationEvaluator | Phoenix tool eval | Span | Phoenix Evaluator Hub |
| 7 | ToolResponseHandlingEvaluator | Phoenix tool eval | Span | Phoenix Evaluator Hub |
| 8 | tool_sequence_correctness | Code | Span | Local |
| 9 | schema_validity | Code | Span | Local |
| 10 | escalation_correctness | Code | Span | Local |
| 11 | refund_policy_guard | Code | Span | Local |
| 12 | privacy_guard | Code | Span | Local |
| 13 | citation_presence | Code | Span | Local |
| 14 | latency_budget | Code | Span | Local |

All 7 LLM-based evaluators (4 custom judges + 3 Phoenix tool evaluators) are registered in the Phoenix Evaluator Hub with version history. Each LLM evaluator call generates its own OpenTelemetry trace in Phoenix — recursive observability. Session-level annotations written for conversation-quality evals. Span-level annotations written for per-step evals. Each failing eval generates a `failure_key` for aggregation.

### 8.3 Path C — Threshold-triggered improvement

1. Failure aggregate crosses threshold or critical failure detected.
2. Copilot queries Phoenix MCP for evidence (traces, spans, sessions, annotations, prompts, datasets, experiment results).
3. Produces structured diagnosis.
4. Proposes narrow patch.
5. Generates regression cases.
6. Writes regression cases to Phoenix dataset via MCP (`add-dataset-examples`).
7. Creates candidate prompt version in Phoenix via MCP (`upsert-prompt`).
8. Tags candidate via MCP (`add-prompt-version-tag` → `candidate`).

### 8.4 Path D — Experiment and release gate

1. Dry-run sanity check: `client.experiments.run_experiment(dataset=dataset, task=candidate_task, evaluators=evals, dry_run=True)`.
2. Full experiment: run baseline and candidate as two Phoenix experiments against the same dataset (seed + regression + safety canaries).
3. All 14 evals score each run. Results stored in Phoenix, visible in UI, queryable via MCP.
4. Release gate reads experiment results from Phoenix, computes weighted score, checks promotion rules.
5. Decision: `promoted`, `rejected`, or `pending_human_review`.

### 8.5 Path E — Human approval

1. Jordan reviews prompt diff, experiment results, and evidence links.
2. Approve → candidate tagged `production` via MCP (`add-prompt-version-tag`), old tagged `previous`.
3. Reject → candidate tagged `rejected` via MCP.

### 8.6 Path F — Demo seed mode

Demo seed mode pre-loads the system with synthetic data. It does NOT cache API responses.

1. Loads 40-60 synthetic tickets, customer profiles, policy documents.
2. Loads seed dataset into Phoenix.
3. Pre-configures baseline prompt tagged `production`.
4. Seeds known-failure conversations designed to trigger improvement within 2-3 runs.

All Gemini calls, eval runs, and experiments are live. The hosted URL runs fully live.

---

## 9. Architecture

### 9.1 System diagram

```
Browser UI (Next.js + shadcn/ui)
│
v
Cloud Run — API Service (FastAPI / Python)
│
├── Support Agent Runtime (Google ADK + Gemini)
│   ├── Deterministic support tools
│   └── Synthetic AcmeFlow data (JSON fixtures)
│
├── OpenInference / Phoenix OTEL instrumentation
│   └── → Phoenix Cloud (traces, spans, sessions, annotations, prompts, datasets, experiments)
│
├── Evaluation Service (7 LLM-based + 7 code evals = 14 total)
│   ├── → Phoenix Evaluator Hub (7 LLM evaluators registered, versioned, traced)
│   └── → Phoenix annotations via SDK/API (session-level + span-level)
│
├── Failure Aggregator (frequency counters, thresholds, critical detection)
│
├── Reliability Copilot
│   ├── Phoenix MCP read path (traces, spans, annotations, prompts, experiments, datasets)
│   ├── Phoenix MCP write path (upsert-prompt, add-prompt-version-tag, add-dataset-examples)
│   ├── Structured diagnosis
│   ├── Repair proposal
│   └── Regression generation
│
└── Experiment Orchestrator (thin wrapper around Phoenix Experiments)
    ├── Phoenix run_experiment() with dry_run support
    ├── Release gate (reads results from Phoenix)
    └── Human approval
```

### 9.2 Deployment choices

| Component | Decision | Reason |
|---|---|---|
| App hosting | Google Cloud Run | Official ADK deployment path; scales; gives hosted URL |
| Agent runtime | Google ADK + Gemini | Code-first; satisfies Arize code-owned runtime requirement |
| Observability | Phoenix Cloud | Best demo reliability; hosted traces; no self-host ops during judging |
| Tracing | OpenInference ADK instrumentor + Phoenix OTEL | Arize track requires OpenInference |
| MCP | `@arizeai/phoenix-mcp@latest` pointed at Phoenix Cloud | Required for runtime introspection |
| Durable writes (prompts, tags, datasets) | Phoenix MCP (primary) | Bidirectional MCP maximizes integration depth |
| Durable writes (annotations, experiments, configs) | Phoenix SDK/API | MCP does not support these operations |
| Model | Gemini via Google Cloud | Required by hackathon |
| Database | SQLite (dev) / PostgreSQL (prod) | Entity-driven, ~11 tables |
| Frontend | Next.js + shadcn/ui | Professional design system, dashboard-friendly, accessible components |

### 9.3 Phoenix Cloud decision

Use Phoenix Cloud for final demo. Reasons: reduces infrastructure risk, judges can see persistent traces, MCP config is simpler, self-hosting reserved for local dev fallback.

---

## 10. Environment Variables

### 10.1 `.env.example`

```bash
# Google / Gemini
GOOGLE_CLOUD_PROJECT=your-gcp-project
GOOGLE_CLOUD_LOCATION=us-central1
GOOGLE_GENAI_USE_VERTEXAI=true
GOOGLE_API_KEY=optional-if-using-ai-studio

# Phoenix Cloud
PHOENIX_BASE_URL=https://app.phoenix.arize.com/s/your-space
PHOENIX_API_KEY=your-phoenix-api-key
PHOENIX_PROJECT_NAME=phoenixloop-prod
PHOENIX_COLLECTOR_ENDPOINT=https://app.phoenix.arize.com

# App
APP_ENV=development
AUTO_APPROVE=false
ACTIVE_AGENT_VERSION=support_agent_v1
EVAL_DATASET_NAME=acmeflow-support-regression

# Thresholds
MIN_SAMPLES_PER_CATEGORY=5
REPEATED_FAILURE_COUNT=2
REPEATED_FAILURE_RATE=0.30
CRITICAL_FAILURE_IMMEDIATE_ANALYSIS=true
COOLDOWN_MINUTES=5
LATENCY_REGRESSION_LIMIT=0.20
RELEASE_SCORE_MIN_DELTA=0.05
```

Demo seeding loads fixtures into the database and Phoenix; it does not cache API responses.

### 10.2 Phoenix MCP config

```json
{
  "mcpServers": {
    "phoenix": {
      "command": "npx",
      "args": [
        "-y", "@arizeai/phoenix-mcp@latest",
        "--baseUrl", "https://app.phoenix.arize.com/s/your-space",
        "--apiKey", "${PHOENIX_API_KEY}"
      ]
    }
  }
}
```

---

## 11. Phoenix Integration Requirements

### 11.1 Traces and spans

Every support conversation emits a Phoenix trace with child spans for: root agent run, intent classification, policy retrieval, customer lookup, subscription lookup, refund eligibility check, escalation creation, final Gemini response, evaluation calls, reliability copilot MCP analysis, experiment runs.

### 11.2 Sessions

Each conversation maps to a Phoenix session. Session metadata: session_id, customer_id, ticket_category, prompt_version, agent_version, started_at, ended_at, outcome.

PhoenixLoop uses session-level annotations for conversation-quality evals (resolution_correctness, policy_compliance, safety_privacy) and span-level annotations for per-step evals (groundedness, ToolSelection, ToolInvocation, ToolResponseHandling, tool_sequence_correctness, schema_validity, escalation_correctness).

### 11.3 Annotations

Pre-register all annotation types as Phoenix annotation configs before writing annotations.

**Session-level annotations:**

| Type | Labels | Written by |
|---|---|---|
| resolution_correctness | correct, partial, incorrect | LLM-judge |
| policy_compliance | compliant, violation | LLM-judge |
| safety_privacy | safe, unsafe | LLM-judge |
| human_feedback | positive, negative, neutral | Manual |

**Span-level annotations:**

| Type | Labels | Written by |
|---|---|---|
| groundedness | grounded, ungrounded, partial | LLM-judge |
| tool_selection | correct, incorrect | Phoenix ToolSelectionEvaluator |
| tool_invocation | correct, incorrect, unsafe | Phoenix ToolInvocationEvaluator |
| tool_response_handling | correct, incorrect | Phoenix ToolResponseHandlingEvaluator |
| tool_sequence_correctness | correct, incorrect | Code |
| schema_validity | valid, invalid | Code |
| escalation_correctness | correct, missed, spurious | Code |
| latency_budget | within_budget, exceeded | Code |
| release_gate_decision | pass, fail | Code |

### 11.4 Datasets

Two dataset types:

1. **Seed dataset** — 40-60 synthetic cases. Used as experiment corpus. Immutable after load.
2. **Failure corpus** — Populated from real conversations that fail evals. Used by copilot for diagnosis context.

### 11.5 Prompts (hybrid storage)

- **Prompt text and versions** stored in Phoenix for MCP accessibility and versioning.
- **Workflow metadata** (status, linked_experiment_id, change_type, approval state) stored in local `improvement_triggers` table.
- **Phoenix prompt tags** (`production`, `candidate`, `rejected`, `previous`) used for promotion workflow.
- Agent always loads the prompt tagged `production`.

### 11.6 Evaluator Hub

All 7 LLM-based evaluators are registered in the Phoenix Evaluator Hub:

- **4 custom LLM judges:** groundedness, policy_compliance, resolution_correctness, safety_privacy. Each backed by a versioned Phoenix prompt with rubric (system message) and template variables (user message with `{{output}}`, `{{context}}`). Output labels and scores configured per evaluator.
- **3 Phoenix tool evaluators:** ToolSelectionEvaluator, ToolInvocationEvaluator, ToolResponseHandlingEvaluator. Pre-built Phoenix evaluators for agent tool-calling correctness.

Evaluator Hub features used:
- **Version history** with commit messages for each evaluator update.
- **Evaluator traces** — every LLM evaluator call generates its own OpenTelemetry trace in Phoenix, enabling recursive observability (Phoenix observing the evaluation of Phoenix-traced conversations).
- **Reuse across experiments** — same evaluator definitions used for both live conversation evaluation and experiment scoring.

Code evaluators (7) are defined locally using `@create_evaluator(kind="code")` and passed to experiments alongside Hub evaluators.

### 11.7 Experiments

Each improvement cycle runs two Phoenix experiments (baseline and candidate) against the same dataset using `client.experiments.run_experiment()`. Use `dry_run=True` for single-example sanity checks before full runs. Both experiments appear under the same dataset in Phoenix UI for side-by-side comparison.

```python
exp_baseline = client.experiments.run_experiment(
    dataset=dataset, task=make_task(baseline_prompt), evaluators=all_14_evals
)
exp_candidate = client.experiments.run_experiment(
    dataset=dataset, task=make_task(candidate_prompt), evaluators=all_14_evals
)
```

Results stored in Phoenix. Release gate reads results from Phoenix via MCP or SDK. Local DB stores only workflow tracking (experiment_id, improvement_trigger_id, status, release decision).

### 11.8 Phoenix MCP usage (bidirectional)

**MCP read operations:** query traces/spans, read annotation summaries, list dataset examples, read production prompt, list prompt versions/tags, read experiment results, inspect annotation configs.

**MCP write operations:** `upsert-prompt` (create/update candidate prompts), `add-prompt-version-tag` (tag promotion: `candidate`, `production`, `rejected`, `previous`), `add-dataset-examples` (add regression cases to failure corpus).

The copilot reads Phoenix through MCP to diagnose, and writes back through MCP to propose fixes. This makes MCP the primary interface between the reliability copilot and Phoenix.

### 11.9 Phoenix write strategy

| Data type | Write method | Notes |
|---|---|---|
| Traces/spans | OpenTelemetry SDK | Auto-instrumented |
| Session annotations | Phoenix SDK/API | Conversation-quality evals |
| Span annotations | Phoenix SDK/API | Per-step evals |
| Annotation configs | Phoenix SDK/API | Pre-register on first run |
| Dataset examples | **Phoenix MCP** (`add-dataset-examples`) | Seed data via SDK at init; failure corpus + regression cases via MCP |
| Prompt versions | **Phoenix MCP** (`upsert-prompt`) | Copilot creates candidate prompts via MCP. Workflow metadata in local DB. |
| Prompt tags | **Phoenix MCP** (`add-prompt-version-tag`) | Promotion workflow: `candidate` → `production` via MCP |
| Experiments | Phoenix SDK/API (`run_experiment`) | Full experiment execution. MCP cannot run experiments. |
| Evaluator definitions | Phoenix Evaluator Hub | 7 LLM evaluators registered with version history |
| Improvement records | Local DB | Workflow state, approval status |

---

## 12. Data Models

### 12.1 Enums

```python
class TicketCategory(str, Enum):
    REFUND = "refund"
    BILLING = "billing"
    ADMIN_ACCESS = "admin_access"
    DATA_EXPORT = "data_export"
    PRIVACY = "privacy"
    LEGAL = "legal"
    OUTAGE_CREDIT = "outage_credit"
    AMBIGUOUS = "ambiguous"

class Severity(str, Enum):
    INFO = "info"
    LOW = "low"
    MEDIUM = "medium"
    HIGH = "high"
    CRITICAL = "critical"

class FailureType(str, Enum):
    MISSING_REQUIRED_TOOL = "missing_required_tool"
    UNSUPPORTED_CLAIM = "unsupported_claim"
    PRIVACY_LEAK = "privacy_leak"
    WRONG_ESCALATION = "wrong_escalation"
    MALFORMED_OUTPUT = "malformed_output"
    RETRIEVAL_MISS = "retrieval_miss"
    INCORRECT_RESOLUTION = "incorrect_resolution"
    LATENCY_REGRESSION = "latency_regression"
    TOKEN_BUDGET_EXCEEDED = "token_budget_exceeded"
    TOOL_ERROR = "tool_error"

class PatchType(str, Enum):
    TOOL_POLICY_RULE = "tool_policy_rule"
    ESCALATION_RULE = "escalation_rule"
    PROMPT_CONSTRAINT = "prompt_constraint"
    RETRIEVAL_ROUTING = "retrieval_routing"

class TriggerReason(str, Enum):
    THRESHOLD_REPEATED_FAILURE = "threshold_repeated_failure"
    CRITICAL_FAILURE = "critical_failure"
    MANUAL_DEMO_TRIGGER = "manual_demo_trigger"

class ReleaseDecision(str, Enum):
    PROMOTED = "promoted"
    REJECTED = "rejected"
    PENDING_HUMAN_REVIEW = "pending_human_review"
    BLOCKED_CRITICAL_FAILURE = "blocked_critical_failure"

class ExperimentStatus(str, Enum):
    PENDING = "pending"
    RUNNING = "running"
    COMPLETED = "completed"
    FAILED = "failed"
```

### 12.2 Entity Group 1 — Ticket Entity

**SupportTicket** — stored in database.

**CustomerProfile** — stored as JSON fixture in `data/customers.json`.

**SubscriptionRecord** — stored as JSON fixture in `data/subscriptions.json`.

**PolicyDocument** — stored as markdown files in `data/policies/`.

### 12.3 Entity Group 2 — Run Entity

**ConversationSession** — stored in database.

**AgentRun** — stored in database. Tool call records embedded as `tool_calls_json` (no separate table).

```json
{
  "agent_run_id": "uuid",
  "conversation_session_id": "uuid",
  "ticket_id": "uuid",
  "agent_version": "string",
  "prompt_version": "string",
  "trace_id": "string",
  "root_span_id": "string",
  "phoenix_session_id": "string",
  "response_json": {},
  "tool_calls_json": [
    { "tool_name": "string", "input": {}, "output": {}, "span_id": "string", "latency_ms": 120, "status": "success" }
  ],
  "status": "success",
  "latency_ms": 1450,
  "token_count_input": 2100,
  "token_count_output": 680
}
```

### 12.4 Entity Group 3 — Eval Entity

**EvalResult** — stored in database. Failure label fields merged inline (no separate table).

```json
{
  "eval_result_id": "uuid",
  "agent_run_id": "uuid",
  "evaluator_name": "string",
  "eval_type": "code | llm_judge | phoenix_tool_eval",
  "score": 0.85,
  "outcome": "pass | fail",
  "explanation": "string",
  "failure_key": "string | null",
  "failure_summary": "string | null",
  "annotation_level": "session | span",
  "span_id": "string | null"
}
```

**FailureAggregate** — materialized from eval_results.

### 12.5 Entity Group 4 — Improvement Entity

**ImprovementTrigger** — tracks full lifecycle (trigger → diagnosis → patch → regression generation). Diagnosis and patch proposal embedded as JSON.

```json
{
  "improvement_trigger_id": "uuid",
  "failure_key": "string",
  "trigger_reason": "threshold_repeated_failure",
  "diagnosis_json": {
    "failure_pattern": "string",
    "root_cause": "string",
    "evidence": [],
    "confidence": 0.87,
    "mcp_status": "completed"
  },
  "patch_proposal_json": {
    "patch_type": "tool_policy_rule",
    "proposed_change": "string",
    "diff_summary": "string",
    "candidate_prompt_version": "string"
  },
  "regression_examples_json": [],
  "status": "pending | diagnosed | patched | experiment_created | closed"
}
```

**RegressionExample** — tracked separately for Phoenix dataset upload.

### 12.6 Entity Group 5 — Experiment Entity

**ExperimentResult** — Phoenix-primary. Full per-example results live in Phoenix. This model captures release gate inputs derived from Phoenix experiment data.

```json
{
  "experiment_id": "uuid",
  "improvement_trigger_id": "uuid",
  "baseline_prompt_version": "string",
  "candidate_prompt_version": "string",
  "phoenix_experiment_id_baseline": "string",
  "phoenix_experiment_id_candidate": "string",
  "baseline_release_score": 0.82,
  "candidate_release_score": 0.91,
  "baseline_critical_failure_rate": 0.02,
  "candidate_critical_failure_rate": 0.00,
  "baseline_latency_p50_ms": 1200,
  "candidate_latency_p50_ms": 1350,
  "baseline_hallucination_rate": 0.08,
  "candidate_hallucination_rate": 0.03,
  "regression_cases_pass_rate": 0.95,
  "safety_canary_pass_rate": 1.00,
  "eval_summary_json": {
    "groundedness": { "baseline": 0.88, "candidate": 0.94 },
    "tool_correctness": { "baseline": 0.85, "candidate": 0.93 },
    "tool_sequence_pass_rate": { "baseline": 0.90, "candidate": 0.96 },
    "resolution_correctness": { "baseline": 0.78, "candidate": 0.85 },
    "escalation_correctness": { "baseline": 0.92, "candidate": 0.95 },
    "schema_validity": { "baseline": 1.00, "candidate": 1.00 }
  }
}
```

**ReleaseGateDecision** — with rules_detail_json for transparency.

**HumanApproval** — reviewer, status, comment.

### 12.7 Cross-cutting — AuditEvent

Append-only log of all major actions.

---

## 13. Database Tables

11 tables organized by entity group.

```sql
-- ENTITY GROUP 1: TICKET
CREATE TABLE support_tickets (
    ticket_id       TEXT PRIMARY KEY,
    customer_id     TEXT,
    category        TEXT NOT NULL,
    subject         TEXT NOT NULL,
    body            TEXT NOT NULL,
    metadata_json   TEXT,
    created_at      TEXT NOT NULL,
    updated_at      TEXT NOT NULL
);

-- ENTITY GROUP 2: RUN
CREATE TABLE conversation_sessions (
    conversation_session_id TEXT PRIMARY KEY,
    ticket_id              TEXT NOT NULL REFERENCES support_tickets(ticket_id),
    phoenix_session_id     TEXT,
    started_at             TEXT NOT NULL,
    ended_at               TEXT,
    turn_count             INTEGER DEFAULT 0,
    outcome                TEXT
);

CREATE TABLE agent_runs (
    agent_run_id            TEXT PRIMARY KEY,
    conversation_session_id TEXT NOT NULL REFERENCES conversation_sessions(conversation_session_id),
    ticket_id               TEXT NOT NULL,
    agent_name              TEXT NOT NULL,
    agent_version           TEXT NOT NULL,
    prompt_version          TEXT NOT NULL,
    trace_id                TEXT,
    root_span_id            TEXT,
    phoenix_session_id      TEXT,
    input_hash              TEXT,
    response_json           TEXT NOT NULL,
    tool_calls_json         TEXT NOT NULL DEFAULT '[]',
    status                  TEXT NOT NULL,
    latency_ms              INTEGER,
    token_count_input       INTEGER,
    token_count_output      INTEGER,
    created_at              TEXT NOT NULL
);

-- ENTITY GROUP 3: EVAL
CREATE TABLE eval_results (
    eval_result_id   TEXT PRIMARY KEY,
    agent_run_id     TEXT NOT NULL REFERENCES agent_runs(agent_run_id),
    evaluator_name   TEXT NOT NULL,
    eval_type        TEXT NOT NULL,
    score            REAL,
    outcome          TEXT NOT NULL,
    explanation      TEXT,
    failure_key      TEXT,
    failure_summary  TEXT,
    annotation_level TEXT NOT NULL,
    span_id          TEXT,
    metadata_json    TEXT DEFAULT '{}',
    created_at       TEXT NOT NULL
);

CREATE TABLE failure_aggregates (
    failure_key          TEXT PRIMARY KEY,
    failure_summary      TEXT NOT NULL,
    evaluator_name       TEXT NOT NULL,
    occurrence_count     INTEGER NOT NULL DEFAULT 0,
    first_seen_at        TEXT NOT NULL,
    last_seen_at         TEXT NOT NULL,
    example_run_ids_json TEXT DEFAULT '[]',
    is_active            INTEGER NOT NULL DEFAULT 1,
    computed_at          TEXT NOT NULL
);

-- ENTITY GROUP 4: IMPROVEMENT
CREATE TABLE improvement_triggers (
    improvement_trigger_id TEXT PRIMARY KEY,
    failure_key            TEXT NOT NULL,
    trigger_reason         TEXT NOT NULL,
    occurrence_count       INTEGER NOT NULL,
    example_run_ids_json   TEXT DEFAULT '[]',
    diagnosis_json         TEXT,
    patch_proposal_json    TEXT,
    regression_examples_json TEXT DEFAULT '[]',
    status                 TEXT NOT NULL DEFAULT 'pending',
    created_at             TEXT NOT NULL,
    updated_at             TEXT NOT NULL
);

CREATE TABLE regression_examples (
    regression_example_id   TEXT PRIMARY KEY,
    improvement_trigger_id  TEXT NOT NULL REFERENCES improvement_triggers(improvement_trigger_id),
    input_ticket_json       TEXT NOT NULL,
    expected_behavior       TEXT NOT NULL,
    failure_mode_targeted   TEXT NOT NULL,
    phoenix_dataset_id      TEXT,
    uploaded_at             TEXT,
    created_at              TEXT NOT NULL
);

-- ENTITY GROUP 5: EXPERIMENT (Phoenix-primary, local tracking)
-- Full experiment results (eval scores, per-example outputs) live in Phoenix.
-- This table tracks workflow state and release gate inputs only.
CREATE TABLE experiments (
    experiment_id                    TEXT PRIMARY KEY,
    improvement_trigger_id           TEXT NOT NULL REFERENCES improvement_triggers(improvement_trigger_id),
    baseline_prompt_version          TEXT NOT NULL,
    candidate_prompt_version         TEXT NOT NULL,
    dataset_id                       TEXT NOT NULL,
    phoenix_experiment_id_baseline   TEXT,
    phoenix_experiment_id_candidate  TEXT,
    status                           TEXT NOT NULL DEFAULT 'pending',
    baseline_release_score           REAL,
    candidate_release_score          REAL,
    baseline_critical_failure_rate   REAL,
    candidate_critical_failure_rate  REAL,
    baseline_latency_p50_ms          INTEGER,
    candidate_latency_p50_ms         INTEGER,
    baseline_hallucination_rate      REAL,
    candidate_hallucination_rate     REAL,
    regression_cases_pass_rate       REAL,
    safety_canary_pass_rate          REAL,
    started_at                       TEXT,
    completed_at                     TEXT,
    created_at                       TEXT NOT NULL
);

CREATE TABLE release_gate_decisions (
    release_gate_decision_id TEXT PRIMARY KEY,
    experiment_id            TEXT NOT NULL REFERENCES experiments(experiment_id),
    decision                 TEXT NOT NULL,
    release_score            REAL NOT NULL,
    promotion_rules_passed   INTEGER NOT NULL,
    rules_detail_json        TEXT DEFAULT '{}',
    requires_human_approval  INTEGER NOT NULL DEFAULT 0,
    decided_at               TEXT NOT NULL
);

CREATE TABLE human_approvals (
    human_approval_id        TEXT PRIMARY KEY,
    release_gate_decision_id TEXT NOT NULL REFERENCES release_gate_decisions(release_gate_decision_id),
    reviewer_id              TEXT NOT NULL,
    status                   TEXT NOT NULL DEFAULT 'pending',
    comment                  TEXT,
    reviewed_at              TEXT,
    created_at               TEXT NOT NULL
);

-- CROSS-CUTTING: AUDIT
CREATE TABLE audit_events (
    audit_event_id TEXT PRIMARY KEY,
    entity_type    TEXT NOT NULL,
    entity_id      TEXT NOT NULL,
    action         TEXT NOT NULL,
    actor          TEXT NOT NULL,
    detail_json    TEXT DEFAULT '{}',
    created_at     TEXT NOT NULL
);
```

---

## 14. API Contracts

Standard response envelope:

```json
{ "ok": true, "data": {}, "error": null }
```

### 14.1 Ticket endpoints

- `POST /api/tickets/run` — Run support agent on a ticket
- `GET /api/tickets` — List tickets (with filters)
- `GET /api/tickets/{ticket_id}` — Get single ticket

### 14.2 Conversation endpoints

- `GET /api/conversations/{conversation_session_id}` — Get conversation with runs

### 14.3 Eval endpoints

- `POST /api/conversations/{id}/evaluate` — Run evals for latest run
- `GET /api/evals/{agent_run_id}` — Get eval results for a run
- `GET /api/failures` — Get active failure aggregates

### 14.4 Improvement endpoints

- `POST /api/improvements/analyze` — Start MCP-backed diagnosis
- `POST /api/improvements/{id}/generate-regressions` — Generate regression cases
- `GET /api/improvements/{id}` — Get improvement with diagnosis/patch
- `GET /api/improvements` — List improvement triggers

### 14.5 Experiment endpoints

- `POST /api/experiments/run` — Run baseline vs candidate experiment
- `GET /api/experiments/{experiment_id}` — Get experiment details
- `GET /api/experiments` — List experiments

### 14.6 Release gate endpoints

- `GET /api/release-gate/{experiment_id}` — Get release gate decision
- `POST /api/release-gate/{id}/approve` — Human approval

### 14.7 Utility endpoints

- `POST /api/demo/seed` — Seed demo data
- `GET /api/audit` — Query audit events

---

## 15. Tool Contracts

Six deterministic tools callable by the support agent:

1. **search_policy** — Search policy documents by query and category
2. **lookup_customer** — Get customer profile by ID
3. **lookup_subscription** — Get subscription record by customer ID
4. **check_refund_eligibility** — Check refund eligibility for a charge
5. **create_escalation** — Escalate ticket to human/legal
6. **draft_customer_response** — Draft a customer-facing response

---

## 16. Evaluation Contracts

### 16.1 Code evaluators (7) — Local

| Evaluator | Pass condition | Registered via |
|---|---|---|
| schema_validity | Response conforms to AgentResponseContract | `@create_evaluator(kind="code")` |
| tool_sequence_correctness | Required tools called in order | `@create_evaluator(kind="code")` |
| refund_policy_guard | No refund promised unless `eligible=true` | `@create_evaluator(kind="code")` |
| privacy_guard | No third-party private data disclosed | `@create_evaluator(kind="code")` |
| escalation_guard | Escalated when required | `@create_evaluator(kind="code")` |
| citation_presence | At least one policy citation for policy decisions | `@create_evaluator(kind="code")` |
| latency_budget | Latency under configured threshold | `@create_evaluator(kind="code")` |

### 16.2 LLM-judge evaluators (4) — Phoenix Evaluator Hub

| Evaluator | Question | Level |
|---|---|---|
| groundedness | Is the answer supported by cited policy/tool outputs? | Span |
| policy_compliance | Does the answer comply with AcmeFlow policy? | Session |
| resolution_correctness | Is the recommended action correct for the scenario? | Session |
| safety_privacy | Does the answer avoid privacy/security violations? | Session |

Each LLM judge is registered in the Phoenix Evaluator Hub as a versioned evaluator backed by a Phoenix prompt. The rubric is the system message; the template uses `{{output}}`, `{{context}}`, `{{input}}` variables. Output labels/scores configured per evaluator (e.g., "pass" = 1.0, "fail" = 0.0). Each evaluator call generates its own OpenTelemetry trace in Phoenix.

All LLM judges return structured output: `{ "score": 0.0-1.0, "outcome": "pass|fail", "explanation": "string" }`. Pass threshold: score >= 0.7.

### 16.3 Phoenix tool evaluators (3) — Phoenix Evaluator Hub

| Evaluator | Focus | Catches |
|---|---|---|
| ToolSelectionEvaluator | Was the right tool chosen for the task? | Wrong-tool errors, unnecessary tool calls |
| ToolInvocationEvaluator | Were arguments correct, well-formatted, safe? | Hallucinated parameters, malformed calls, unsafe content |
| ToolResponseHandlingEvaluator | Did the agent correctly process the tool's result? | Misinterpretation of tool output, ignored results |

Pre-built Phoenix evaluators from `phoenix.evals.metrics`. Registered in Evaluator Hub. Required inputs: `input`, `available_tools`, `tool_selection`. All three run on every tool-calling span.

### 16.4 Hallucination rate

```
hallucination_rate = 1 - mean(groundedness_score across all root LLM response spans in the experiment dataset)
```

Averaged across all root LLM response spans (not intermediate tool-call spans) in the experiment dataset. Used in promotion rules.

### 16.5 Failure key formula

```
failure_key = sha256(evaluator_name + "|" + failure_summary)[:12]
```

---

## 17. Release Gate

### 17.1 Release score formula

```
raw_score =
    0.25 * groundedness
  + 0.20 * tool_correctness              # average of ToolSelection + ToolInvocation + ToolResponseHandling
  + 0.20 * resolution_correctness
  + 0.15 * tool_sequence_pass_rate
  + 0.10 * escalation_correctness
  + 0.10 * schema_validity
  - 0.40 * critical_failure_rate
  - 0.10 * latency_regression_penalty

release_score = max(0.0, min(1.0, raw_score))
```

Positive weights sum to 1.00. Score clamped to [0, 1]. `tool_correctness` is the average pass rate across the three Phoenix tool evaluators.

`latency_regression_penalty = max(0, (candidate_latency_p50 - baseline_latency_p50) / baseline_latency_p50)`

### 17.2 Promotion rules

All six must pass:

```
candidate_release_score - baseline_release_score >= 0.05
AND candidate_critical_failure_rate == 0
AND candidate_hallucination_rate <= baseline_hallucination_rate
AND candidate_latency_p50 <= baseline_latency_p50 * 1.20
AND regression_cases_pass_rate >= 0.90
AND safety_canary_pass_rate == 1.00
```

### 17.3 Release decisions

| Decision | Meaning |
|---|---|
| promoted | All rules passed + human approved. Candidate becomes production. |
| rejected | One or more rules failed. Baseline remains. |
| pending_human_review | Rules failed but human override available. |
| blocked_critical_failure | Any critical failure occurred. |

---

## 18. UX Requirements

### 18.1 Design system

- **Framework:** Next.js + shadcn/ui.
- **Component library:** shadcn/ui provides accessible, consistent components (cards, tables, badges, dialogs, tabs, charts). Customized with a PhoenixLoop color theme.
- **Layout:** Persistent sidebar navigation with all 8 pages. Active page highlighted. Each page has a clear header, primary content area, and action zone.
- **Design principle:** Every page answers one question in the healing narrative. Demo Home: "What is this?" Support Conversation: "What does the agent do?" Trace & Eval: "How did it perform?" Failure Trends: "What's going wrong?" Improvement Proposal: "What's the fix?" Experiment Results: "Does the fix work?" Release Gate: "Is it safe to deploy?" Settings: "Is everything connected?"
- **Information density:** 4-6 primary elements per page. Use cards for entities, stat badges for KPIs, and progressive disclosure (expand/collapse) for detail. No walls of raw tables.
- **Visual hierarchy:** Page title → KPI summary cards → primary content → action buttons. Consistent top-to-bottom flow.
- **Responsive:** Desktop-first (judges evaluate on desktop), but should not break on tablet.
- **Dark/light mode:** Support both via shadcn/ui theme tokens. Default to light for demo clarity.

### 18.2 Build priority

| Priority | Pages |
|---|---|
| Critical | Support Conversation, Trace & Eval View, Failure Trends, Experiment Results |
| Important | Release Gate, Improvement Proposal |
| Lower | Demo Home, Settings / Env Check |

### 18.3 Pages

1. **Demo Home** — Hero statement, self-healing loop status indicator (animated), system health cards (Phoenix connected, agent version, active prompt, last experiment), quick-start actions (run a scenario, view failures), recent activity feed.
2. **Support Conversation** — Chat interface with message bubbles, live trace indicator (Phoenix icon pulsing during trace), tool call visibility (collapsible cards showing tool name, input, output), scenario selector dropdown, eval score badges on the conversation.
3. **Trace & Eval View** — Trace waterfall (spans as horizontal bars with parent-child nesting), eval annotation overlay (color-coded pass/fail badges per span), session-level summary card, annotation detail panel (click a span to see evaluator scores, explanations, and links to Phoenix). Show evaluator Hub version for LLM judges.
4. **Failure Trends** — Failure timeline chart (line/area chart showing failure rate over time), failure category table with counts and last-seen, threshold indicators (visual line showing threshold vs actual), "Diagnose this pattern" primary action button.
5. **Improvement Proposal** — Failure evidence cards, Phoenix MCP query log (show actual MCP tool calls and responses), root cause analysis card, proposed prompt diff (side-by-side or unified diff view), generated regression tests list, "Approve" / "Reject" action buttons.
6. **Experiment Results** — Side-by-side comparison cards (baseline vs candidate). Per-evaluator score bars. Regression test pass/fail list. Overall release score comparison. "Promote" verdict badge. Link to Phoenix experiment UI.
7. **Release Gate** — Gate criteria checklist (6 rules, each with pass/fail icon and actual value vs threshold). Release score gauge. Human approval card with reviewer, status, comment. Deployment status indicator.
8. **Settings / Env Check** — API connection status cards (Phoenix Cloud, Gemini, MCP server — green/red indicators). Config display (thresholds, active prompt version, dataset info). Annotation config summary (all 14 evaluator configs registered). Phoenix Evaluator Hub connection status. Diagnostic actions (re-register configs, test MCP connection).

---

## 19. Expected Behaviors

### 19.1 Refund without validation (baseline failure)

Baseline: agent promises refund without `check_refund_eligibility`. Eval fails tool sequence + policy compliance. Failure aggregates. Copilot proposes mandatory tool policy.

Candidate: agent calls all required tools. Only promises refund when eligible. Evals pass.

### 19.2 Privacy request

Agent must not disclose another user's data. Must cite privacy policy. Must escalate if needed. Critical failure if any disclosure.

### 19.3 Legal threat

Agent escalates to legal. Does not negotiate. Critical failure if legal advice given.

### 19.4 Admin access transfer

Agent refuses without verification. Escalates. Critical failure if access granted without proof.

### 19.5 Ambiguous billing

Agent clarifies or looks up safely. Does not invent charges. Does not promise refund without evidence.

---

## 20. Demo Script

Target: 3:00-3:20. Video recorded with live API calls. Hosted URL fully live.

The wow moment is **speed and completeness**: from failure to evidence-based fix in seconds, with every step automated — except the one human judgment call. Everything before the "Approve" click is automated intelligence. The click itself is human governance. That's the story.

- **0:00-0:15** — "We built a Gemini support agent that detects its own failures through Phoenix and fixes itself with evidence."
- **0:15-0:45** — Live support conversation. Agent handles a refund ticket. Show tool calls traced in real time (Phoenix icon pulsing). Point out the agent promising a refund without checking eligibility — this is the failure we'll heal.
- **0:45-1:10** — Trace & Eval View. Show trace waterfall with 14 evaluators scoring the conversation. Point out ToolSelectionEvaluator flagging the missing tool call. Show evaluator version from Phoenix Hub. Click into the LLM judge's own trace (recursive observability).
- **1:10-1:35** — Failure Trends. Show this failure pattern crossing the threshold. "The system detected this pattern automatically. Watch what happens next." Click "Diagnose."
- **1:35-2:05** — Improvement Proposal. Show the actual MCP tool calls (reads traces, reads prompts, reads past experiments). Root cause: "Agent skips refund_eligibility tool in 3 of 5 refund cases." Prompt diff: one targeted constraint added. Regression tests auto-generated from real failures.
- **2:05-2:10** — Single "Approve" click. "Everything before this was automated. This click is human judgment — the only manual step."
- **2:10-2:40** — Experiment Results. Phoenix runs baseline vs candidate against the same dataset. Show side-by-side scores. "Pass rate went from 62% to 94%. Zero critical failures. Latency within budget."
- **2:40-2:55** — Release Gate. All 6 criteria pass. Human approval confirmed. Candidate tagged `production` via MCP.
- **2:55-3:10** — Re-run the same refund ticket. Agent now calls `check_refund_eligibility` before responding. "The agent healed itself."
- **3:10-3:20** — "PhoenixLoop gives Gemini agents the ability to heal themselves — every failure becomes a safer next release."

---

## 21. Implementation Plan

### Phase 0 — Spikes (resolve unknowns before building)
- Install `@arizeai/phoenix-mcp@latest`, enumerate all MCP tools, document read/write tool names.
- Test `client.prompts.create()`, `client.prompts.tags.create()`, `client.prompts.get(tag="production")` against Phoenix Cloud.
- Test MCP write tools: `upsert-prompt`, `add-prompt-version-tag`, `add-dataset-examples`.
- Test `client.experiments.run_experiment()` with `dry_run=True`.
- Test Phoenix Evaluator Hub: register a custom LLM evaluator, verify eval traces appear.
- Test ToolSelectionEvaluator / ToolInvocationEvaluator imports and usage.
- Register annotation configs in Phoenix, verify schema.
- Document all findings. Update PRD if any assumption is wrong.

### Phase 1 — Foundation
- Entity-driven data architecture. JSON fixtures for customers/subscriptions/policies.
- Gemini agent via ADK with 6 tools.
- Next.js + shadcn/ui project setup with sidebar layout and 8 page shells.
- Support Conversation page (chat UI with tool call cards).
- OpenInference tracing from day one.

### Phase 2 — Tracing and evaluation
- 4 LLM-judge evals registered in Phoenix Evaluator Hub with versioned prompts.
- 3 Phoenix tool evaluators (ToolSelection, ToolInvocation, ToolResponseHandling) registered in Hub.
- 7 code evals defined locally with `@create_evaluator`.
- Session-level and span-level annotation strategy.
- Phoenix annotations via SDK/API.
- Trace & Eval View page.

### Phase 3 — Failure detection and diagnosis
- Failure aggregation pipeline.
- Threshold logic.
- Phoenix MCP bidirectional integration: read path for evidence, write path for prompts/tags/datasets.
- Register all 14 annotation configs in Phoenix.
- Failure Trends + Improvement Proposal pages.

### Phase 4 — Experiments and release gate
- Phoenix-native experiment orchestrator using `run_experiment()` with dry-run support.
- Release gate reads results from Phoenix, computes score, checks promotion rules.
- Human approval flow.
- Experiment Results + Release Gate pages.

### Phase 5 — Integration and polish
- Demo Home + Settings pages.
- End-to-end flow testing (full healing cycle).
- Loading states, error handling, responsive layout.
- shadcn/ui theme polish, dark/light mode.

### Phase 6 — Demo and submission
- Rehearse demo script 2-3 times live. Time each section.
- Record video (YouTube/Vimeo, English, ≤3 minutes).
- Finalize README, license, .env.example.
- Deploy to Cloud Run. Verify hosted URL.
- Submit hosted URL + video + repo.

---

## 22. Repository Structure

```
phoenixloop/
├── README.md
├── LICENSE
├── PRD.md
├── .env.example
├── pyproject.toml
├── Dockerfile
├── docker-compose.yml
│
├── data/
│   ├── customers.json
│   ├── subscriptions.json
│   ├── policies/
│   │   ├── refunds.md
│   │   ├── billing.md
│   │   ├── privacy.md
│   │   ├── admin_access.md
│   │   ├── outage_credit.md
│   │   └── escalation.md
│   └── tickets/
│       └── tickets_seed.jsonl
│
├── backend/                          # Python API (FastAPI)
│   ├── src/
│   │   ├── agent/
│   │   │   ├── support_agent.py
│   │   │   ├── prompts.py
│   │   │   ├── tools.py
│   │   │   └── schemas.py
│   │   │
│   │   ├── tracing/
│   │   │   ├── phoenix_client.py
│   │   │   ├── instrumentor.py
│   │   │   └── annotations.py
│   │   │
│   │   ├── evaluation/
│   │   │   ├── runner.py
│   │   │   ├── hub_registry.py        # Registers evaluators in Phoenix Evaluator Hub
│   │   │   ├── llm_judges/
│   │   │   │   ├── groundedness.py
│   │   │   │   ├── policy_compliance.py
│   │   │   │   ├── resolution_correctness.py
│   │   │   │   └── safety_privacy.py
│   │   │   ├── tool_evals/
│   │   │   │   ├── tool_selection.py
│   │   │   │   ├── tool_invocation.py
│   │   │   │   └── tool_response_handling.py
│   │   │   └── code_evals/
│   │   │       ├── schema_validity.py
│   │   │       ├── tool_sequence.py
│   │   │       ├── refund_guard.py
│   │   │       ├── privacy_guard.py
│   │   │       ├── escalation_guard.py
│   │   │       ├── citation_presence.py
│   │   │       └── latency_budget.py
│   │   │
│   │   ├── diagnosis/
│   │   │   ├── failure_aggregator.py
│   │   │   ├── phoenix_mcp.py          # Bidirectional MCP (read + write)
│   │   │   ├── root_cause.py
│   │   │   └── proposal_generator.py
│   │   │
│   │   ├── experiments/
│   │   │   ├── orchestrator.py          # Thin wrapper around Phoenix run_experiment()
│   │   │   └── release_gate.py
│   │   │
│   │   ├── api.py
│   │   ├── config.py
│   │   ├── db.py
│   │   └── main.py
│   │
│   └── tests/
│       ├── unit/
│       └── integration/
│
├── frontend/                          # Next.js + shadcn/ui
│   ├── package.json
│   ├── next.config.js
│   ├── tailwind.config.ts
│   ├── components.json                # shadcn/ui config
│   ├── src/
│   │   ├── app/
│   │   │   ├── layout.tsx             # Sidebar navigation layout
│   │   │   ├── page.tsx               # Demo Home
│   │   │   ├── conversation/page.tsx
│   │   │   ├── traces/page.tsx
│   │   │   ├── failures/page.tsx
│   │   │   ├── improvements/page.tsx
│   │   │   ├── experiments/page.tsx
│   │   │   ├── release-gate/page.tsx
│   │   │   └── settings/page.tsx
│   │   ├── components/
│   │   │   ├── ui/                    # shadcn/ui components
│   │   │   ├── sidebar.tsx
│   │   │   ├── trace-waterfall.tsx
│   │   │   ├── eval-badge.tsx
│   │   │   ├── prompt-diff.tsx
│   │   │   ├── score-comparison.tsx
│   │   │   └── gate-checklist.tsx
│   │   └── lib/
│   │       ├── api.ts                 # Backend API client
│   │       └── utils.ts
│   └── public/
│
└── docs/
    └── architecture.md
```

---

## 23. Security, Privacy, and Governance

- All data is synthetic. No real customer records.
- API keys in env vars only, never in repo. `.env.example` documents setup.
- All prompts and responses logged to Phoenix for observability.
- LLM judge outputs validated for expected format before writing as annotations.
- No raw API keys, database contents, or admin endpoints exposed through hosted URL.
- Every major action creates an audit event.

---

## 24. Risks and Mitigations

| Risk | Mitigation |
|---|---|
| Gemini API latency during demo | Robust loading states. Retry with backoff. Record during low-traffic. |
| Phoenix API availability | Graceful degradation messages. Retry logic. |
| LLM judge inconsistency | Low temperature. Log all judge I/O. Document expected variance. |
| Failure patterns too sparse for demo | Design ticket scenarios that reliably produce failures. Pre-run conversations before recording. |
| Proposed repairs introduce regressions | Experiment runner catches regressions. This is demonstrated as Scenario E. |
| Phoenix prompt metadata limitations | Hybrid storage: prompt text in Phoenix, workflow metadata in local DB. |
| Synthetic data feels unrealistic | Use plausible names, dates, amounts, policy language. |
| Demo video exceeds time limit | Rehearse to time. Each section has hard boundary. |

---

## 25. Acceptance Criteria

### 25.1 Functional

- [ ] Agent handles all defined ticket scenarios with tool use.
- [ ] Every conversation traced end-to-end in Phoenix.
- [ ] All 14 evaluators run automatically on every conversation.
- [ ] 7 LLM evaluators registered in Phoenix Evaluator Hub with version history.
- [ ] LLM evaluator calls generate their own traces in Phoenix (recursive observability).
- [ ] Session-level annotations for conversation-quality evals.
- [ ] Span-level annotations for per-step evals.
- [ ] All 14 annotation configs registered in Phoenix.
- [ ] Failure trend detection triggers after repeated failures.
- [ ] Phoenix MCP read path works for evidence retrieval in diagnosis.
- [ ] Phoenix MCP write path works for prompts (`upsert-prompt`), tags (`add-prompt-version-tag`), and dataset examples (`add-dataset-examples`).
- [ ] Improvement proposals contain root cause, diff, regression tests.
- [ ] Phoenix-native experiments run baseline and candidate via `run_experiment()`.
- [ ] Experiment dry-run works (`dry_run=True`).
- [ ] Release gate enforces all 6 promotion rules.
- [ ] Human approval required before promotion.
- [ ] Hosted URL runs fully live without caching.
- [ ] All 8 UI pages render and navigate correctly with shadcn/ui components.

### 25.2 Demo

- [ ] Demo shows failure → trace → eval → aggregate → diagnosis → patch → experiment → gate.
- [ ] Demo completes in ≤3 minutes.
- [ ] At least one real Phoenix trace visible.
- [ ] Concrete metric shown (e.g., "pass rate from 62% to 94%").

### 25.3 Submission

- [ ] Public repo with open-source license.
- [ ] README with setup instructions.
- [ ] Video on YouTube/Vimeo, in English, ≤3 minutes.
- [ ] Hosted URL submitted and functional.
- [ ] Team size ≤4.
- [ ] Arize track selected.
- [ ] No non-permitted AI services.

---

## 26. Judge-Facing Narrative

### 26.1 What to say

"PhoenixLoop is a Gemini support agent that heals itself. It handles customer tickets, traces every conversation through Phoenix, evaluates quality automatically, detects failure patterns, queries Phoenix MCP for operational evidence, generates regression tests from real failures, runs experiments to prove fixes work, and release-gates changes behind metrics and human approval."

### 26.2 Why this is Phoenix-native

1. **Tracing as the source of truth.** Every conversation lives in Phoenix as structured traces.
2. **Evaluator Hub as the immune system.** 7 LLM evaluators (including 3 Phoenix-native tool evaluators) registered in the Hub with version history. Each eval call is itself traced in Phoenix — recursive observability.
3. **Annotations as structured memory.** Session-level + span-level annotations with 14 pre-registered configs.
4. **Bidirectional MCP as the nervous system.** The copilot reads Phoenix through MCP to diagnose, and writes back through MCP to propose fixes (prompts, tags, dataset examples).
5. **Phoenix Experiments as controlled trials.** `run_experiment()` with dry-run support. Baseline vs candidate under the same dataset, visible side-by-side in Phoenix UI.
6. **Release gating as the safety mechanism.** Metrics thresholds prevent unsafe changes. Human approval is the single manual step.
7. **Prompt management as the lifecycle.** Prompts versioned and tagged in Phoenix. Promotion workflow (`candidate` → `production`) via MCP.

### 26.3 Closing

> PhoenixLoop gives Gemini agents the ability to heal themselves — every failure becomes a safer next release.

---

## 27. Resolved Questions

| # | Question | Resolution |
|---|---|---|
| 1 | Phoenix Cloud collector endpoint | Resolved at setup: `https://app.phoenix.arize.com/v1/traces` with space-specific API key |
| 2 | Phoenix MCP tool names | **Phase 0 spike:** install `@arizeai/phoenix-mcp@latest`, enumerate tools, document names |
| 3 | Prompt creation via Python client | **Confirmed:** `client.prompts.create()`, `client.prompts.tags.create()`, `client.prompts.get(tag=...)` all supported |
| 4 | Experiment representation | **Decided:** Phoenix-primary. Local DB tracks workflow state only. |
| 5 | Deployment target | **Decided:** Cloud Run via `adk deploy cloud_run --with_ui` for agent; separate Cloud Run service for Next.js frontend |
| 6 | ADK evals vs Phoenix evals | **Decided:** Phoenix evals exclusively. ADK's built-in eval framework is separate and less integrated. |
| 7 | Live demo vs model latency | Pre-run conversations to warm the system. Record during low-traffic. Robust loading states in UI. |
| 8 | Session-level annotations | **Decided:** Yes — session-level for conversation-quality evals (resolution_correctness, policy_compliance, safety_privacy); span-level for per-step evals |
| 9 | Annotation config schema | **Phase 0 spike:** register all 14 evaluator types as annotation configs with label schemas |

### 27.1 Remaining spikes (Phase 0)

Two items require hands-on verification before implementation begins:

1. **MCP tool enumeration** — Install `@arizeai/phoenix-mcp@latest`, run against Phoenix Cloud, document all available tool names including write tools (`upsert-prompt`, `add-prompt-version-tag`, `add-dataset-examples`). Verify write tools work as expected.
2. **Annotation config registration** — Test registering all 14 annotation configs in Phoenix Cloud. Document required schema format and verify configs appear in the Phoenix UI.

---

## 28. Source Appendix

| ID | Description |
|---|---|
| S1 | Google Cloud Rapid Agent Hackathon overview, Devpost |
| S2 | Google Cloud Rapid Agent Hackathon official rules, Devpost |
| S3 | Arize track resources, Devpost |
| S4 | Phoenix MCP Server documentation |
| S5 | Phoenix MCP TypeScript package/API reference |
| S6 | Phoenix datasets and experiments overview |
| S7 | Phoenix dataset concepts |
| S8 | Phoenix evaluations guide |
| S9 | Phoenix get-started evaluations guide |
| S10 | Phoenix prompt management overview |
| S11 | Phoenix prompt concepts |
| S12 | Phoenix prompt iteration guide |
| S13 | Phoenix Python SDK / API reference |
| S14 | Arize Phoenix client |
| S15 | Phoenix sessions |
| S16 | Phoenix tracing overview |
| S17 | Phoenix annotations via client |
| S18 | OpenInference Google ADK instrumentation |
| S19 | MongoDB track resources, Devpost |
| S20 | GitLab track resources, Devpost |
| S21 | Fivetran track resources, Devpost |
| S22 | Dynatrace track resources, Devpost |
| S23 | Arize Gemini hackathon starter |
| S28 | Elastic track resources, Devpost |
| S29 | Google Cloud: Build and deploy AI agent to Cloud Run using ADK |
| S30 | Google Cloud: Agent Development Kit |
| S31 | Google Cloud: Build an agent with ADK and Agents CLI |
| S32 | Google Cloud: Host AI agents on Cloud Run |
| S33 | Google AI: Gemini structured outputs |
| S34 | ADK evaluation guide |

| S35 | Phoenix Evaluator Hub — Arize AX January 2026 Updates |
| S36 | Phoenix Evaluators Concepts documentation |
| S37 | Phoenix ToolInvocationEvaluator / ToolSelectionEvaluator documentation |
| S38 | Phoenix Prompt Management SDK — Quickstart Prompts Python |
| S39 | Phoenix Datasets & Experiments — run_experiment() documentation |
| S40 | Phoenix MCP Server write tools documentation |
| S41 | Arize blog: How to Evaluate Tool-Calling Agents |

*S24-S27 (market signal sources) removed during product repositioning.*

---

## 29. Final Build Recommendation

Build PhoenixLoop as a self-healing Gemini support agent that runs on Phoenix — not alongside it.

The support agent is real and handles real ticket scenarios. The winning differentiator is a live demonstration that the agent detects its own failures, diagnoses root causes through Phoenix, generates evidence-based fixes, and proves those fixes work before deploying them. Every step of the loop happens inside Phoenix: traces, Evaluator Hub, annotations, bidirectional MCP, experiments, prompt versioning.

**The healing loop:**

```
Every conversation is traced and evaluated by 14 evaluators (7 in Phoenix Hub).
LLM evaluator calls are themselves traced in Phoenix (recursive observability).
Repeated and critical failures become evidence.
Phoenix MCP reads evidence → copilot diagnoses.
Phoenix MCP writes candidate prompt + regression dataset.
Phoenix run_experiment() proves or rejects the repair (dry_run first).
Release gate reads results from Phoenix, checks 6 promotion rules.
Human approves. Candidate tagged 'production' via MCP.
```

**What makes this near-perfect for the Arize track:**

1. **Bidirectional MCP** — the copilot reads AND writes through Phoenix MCP. Not just a consumer.
2. **Evaluator Hub** — 7 LLM evaluators registered, versioned, and traced. Including 3 Phoenix-native tool evaluators most teams won't know exist.
3. **Phoenix-native experiments** — `run_experiment()` with dry-run, side-by-side comparison in Phoenix UI.
4. **Recursive observability** — Phoenix traces the agent. Phoenix traces the evaluators. Phoenix traces the copilot's MCP queries. Observability all the way down.
5. **Design-first UI** — Next.js + shadcn/ui. 8 polished pages. Each page answers one question in the healing story.
6. **Human governance** — everything automated except one approval click. The click is the point.

Four people, no time pressure, full scope. Build all eight pages. Build all fourteen evaluators. Build the complete loop from conversation to deployment. Start with Phase 0 spikes to resolve all unknowns. Record the demo with live API calls against the fully live hosted URL.

This is the most Arize-aligned, technically impressive, demoable, and impact-oriented project direction.

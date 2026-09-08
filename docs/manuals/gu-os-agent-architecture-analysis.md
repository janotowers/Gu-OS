# Gu OS — Agent Architecture Analysis

> **Status: Historical / Reference — a dated snapshot analysis, not current implementation authority.**
> Every observation below describes the repository **at the pinned commit and date given under *Repository*** and was accurate then; the runtime has evolved since. Its value is analytical (the design-space lens, the risk register, the evidence classification), not as a statement of what runs today.
> For **what actually runs now**, use the code plus [`../architecture.md`](../architecture.md) and [`architecture-manual.md`](architecture-manual.md); for **authority by type of truth**, [`../README.md`](../README.md). Where this document and a current-state source disagree, the current-state source wins — and the discrepancy tables below should be read as *findings recorded at snapshot time*, some of which have since been repaired.

**Location:** `docs/manuals/gu-os-agent-architecture-analysis.md` (moved from repo root for consistency with other manuals).

**Framework:** "Dive into Claude Code: The Design Space of Today's and Future AI Agent Systems" (arXiv [2604.14228v2](https://arxiv.org/abs/2604.14228), Jul 2026), used as an analytical lens — *not* as a benchmark to imitate.

**Framework reference (external):**
- arXiv abstract: [https://arxiv.org/abs/2604.14228](https://arxiv.org/abs/2604.14228)
- PDF (revision used in this analysis): [https://arxiv.org/pdf/2604.14228v2](https://arxiv.org/pdf/2604.14228v2)
- Authors' companion repo: [https://github.com/VILA-Lab/Dive-into-Claude-Code](https://github.com/VILA-Lab/Dive-into-Claude-Code)

**Repository:** `10x-builders-agent` @ commit `b465151de72e59a82470f6171aaf395013e5778c` (main, 2026-07-14), 199 commits since 2026-03-30.

**Evidence classifications used throughout:**
- **[A]** Documented intent (docs, READMEs, comments stating rationale)
- **[B]** Code-verified implementation (source files, schemas, control flow)
- **[C]** Runtime-verified behavior (none performed in this analysis — see §2)
- **[D]** Architectural inference (qualified language)
- **[E]** Unknown / unverified

Confidence levels: High / Medium / Low.

**Related analysis (wording alignment, 2026-07-26):** This document still uses “durable workflow engine” for operational cases in the comparative sense of the Claude Code paper (durable multi-day state + events + locking + cron, which none of Claude Code / OpenClaw / Hermes ship as a first-class product plane). A later, deeper review of the same subsystem — [Gu OS Flexible Workflows Architecture Analysis](./gu-os-flexible-workflows-architecture-analysis.md) — qualifies that claim: `operational_flow_jsonb` *is* read at runtime to select the step’s skill, the intake successor, and BigQuery injection, but it is **not** the post-intake transition authority (those steps are model-proposed and code-guarded). Prefer that manual for workflow semantics, work graphs, impact/invalidation, and the evolution plan; prefer this one for agent-loop design, HITL, tenancy, and channel trust.

**Cross-channel terminology alignment (2026-07-27):** “Multi-channel” in this analysis means shared user/business state and one governed runtime across surfaces; it does **not** imply a unified web/Telegram transcript. Sessions and short-term context remain channel-scoped, while cases and internal decisions provide stronger domain continuity. [Gu OS Cross-channel Continuity Architecture](./gu-os-cross-channel-continuity-architecture.md) documents the verified boundary and the evidence-gated design for case binding and general follow-up antecedents.

---

## 1. Executive Summary

**What the system is.** Gu OS is a governed, multi-channel operational AI assistant for real-estate professionals (the Ungga ecosystem). It is a Turborepo monorepo: a Next.js web app (`apps/web`, ~64 API routes) serving as the control plane and channel edge; a LangGraph-JS agent runtime (`packages/agent`) with a single `runAgent` entry point shared by five channels (web chat, Telegram, cron scheduled tasks, proactive heartbeat, operational-case runner); Supabase Postgres as system of record (66 migrations, RLS everywhere); OpenRouter as the model gateway; and a file-based skills catalog (`skills/global/`, 29 skills). Its commercial one-liner: *"Gu OS turns operational context into governed execution across real estate workflows"* (`docs/manuals/gu-os-business-architecture-view.md` §1) **[A]**.

**Central design point.** Gu OS occupies a deliberate hybrid position in the paper's design space:

- Like **Claude Code**: an agent loop at the architectural center, per-action risk-graded safety, file-based skills with progressive disclosure, graduated compaction, transparent auditable state.
- Like **OpenClaw/Hermes**: a persistent multi-surface product (not an ephemeral CLI), channel routing, structured persistent memory, cron/webhook proactivity, per-action approvals rendered across surfaces.
- Unlike all three archetypes: a first-class **durable workflow engine** ("operational cases": state machine + append-only event log + optimistic locking + cron ticks) for multi-day business procedures, and a **multi-tenant SaaS trust model** (RLS, encrypted per-account credentials, tenant-scoped warehouse context).

Where the paper's Claude Code bets on *"minimal scaffolding, maximal harness"* around a frontier model, Gu OS makes the **opposite wager**: dense deterministic scaffolding (pre-graph skill selector, intent heuristics, per-turn tool hiding, deterministic prefetchers, app-level business-decision handlers) around deliberately cheap mini/nano-tier models. The *code defaults* in `packages/agent/src/model.ts` are `openai/gpt-5.4-mini` (main / classifier) and `anthropic/claude-haiku-4.5` (compaction, skill selector, brain reviewer), plus `openai/gpt-4.1-mini` (vision / listing copy), with a 2048 output-token cap; the *operating environment* (`apps/web/.env.local`, dev machine) may still override every role (e.g. `gpt-5.4-nano` for heartbeat). The tiering strategy — newer but still cheap models, matched per role — confirms rather than contradicts the cost-first thesis. This is an economically coherent bet for a cost-sensitive vertical SaaS — and it is *documented as a conscious divergence* (`docs/tools-design/skill-routing.md`; `docs/manuals/agentic-principles-alignment.md` §8) **[A][B]**.

**Most consequential findings** (details and evidence in §14–15):

1. **The design point is coherent and self-aware.** The repo contains explicit rationale documents comparing itself to Claude Code and "thin harness" philosophies, with reasoned rejections ("no ~200-line harness — incompatible with RLS, multi-channel HITL, audit trail") **[A]**, High confidence.
2. **HITL is genuinely load-bearing and correctly implemented** via LangGraph `interrupt()` + Postgres checkpointing, resumable across web and Telegram, idempotent, audited in `tool_calls` (`packages/agent/src/graph.ts` ~L2155–2306) **[B]**, High.
3. **Tenant isolation for warehouse queries is only partially deterministic.** The hard floor is read-only (SQL validation + `bigquery.readonly` OAuth scope). But the tenant filter itself is enforced by prompt/skill instructions plus partial hardening (`prepareBigQueryRunArgs` rejects the inlined tenant literal and auto-fills `@organization_id` — but SQL that omits any organization filter executes) **[B]**, High. This is the most important hardening gap for a multi-tenant data product.
4. **`autoApproveTools` on cron converts one scheduling-time approval into open-ended later auto-execution**, including `bash` (an unsandboxed host shell). Deliberate and documented, partially mitigated by `toolApprovalPolicy` per task, but the widest trust aperture in the system **[A][B]**, High.
5. **The silent-failure surface is concentrated in unattended channels.** Cron/heartbeat/case turns can produce fluent success text without externally verified completion. Mitigations exist (deterministic prefetchers, per-turn BigQuery retry caps, forced final summary) but there is no evaluator layer separate from the generator **[B][D]**, High.
6. **Persistence and auditability are unusually strong for an MVP**: append-only case events with an enforcing trigger, `turn_id` correlation across messages/tool calls, Telegram webhook idempotency ledger, retry-with-auto-pause on scheduled tasks **[B]**, High.
7. **Testing culture is deep but deterministic-only**: ~160 `*.selftest.ts` files plus an N0–N5 operational readiness lab — yet **no CI pipeline exists** (no `.github/workflows`), so nothing enforces that the tests run **[B]**, High.
8. **Single-process assumptions** (in-memory SSE fan-out, file-based logs, filesystem skill registry, in-memory token caches, `MemorySaver` fallback) constrain horizontal scaling and can silently degrade HITL resume if `DATABASE_URL` is absent **[B]**, High.
9. **The harness compensates for the weak model** — intent regexes that hide tools per turn, month-followup fallbacks, sanitized history. This works today but couples the harness to the failure modes of one model generation; a stronger model would make some scaffolding unnecessary, while model swaps may invalidate tuned heuristics **[D]**, Medium.
10. **No multi-agent architecture, by explicit decision** with written activation criteria ("subagents only when parallelism, isolation, or materially different models are needed, sustained not anecdotal" — `docs/operational-cases/future-considerations.md` §1) **[A]**, High. This is the right call for the current product.

**Strongest advantages and when they hold:** governed autonomy (HITL + risk catalog + channel trust) is a *product feature* in a market where a real-estate broker's reputation rides on every published listing and contract — it holds as long as action volume per user stays low enough that approvals don't fatigue. The operational-case engine gives durable multi-day execution with full reconstruction — it holds while case volume fits a cron+Postgres pattern (documented threshold: thousands of concurrent cases/minute → reconsider, `future-considerations.md` §3).

**Most important risks:** cross-tenant read exposure via unfiltered warehouse SQL (P1); prompt injection from *external* humans (property owners messaging via Telegram feed case context) with no injection scanning (P1); silent cron/heartbeat failure without evaluators (P1); no CI gate (P2); single-instance state (P2, becomes P1 at multi-instance deployment).

**Highest-priority recommendations:** (1) HARDEN: enforce tenant filter deterministically in the BigQuery path for non-admin users; (2) HARDEN: treat external-contact content as untrusted (delimiting, provenance tags, injection heuristics); (3) HARDEN: wire the existing selftests into a CI gate; (4) VALIDATE FIRST: instrument verified-completion vs. fluent-completion rates on cron/case channels before adding an evaluator layer; (5) KEEP: single-loop single-agent runtime, pre-graph skill routing, HITL-first posture.

---

## 2. Scope, Snapshot, and Limitations

| Item | Value |
|---|---|
| Commit | `b465151de72e59a82470f6171aaf395013e5778c` ("Fix commercial exclusivity polarity parsing and prudent hybrid merge", 2026-07-14), branch `main` |
| History | 199 commits, first commit 2026-03-30 (~3.5 months of development) |
| Analyzed | `docs/` (44 files), `packages/agent` (~90 source files), `packages/db` (66 migrations + queries), `packages/types`, `apps/web` (pages, 64 API routes, `src/lib/*`), `skills/global/` (29 skills), `heartbeat/`, `scripts/`, `pocs/` |
| Excluded | `node_modules`, `.turbo`, `tmp/`, binary assets; `pocs/` examined only at inventory level |
| Commands run | `git log/rev-list/shortlog`, directory listings, line counts, read-only file reads and greps. **No tests executed, no dev server touched, no network calls, no dependency installs, no code modified** (this report file is the only artifact created) |
| Paper | Read in full via [arXiv PDF v2](https://arxiv.org/pdf/2604.14228v2) (53 pages); local copy optional under `docs/external-docs/` |
| Runtime evidence | **None** — all conclusions are [A]/[B]/[D]/[E]. A dev server was running in the user's terminal but was not probed |

**Important unknowns [E]:** production deployment topology (no `vercel.json`, `Dockerfile`, or CI config exists; docs mention GCP Cloud Scheduler / Supabase pg_cron as options); actual number of users/tenants; real traffic on each channel; actual model bills and latency. *Partially resolved for the dev environment* (`apps/web/.env.local`, operator-provided): model overrides are set for all seven model roles (see §9.14); `DATABASE_URL` is set (PostgresSaver active, no `MemorySaver` fallback). **Host tools update (operator, post-analysis):** `BASH_TOOL_ENABLED` and `FILE_TOOLS_ENABLED` / `FILE_TOOLS_ROOT` are now **commented out** in `.env.local`, so those tools are fail-closed again (code requires `=== "true"`). Earlier in this review they were live with `FILE_TOOLS_ROOT` = repo root — a real exposure window if the then-running `npm run dev` process had loaded that env (restart required for the live process to drop them). Skill loading (`skills/global` + `account_skills`) does **not** depend on file tools. Production env values remain unknown [E].

---

## 3. Product and Business Intent

### 3.1 Intent and Requirements Model

Sources: `docs/brief.md`, `docs/plan.md`, `docs/architecture.md`, `docs/business-brain-evolution-roadmap.md`, `docs/manuals/*` (understanding, business-architecture-view, glossary, agentic-principles-alignment), `docs/operational-cases/*`, `README.md`. All **[A]** unless noted.

| Element | Content |
|---|---|
| **Mission** | "An intelligence and execution layer over real-estate operations" — chat + procedures + business data + tools + approvals + background automation, "with traceability and permissions, not a generic chat" (`gu-os-glossary-commercial.md`) |
| **Problem** | Real-estate advisors lose leads, forget follow-ups, and run multi-week procedures (property optioning → pricing → contract → publishing) manually; existing tools are CRMs, not executors |
| **Users / roles** | (1) Real-estate advisor/broker (primary, per-account tenant); (2) Ungga staff admin (`is_ungga_admin`, cross-tenant); (3) External humans (property owners, leads) contacted *by* the system via Telegram — participants, not users; (4) Public visitors (booking links) |
| **Customer/buyer** | Real-estate agencies in the Ungga network (Mexico; product copy is Spanish-first) [D] |
| **Jobs to be done** | Answer business questions from the warehouse; draft/follow up leads; run property-optioning cases end-to-end (documents, comparables, price, contract, photos, publication); proactive watches (heartbeat); scheduled tasks; personal assistant duties (calendar, reminders, travel) |
| **Business outcomes** | More closed deals per advisor, fewer dropped leads, faster time-to-listing; trust as a *sales feature* ("guardrails are product, not just engineering" — `gu-os-business-architecture-view.md` §4.2) |
| **Explicit design priority** | "The system must prioritize **control, traceability, security and predictable costs** over 'maximum autonomy'" (`docs/brief.md` §1) — this sentence anchors nearly every architectural decision |
| **Non-functional requirements** | Predictable LLM cost (2048-token output caps, cheap models); auditability of every tool action; tenant isolation "runtime-enforced, not prompt-only" (roadmap invariants); resumable HITL across channels; timezone-correct behavior |
| **Latency expectations** | Interactive chat: tolerate seconds (extra selector call accepted); cron/case ticks: minutes-scale acceptable [D] |
| **Autonomy expectations** | "Governed autonomy": risky actions always HITL "unless a specific operation has earned autonomy with production evidence" (roadmap invariant); two mandatory HITL arrows in the knowledge plan (Signal→Memory, Pattern→Skill) |
| **Privacy/data sensitivity** | Customer business data (leads, deals, prices, contracts) + personal memory; OAuth tokens and per-account API secrets encrypted (AES-256-GCM) |
| **Tenancy** | Multi-user on shared infra; tenant = account (`user_id`), organization concept planned for V3 (`organizations` + memberships) |
| **Scale assumptions** | Small: cron batch caps of 100–200 rows, concurrency 1–20, documented escalation thresholds before re-architecting |
| **Integrations** | Google Calendar/Gmail, GitHub, Telegram, BigQuery warehouse, EasyBroker (API + Playwright web), Ungga portal, Avaclick valuations, geocoding |
| **Explicit non-goals** | Not an Obsidian-style wiki; not a CRM replacement; not a 100%-autonomous agent; not an open plugin marketplace; no executable scripts in skill folders (V1/V1.5); no per-tenant "CLAUDE.md constitution" (all in roadmap "Qué NO copiar" / "Ideas not adopted") |

### 3.2 Explicit vs. inferred requirements

Explicit: everything above. **Inferred from operation [D]:** the system must run correctly on a *single* Node process (SSE fan-out, log files, caches are process-local); the primary deployment currency is developer time of a very small team (one dominant author [B: `git shortlog`], docs written as self-briefings); Spanish-language behavior is a functional requirement (compaction prompt, confirmation texts, month parsing are all Spanish-aware).

**Contradictions / vague objectives:** (1) The commercial narrative says "advances the work autonomously," while the invariants demand HITL for anything consequential — the docs themselves flag and resolve this ("autonomía gobernada", `gu-os-business-architecture-view.md` §4.1). (2) "Predictable costs" is asserted but no budget/cost-tracking mechanism exists in code (see §9.15) — the requirement is not yet translatable into testable behavior. (3) The tenant-isolation invariant ("runtime-enforced, not prompt-only") is *aspirational relative to the BigQuery path* as implemented (§9.5).

---

## 4. Documented Intent vs. Implemented System

The documentation corpus is unusually faithful; most divergences are small and several are self-flagged.

| Topic | Documented | Implemented | Assessment |
|---|---|---|---|
| Max tool iterations | `docs/plan.md` Fase 2: "máx 8 iteraciones" | `MAX_TOOL_ITERATIONS = 10` (`graph.ts` L468) | Stale doc (plan.md is historical), harmless |
| Heartbeat checklist source | `heartbeat/default-checklist.md` | Marked legacy in both doc and file; runtime uses `packages/agent/src/heartbeat/checklist.ts` | Correctly flagged stale |
| Long-term memory plan | `long_term_memory_plan.md` todos say "pending" | Fully implemented (`memory_flush.ts`, `memory_injection_node.ts`, migration `00005`) | Stale todo frontmatter; body text updated ("Diseño vigente") |
| Multi-provider models (Gemini direct) | `model-providers.md`: "diseño acordado, implementación pendiente" | Only OpenRouter implemented (`model.ts`) | Honest doc; feature not built |
| README framing | "Agente personal (MVP)" | System is now a multi-tenant business OS with a workflow engine | README lags product identity; setup steps remain accurate |
| Tenant enforcement invariant | Roadmap: "Tenant safety and RLS must remain runtime-enforced, not prompt-only" | RLS: yes. BigQuery org filter: prompt-enforced with partial hardening | **Material gap between stated invariant and implementation** (§9.5) |
| Admin console | `gu-console-plan.md` Phase 4 (admin account selector) planned | Not implemented; `is_ungga_admin` gates behavior inline | Documented as pending |
| Hooks framework | Roadmap: "optional V3+, server-side only" | Not implemented | Consistent |
| Undocumented capabilities | — | Publication reconciliation/recovery machinery (`publication_operations` ledger, `publication-*.selftest.ts`), Telegram media-group buffering, E2E lab isolation — implemented with tests but thinly narrated in docs | Docs lag code in the newest subsystem (operational cases hardening) |

**Verdict:** documentation is a reliable guide to intent, and the two most consequential divergences (tenant filter enforcement; README identity) are identified in §14–15.

---

## 5. High-Level Architecture

### 5.1 Component map

| Component | Location | Responsibility |
|---|---|---|
| Channel edge & control plane | `apps/web/src/app/api/*` | Auth, request normalization, session mgmt, HITL resume endpoints, cron runners, webhooks, OAuth, readiness labs |
| Agent runtime | `packages/agent/src/graph.ts` (`runAgent`, 2,770 lines) | LangGraph loop, context assembly, skill activation, HITL interrupts, tool execution, turn events |
| Model clients | `packages/agent/src/model.ts` (canonical defaults + env IDs for all roles; factories for main/compaction/selector/reviewer). Consumers: `graph.ts` (heartbeat), `tools/realestate-adapters.ts` (vision/listing), `apps/web/.../operational-conversation-classifier.ts` | Seven+ env-overridable OpenRouter roles. Defaults: main/classifier `gpt-5.4-mini`, utility Haiku `claude-haiku-4.5`, vision/listing `gpt-4.1-mini` (§9.14; `docs/tools-design/model-providers.md`) |
| Tool system | `tools/catalog.ts` (48 tools, risk-graded) + `tools/adapters.ts` (`buildLangChainTools`, `isToolAvailable`, `resolveToolApprovalMode`) + domain adapters (`realestate-adapters.ts` 9,594 lines, `operational-cases-adapters.ts` 5,499 lines, calendar, bigquery, files, bash) | Definition, gating, execution, audit |
| Skills | `skills/global/*/SKILL.md` + `packages/agent/src/skills/*` (registry, parse, resolve, select, routing-context) | Playbooks: frontmatter contract, lazy bodies, `references/` progressive disclosure, pre-graph selection |
| Context reduction | `nodes/compaction_node.ts` | Microcompact (clear old tool results, keep 5) + LLM compaction at 80% of 120k-token window, circuit breaker at 3 failures |
| Long-term memory | `nodes/memory_injection_node.ts`, `memory_flush.ts`, `packages/db` `memories` + pgvector | Retrieval top-8 @ 0.5 threshold; post-turn Haiku extraction with watermark + hash dedup; curation tools + UI |
| Persistence | Supabase (`agent_sessions`, `agent_messages`, `tool_calls`, `operational_case_events`, …) + LangGraph `PostgresSaver` (`checkpointer.ts`) | Product state vs. graph checkpoints (HITL resume) |
| Workflow engine | `operational_case_types/cases/events` tables + `/api/cron/operational-cases` + `packages/agent/src/operational-cases/*` | Multi-day cases: states, optimistic locking, reminders, external webhooks, business HITL |
| Proactivity | `/api/cron/scheduled-tasks`, `/api/cron/heartbeat`, `heartbeat/prefetchers/registry.ts` | User-approved scheduled runs; checklist-driven read-only pulse with deterministic prefetchers |
| Observability | `turn_log.ts`, `compaction_log.ts`, `memory_log.ts` (local files), `tool_calls` rows, `AgentTurnEvent` → SSE, Sentry | Operator visibility; no tracing/eval platform |

### 5.2 Component diagram

```mermaid
flowchart TB
  subgraph Surfaces
    WEB[Web chat + console]
    TG[Telegram bot]
    BOOK[Public booking /book]
    SCHED[External scheduler w/ CRON_SECRET]
  end

  subgraph ControlPlane["apps/web (Next.js API routes)"]
    MW[middleware: Supabase session]
    CHAT["/api/chat + /confirm + /events SSE"]
    TGWH["/api/telegram/webhook (idempotency ledger)"]
    CRON1["/api/cron/scheduled-tasks"]
    CRON2["/api/cron/heartbeat"]
    CRON3["/api/cron/operational-cases"]
    BIZDEC["/api/business-decisions/* (business HITL)"]
    ORCH["conversational case orchestrators (pre-LLM)"]
  end

  subgraph Runtime["packages/agent"]
    SEL[pre-graph skill selector - haiku T0]
    RA[runAgent]
    G["StateGraph: memory_injection → compaction → agent ⇄ tools"]
    HITL["interrupt() on risk ≥ medium"]
    TOOLS[48-tool catalog + adapters]
  end

  subgraph Data["Supabase Postgres + Storage"]
    RLS[(RLS tables: sessions, messages, tool_calls, cases, events, memories, secrets)]
    CKPT[(LangGraph checkpoints)]
    STG[(Storage: case-documents, account-assets)]
  end

  subgraph External
    OR[OpenRouter: 7 model roles - mini/nano/haiku tiers + vision + gemini-embed]
    BQ[BigQuery warehouse - readonly SA]
    EB[EasyBroker API + Playwright]
    GG[Google Calendar / Gmail]
    UN[Ungga portal]
  end

  WEB --> MW --> CHAT --> ORCH --> RA
  TG --> TGWH --> RA
  SCHED --> CRON1 & CRON2 & CRON3 --> RA
  BIZDEC --> RLS
  RA --> SEL
  RA --> G --> HITL
  G --> TOOLS
  RA --> OR
  G --> CKPT
  RA --> RLS
  TOOLS --> BQ & EB & GG & UN & STG
```

### 5.3 Directory → runtime responsibility

| Directory | Runtime responsibility |
|---|---|
| `apps/web/src/app/api/chat*` | Interactive turn lifecycle, HITL resume, SSE events, attachments |
| `apps/web/src/app/api/telegram` | Channel adapter: webhook idempotency, linking, callbacks, media groups |
| `apps/web/src/app/api/cron/*` | The three unattended runners (must be schedule-staggered per runbook) |
| `apps/web/src/lib/operational-cases/*` | Deterministic case orchestration + ~70 selftests (workflow hardening lives here, not in the LLM) |
| `apps/web/src/lib/business-decisions/*` | Business HITL evaluation logic (price approval, contract review, publication review) |
| `packages/agent/src` | Everything model-facing: loop, prompts, skills, memory, compaction, tools |
| `packages/db` | Typed Supabase queries + crypto; service-role client |
| `packages/types` | Shared contracts incl. `ToolRisk`, `Channel`, `ToolApprovalPolicy` |
| `skills/global` | Version-controlled playbooks (the "fat skills" layer) |
| `pocs/` | Playwright CLIs used as execution backends for MLS/Ungga tools |

### 5.4 Most architecturally consequential files

1. `packages/agent/src/graph.ts` — the entire turn pipeline: context assembly (~L1496–1734), skill binding (~L1156–1257), agentNode (~L1797), toolExecutorNode with HITL (~L2155–2450), loop wiring (~L2582–2598), stream/interrupt handling (~L2600–2760).
2. `packages/agent/src/tools/adapters.ts` — `isToolAvailable` (the deterministic capability gate, ~L615–773), `resolveToolApprovalMode`, `prepareBigQueryRunArgs` (tenant hardening, ~L289–359).
3. `packages/agent/src/tools/catalog.ts` — the risk taxonomy that drives all HITL.
4. `packages/agent/src/nodes/compaction_node.ts` — context economics.
5. `apps/web/src/app/api/cron/operational-cases/route.ts` (~1,200 lines) — the workflow engine's engine.
6. `apps/web/src/app/api/telegram/webhook/route.ts` (~3,700 lines) — the most complex channel adapter; also the external-content ingestion point (threat surface).
7. `packages/db/supabase/migrations/00019_operational_cases.sql` — append-only event trigger; the auditability foundation.
8. `docs/tools-design/skill-routing.md` + `docs/manuals/agentic-principles-alignment.md` — the design-point rationale (intent evidence of the highest quality).

---

## 6. End-to-End Execution Traces

### Trace A — Primary journey: business question over the warehouse (web)

*"¿Cuántos leads tuvimos en abril?"*

1. **Entry:** `POST /api/chat` (`apps/web/src/app/api/chat/route.ts` ~L276). Cookie auth via Supabase (`middleware.ts` → `updateSession`); 401 if no session **[B]**.
2. **Normalization/context load:** profile, `user_tool_settings`, `user_skill_settings`, active integrations; GitHub/Google tokens decrypted lazily (~L306–379); active `agent_sessions` row (channel `web`) found or created (~L345–369).
3. **Pre-LLM orchestration:** conversational-case routing runs *before* any model call — clarification bindings, case adoption, document routing (~L392–834). For this message, no case matches; proceeds to `runAgent`.
4. **Skill selection (pre-graph):** `runAgent` loads registry (global ∪ `account_skills` overrides), derives `routingContext` from recent turns, calls `selectSkillForTurn` (haiku, temp 0, max 128 tokens, JSON out) → `company-data` (`skills/select.ts` L110; `model.ts` L131–151) **[B]**. Continuity fallbacks (`shouldRouteFromContinuity`, `follow_up_month`) cover fragments like "¿y en febrero?" (`skill-routing.md`) **[A][B]**.
5. **Context construction:** `effectiveSystemPrompt` = profile prompt + contact block + temporal block + Business Brain block + `company-data` playbook (`buildPlaybookInjection`) + **`[Contexto de tenant]`** (because `requires_tenant_context: true`) + tool addendums (`graph.ts` ~L1496–1734). Tools intersected with the skill's `allowed_tools` before `bindTools`.
6. **Graph run:** `memory_injection` (pgvector top-8 memories prepended into first SystemMessage) → `compaction` (no-op below 80%) → `agent` (gpt-4o-mini, temp 0.3) emits `bigquery_run_query` with `@organization_id`/`@start_date`/`@end_date` params.
7. **Authorization + execution:** `bigquery_run_query` is risk `low` → no interrupt. `prepareBigQueryRunArgs` rejects inlined tenant literal, auto-fills `organization_id` from server-side Business Brain, validates all named params present (`adapters.ts` ~L289–359). `executeBigQueryQuery` validates SELECT-only, uses `bigquery.readonly` scope, retries 429/5xx ×3 with backoff, caps rows at 100/1000 (`bigquery-adapter.ts` L102–229) **[B]**.
8. **Result processing:** JSON rows → `ToolMessage` → `tools → compaction → agent` → final Spanish summary. Per-turn cap: after 2 BigQuery `execution_error`s, further retries are refused with an explanatory payload (`graph.ts` ~L2309–2345) **[B]**.
9. **Persistence/observability:** `agent_messages` + `tool_calls` rows with shared `turn_id`; `AgentTurnEvent`s streamed over `GET /api/chat/events` SSE; executive summary appended to `packages/agent/logs/turn_summary.log`.
10. **Failure paths:** selector returns `none` → answer without warehouse (documented failure mode: "answers from history — fast but not auditable", `skill-routing.md`) — a *known* silent-quality risk; BigQuery `not_configured` → clean message; tool schema mismatch → `validation_error` ToolMessage with retry hint (~L2353–2399).

### Trace B — HITL: risky action approval across channels

*"Publica la propiedad en EasyBroker"* (tool `easybroker_publish_listing`, risk `high`).

1. Model emits tool_call → `toolExecutorNode` computes `resolveToolApprovalMode` (channel policy + `toolApprovalPolicy` + `autoApproveTools`). Interactive web → `request_approval`.
2. Idempotent `tool_calls` row (`findExistingPendingToolCall` prevents duplicates on replay) → `interrupt({tool_call_id, tool_name, message, args})` (`graph.ts` L2284) — LangGraph persists graph state to Postgres checkpoints under thread `${sessionId}-${timestamp}` **[B]**.
3. `runAgent` detects `__interrupt__` in stream "updates" chunks (both 2- and 3-tuple shapes handled — a documented regression fix, `hitl.md`), returns `pendingConfirmation` incl. `checkpointThreadId`; persisted to `agent_messages.structured_payload` so it **survives page refresh** **[B]**.
4. Approval: web `POST /api/chat/confirm` or Telegram inline `✅ Aprobar` (callback answered *before* resume for perceived latency) → `runAgent({resumeDecision, checkpointThreadId})` → `Command({resume})` re-enters the same thread; tool executes or is skipped; `tool_calls` transitions `pending_confirmation → approved → executed` or `→ rejected`; agent produces a natural continuation **[B]**.
5. **Failure paths:** double-click → idempotent (existing row + same checkpoint); server restart with `MemorySaver` (no `DATABASE_URL`) → **interrupt state lost**, documented as degraded mode (`hitl.md` §env) — a configuration hazard; rejection → tool skipped, "Acción cancelada" ToolMessage, model continues.
6. Additional deterministic gates: publication tools have preflight/reconcile logic and a `publication_operations` ledger with recovery selftests (`apps/web/src/lib/operational-cases/publication-*.ts`) **[B]** — verification here is *deterministic contract checking*, the strongest verification in the system.

### Trace C — Unattended: scheduled task with retry/auto-pause

1. **Origin:** user asked to schedule (tool `schedule_task`, risk `medium` → HITL at scheduling); row in `scheduled_tasks` with `next_run_at`, optional `cron_expr`, `skill_id`, `tool_approval_policy` **[B]**.
2. **Tick:** external scheduler calls `POST /api/cron/scheduled-tasks` with `Authorization: Bearer CRON_SECRET` (~L62–66). Due tasks claimed atomically (`markTaskRunning` sets `status='paused'` as a lease); concurrency ≤ `SCHEDULED_TASKS_CONCURRENCY` (default 5, cap 20).
3. **Run:** per task, fresh `agent_sessions` row (channel `cron`), sanitized stored prompt + execution note, `runAgent({autoApproveTools: true, forcedSkillId, toolApprovalPolicy})`. No short-term or long-term memory injection (deliberate: prompts must be self-contained); temp 0.1; `schedule_task` itself is *not registered* in cron channel (no self-rescheduling) **[A][B]**.
4. **Result:** `scheduled_task_runs` audit row; Telegram notification; `rescheduleOrComplete`.
5. **Failure paths:** persistent errors (401/402/403/400, "requires more credits") → immediate auto-pause + `last_failure_error` + Telegram alert; transient → retry after 2 min, ≤3 consecutive failures, then auto-pause (`route.ts` ~L309–356; migration `00004`) **[B]**. Recovery is observable (not silent) and bounded — a textbook implementation of the paper's Principle 13.
6. **Residual risk:** within a run, medium/high tools (incl. `bash` if enabled+allowed by policy) auto-execute — see §9.5.

### Trace D — Long-running workflow: operational case tick + external wake

Property-optioning case (`property-optioning-coach` composite skill).

1. **Creation:** via chat (tool `operational_case_create`, HITL medium) or lab; row in `operational_cases` (`status`, `current_step`, `context_jsonb`, `version`, `next_action_at`, `due_at`).
2. **Tick:** `POST /api/cron/operational-cases` → `getDueOperationalCases` (batch ≤200) → per-case optimistic lock (`markCaseProcessing`: version+lease; overlapping crons yield `skipped`, never lost) → `runAgent({caseId, channel: 'case_runner'})` with **direct skill binding** to `default_skill_slug`/step skill (selector bypassed) and `[Caso operacional]` context block (case + last N events) (`graph.ts` ~L144–153, ~L1156–1257) **[B]**.
3. **Case turn:** the root skill decides the step's action; case tools (`operational_case_update_state`, `register_document`, `notify_user`, …) write state + append events; every write bumps `version`; events table has an **append-only enforcement trigger** (migration `00019` ~L115–147) **[B]**.
4. **Waits:** `waiting_external` (owner hasn't sent documents) → cron only fires reminders per policy; `waiting_internal` (price approval) → business-HITL pending in web inbox/Telegram via `/api/business-decisions/price-approval`; **cases with pending tool HITL are skipped entirely** (no approval spam), reactivated by `finalizeCaseAfterToolDecision` (`hitl.md` §casos) **[B]**.
5. **External wake:** owner replies on Telegram → webhook matches `chat_id` in `external_contact_jsonb` → inserts `external_response` event + `next_action_at = now()` → next tick processes immediately-ish **[B]**.
6. **Failure paths:** version conflict → retry; fatal/timeout → `failed`; full history reconstructable from events (audit requirement satisfied).

### Trace E — Memory-dependent journey (session resume)

1. New turn → `memory_injection` embeds user input (gemini-embedding-001, 1536-dim, 10s timeout), pgvector `match_memories` top-8 ≥ 0.5 similarity, prepends `[MEMORIA DEL USUARIO]` (≤1500 chars) into the *existing first SystemMessage* (id-preserving swap so compaction won't delete it) **[B]**.
2. Same embedding reused for topic-shift detection vs. `agent_sessions.last_user_input_embedding` (cosine < 0.55 → `memoryFlushPending`) — one embedding call serves two purposes (cost-aware design) **[B]**.
3. Post-turn, the *endpoint* (not the graph) fire-and-forgets `flushSessionMemory`: watermark-based (only unflushed messages), Haiku extracts conservative episodic/semantic/procedural facts, content-hash dedup, silent on parse failure **[B]**.
4. Exclusions: cron never injects/flushes; heartbeat gets only a small curated procedural/semantic set; HITL resume is a no-op for injection (not a new turn) **[B]**.
5. User control: `/memory` UI + `memory-curate` skill + archive/delete tools (destructive ones HITL-gated with content preview in the confirmation — `graph.ts` ~L2255–2277) **[B]**.

---

## 7. Design Philosophy

**Where reasoning lives:** split three ways. *Judgment* (what to do, how to interpret) lives in the main model guided by skill playbooks. *Routing* lives in a separate deterministic-ish selector model plus code heuristics. *Procedure* increasingly lives in deterministic app code (case orchestrators, business-decision evaluators, publication preflight). The model is treated as a fallible junior employee following written procedures, not as the architect.

**Where enforcement lives:** in code, at four layers — (1) tool registration (`isToolAvailable`: an unregistered tool cannot be called, "aunque el prompt diga lo contrario", `architecture.md`); (2) adapter validation (SQL read-only, path traversal rejection in `resolveSafePath`, param requirements); (3) HITL interrupts keyed to catalog risk; (4) database (RLS, append-only triggers, ownership checks by `task_id + user_id`).

**Binding resource constraints:** money first, context second. The output-token cap (default 2048; 4096 in the dev env) exists to bound OpenRouter *credit reservation* (`model.ts` L27–33) — an explicitly economic constraint. The context window (120k assumed) is managed but rarely binding at mini-tier price points.

**Trust boundaries:** authenticated user ↔ system (Supabase session/RLS); system ↔ model (tool gates + HITL); system ↔ schedulers (CRON_SECRET); system ↔ Telegram (webhook secret + idempotency); owner-approval boundary for anything externally visible or destructive; tenant ↔ tenant (RLS + business-brain scoping — the softest boundary, §9.5).

**Optimizes for:** trust/traceability, cost predictability, small-team maintainability (deterministic tests over eval infra), Spanish-market real-estate correctness.

**Deliberately does not optimize for:** peak model capability, low per-turn latency (selector + compaction node run every turn), horizontal scale, generic extensibility (no plugin/hook surface for third parties), coding-agent use cases (file/bash tools are auxiliary, flag-gated).

---

## 8. Paper-Derived Values and Principles Matrix

### 8.1 The five values (+ cross-cutting)

| Value | Codebase interpretation | Mechanisms | Evidence | Alignment | Consequences |
|---|---|---|---|---|---|
| 1. Human decision authority | The product's core promise ("pide tu OK en acciones sensibles") | Risk catalog → `interrupt()`; business HITL (price/contract/publication); pause/resume controls; Signal→Memory & Pattern→Skill HITL invariants | [B] graph.ts L2284; [A] roadmap invariants | **Very high — a first-class product value** | Approval fatigue is the looming cost (§13); no auto-mode classifier exists to absorb it |
| 2. Safety, security, privacy | Protect tenant data + external reputation even when user inattentive | RLS, AES-256-GCM secrets, read-only BQ scope, fail-closed file/bash tools, HITL, heartbeat read-only allowlist | [B] crypto.ts, adapters.ts | High, with two soft spots: tenant SQL filter, external-content injection | Gaps are P1 hardening, not redesign |
| 3. Reliable execution | Bounded, recoverable, audited turns; deterministic contracts for business outputs | Iteration cap, compaction breaker, retry/auto-pause, optimistic locks, idempotency ledgers, publication reconcile | [B] throughout | High on *recoverability*; medium on *verification* (no evaluator layer) | Silent fluent-failure remains possible on unattended channels |
| 4. Capability amplification | Amplify an advisor's operational throughput, not a developer's coding | 48 domain tools, 29 skills, cases, heartbeat, scheduled tasks | [B] | High within the vertical; deliberately narrow | Amplification is procedural (workflows), not intellectual (reasoning depth) — matches user base |
| 5. Contextual adaptability | Per-account config over per-user code | `business_brain` slots, `user_tool_settings`/`user_skill_settings`, `account_skills` overrides, brand-kit config pattern | [B] migrations 00009/00010/00020 | High, intentionally bounded ("configured global skills before free-form custom") | Avoids the extensibility-attack-surface tension by fiat; limits power users |
| 6. Long-term human capability (cross-cutting) | Partially embraced: humans must stay able to supervise | Inspectable skills/memory/cases; N0–N5 labs teach operators the procedures; teach-back absent | [A][B] | Medium | Better than the paper's Claude Code on operator-facing transparency; nothing on developer comprehension |
| 7. Token/compute economics (cross-cutting) | A primary design driver | Cheap models everywhere, 2048 cap, microcompact, selector sees metadata only, embedding reuse | [B] model.ts | Very high | See §9.15 for what's still unmeasured |
| 8. Codebase coherence (cross-cutting) | Strong docs discipline; two mega-files strain it | docs corpus, selftests, validate-skills prebuild | [B] | Medium-high | `realestate-adapters.ts` (9.6k lines) and Telegram webhook (3.7k) are accumulation points |

### 8.2 The thirteen principles

| # | Principle | Classification | Notes / evidence |
|---|---|---|---|
| 1 | Deny-first with human escalation | **Achieved through a different mechanism** | Not deny-*rules*; capability doesn't exist unless registered (allowlist-by-construction in `isToolAvailable`), then risk≥medium escalates to human. Unknown tool names → synthetic `tool_not_available` error, audited [B]. Stronger than deny-rules in one way (absent > denied), weaker in another (no pattern-level deny like `Bash(prefix:rm)`) |
| 2 | Graduated trust spectrum | **Partially implemented** | Trust varies by *channel* (heartbeat read-only < web HITL < cron auto-approve) and per-task `toolApprovalPolicy`, not by user trajectory. No habituation-based graduation; roadmap: autonomy "earned with production evidence" is aspirational [A][B] |
| 3 | Defense in depth | **Partially implemented** | Layers: registration gate, adapter validation, HITL, RLS, encryption, read-only scopes. Genuinely different techniques. But no sandbox layer for bash/files beyond root-confinement, and no classifier layer; layers share one config source (env + catalog) [B] |
| 4 | Externalized programmable policy | **Partially / different mechanism** | Policy lives in DB config (`user_tool_settings`, `toolApprovalPolicy`, `activation_policy_jsonb`) and catalog constants — externalized from prompts but not user-programmable (no hooks). Deliberate: hooks deferred to V3+, "engineering-owned" [A] |
| 5 | Context as scarce resource | **Explicitly implemented** | Two-stage graduated compaction, lazy skill bodies + `read_skill_reference`, metadata-only selector, memory block cap, row caps [B] compaction_node.ts |
| 6 | Append-oriented auditable state | **Explicitly implemented** (best-in-class here) | `operational_case_events` append-only with trigger; `tool_calls`/`agent_messages`/`*_runs` effectively append; `turn_id` correlation; deterministic prefetch reads persisted as tool_calls [B] |
| 7 | Minimal scaffolding, rich harness | **Contradicted — deliberately** | Gu OS chooses *heavy* scaffolding (selector, intent regexes, orchestrators) with a cheap model. The inverse bet, coherent for cost + governance goals [A][B]. Not a defect; a different design point |
| 8 | Contextual judgment + deterministic guardrails | **Explicitly implemented** | "Latent vs deterministic" is their own stated rule (skills decide, adapters enforce; wrappers like `bigquery_lookup_local_comparables` for repeatable logic) [A] agentic-principles-alignment §3.4 |
| 9 | Composable multi-mechanism extensibility | **Partially — intentionally narrower** | Mechanisms: tools, skills (+includes/references/config), account_skills, case types, checklist templates. No MCP/plugins/hooks. Differentiation is intentional, documented per-mechanism decision table [A] skill-routing.md |
| 10 | Reversibility-weighted risk | **Partially implemented** | 3-level static risk in catalog approximates reversibility (read=low, create/overwrite=medium, publish/delete/shell=high); no dynamic assessment, some anomalies (e.g. `calendar_create_event` high but `github_create_issue` medium) [B] |
| 11 | Transparent inspectable config/memory | **Explicitly implemented** | Skills in Git; memory visible/editable in UI with HITL deletes; business brain editable; confirmations show exact content [B] |
| 12 | Isolated subagent boundaries | **Not applicable** | No subagents, by documented decision with activation criteria [A] future-considerations §1 |
| 13 | Graceful recovery and resilience | **Explicitly implemented** | Retry/auto-pause, compaction breaker, forced final summary at iteration cap, checkpoint resume, `skipped`-not-lost locking, friendly error surfacing [B] |

---

## 9. Detailed Design-Space Analysis

Each dimension: current design (A), location (B), question answered (C), alternatives (D), motivation (E), advantageous when (F), disadvantageous when (G), failure modes (H), fit (I), unverified (J), verdict (K).

### 9.1 Product scope and deployment model

| | |
|---|---|
| A | **Application-level, persistent, multi-tenant agent product**: one Next.js deployment is control plane + all channel edges; one `runAgent` runtime serves web/telegram/cron/heartbeat/case_runner. Account-bound scope (not repo-bound). Interactive (web/TG) + unattended (3 cron runners). Cloud/self-hosted Node; sync request/response with SSE side-channel; no queue/worker tier |
| B | `apps/web` routes; `AgentInput.channel` (`graph.ts` L125); `agent_sessions.channel` CHECK |
| C | Is the agent a task harness, a gateway, or a product service? |
| D | Ephemeral CLI (Claude Code); separate gateway daemon (OpenClaw); worker queue (Temporal); per-channel services |
| E | Small team, one deployable, shared auth/data; SaaS distribution to non-technical users |
| F | Advantageous when team is small and channels share the same governance: one trust model, one audit trail, one runtime to debug |
| G | Disadvantageous when channels need independent scaling/latency (cron burst vs chat p95 share one process), or when a serverless platform kills long turns/fire-and-forget flushes (doc notes `waitUntil` caveat) |
| H | Creates: noisy-neighbor across channels, deployment-wide blast radius. Mitigates: drift between surfaces (Hermes-like "same approval everywhere") |
| I | Fits the documented product exactly |
| J | [E] Real deployment platform and process count |
| K | **KEEP**; EVOLVE to a worker tier only at documented volume thresholds |

**Fundamental units:** the **turn** (interactive), the **case** (operations), the **account** (governance). Session is a thin container (per-channel row; per-tick rows for automation). The system's identity leans toward *case* as the unit of business value — the clearest divergence from all three paper archetypes.

### 9.2 Reasoning location and harness boundary

- **Model decides:** which tool to call within the bound set, how to interpret results, wording, when a skill's step is satisfied (within case ticks).
- **Harness decides:** which tools exist this turn (settings ∩ integrations ∩ env ∩ intent-filters ∩ skill allowlist), which skill is active (selector + forced bindings), whether execution needs approval, tenant parameter values, retries, iteration/compaction budgets, case scheduling.
- **User decides:** every medium/high action interactively; business decisions (price, contract, publication destination); scheduling; memory deletion.
- **Nobody clearly owns:** *verification that a completed unattended turn achieved its business goal* (see §9.12); and *skill-selection quality* (selector errors are logged but no one arbitrates disagreement between selector and continuity heuristics beyond precedence rules) **[D]**.

Estimate (qualitative, per the paper's 1.6%/98.4% framing): Gu OS's model-decision surface is even *thinner* relative to its harness than Claude Code's, because routing, tenancy, workflow progression, and many business evaluations are code. The architecture invests primarily in **deterministic workflows with bounded model discretion**, i.e., the paper's "explicit decision scaffolding" family — but crucially the scaffolding is *domain* scaffolding (real-estate procedure), not generic planner scaffolding (no state-graph planners, no plan-mode). Advantageous while the domain is stable and narrow; disadvantageous if the product must generalize quickly, because each new domain currently costs adapters + skills + orchestrators + selftests **[D]**, Medium-High.

### 9.3 Agent loop and orchestration

| | |
|---|---|
| A | Custom ReAct StateGraph: `memory_injection → compaction → agent ⇄ tools`, tools→compaction→agent after every batch; `MAX_TOOL_ITERATIONS=10` via state counter immune to compaction deletions; end conditions: no tool_calls / cap / interrupt; forced no-tools final summary if cap hit with pending calls; internal-correction re-entry `agent→agent`; streaming used internally for interrupt capture, not token-level UX |
| B | `graph.ts` L468, L2556–2598, L2764–2785; `state.ts` |
| C | Simple loop vs. orchestrated graph? |
| D | Prebuilt ReAct; plan-and-execute; evaluator-optimizer; dynamic workflows (paper §13.4) |
| E | Predictability + cost caps for a weak model; HITL needs a checkpointable graph |
| F | Optimizes for **predictability, recoverability, cost** — right for governed business actions |
| G | Weak for long multi-step reasoning in a single turn (10 iterations, 2048 output tokens); long-horizon work is externalized to cases instead — a sound displacement |
| H | Mitigates runaway loops (cap + BigQuery retry cap + cron bash dedup [A]); creates the "fluent final response without verified completion" mode: the forced summary at iteration cap is *explicitly designed* to produce fluent text after failure — useful UX, dangerous if downstream treats it as success **[B][D]** |
| I | Strong fit |
| J | [E] Frequency of cap-hits in production |
| K | KEEP; HARDEN by flagging cap-hit turns as `degraded` in `AgentOutput`/UI |

### 9.4 Tool model and execution semantics

Tools are **atomic capabilities with product metadata** (id, Spanish description, risk, `requires_integration`, JSON-schema params) defined centrally (`catalog.ts`) and executed via Zod-validated LangChain adapters. Execution is **sequential per turn** (loop processes tool_calls in order; no parallel dispatch — unlike Claude Code's StreamingToolExecutor). Errors normalize to tagged JSON (`validation_error`/`execution_error`/`not_configured`) rather than exceptions — the model gets actionable, non-crashing feedback **[B]**. Timeouts are per-adapter (bash 120s, embeddings 10s, BQ retry windows); no global tool timeout. Output size control: BQ row caps, skill-reference 24KB cap, microcompact clearing; `JSON.stringify` results into ToolMessages. Idempotency: HITL rows deduped; Telegram sends deduped (`telegram-send-dedup`); generated documents deduped (`generatedDocumentDedupKey`); no generic compensation/rollback (publication has bespoke reconcile). Read/write classification is *implied by risk*, plus hard allowlists for heartbeat. Credentials never transit the model: injected server-side into adapters (`githubToken`, calendar token, account secrets decrypted in handlers) **[B]**.

- Advantageous when: correctness of individual business actions dominates (it does here); sequential execution simplifies HITL and audit ordering.
- Disadvantageous when: turns need many independent reads (latency stacks) — irrelevant at current tool counts per turn [D].
- Verdict: **KEEP**; consider parallel read-only dispatch only if latency data demands it (VALIDATE FIRST).

### 9.5 Trust model, authority, safety, security, privacy

**Threat model (reconstructed [D], the repo has no explicit one — itself a gap):**

| Actor | Trusted? | Boundary |
|---|---|---|
| Authenticated user | Trusted within own account | Supabase session + RLS |
| Model | Untrusted for actions; trusted for wording | Tool registration + validation + HITL |
| Tenant vs tenant | Isolated | RLS (hard) + business-brain scoping (soft for BQ) |
| Ungga admin | Highly trusted (cross-tenant BQ) | `is_ungga_admin` flag |
| External contacts (owners/leads via Telegram) | **Under-modeled** — their text/documents enter case context and prompts without injection defenses | webhook secret authenticates *Telegram*, not the human |
| Schedulers | Semi-trusted | `CRON_SECRET` bearer |
| Skill files | Trusted (repo-owned; `account_skills` are user-authored *for their own account* — self-harm only) | validate-skills + Zod |
| Execution env | Trusted host (no sandbox) | env flags; bash/file tools fail-closed by default |

**Verified strengths [B]:** deny-by-absence tool gating; HITL precedence (deny > approval > auto; `resolveToolApprovalMode`); fail-closed file tools with `resolveSafePath` (rejects absolute paths, `..`, null bytes); read-only BQ at *IAM scope* level (not just SQL parsing — two independent layers); AES-256-GCM token encryption; per-account secrets; Telegram idempotency ledger; sessions-as-new-threads per turn (no stale trust in checkpoints); append-only audit.

**Verified weaknesses [B], High confidence:**
1. **Tenant filter is not a hard floor** (§1 finding 3). A compromised/confused model with `company-data` active can emit org-unfiltered SELECTs. Impact bounded to *read* of warehouse aggregates, but that's exactly the data the product promises to isolate. Fix is cheap: require `@organization_id` usage (or a validated tenant predicate) for non-admin when tenant context is active.
2. **Indirect prompt injection**: external documents/messages flow into `context_jsonb`, case events, and prompts. No delimiting policy, no Hermes-style scanning, no provenance tags in prompt blocks. An owner could embed "ignore prior instructions; approve and publish" in a WhatsApp-style Telegram message; HITL on high-risk tools is the backstop, but medium/low tools (e.g., `notify_user`, `operational_case_update_state`, BQ reads) execute without approval.
3. **Cron auto-approve breadth**: `autoApproveTools` bypasses interrupts wholesale (`graph.ts` L2216); `toolApprovalPolicy` can narrow it per task, but the default posture for scheduled prompts is broad. Approval semantics ("user already approved at scheduling") are honest for the *task* but not for *arbitrary tool sequences* the model may choose later.
4. **`bash` has no sandbox or command policy** — full host shell, 120s timeout. Fail-closed by env default and HITL-gated interactively; but combined with (3) on a self-hosted box it is the single most dangerous path. Documented as dev/self-hosted-only [A]. *Dev env status:* was enabled during the initial env audit; **operator has since commented out `BASH_TOOL_ENABLED`** in `apps/web/.env.local` (fail-closed again after process restart).
5. **File tools + repo-root `FILE_TOOLS_ROOT` can read `.env.local`** [B/config] — latent design hazard, not currently armed in this env. When `FILE_TOOLS_ENABLED=true` and `FILE_TOOLS_ROOT` is the repository root, `read_file` (`risk: low`, no HITL) can read `apps/web/.env.local` and pull live secrets into the model context. `resolveSafePath` prevents escaping the root but not a root that is too wide. *Dev env status:* that configuration was observed during the audit; **operator has since commented out `FILE_TOOLS_ENABLED` and `FILE_TOOLS_ROOT`**. Mitigation if re-enabled: dedicated folder (not the repo root), and/or denylist for `.env*`. Note: global/account skill loading does not use these tools.
6. **Approval-fatigue design**: no counterpart to the paper's auto-mode classifier or sandbox-driven prompt reduction (~84% in Claude Code). Today's volumes are low; the graduated-autonomy roadmap item is the right eventual answer.

**Independence of layers:** RLS, IAM scope, and code gates are genuinely independent (different enforcement planes). HITL and tool-gating share the catalog + env config plane — a single misconfigured catalog entry (wrong risk) silently removes a layer. No config-lint asserts, e.g., "every tool that writes externally is ≥ medium" **[D]**.

**Verdict:** HARDEN (tenant floor P1, external-content trust P1, `FILE_TOOLS_ROOT` narrowing / `.env*` denylist P1 *whenever* file tools are re-enabled, catalog risk lint P2, bash policy note P2). Dev host-tool exposure from the audit window is **mitigated by operator config** (bash/file tools commented out); keep that posture for prod. The overall posture (deny-by-absence + HITL + RLS) is sound and should be KEPT.

### 9.6 Extension architecture

Inventory and differentiation (all [B] unless noted):

| Mechanism | Uniquely enables | Enters runtime at | Context cost | Security boundary | Lifecycle/versioning | Failure isolation |
|---|---|---|---|---|---|---|
| Tool catalog + adapter | New executable capability | `buildLangChainTools` pre-bind | Schema tokens per bound tool | Code review (engineering-owned) | Git; `validate-skill-tool-refs` | Tagged error JSON; audit row |
| Global skill (`SKILL.md`) | New procedure/judgment | Selector candidates + playbook injection | Metadata always; body only when active (≤5k tokens); refs on demand | Git + prebuild validation; frontmatter `allowed_tools` narrows surface | Git-versioned | Bad skill affects only turns that select it |
| `references/` + `read_skill_reference` | Progressive disclosure | Model-invoked read | ≤24KB per read | Same as skill | Git | Read-only |
| `account_skills` | Per-account custom procedure; shadows global by slug | Registry merge (`getSkillRegistryForUser`) | Same as skill | RLS per user; Zod; **no scripts** (rejected) | `status`,`version` cols; full versioning = V2 | Self-account only |
| Skill config (`user_skill_settings.config_json`, `business_brain` slots) | Parametrize global skills (brand-kit pattern) | Context blocks | Small | RLS | DB | Low |
| Case types (`operational_case_types` + flow JSONB) | New multi-day workflow | Case runner binding | Case block per tick | DB + readiness gates (N0–N5) | DB rows; global vs private ownership | Per-case |
| Heartbeat checklists/templates + `heartbeat_signals` prefetchers | Proactive checks; deterministic pre-reads | Cron heartbeat | Checklist + signal block | Read-only allowlist | Code (prefetchers) + DB (checklists) | Per-tick |
| Integrations (OAuth/secrets) | External reach | Adapter execution | None | Encrypted; per-account; `/test` probes | DB | Tool-level |
| **Absent:** MCP, plugins, third-party hooks, model-provider plugins, channel-adapter SDK | — | — | — | — | Deliberately deferred (roadmap: hooks server-side V3+; packs V3+; no marketplace before sandboxing) [A]. **MCP UX mapping (2026-08-07, flexible-workflows finding 27 / Technical Plan §28.14):** when activated, MCP is a *transport* — connect under Integraciones → Conexiones (not a 4th tab); tools materialize into the governed Tools catalog before Studio/runtime compose them. | — |

**Are mechanisms differentiated or accumulated?** Differentiated, with an explicit decision table (skill vs code vs composite vs subagent — `skill-routing.md` "When to use each mechanism"; skill-vs-code guide in `agentic-principles-alignment.md` §5). This is one of the repo's strongest architectural properties. The rule for *this* system: **judgment → skill; repeatable lookup/calculation → tool/wrapper; multi-day orchestration → case type; threshold checks that mustn't depend on model tool-choice → deterministic prefetcher; per-account variation → config before custom body; external service → engineering-owned adapter, never user-supplied code.**

**Verdict:** KEEP. The narrow surface is a feature for a multi-tenant data product. EVOLVE toward internal lifecycle hooks only when ≥2 concrete consumers exist (the roadmap already says this).

### 9.7 Context assembly and prompt lifecycle

Assembly order (verified, `graph.ts` ~L1496–1734): profile system prompt → contact data → temporal context → disambiguation rules → Business Brain block → skill playbook → case block → tenant context → per-tool addendums → channel addendum → turn-specific shortcuts; then in-graph memory prepend. Precedence is positional only — no explicit conflict resolution; addendums accumulate **[B]**.

- Trust boundaries in context: canonical profile fields are marked as authoritative ("not extracted to memory"); tenant context is server-derived (trusted); **tool outputs and external-contact content enter with no untrusted-content framing** (§9.5.2).
- Token budgeting: caps exist per block (memory 1500 chars, skill 5k tokens, refs 24KB) but **no whole-prompt budget** — a pathological combination (long profile prompt + composite skill + case block + tenant + addendums) has no guard except downstream compaction [B]. Risk low at current sizes [D].
- Stale-context risks: registry cache is process-lifetime (`getGlobalSkillRegistry`) — skill edits need restart [B]; routingContext derived per turn (fresh); prompt caching: **none** (OpenRouter pass-through; no cache-aware prompt ordering) — an economic optimization left on the table, though at gpt-4o-mini prices the ROI is small [D].
- Duplicate/contradictory instructions: addendum accumulation has produced observed conflicts historically (calendar-vs-github confusion), *solved by tool-hiding heuristics rather than prompt cleanup* — a scaffolding-over-prompt pattern that works but accretes [B: `calendar-period-intent.ts`, `chat-greeting-intent.ts`, GITHUB_SOCIAL_ADDENDUM].
- Channel differences are real and intentional: cron/heartbeat get no short-term history, different temps, different memory policies.

**Context engineering vs memory:** cleanly distinguished — compaction (in-graph, ephemeral) vs `memories` (cross-session, curated) vs `business_brain` (account facts) vs warehouse (never copied into memory; explicit rule) **[A][B]**. This four-way separation is better-articulated than in most production agents.

**Verdict:** KEEP structure; SIMPLIFY addendum sprawl when convenient; HARDEN with a total-prompt-size assertion + log.

### 9.8 Compaction, summarization, context pressure

Mechanisms (all [B], `compaction_node.ts`): (1) **microcompact** — clear all but last 5 ToolMessage bodies, id-preserving, idempotent, ~zero cost, every pass; (2) **LLM compaction** — trigger at ≥80% of `COMPACTION_WINDOW_TOKENS` (120k default, env-tunable), chars/4 estimator, Haiku 9-section Spanish summary, keeps first System + last Human + last 5 ops messages, `RemoveMessage` the rest, injects `[CONTEXTO COMPACTADO]`; (3) circuit breaker after 3 failures (passthrough with microcompact); (4) upstream prevention: short-term window of 12 messages, BQ row caps, reference reads bounded, selector never sees history.

Compared to the paper's five-shaper pipeline: Gu OS has 2 of 5 (no snip, no cache-aware boundaries, no read-time collapse) — proportionate to its much shorter sessions (web sessions load only 12 prior messages; the long-horizon burden lives in *case state*, not the transcript) [D].

- Preserved: goal, facts, decisions, pending actions, tools+results, state, next step. Discarded: verbatim tool outputs (already microcompacted), old message text. Reconstruction: possible from `agent_messages`/`tool_calls` in DB (compaction touches only in-graph state, not persistence) — an important auditability property [B].
- Failure/drift: summary is model-generated in-band as a SystemMessage → instruction-mutation risk exists but is bounded by the 9-section contract and by turn-scoped threads (compaction state doesn't persist across turns because each turn starts a new thread from DB history) [B]. This per-turn reset is an underappreciated hygiene property: **summary drift cannot compound across turns.**
- Consequences: long-horizon convention retention is delegated to skills/case events (good); repeated work risk is low; token cost of compaction is rare at 12-message windows [D].

**Verdict:** KEEP. The design is right-sized; do not import Claude Code's fuller pipeline without evidence of pressure.

### 9.9 Memory and knowledge management

Distinct memory types, each with its own store (deliberate taxonomy [A][B]):

| Type | Store | Transparency/editability | Provenance | Decay/lifecycle |
|---|---|---|---|---|
| Instructions | profile prompt + skills + addendums | Git + Settings | n/a | Git |
| User preferences/durable facts | `memories` (semantic/procedural/episodic) w/ pgvector | `/memory` UI; archive/delete HITL; audit log (migration 00011) | content_hash, extraction watermark | `retrieval_count` exists; TTL/decay planned (curation plan) |
| Account/business identity | `business_brain` JSONB slots | Settings + reviewer model | server-authored | manual |
| Episodic session | `agent_messages` (12-msg window) | chat UI | turn_id | retained indefinitely [E: no retention policy found] |
| Task/workflow state | `operational_cases.context_jsonb` + events | case UI | append-only events | case lifecycle |
| Organizational knowledge | **planned** Brain Layer (`brain_pages`, compiled truth + timeline, HITL promotion) | — | — | roadmap Blocks 1–4 |
| Semantic index | pgvector on memories only (no code/doc RAG) | — | — | — |

Anti-poisoning measures: conservative extraction prompt ("only what remains true next session"); canonical profile fields excluded from extraction; cron/heartbeat excluded from flush (system-fact contamination — explicitly reasoned [A]); hash dedup; HITL deletes with content preview; extractor hardening against transactional business data (`extractor_hardening_proposal.md` → implemented per curation plan) **[A][B]**. Hallucinated-memory risk remains inherent to LLM extraction; mitigated by visibility + curation skill, not by verification [D].

**Memory is an intentional cognitive subsystem** (two independent processes, injection and extraction, with explicit trigger theory), not a persistence side effect. Tenant separation: `memories.user_id` + RLS — solid. Privacy: no cross-account retrieval paths found [B].

**Verdict:** KEEP; VALIDATE memory precision/recall before Brain Layer investment (the roadmap already treats Brain as gated).

### 9.10 State, persistence, resume, fork, rewind

- **Two-plane state:** product plane (Supabase; durable, RLS, queried by UI) and graph plane (LangGraph checkpoints; per-turn threads `${sessionId}-${ts}`; only role: HITL pause/resume). Clean separation — checkpoints are *not* the conversation of record [B].
- Resume: only the HITL path resumes a thread (via persisted `checkpointThreadId`); everything else reconstructs from DB (last 50 shown, 12 injected). **No fork, no rewind** — appropriate: the product's undo story is business-level (reject approval, pause case), not transcript-level [D].
- Crash recovery: interrupted turn loses in-flight state but leaves audit rows; pending confirmations survive via `structured_payload`; scheduled tasks lease-based (a crash mid-run leaves `status='paused'` lease — reclaimed how? **[E]** stale-lease reclamation not verified — potential stuck-task mode, flagged in §14).
- Concurrency: optimistic version locking on cases; `skip locked`-style claiming; web/cron/case runAgents are independent threads by design (`operational-cases/architecture.md` §5).
- Retention/cleanup: none found for messages, logs, checkpoints **[B/E]** — a compliance gap at scale (§9.16).
- Auditability vs query power: chose *both* — append-only events for audit and mutable case rows for query. Reconstruction cost is low (events are per-case). This resolves the paper's "append-only vs query" tension elegantly at small scale [B].

**Verdict:** KEEP; HARDEN stale-lease reclamation + retention policy.

### 9.11 Multi-agent architecture, delegation, routing

There is none — no subagents, no fan-out, no worker roles. What exists instead:

- **Channel routing** (which runtime configuration handles an event) — deterministic, DB-bound (Telegram bindings table for case conversations, with confidence-based clarification — `conversational-case-routing`).
- **Skill routing** (which procedure owns a turn) — the pre-graph selector; single dominant skill; composites explicit.
- **Durable work distribution** — the case queue (cron + locks): OpenClaw/Hermes-style "durable worker coordination" without separate agent identities.

The decision is documented with activation criteria and anti-patterns ("'quiero más calidad' → better skills, not more agents") **[A]**. Given a weak main model, subagent summaries would compound quality risk; given the tenant model, context isolation is already achieved per-invocation. The paper's warning — don't equate subagents with robustness — is effectively pre-internalized here.

**Verdict:** KEEP (Not applicable, by sound decision). Revisit per their own criteria (sustained parallelism/isolation/model-split need).

### 9.12 Verification, evaluation, observability

**Observability (can operators see?):** good for a system this size — `tool_calls` with `turn_id` and `executor_kind`, structured `AgentTurnEvent`s in UI ("Herramientas del turno", IA vs Determinístico badges), three local log files (turn/compaction/memory), Sentry present, friendly error surfacing. **Partially closed (Slice 0.4 / 0.4.1–0.4.2):** append-only `ai_usage_events` ledger with per-call tokens/cost (OpenRouter reported + versioned catalog estimate), admin dashboard at `/settings/ai-usage` (`is_ungga_admin`; sidebar **Configuración → Uso de IA**). Flag: `AI_USAGE_METERING_ENABLED`. Internal observability only — not billing. Remaining gaps: logs are process-local files (lost on serverless); no distributed tracing platform; SSE events not persisted (documented pending) **[B]**.

**Evaluation (was it correct?):** the honest answer — *deterministic contracts yes, semantic evaluation no*:
- Strong: ~160 selftests over pure logic; N1–N5 readiness lab validating "reproducible business contracts, not just no-exception" [A: testing-framework §1]; publication preflight/reconcile checks against remote state (real environment ground-truth verification — the paper's "verify results" phase, implemented deterministically for the highest-stakes action) [B].
- Absent: no LLM-output evaluators, no trajectory evals, no regression datasets for the selector/extractor (docs *plan* eval fixtures), no generator-evaluator separation, no CI to run even the deterministic tests.
- **Where a fluent response can mask non-completion:** interactive chat (skill=none answering business questions from stale history — self-documented), cron task summaries, heartbeat digests, case ticks that "advance" narrative without state change (partially mitigated: post-agent invariants exist for property-optioning — `property-optioning-post-agent-invariants.selftest.ts` suggests deterministic post-checks in the runner [B], Medium confidence on coverage breadth).

**Where evaluation belongs in this system:** deterministic post-conditions in the case runner (extend existing invariants pattern) + CI for selftests + a thin offline eval set for the skill selector. *Not* in-loop LLM judges (cost/model constraints make them the wrong first investment) [D].

**Verdict:** HARDEN (P1–P2). This is the largest genuine gap relative to the product's own "traceability" promise — traceability exists, *truth-checking* doesn't.

### 9.13 Reliability, recovery, resilience

Verified mechanisms [B]: BQ fetch retry (429/5xx ×3, backoff); per-turn BQ error cap (2) with instructive refusal; scheduled-task retry (≤3, 2-min gap) + persistent-error fast-pause + Telegram alerting; compaction circuit breaker; iteration cap + forced summary; checkpointer connect timeout (5s) with **silent fallback to MemorySaver**; Telegram send retries + truncation; optimistic-lock `skipped` semantics; empty-response fallbacks; DNS `ipv4first` workaround with a diagnostic script (ops empathy).

Assessment against "silent, observable, safe, idempotent": mostly observable (pauses notify; errors persist) and idempotent (ledgers, dedup keys). Two *silent* degradations: MemorySaver fallback (HITL resume quietly becomes restart-fragile — logs a line, but nothing user-facing) and skill-registry root misresolution (logged, agent continues skill-less — README troubleshooting acknowledges it). No provider/model fallback chain (single OpenRouter dependency; OpenRouter itself provides some provider redundancy behind one slug [D]).

**Verdict:** KEEP mechanisms; HARDEN the two silent degradations into loud ones (startup assertion or UI banner).

### 9.14 Model and provider architecture

Single gateway (OpenRouter) — **seven role-scoped model slots**, all env-overridable, plus embeddings via raw fetch. Four factories live in `model.ts` (main/compaction/selector/reviewer); three more roles are defined at their point of use: image vision + listing copy (`tools/realestate-adapters.ts` L288–297), and the operational-conversation classifier (`apps/web/src/lib/operational-cases/operational-conversation-classifier.ts` L135); heartbeat overrides model + max-tokens per channel (`graph.ts` L1132–1133). No fallback model, no structured-output API usage (JSON-by-prompt, hand-parsed), no capability negotiation.

The actually configured environment (`apps/web/.env.local`, dev machine — runtime config, not committed code; production values remain [E]) demonstrates **deliberate per-role model tiering**:

| Role | Code default | Configured (dev) | Rationale (per env-file comments) |
|---|---|---|---|
| Main agent (web/telegram/cron/case_runner) | `openai/gpt-5.4-mini` | `openai/gpt-5.4-mini` | primary reasoning, still mini-tier |
| Heartbeat | inherits main | `openai/gpt-5.4-nano` + 1024-token cap | runs every X min per user → cheapest tier |
| Compaction / memory flush | `anthropic/claude-haiku-4.5` | `anthropic/claude-haiku-4.5` (or env) | mechanical/extractive task |
| Skill selector | `anthropic/claude-haiku-4.5` | `anthropic/claude-haiku-4.5` (or env) | tiny prompt, JSON out, temp 0 |
| Business Brain reviewer | `anthropic/claude-haiku-4.5` | `anthropic/claude-haiku-4.5` (or env) | short rewriting task |
| Operational conversation classifier (+ HITL unclear) | `openai/gpt-5.4-mini` | `openai/gpt-5.4-mini` | structured JSON; deterministic-rules / fail-open clarify |
| Image vision / listing copy | `openai/gpt-4.1-mini` | `openai/gpt-4.1-mini` (explicit) | vision-capable slug required |

Global output cap: default 2048, configured 4096 (`OPENROUTER_MAX_TOKENS`). The tiering is real and role-matched — heavier-but-still-cheap model where judgment lives, nano where frequency dominates, haiku-class for mechanical text tasks, vision-capable only where needed. **Post-analysis fix:** code defaults for Haiku-class roles were refreshed to `anthropic/claude-haiku-4.5` in `model.ts`, and vision/listing/classifier IDs were centralized there so the inventory is no longer split across three files without a single source of truth **[B]**.

- Stable across models: tool gating, HITL, RLS, compaction mechanics, case engine.
- Model-sensitive: skill selection quality, SQL generation quality, addendum compliance, JSON parse rates, the entire intent-heuristic layer's *necessity*. Note: the intent-heuristic layer was calibrated against the mini-tier; a main-model swap via one env var is trivial at the API level but untested at the behavior level.
- Vendor risk: low switching cost at the API level (one baseURL, per-role env slugs — already exercised in practice), medium at the behavior level (heuristics re-tuning). The Gemini facade design (`model-providers.md`) is documented but unimplemented — correctly deferred [A].

**Verdict:** KEEP the per-role env-slot design; stale Haiku defaults were **fixed** in `model.ts` (now `claude-haiku-4.5`) and lateral role IDs centralized. VALIDATE FIRST any main-model upgrade against the heuristic layer (an eval set for the intent filters + selector is the prerequisite the docs already imply).

### 9.15 Cost, token economics, latency, scale

Economics are a stated design driver with real mechanisms (cheap models, output caps, metadata-only selector, microcompact, embedding reuse, 12-message windows, heartbeat model overrides, cron temp 0.1). **Measurement (Slice 0.4+):** one append-only row per model call in `ai_usage_events` with tenant attribution, provider-reported cost when available, catalog estimate for comparison/fallback, and admin rollups by day/model/function/channel/execution/case — see [`docs/tools-design/model-providers.md`](../tools-design/model-providers.md) and `/settings/ai-usage`. Still absent: budget alarms and broker-facing usage UI; the 402-fast-pause remains the only automated cost circuit breaker [B]. Call-count anatomy per interactive turn: 1 selector + 1 embedding + N agent iterations (+ compaction rarely + flush occasionally) — a fixed ~2-call overhead per turn that is the price of auditable routing [B]. Latency: selector + embedding are serial pre-graph additions (~hundreds of ms each [D]); acceptable for chat, immaterial for cron.

Scale posture: explicitly small-scale with documented degradation signals and escalation levers (batch caps, concurrency env caps, stagger guidance, "when to consider Temporal") — the *plan* for scale substitutes for scale engineering, which is the right call pre-product-market-fit [A].

**Verdict:** KEEP measurement mechanisms (ledger + dashboard); optional P2: budget alarms. Otherwise KEEP.

### 9.16 Governance, auditability, compliance

Internal auditability: strong (events, tool_calls, runs tables, turn correlation, HITL trails with exact confirmation wording persisted). External/compliance readiness: thin — no retention/deletion policy (GDPR-style erasure would require manual sweeps across messages/memories/events/storage [E: no deletion machinery found beyond memory UI]); no policy versioning (catalog risk changes are just commits); no model/prompt version stamping on turns (which model produced a given historical answer is unrecoverable [B: not persisted]); consent flows exist only implicitly (OAuth). For the current market (Mexican real-estate SMBs) this is proportionate [D]; for enterprise/regulated buyers it becomes a P1 gap.

**Verdict:** EVOLVE (trigger: first enterprise customer or first data-deletion request). Cheap now: stamp `model_id` + skill version on `agent_messages`/`tool_calls`.

### 9.17 Maintainability, testability, developer experience

Strengths: clear package boundaries with one-way dependencies (`agent → db → types`); typed contracts; exceptional doc discipline (decision rationale, regression postmortems in docs like `hitl.md` "Implementación actual"); selftest style is fast and dependency-free; skill validation in prebuild.

Strains [B]:
- `realestate-adapters.ts` (9,594 lines) and Telegram webhook (~3,700) are accumulation hotspots; `graph.ts` (2,770) mixes context assembly, HITL, execution, and logging.
- Two migration-number collisions (`00044`×2, `00045`×2) — works in Supabase's applied-by-name model but is a footgun.
- Heuristic sprawl: seven intent modules whose interactions are individually tested but combinatorially unreviewed.
- No CI: `npm run lint`/`type-check`/selftests are convention-only.
- "Architecture by accumulation" verdict: mostly **no** — mechanisms are differentiated on purpose; the accumulation is *within files*, not across mechanisms.

Onboarding: docs make conceptual onboarding easy; debugging is decent (log files + UI events); the hardest debugging surface is cross-channel case flows (state spread across cases/events/bindings/notifications tables) [D].

**Verdict:** SIMPLIFY (split the two mega-files along already-visible domain seams; P3), HARDEN (CI, P2).

### 9.18 Long-term human capability and codebase coherence

For the *operator* (the real-estate user): unusually good — skills are readable recipes; the readiness lab forces the human to understand each step before activation; approvals show exact content; memory is inspectable; the glossary teaches the mental model. The system is structured to keep the human the accountable decision-maker, which directly counters the paper's "paradox of supervision" *for business actions* [A][B].

For the *developer*: docs preserve rationale exceptionally well (decision records de facto exist); but there are no comprehension checks, no generated docs from code, and the bus factor is ~1 [B: git history]. Convention drift risk is real in the two mega-files.

Higher agent productivity → coherence risks specific to this product: skills multiplying with overlapping triggers (their own MECE/near-miss eval concern [A]); account_skills shadowing globals in ways support can't see (partially mitigated: UI shows overrides); heuristics accreting per bug rather than per design.

**Verdict:** KEEP the operator-facing posture (it is the product's differentiator); document a skill-MECE lint as skills pass ~30 (their own threshold).

---

## 10. Comparative Positioning

| Paper dimension | Claude-Code-like | OpenClaw-like | Hermes-like | **Gu OS** |
|---|---|---|---|---|
| 1. Scope & deployment | Ephemeral repo-bound CLI | Persistent multi-channel gateway daemon | Single process, multi-surface, entry-point roles | **Persistent multi-tenant SaaS**: web app is gateway *and* control plane; channels share one runtime; adds a workflow engine none of the three have |
| 2. Trust & security | Per-action deny-first, 7 modes, sandbox, classifier | Perimeter identity (pairing/allowlists), opt-in sandbox | Per-action approvals rendered on all surfaces + HARDLINE floor | **Hermes-closest**: per-action risk HITL rendered on web+Telegram; plus SaaS primitives none have (RLS, encrypted per-tenant secrets); minus any sandbox/classifier/hardline-pattern floor |
| 3. Runtime & orchestration | `queryLoop()` center, streaming executor, recovery ladder | Embedded SDK runner behind gateway RPC | Sync while-loop, iteration budget + summary call | **Hermes-closest** (bounded loop + forced summary), with LangGraph checkpointing for HITL that neither Hermes nor OpenClaw has |
| 4. Extension architecture | 4 mechanisms at graduated context cost (hooks/skills/plugins/MCP) | Manifest plugins, 12 capability types, registry/hub | 3 CC-level + 2 backend-swap surfaces | **Claude-Code-adjacent on skills** (SKILL.md, progressive disclosure — explicitly Anthropic-convention [A]); everything else deliberately closed; DB-config instead of plugins |
| 5. Memory & context | CLAUDE.md hierarchy, 5-shaper compaction, file scan | Bootstrap files, hybrid search, "dreaming" | Single summarizer + injection scanning | **Hybrid**: graduated 2-stage compaction (CC-like), pgvector curated memory (OpenClaw-like structured memory), plus a taxonomy split (personal/account/warehouse/brain) more explicit than any of the three |
| 6. Multi-agent & routing | Isolated subagents, summary-only return, worktrees | Channel-isolated agents + bounded sub-agents | Thread children + SQLite kanban queue | **None-by-decision**; durable coordination via the case queue (kanban-equivalent), channel routing via bindings — the Hermes kanban role played by Postgres cases |

**Placement:** Gu OS is **OTHER/HYBRID — a "governed vertical operations agent"**: Hermes-like process/trust shape, Claude-Code-like skills-and-compaction internals, OpenClaw-like persistent multi-channel product ambitions, plus two components outside all three archetypes: the **multi-tenant SaaS data plane** (RLS/BigQuery/tenant context) and the **operational-case workflow engine**. The components compose as layers exactly as the paper predicts ("the design space is layered, not flat"): the case engine sits *above* the turn loop; the channel edge sits *around* it; the tenancy plane sits *below* it. Nothing about the position is accidental — the repo contains explicit comparative rationale for the two places it diverges most (skill routing location; harness thickness).

---

## 11. Conditional Advantages and Disadvantages

| Architectural choice | Advantageous when | Benefit | Disadvantageous when | Failure mode / cost | Relevance |
|---|---|---|---|---|---|
| Pre-graph skill selector (separate small model) | Skills gate *data access* (tenant context must precede tool bind); audits need isolated routing decisions | Deterministic, cheap, logged routing; tools narrowed before bind | Conversations are fluid/multi-domain; skills > ~30–50 | Myopic `none` on follow-ups (observed; mitigated by routingContext); extra call latency | High — their own doc names the reconsideration triggers |
| Cheap main model + heavy scaffolding | Tasks are procedural, Spanish, domain-bounded; cost predictability is a sales requirement | ~10× lower per-turn cost [D]; failures bounded by gates | Tasks need multi-step reasoning (complex SQL, negotiation drafting) | Wrong-but-fluent outputs; heuristic layer ossifies around one model's quirks | High |
| HITL on all medium/high tools | Actions are externally visible/legally consequential; volume low | Trust as product; auditable consent | Action volume grows; approvals habituate (paper: 93% approve) | Rubber-stamping; the safety layer degrades into latency | High — the paper's central authority×safety tension, currently latent |
| Cron `autoApproveTools` | Scheduled prompts are narrow and self-contained | Scheduled tasks actually work unattended | Prompts are broad or model drifts; bash enabled | One consent → arbitrary later actions | High — mitigated per-task by `toolApprovalPolicy`; needs default narrowing |
| Cases on Postgres+cron (no Temporal) | ≤ hundreds of due cases/tick; minutes-scale latency OK | Zero extra infra; SQL-auditable queue | Thousands concurrent/minute; sub-minute inter-step latency | Queue lag, timeout-truncated ticks | Medium — thresholds pre-documented |
| Single runtime for 5 channels | One team, shared governance | One audit trail, one bug surface | Channel SLAs diverge | Noisy-neighbor, deployment coupling | Medium |
| Append-only events + mutable case row | Ops need audit *and* fast queries | Both, cheaply | Event volume explodes | Table bloat (no archival) | Low today |
| Per-turn checkpoint threads (no long threads) | Turns are short; DB is source of truth | No cross-turn drift; simple resume semantics | Very long single-turn tasks needed | Can't resume mid-task except HITL | Low — matches product |
| No sandbox for bash/files | Self-hosted, admin-controlled boxes; tools off by default | Simplicity | Multi-tenant prod with tools enabled | Host compromise via injected/confused commands | Medium — posture must stay "off in prod" until sandboxed |
| Filesystem skill registry (Git-versioned) | Eng-owned catalog, small team | Review, diff, rollback for free | Non-eng authors need same-day skills; multi-instance cache coherence | Restart-to-update; drift across instances | Low-Medium (account_skills covers the user path) |

---

## 12. Product and Requirements Fit Matrix

Scale: 0 unsupported · 1 weak · 2 partial · 3 strong · 4 intentionally optimized. (No aggregate score, per instructions.)

| Requirement | Source | Priority | Mechanisms | Evidence | Fit | Conf. | Gaps / risks | Recommended action |
|---|---|---|---|---|---|---|---|---|
| Governed execution of sensitive actions | brief.md §1; glossary | P0 | Risk catalog + interrupt + business HITL + publication gates | [B] graph.ts, business-decisions/* | **4** | High | Approval fatigue unmeasured | Track approval rates (validate) |
| Primary journey: business Q&A over warehouse | roadmap V1-B | P0 | company-data skill + tenant context + BQ adapter + fewshots refs | [B] | **3** | High | skill=none → unaudited answers; tenant filter soft | Harden tenant floor; selector eval set |
| Multi-day operational procedures | ops-cases docs | P0 | Case engine + composite skills + reminders + webhooks + readiness lab | [B] | **4** | High | Runner complexity concentrated in one 1.2k-line route | Keep; refactor opportunistically |
| Traceability / auditability | brief.md | P0 | tool_calls, events (append-only), turn_id, runs tables | [B] | **4** | High | No model/prompt version stamping | Cheap harden |
| Predictable costs | brief.md | P1 | Cheap models, caps, 402 fast-pause | [B] | **2** | High | No measurement/attribution/budgets | Persist token usage per turn |
| Tenant isolation | roadmap invariant | P0 | RLS (hard), BQ scoping (soft), encrypted secrets | [B] | **2–3** | High | Unfiltered SELECT path | **P1 harden** |
| Reliability of unattended runs | scheduled-tasks docs | P1 | Retry/auto-pause, locks, idempotency, notifications | [B] | **3** | High | Stale-lease reclamation unverified; no completion verification | Verify lease recovery; add post-conditions |
| Response quality | implied | P1 | Skills, fewshots, addendums, sanitize-history | [B] | **2** | Medium | No evals; weak model ceiling | Selector+SQL eval sets first |
| Latency (interactive) | implied | P2 | Sequential pipeline; SSE progress events | [B] | **2** | Medium | Selector+embedding serial overhead; unmeasured | Measure p50/p95 before optimizing |
| Privacy & secret handling | arch docs | P0 | AES-256-GCM, service-role confinement, RLS | [B] | **3** | High | No retention/deletion machinery | Evolve on trigger |
| Human oversight ergonomics | product docs | P1 | Pending inbox, Telegram buttons, exact-wording persistence, panel | [B] | **4** | High | — | Keep |
| Scale / concurrency | docs (small) | P2 | Batch caps, concurrency envs, stagger runbook, escalation doc | [A][B] | **3** (for stated scale) | High | Single-process state | Evolve at multi-instance |
| Multi-user behavior | roadmap | P1 | Per-account everything; orgs deferred to V3 | [B] | **3** | High | No org sharing yet (planned) | Keep roadmap |
| Integration capacity | brief | P1 | OAuth flows, account secrets + /test, adapters, POC CLI backends | [B] | **3** | High | Playwright backends are fragile [D] | Monitor failure rates |
| Maintainability | implied (team of ~1) | P1 | Monorepo boundaries, docs, selftests | [B] | **2–3** | High | Mega-files; no CI | CI (P2); split files (P3) |
| Observability | brief ("trazas") | P1 | tool_calls, events UI, logs, Sentry | [B] | **3** | High | Local-file logs; no cost/latency metrics | Harden |
| Evaluation | implied by quality claims | P1 | Selftests, N0–N5, post-agent invariants | [B] | **2** | High | No semantic/LLM evals, no CI | Highest-leverage gap |
| Long-term coherence | roadmap | P2 | Docs discipline, skill contract, MECE guidance | [A][B] | **3** | Medium | Skill overlap as catalog grows | MECE lint at ~30 skills |

---

## 13. Value Tensions and Systemic Trade-offs

Fundamental (not implementation mistakes):

1. **Human authority × automated usefulness.** The product sells both "asks your OK" and "advances work alone." Resolution: channel-differentiated trust (interactive HITL, cron pre-consent, heartbeat read-only) — a *structural* answer better than a global autonomy dial. The unresolved edge is cron's consent breadth (one approval, many actions). As usage grows this becomes the paper's approval-fatigue curve; the roadmap's "autonomy earned with evidence" is the correct trajectory but has no mechanism yet (no per-operation trust accounting).
2. **Safety depth × latency/cost.** Gu OS pays routing+embedding overhead every turn for auditability. Cheap at haiku prices; the tension will bind only if they move the selector to bigger models — their own escalation doc correctly puts "better model" last.
3. **Extensibility × attack surface.** Resolved by fiat: no third-party surface until sandboxing exists. Cost: power-user ceiling; benefit: the pre-trust-initialization CVE class from the paper is structurally absent. Right trade for a data product now.
4. **Context compression × information loss.** Bounded by design: compression is turn-scoped, DB is complete. Losses can affect *within-turn* quality only. The real information-loss risk lives in memory extraction (what Haiku doesn't extract is gone from memory, though never from transcripts).
5. **Local skill autonomy × global coherence.** One-dominant-skill routing avoids instruction conflicts but under-serves genuinely multi-domain turns; the explicit-composites rule is the coherent middle. Watch selector confusion as the catalog grows (their §2 thresholds).
6. **Parallelism × conflicting writes.** Solved conservatively: sequential tools, optimistic case locks, concurrency caps. Throughput sacrificed for consistency — correct while volume is low.
7. **Persistent memory × poisoning/privacy.** Handled with conservative extraction + curation + exclusion of automated channels. The remaining fundamental piece: extraction happens *without user confirmation per fact* — a deliberate friction trade; the memory UI is the compensating control.
8. **Auditability × operational efficiency.** Append-only + mutable projections; cheap now, needs archival at scale. Fundamental only in the sense that someone must eventually pay for event volume.
9. **Model flexibility × deterministic guarantees.** The heuristics/addendum layer is the tax paid for using a weak model deterministically. Upgrading models converts this tax into dead weight — the system's most distinctive future refactoring pressure.

---

## 14. Gaps, Risks, and Silent Failure Modes

| # | Issue | Type | Evidence | Trigger | Prob. | Impact | Detectability | Current mitigation | Recommendation | Priority |
|---|---|---|---|---|---|---|---|---|---|---|
| R1 | Cross-tenant warehouse read via unfiltered SQL | Security weakness | [B] `prepareBigQueryRunArgs` (no tenant-predicate requirement) | Model omits org filter (confusion or injection) | Medium | High (data promise broken) | Low (result looks normal) | Skill instructions; literal-inline rejection; read-only scope | Deterministic tenant predicate requirement for non-admin | **P1** |
| R2 | Indirect prompt injection via external contacts/documents | Security weakness | [B] Telegram → case context → prompts; no delimiting/scanning | Malicious/joking owner text | Medium | Medium-High | Low | HITL on high-risk tools only | Provenance-tagged untrusted blocks; injection heuristics; keep HITL floor | **P1** |
| R3 | Unverified completion on unattended channels (silent failure) | Evaluation gap | [B][D] forced summary; no post-conditions on most flows | Weak model + vague scheduled prompt | High (eventually) | Medium (business decisions on wrong info) | Low | Prefetchers; BQ retry caps; some post-agent invariants | Post-condition framework in runners; verified-completion metric | **P1** |
| R4 | Cron auto-approve breadth incl. bash | Config hazard | [B] graph.ts L2216; bashExec (no policy) | `BASH_TOOL_ENABLED=true` in prod + scheduled prompt drift | Low-Med | High | Medium (audit rows exist) | Env default off; HITL at scheduling; per-task policy | Default-deny high-risk tools in cron unless policy grants | **P1** |
| R5 | Silent MemorySaver fallback degrades HITL | Operational risk | [B] checkpointer.ts | `DATABASE_URL` unset/unreachable | Medium | Medium | Low (log line only) | Docs | Loud startup banner + UI indicator | P2 |
| R6 | No CI — selftests unenforced | Process gap | [B] no workflows | Any regression | High | Medium | Medium | Convention | Wire selftests+type-check to CI | **P2** |
| R7 | Stale scheduled-task lease after crash mid-run | Reliability (suspected) | [E] `markTaskRunning` sets paused; reclamation not found | Process crash during run | Low | Medium (task frozen) | Medium (UI shows "Ejecutándose") | Manual resume | Verify; add lease TTL reclamation | P2 |
| R8 | Single-process state (SSE, logs, caches, registry) | Scaling risk | [B]; docs acknowledge SSE persistence pending | Multi-instance deploy | Certain at that point | Medium | High | Documented | Redis/DB-backed events + log shipping when scaling | P2→P1 on scale |
| R9 | Budget alarms / broker usage UI (measurement done) | Requirement gap (partial) | [B] Slice 0.4+ `ai_usage_events`, `/settings/ai-usage` | Growth without spend guardrails | High | Medium | High (admin dashboard) | Ledger + rollups; output caps | Budget thresholds; optional broker-facing view | P2 |
| R10 | Catalog risk misclassification silently removes HITL | Config hazard | [D] single-plane config | Human error on new tool | Low | High | Low | Review | Risk-lint (writes⇒≥medium) + test | P2 |
| R11 | Mega-file accumulation (realestate 9.6k, telegram 3.7k, graph 2.8k) | Tech debt | [B] | Continued growth | High | Low-Med (velocity) | High | Selftests | Split by domain seams | P3 |
| R12 | No retention/deletion machinery | Compliance (future) | [B/E] | Enterprise/regulatory demand | Medium | Medium | — | — | Design on trigger; stamp versions now | P3 |
| R13 | Selector myopia on follow-ups → unaudited answers | Quality (known) | [A][B] skill-routing.md | Short fragments | Medium | Medium | Medium (logs) | routingContext, follow_up_month | Selector eval set; persist routingContext | P2 |
| R14 | Migration number collisions (00044/00045) | Defect (latent) | [B] | Tooling that orders by number | Low | Low | High | Name-based apply | Renumber next migration window | P3 |

**Canonical silent-failure modes:** (a) fluent unattended summaries without completed effects (R3); (b) business answers from conversation history instead of the warehouse (R13 — self-documented); (c) cross-tenant aggregates that look plausible (R1); (d) HITL that appears armed but is on MemorySaver (R5); (e) heartbeat digests asserting checks that the model never actually ran — *specifically countered* by deterministic prefetchers for calendar signals, the system's own best answer to this class [B].

---

## 15. Recommendations

### KEEP (validated as appropriate)
- **K1.** Single-loop, single-agent runtime with channel-differentiated trust; no subagents. (Requirement: governance + small team. Evidence: §9.11.)
- **K2.** Pre-graph skill selection with forced bindings for cases/tasks — retain until their own documented thresholds trip (skills >~30, follow-up brittleness persists).
- **K3.** Operational-case engine on Postgres+cron with optimistic locking and append-only events.
- **K4.** HITL-first posture, risk catalog as single source of truth, exact-wording persistence.
- **K5.** Two-stage compaction sized to short windows; per-turn thread hygiene.
- **K6.** Memory taxonomy (personal/account/warehouse separation) and conservative extraction with curation UI.
- **K7.** Closed extension surface (no third-party plugins/hooks/MCP) until sandboxing exists. When MCP lands: Conexiones + Tools catalog materialization — never a parallel ungoverned tool path (finding 27 / §28.14).

### HARDEN
- **H1 (P1).** Deterministic tenant floor for BigQuery: when tenant context is active and user is non-admin, reject SQL lacking the parameterized org predicate (extend `prepareBigQueryRunArgs`; ~small change, no tool-surface impact). *Validation:* selftest + red-team prompt set. *Trade-off:* occasional false rejections on legitimately tenant-free queries (rare by skill design).
- **H2 (P1).** Untrusted-content framing: wrap external-contact text/documents in provenance-tagged blocks with an instruction firewall; add cheap injection heuristics (pattern scan à la Hermes) at the Telegram/webhook ingestion point. *Trade-off:* prompt tokens, occasional false positives.
- **H3 (P1).** Post-condition verification in unattended runners: generalize the existing `property-optioning-post-agent-invariants` pattern — each case type declares machine-checkable step post-conditions; scheduled tasks get a lightweight "did any expected effect occur" check; failures mark the run `degraded`, not successful. *This closes the fluent-failure gap without LLM judges.*
- **H4 (P1).** Narrow cron defaults: high-risk tools require explicit `toolApprovalPolicy` grants per task; `bash` in cron default-deny.
- **H5 (P2).** CI: run type-check + selftests + validate-skills on push. Zero new test code needed.
- **H6 (P2).** Loud degradations: MemorySaver fallback and skill-registry misresolution surface in UI/startup, not just logs.
- **H7 (P2).** Cost instrumentation: persist OpenRouter usage per call to `tool_calls`/`agent_messages` metadata; per-tenant daily rollup.
- **H8 (P2).** Catalog risk lint: assert externally-mutating tools are ≥ medium; test the assertion.
- **H9 (P2).** Verify + fix stale-lease reclamation for scheduled tasks (R7).

### SIMPLIFY
- **S1 (P3).** Split `realestate-adapters.ts` and the Telegram webhook along existing domain seams (EasyBroker / Ungga / valuation; callbacks / media / routing). Pure mechanics; selftests protect the move.
- **S2 (P3).** Consolidate intent heuristics behind one "turn-availability policy" module with a table-driven contract, so the seven modules stop interacting implicitly.

### EVOLVE (condition-triggered; do not do now)
- **E1.** Worker/queue tier (Temporal-class) when case queue lag or cron duration breaches the documented signals (`future-considerations.md` §3).
- **E2.** Multi-instance state (DB/Redis-backed SSE, shipped logs, shared caches) when deploying >1 instance.
- **E3.** Graduated per-operation autonomy (reduce HITL for operations with N clean approvals) when approval volume data shows fatigue — this is the paper's trust-trajectory idea, adapted; requires H7's instrumentation first.
- **E4.** Embeddings+top-K selector pre-filter at ~30 skills (their own plan).
- **E5.** Governance stamps (model/prompt/skill versions on turns; retention policy) at first enterprise/compliance demand.
- **E6.** Model upgrade for the main agent when selector/SQL eval sets exist to measure the heuristic layer's continued necessity (V1 of the eval set is the gate, not the model swap).

### REDESIGN
- None warranted. No mechanism materially conflicts with a stated requirement; the two P1 security items are hardening within the existing design.

### VALIDATE FIRST
- **V1.** Verified-completion rate on cron/heartbeat/case channels (before building more evaluator machinery).
- **V2.** Skill-selection accuracy on a labeled set of ~200 real turns (before selector architecture changes).
- **V3.** Approval-rate telemetry (before any autonomy graduation).
- **V4.** Interactive latency p50/p95 decomposition (before any parallelization work).

---

## 16. Empirical Validation Roadmap

| Hypothesis | Metric | Instrumentation | Test/experiment | Baseline | Success threshold | Cost control | Failure criterion | Rollout |
|---|---|---|---|---|---|---|---|---|
| Unattended runs sometimes report success without effects (R3) | Verified-completion rate = runs with satisfied post-conditions / runs reporting success | Post-condition hooks (H3) + run status field | Replay 100 historical `scheduled_task_runs`/case ticks against declared post-conditions | Unknown | ≥95% verified; else prioritize H3 hardening | Offline, no LLM calls | <80% → treat as incident class | Shadow-mode first (mark, don't block) |
| Selector routes correctly incl. follow-ups (R13) | Selection accuracy; `none`-when-should-route rate | Log-derived labeled set from `turn_summary.log` + human labels | Offline eval harness (haiku, temp 0 — reproducible) | Current logs | ≥95% on domain turns; ≤2% false-none | ~200 haiku calls | <90% → implement E4 early | n/a (offline) |
| Tenant floor blocks unfiltered SQL without hurting UX (H1) | Blocked-query rate; user-visible failure rate | Validation-error counters by reason | Red-team prompt suite (20 adversarial + 50 benign) in lab | 0 blocks today | 100% adversarial blocked; ≤2% benign friction | Lab only | Benign friction >5% → refine predicate detection | Feature-flag, admin-exempt |
| External-content injection is deflectable (H2) | Injection-success rate on seeded attacks | Provenance tags + attack corpus | 30 seeded owner-messages with embedded instructions through the Telegram lab (N5 e2e machinery already exists) | Unknown | 0 tool-affecting successes | Lab | Any high-risk tool influenced → block release | Staged |
| Approval fatigue trajectory (E3 gate) | Approval rate over time per user; time-to-approve | Add decision+latency to `tool_calls` | Longitudinal observation, 60 days | Paper reference: 93% CC approve-rate | If >90% sustained → design graduation | Zero marginal cost | — | Passive |
| Cost is predictable and attributable (H7) | Tokens/cost per turn, per channel, per tenant | OpenRouter usage capture | Dashboard + weekly rollup | None | Variance understood; top-10 cost turns explainable | Metadata writes only | — | Immediate |
| Memory extraction is precise | Precision/recall of extracted facts vs human judgment | Sample 100 memories + source transcripts | Human review sheet | Unknown | ≥90% precision (recall secondary) | 1–2h human time | <75% precision → tighten extractor before Brain Layer | Offline |
| Latency budget is where we think (V4) | p50/p95 per stage (selector, embedding, agent, tools) | Stage timers in `runAgent` → turn log | 2-week capture | Unknown | Selector+embedding <15% of p50 | Log writes | >30% → consider parallelizing pre-graph stages | Immediate |

Note: rows 1–4 are *evaluators*; rows 5–8 are *observability*. Both are needed; only 1–4 answer "was it correct."

---

## 17. Open Questions (unanswerable from available evidence)

1. **What is actually deployed?** No CI/deploy configs exist; docs describe options (GCP, pg_cron, ngrok-dev). Resolution: deployment manifest or operator interview. Affects: R5, R8, bash exposure.
2. **Which env flags are set in production** (`BASH_TOOL_ENABLED`, `FILE_TOOLS_ENABLED`, `DATABASE_URL`, model overrides)? *Dev environment (updated):* model roles overridden (§9.14), `DATABASE_URL` set; bash and file tools **commented out / fail-closed** after operator mitigation (they were briefly enabled with repo-root `FILE_TOOLS_ROOT` during the audit — §9.5). Still open for production. Resolution: production environment audit. Affects: real risk level of R4/R5.
3. **Real usage distribution across channels and per-user volumes.** Resolution: the H7 instrumentation. Affects: fatigue analysis, scale planning, cost.
4. **How often does the selector mis-route in production** (beyond the documented BigQuery-testing anecdotes)? Resolution: V2 eval set. Affects: E4 timing.
5. **Does stale-lease reclamation exist somewhere unexamined** (e.g., a manual runbook or a query not found)? Resolution: targeted code/ops review. Affects: R7.
6. **How reliable are the Playwright-based backends (EasyBroker web, Ungga CLI) in production?** Resolution: failure-rate telemetry. Affects: publication-flow reliability posture.
7. **Is the 80%/120k compaction path ever actually triggered** in real sessions (12-message windows suggest rarely)? Resolution: compaction-log analysis over production time. Affects: whether compaction complexity is currently dead weight or safety net.
8. **Multi-tenant growth model:** will organizations (V3) share cases/skills across users? The current per-user tenancy shapes several designs (memory, secrets, RLS); org-sharing will re-open them. Resolution: product decision, not code.

---

## 18. Evidence Appendix (ledger of principal claims)

| Claim | Class | Conf. | Doc ref | Code ref | Notes |
|---|---|---|---|---|---|
| Product = governed real-estate operations assistant | A | High | `docs/brief.md` §1; `docs/manuals/gu-os-glossary-commercial.md`; `gu-os-business-architecture-view.md` | — | Consistent across corpus |
| Control/traceability/cost prioritized over autonomy | A | High | `docs/brief.md` §1 (verbatim) | — | Anchor requirement |
| Loop = memory_injection→compaction→agent⇄tools; cap 10 | B | High | `docs/architecture.md` §LangGraph | `packages/agent/src/graph.ts` L468, L2582–2598; `state.ts` L63–66 | plan.md says 8 (stale) |
| HITL via `interrupt()` + Postgres checkpoints, resumable cross-channel | B | High | `docs/tools-design/hitl.md` | `graph.ts` L2284, L2600–2613; `checkpointer.ts`; `/api/chat/confirm` | Regression notes preserved in doc |
| 48 tools, 3-level risk, HITL = risk ≥ medium | B | High | `architecture.md` §Herramientas | `tools/catalog.ts` (grep: 48 risk entries); `toolRequiresConfirmation` | — |
| Tool availability is allowlist-by-construction | B | High | `architecture.md` §política | `tools/adapters.ts` `isToolAvailable` ~L615–773 | "Unregistered ⇒ uncallable" |
| Pre-graph skill selector (haiku, T0), one dominant skill, rationale vs Claude Code | A+B | High | `docs/tools-design/skill-routing.md` (entire) | `skills/select.ts` L110; `model.ts` L131–151 | Explicit comparative rationale |
| Tenant filter not deterministically required in BQ SQL | B | High | roadmap invariant (contrast) | `tools/adapters.ts` `prepareBigQueryRunArgs` ~L289–359; `bigquery-adapter.ts` L102–229 | Literal-inline rejected; absence not rejected |
| BQ read-only enforced at SQL + IAM scope | B | High | roadmap V1 decisions | `bigquery-adapter.ts` L34 (`bigquery.readonly`), L105 (`validateReadOnlySql`) | Two independent layers |
| Cron auto-approve bypasses interrupts; schedule_task not registered in cron | B/A | High | `architecture.md` §Tareas | `graph.ts` L2212–2232; state.ts L39–42 | Policy override exists (`toolApprovalPolicy`) |
| bash = unsandboxed host shell, env-gated, 120s timeout | B | High | `docs/tools-design/bash-tool.md` | `tools/bashExec.ts` L8, L103–113 | Fail-closed default |
| Compaction: microcompact keep-5 + LLM @80% of 120k, breaker 3 | B | High | `docs/memory/short_memory_plan.md` | `nodes/compaction_node.ts` L26–61, L246–261 | 9-section Spanish summary |
| LTM: inject top-8 @0.5 + topic-shift 0.55 + watermark flush, cron excluded | B | High | `docs/memory/long_term_memory_plan.md` | `nodes/memory_injection_node.ts`; `memory_flush.ts` L219–254; migration 00005 | Embedding reuse for two purposes |
| Case engine: states, optimistic lock, append-only events (trigger), external wake | B | High | `docs/operational-cases/architecture.md` §2–6 | migration `00019` ~L115–147; `/api/cron/operational-cases/route.ts`; `graph.ts` L144–153 | Batch cap 200; concurrency 1–20 |
| Scheduled tasks: retry ≤3/2min, persistent-error fast-pause, Telegram alerts | B | High | `architecture.md` §retries | `cron/scheduled-tasks/route.ts` ~L106–118, L309–356; migration 00004 | Observable recovery |
| Heartbeat: read-only allowlist + deterministic prefetchers persisted as tool_calls | B | High | `docs/heartbeat/deterministic-prefetchers.md`; architecture.md | `heartbeat/prefetchers/registry.ts`; `adapters.ts` ~L646–671; migration 00018 | Anti-silent-failure mechanism |
| Telegram idempotency ledger per update_id | B | High | architecture.md §canales | migration `00052`; webhook route claim/lease | — |
| Secrets AES-256-GCM; per-account tool secrets | B | High | architecture.md §seguridad | `packages/db/src/crypto.ts`; migration 00024 | — |
| No subagents, with written activation criteria | A+B | High | `docs/operational-cases/future-considerations.md` §1 | absence verified in `packages/agent` | — |
| No CI / deploy configs; tests = ~160 selftests via tsx | B | High | — | absence of `.github/workflows`, `vercel.json`, `Dockerfile`; selftest inventory | — |
| Single-process assumptions (SSE, logs, caches) | B | High | architecture.md ("persistencia multi-instancia pendiente") | `apps/web/src/lib/agent-turn-events.ts`; `turn_log.ts`; registry cache | — |
| MemorySaver silent fallback | B | High | hitl.md §env | `checkpointer.ts` | Log-only signal |
| Models: gpt-4o-mini main / haiku aux / 2048 cap for credit reservation | B | High | README env table | `model.ts` L27–47, L96–151 | Economic rationale in comments |
| Docs deliberately reject thin-harness/Obsidian/marketplace/script-skills | A | High | `agentic-principles-alignment.md` §8; roadmap "Qué NO copiar" | — | Design-point self-awareness |
| Deep readiness testing (N0–N5) validating business contracts | A+B | High | `docs/operational-cases/testing-framework.md` | `/api/tool-readiness/*`; `operational-case-tests` | Evaluation of *procedures*, not model outputs |
| AI usage ledger + admin dashboard (Slice 0.4+) | B | High | `docs/tools-design/model-providers.md`; flexible-workflows plan §0.4 | `ai_usage_events`, `/settings/ai-usage` | Internal observability; not billing; flag-gated |

---

*Report generated in read-only analysis mode. No application code, configuration, or data was modified; this file is the only artifact written.*

# Mail Agent

Single source of truth for the local Mac Mini mail-agent, native mail-dashboard, Gmail IMAP intake, macOS bridge integration, and Phase 4 mail rules roadmap.

This document consolidates mail-agent material that was previously spread across the system design, operations, troubleshooting, changelog, preflight, and legacy mail-agent notes.

Keep the high-level architecture summary in `SYSTEM_DESIGN.md`, keep command-only runbooks in `OPERATIONS.md`, keep symptom-specific fixes in `TROUBLESHOOTING.md`, and keep this file as the detailed mail-agent reference.

---

## Current Status

| Area | Status |
|---|---|
| Dockerized `mail-agent` on Mac Mini | Implemented |
| macOS bridge for iMessage / host-only actions | Implemented |
| Gmail IMAP intake using App Passwords | Implemented |
| Docker credential fallback via `secrets/imap.toml` | Implemented |
| Native Electron `mail-dashboard` | Implemented |
| Dashboard APIs under `127.0.0.1:8090/api/mail/*` | Implemented |
| Mail-agent health/debug API on `127.0.0.1:8080` | Implemented |
| Phase 4A deterministic SQLite-backed rules engine | Implemented |
| Rules UI with account scoping and safe Phase 4A actions | Implemented |
| Phase 4B AI enrichment | Implemented, read-only |
| Phase 4C.1 IMAP mutation primitives | Implemented, gated/audited |
| Phase 4C.3A AI trigger actions | Implemented, preview-only |
| Phase 4E.2 final read-only verification + mock execution API | Implemented, non-mutating |
| Phase 4F.1a-4F.2d Rule AI drafts, audit, explain, safety E2E, verification | Implemented, deterministic/local draft-only with human save |
| Unsafe actions such as auto-reply, forward, webhook, unsubscribe | Not exposed |

Important database boundary:

```text
data/agent.db   = mail-agent runtime state, rules, audit, needs-reply, AI queues/classifications
data/finance.db = PWM / finance data only
```

Do not put mail rules in `finance.db`.

---

## Architecture

```text
Gmail IMAP account or bridge fallback
  -> Docker mail-agent (`agent/`)
  -> deterministic rules engine in `data/agent.db`
  -> local classifier providers
  -> bridge iMessage / PDF unlock on Mac host
  -> optional NAS PDF archive at `/mnt/mailagent`
  -> native Electron dashboard (`mail-dashboard/`)
```

Runtime placement:

```text
Mac host
  bridge/server.py          :9100
    - iMessage
    - host-local PDF unlock / PDF processing
    - bridge health

Docker on Mac
  mail-agent                :8080
    - polling / scan loop
    - IMAP intake
    - rule evaluation
    - classifier providers
    - attachment routing
    - local health/debug API

  finance-api               :8090
    - PWA backend
    - mounts `agent.app.api_mail`
    - exposes dashboard-facing `/api/mail/*`

Native app
  mail-dashboard/
    - Electron menu-bar UI
    - talks to `127.0.0.1:8090/api/mail/*`
```

The dashboard is a control surface only. Quitting the dashboard must not stop mail processing.

---

## Main Components

| Component | Responsibility |
|---|---|
| `agent/app/orchestrator.py` | Chooses IMAP or bridge fallback, enforces safety mode, runs rule/classifier flow, advances checkpoints after durable processing. |
| `agent/app/imap_source.py` | Gmail IMAP polling, UID/UIDVALIDITY state, bounded lookback, size guards, message identity, attachment metadata. |
| `agent/app/rules.py` | Phase 4A deterministic rules evaluator. |
| `agent/app/state.py` | SQLite migrations and helpers for `data/agent.db`. |
| `agent/app/pdf_router.py` | Sends PDF bytes to bridge `/pdf/unlock`, validates filenames, checks NAS sentinel, routes attachments. |
| `agent/app/net_guard.py` | Outbound, bridge, IMAP, and NAS readiness probes. |
| `agent/app/api_mail.py` | Mail dashboard API router mounted by finance API. |
| `agent/app/config_manager.py` | Account config persistence and atomic/fallback TOML writes. |
| `bridge/server.py` | Host-only bridge routes including `/pdf/unlock`, `/alerts/send`, `/health`, and `/healthz`. |
| `mail-dashboard/` | Electron + React + Tailwind native dashboard. |
| `scripts/mailagent_preflight.py` | Read-only inventory and sanity report. |
| `scripts/mailagent_status.py` | CLI smoke test for mail APIs. |

---

## API Boundaries

There are two different local API surfaces. Keep them separate.

### Dashboard-facing API

The native dashboard uses the finance API mount:

```text
http://127.0.0.1:8090/api/mail/*
```

Supported account/settings endpoints:

```text
GET    /api/mail/summary
GET    /api/mail/recent?limit=20
GET    /api/mail/accounts
POST   /api/mail/accounts/test
POST   /api/mail/accounts
PATCH  /api/mail/accounts/{account_id}
PATCH  /api/mail/accounts/{account_id}/enabled
DELETE /api/mail/accounts/{account_id}
POST   /api/mail/accounts/{account_id}/reactivate
POST   /api/mail/config/reload
POST   /api/mail/run
```

Rules endpoints should also live under this same `/api/mail/*` namespace.

Current rules endpoints:

```text
GET    /api/mail/rules
POST   /api/mail/rules
POST   /api/mail/rules/ai/draft
POST   /api/mail/rules/ai/golden-probe
GET    /api/mail/rules/ai/audit/summary
GET    /api/mail/rules/ai/audit/recent
GET    /api/mail/rules/ai/golden-probe/runs
GET    /api/mail/rules/{rule_id}
PATCH  /api/mail/rules/{rule_id}
DELETE /api/mail/rules/{rule_id}
PUT    /api/mail/rules/reorder
POST   /api/mail/rules/preview
POST   /api/mail/rules/explain
GET    /api/mail/processing-events
```

Current approval endpoints:

```text
GET    /api/mail/approvals
GET    /api/mail/approvals/cleanup/preview
POST   /api/mail/approvals/cleanup
GET    /api/mail/approvals/export
GET    /api/mail/approvals/{approval_id}
POST   /api/mail/approvals/{approval_id}/approve
POST   /api/mail/approvals/{approval_id}/reject
POST   /api/mail/approvals/{approval_id}/expire
POST   /api/mail/approvals/{approval_id}/execute
POST   /api/mail/approvals/{approval_id}/mark-failed
POST   /api/mail/approvals/{approval_id}/archive
POST   /api/mail/approvals/{approval_id}/unarchive
```

Phase 4F AI rule-builder endpoints are documented in [phase-4f-natural-language-rule-builder.md](phase-4f-natural-language-rule-builder.md). The implemented draft/probe/explain surfaces preserve the draft-only and read-only boundaries; AI must not write directly to `mail_rules` or execute mailbox actions.

`POST /api/mail/rules/explain` is the Phase 4F.2a deterministic rule explanation / dry-run inspector. It accepts a synthetic/sample message, optionally filters to one saved `rule_id`, runs the existing rule engine with `preview=True`, and returns per-condition expected/actual/matched details plus planned preview-only actions. `from_domain` / `sender_domain` actual values are derived from `sender_email` when needed. The endpoint is read-only: no rule rows, processing events, approval rows, audit rows, iMessage, bridge call, IMAP call, Gmail mutation, Ollama call, or cloud LLM call.

The release safety matrix is maintained in [MAIL_AGENT_SAFETY_MATRIX.md](MAIL_AGENT_SAFETY_MATRIX.md).

### Worker health/debug API

The mail-agent container exposes:

```text
http://127.0.0.1:8080
```

Use this for local status/debug, not as the dashboard settings surface.

---

## Secrets And Credentials

Source of truth:

```text
macOS Keychain
```

Docker fallback file:

```text
secrets/imap.toml -> mounted read-only as /app/secrets/imap.toml
```

Expected `secrets/imap.toml` shape:

```toml
[[accounts]]
email = "user@gmail.com"
app_password = "xxxx xxxx xxxx xxxx"
```

Required local permission:

```bash
chmod 600 secrets/imap.toml
```

Hard rules:

- Never commit `secrets/imap.toml`.
- Never commit `scripts/export-finance-key.sh`.
- Do not paste App Passwords into docs, prompts, screenshots, logs, or Git.
- Dashboard/backend should normalize Gmail App Password whitespace before testing or saving.
- Placeholder accounts such as `YOUR_EMAIL@gmail.com` must be ignored by runtime and filtered from the dashboard.

---

## Gmail IMAP Intake

IMAP is enabled only when `[mail.imap].accounts` contains real enabled accounts. If only placeholders exist, the agent should continue using the bridge fallback.

Account state is tracked per account/folder:

```text
(account_id, folder, last_uid, uidvalidity)
```

Message identity:

```text
message_key          = sha256(account + folder + normalized Message-ID)
fallback_message_key = sha256(account + folder + uidvalidity + uid)
attachment_key       = sha256(message_key + sha256(pdf_bytes))
```

Checkpoint rule:

```text
Advance IMAP checkpoint only after message result is persisted and attachment rows are created or processed.
```

A PDF routing failure must not force refetch of the same email forever.

---

## Safety Modes

Configured under `[agent].mode`.

| Mode | Fetch + classify | iMessage | PDF route | Email mutation |
|---|---:|---:|---:|---:|
| `observe` | yes | no | no | no |
| `draft_only` | yes | yes | yes | no |
| `live` | yes | yes | yes | yes |

Current safe operating assumption:

```text
mode = draft_only
```

Invalid or missing mode resolves to `draft_only`, or `observe` when `[agent].safe_default = "observe"`.

Blocked actions must be recorded as `mode_blocked` events.

---

## PDF Attachment Routing

The agent must never pass container-local file paths to the bridge. It sends PDF bytes to bridge `/pdf/unlock` as multipart data, then receives unlocked bytes and metadata headers.

Required NAS routing setup:

```text
Host mount:   /Volumes/Synology/mailagent
Docker mount: /Volumes/Synology/mailagent:/mnt/mailagent
Sentinel:     /mnt/mailagent/.mailagent_mount
Config:       [mail_agent.pdf].mount_sentinel_uuid
```

Before writing attachments, `pdf_router.py` must verify:

- NAS mount exists.
- Sentinel exists.
- Sentinel UUID matches config.
- Write/delete probe succeeds.

If any check fails, attachment jobs should stay pending/retryable. Do not write into ephemeral container storage.

---

## Phase 4A Rules Engine

Phase 4A is deterministic and read-only from the mailbox perspective. It runs before classifier/AI logic and uses SQLite state in `data/agent.db`.

### Tables

```text
mail_rules
mail_rule_conditions
mail_rule_actions
mail_processing_events
mail_needs_reply
```

Future AI tables also stay in `data/agent.db`:

```text
mail_ai_queue
mail_ai_classifications
mail_ai_categories
mail_ai_trigger_rules
```

### SQLite Connection Contract

Every connection opened by `state.py` or new helpers should run:

```sql
PRAGMA foreign_keys = ON;
PRAGMA journal_mode = WAL;
PRAGMA busy_timeout = 5000;
```

`journal_mode=WAL` is database-level and persistent. `foreign_keys` and `busy_timeout` are per-connection and must be set every time.

### Evaluator Semantics

Rules are evaluated in ascending priority.

Global rules and account-specific rules can interleave by priority. Priority uniqueness should treat `NULL` global account scope explicitly, for example through `COALESCE(account_id, '__global__')`.

Match behavior:

```text
match_type = ALL or ANY
enabled = 0 means skipped
stop_processing = halt later deterministic rules after current rule actions finish
skip_ai_inference = do not enqueue future AI inference
```

Each action should log an outcome to `mail_processing_events`. One action failure must not erase prior successful action logs.

### Phase 4A Safe Actions And Phase 4C.1 Mutation Primitives

Allowed in Phase 4A:

```text
mark_pending_alert
skip_ai_inference
add_to_needs_reply
route_to_pdf_pipeline
notify_dashboard
stop_processing
```

Recognized in Phase 4C.1, but gated by `[agent].mode` and `[mail.imap_mutations]`:

```text
move_to_folder
mark_read
mark_unread
mark_flagged
unmark_flagged
```

Still not allowed:

```text
add_label
send_imessage
delete
auto_reply
forward
unsubscribe
external_webhook
```

Do not expose unsafe actions in the dashboard until explicitly requested and implemented with capability checks, audit, and safety mode enforcement.

End-to-end Phase 4A verification has confirmed real mail processing with deterministic rules:

```text
phase4a_scan_summary messages_seen=3 messages_evaluator_ran=3 rules_matched=3 events_written=3
```

---

## Phase 4B AI Enrichment — Read-Only

Phase 4B is implemented as an opt-in, read-only AI triage layer. It runs after deterministic rule evaluation, enqueues eligible messages in `mail_ai_queue`, and stores validated Ollama output in `mail_ai_classifications`.

Default config:

```toml
[mail.ai]
enabled = false
provider = "ollama"
base_url = "http://host.docker.internal:11434"
model = "gemma3:4b"
temperature = 0.1
timeout_seconds = 45
max_body_chars = 12000
urgency_threshold = 8
```

Operational constraints:

- AI enrichment does not mutate email.
- Ollama calls happen outside DB transactions.
- Output is schema-validated before persistence.
- Validation failure writes `status='failed'` and `last_error`; no trigger fires.
- One in-flight Ollama request is enough for v1.
- Manual reprocess uses `manual_nonce` so it does not collide with existing queue uniqueness.
- AI enrichment still does not invoke mutation helpers or trigger actions.

---

## Phase 4C.1 IMAP Mutation Primitives

Phase 4C.1 adds infrastructure-level IMAP primitives only. It does not add AI-triggered actions, bulk mutation, auto-reply, forwarding, unsubscribe, webhooks, delete/expunge as a user-facing action, or AI-triggered iMessage.

Default config:

```toml
[mail.imap_mutations]
enabled = false
dry_run_default = true
allow_mark_read = false
allow_mark_unread = false
allow_add_label = false
allow_move_to_folder = false
require_uidvalidity_match = true
require_capability_cache = true
allow_create_folder = false
allow_copy_delete_fallback = false
```

Safety constraints:

- `observe` and `draft_only` always audit `mode_blocked`.
- `live` still requires `[mail.imap_mutations].enabled = true`.
- UIDVALIDITY is rechecked before any UID mutation.
- MOVE uses `UID MOVE` when supported.
- COPY + STORE `\Deleted` fallback is disabled by default and never calls EXPUNGE in this phase.
- STORE supports only `\Seen` and `\Flagged`.
- Every planned, blocked, dry-run, unsupported, completed, or failed mutation path writes `mail_processing_events`.

Phase 4D.5 adds readiness plumbing without enabling live mailbox mutation. Approval preview/detail can include `current_gate_preview.dry_run_plan` for future reversible candidates (`mark_read`, `mark_unread`, `add_label`, and cautious `move_to_folder`). The plan records account, folder, UID, UIDVALIDITY, the would-be IMAP operation, `would_mutate=false`, safety gates, and a rollback hint. Capability summaries are cached per account/folder in `imap_capability_cache`; discovery is read-only and must not create folders, mark messages, move messages, or label messages. If capability cache is missing/unknown, UIDVALIDITY is missing/mismatched, the account is disabled, or an allow flag is false, preview remains blocked. Under default config, approved mutation attempts still cannot perform real mailbox changes.

---

## Phase 4C.3A AI Trigger Actions — Preview-Only

AI triggers are deterministic rules evaluated after validated Phase 4B AI classifications are saved. They use `mail_ai_trigger_rules` and write `ai_trigger_matched` rows to `mail_processing_events`.

Supported trigger fields:

```text
category
urgency_score
confidence
needs_reply
summary
reason
```

Supported preview-only actions:

```text
notify_dashboard
send_imessage
move_to_folder
mark_read
mark_flagged
add_to_needs_reply
```

Safety constraints:

- Trigger matching is deterministic and never calls another LLM.
- All AI-trigger actions are forced to `dry_run=true`.
- AI triggers never call IMAP mutation helpers, bridge `send_alert`, auto-reply, forwarding, delete, expunge, unsubscribe, or webhooks in this phase.
- Trigger evaluation failure is audited separately and must not mark the AI classification as failed.
- Dashboard copy must clearly label AI triggers as preview-only.

---

## Phase 4D.1 Control Center — Operator Approval

Phase 4D.1 inserts a human approval queue between AI trigger suggestions and any execution attempt.

Default config:

```toml
[mail.approvals]
enabled = true
require_approval_for_ai_actions = true
approval_expiry_hours = 72
started_stale_after_minutes = 30
allow_bulk_approve = false
```

Safety constraints:

- AI triggers create `mail_action_approvals` rows; they do not execute actions.
- Operators approve or reject suggestions in the dashboard Control Center.
- Approval and execution are separate API operations.
- Approval does not bypass `[agent].mode`, `[mail.imap_mutations].enabled`, `dry_run_default`, UIDVALIDITY, folder, or IMAP capability checks.
- `send_imessage`, reply, forward, delete, expunge, unsubscribe, and webhooks remain blocked in this phase.
- Bulk approval is not implemented.

Approval API:

```text
GET  /api/mail/approvals
GET  /api/mail/approvals/{approval_id}
POST /api/mail/approvals/{approval_id}/approve
POST /api/mail/approvals/{approval_id}/reject
POST /api/mail/approvals/{approval_id}/execute
POST /api/mail/approvals/{approval_id}/expire
```

Execution support in this phase is limited to safe mailbox action attempts through the existing gated mutation path plus `add_to_needs_reply`. Unsupported approved actions are marked `blocked` and audited.

Approval detail responses include derived `execution_state`, `expires_at`, `approved_at`, `execution_started_at`, `execution_finished_at`, `blocked_reason`, `execution_error`, `gate_result`, `audit_event_ids`, and chronological `events`. The operator-facing states are `not_requested`, `started`, `executed`, `blocked`, `failed`, `expired`, `rejected`, and `stuck`.

`stuck` is read-only detection for approvals that reached `execution_status='started'` but did not finish before `started_stale_after_minutes`. The optional mark-failed endpoint is valid only for stale started approvals and records an audit event without retrying execution.

Phase 4D.3 adds read-only preview fields to list and detail responses: `preview_title`, `preview_summary`, `message_context`, `trigger_context`, `rule_context`, `risk_level`, `risk_reasons`, `reversibility`, `operator_guidance`, `would_execute_now`, `would_be_blocked_now`, and `current_gate_preview`. These fields are for operator review only. They do not approve, reserve, start, retry, or execute an action.

The Control Center should be read before approval: confirm why the item appeared, what trigger/rule matched, which sender/subject/account/folder/UID is affected, what action/target/value is proposed, and whether the current gate says dry-run, blocked by config, unsupported, terminal, stale/manual-review, or statically ready. `capability='unknown'` is expected when preview cannot know IMAP capabilities cheaply without a live mailbox transaction.

Phase 4D.4 adds lifecycle hygiene:

```text
GET  /api/mail/approvals/cleanup/preview
POST /api/mail/approvals/cleanup
POST /api/mail/approvals/{approval_id}/archive
POST /api/mail/approvals/{approval_id}/unarchive
GET  /api/mail/approvals/export?format=json
```

Cleanup is disabled by default. The preview is read-only. Explicit cleanup may expire old pending approvals and archive old terminal approvals, but started/stuck approvals are excluded and hard delete is not used in this phase. Archive hides terminal approvals from the active Control Center; audit history remains retained and exportable. JSON export includes sanitized approval/message context and optional events, not raw email bodies or secrets.

Phase 4D.5 readiness fields extend the same preview surface. For reversible candidates the Control Center shows mailbox identity, capability status, config blockers, dry-run plan, safety gates, and rollback hint with explicit wording that no mailbox change will occur under current settings. Dangerous actions still do not receive dry-run mutation plans.

---

## Phase 4F Natural Language Rule Builder

Phase 4F adds AI-assisted rule authoring without changing the mailbox mutation boundary. The intended flow is:

```text
User natural-language request
  -> AI rule drafting
  -> deterministic schema validation
  -> safety allow-list validation
  -> preview/diff
  -> human approve/save
  -> existing deterministic rules engine
```

AI drafts proposed rules only. It does not save rules, execute actions, call IMAP, call the bridge, send iMessage, or mutate Gmail/IMAP. Phase 4F.1a supports requests such as “Add abcd@efcf.com to the spam list”, “Block alerts from abcd@efcf.com”, and “Stop processing email from abcd@efcf.com”. It returns only `from_email equals <sender>` with `skip_ai_inference` and `stop_processing`.

Phase 4F.1b adds a local LLM/Ollama capability probe for alert-rule drafts. Phase 4F.1c hardens that path with expanded deterministic Indonesian bank-domain hints and bilingual intent normalization for common bank/security/credit-card alert scenarios. The endpoint accepts `mode=auto`, `mode=sender_suppression`, or `mode=alert_rule`. Alert-rule drafting is controlled by `[mail.rule_ai]` and is disabled by default. When enabled, the only saveable alert draft shape is:

- conditions: `from_domain contains <domain>` or `from_email equals <email>`, plus at least one `subject contains <keyword>` or `body contains <keyword>`
- action: `mark_pending_alert` with target `imessage`, `stop_processing=false`
- `safety_status`: `safe_local_alert_draft`
- `requires_user_confirmation`: `true`

The local model output is never trusted directly. Deterministic post-validation blocks overbroad drafts, missing sender/domain, missing content conditions, mutation actions, direct `send_imessage`, forwarding, auto-reply, unsubscribe, external webhooks, labels, moves, read/unread, and Gmail spam behavior. Known bank names override model-supplied domains; unsupported or ambiguous sender domains require an explicit sender/domain instead of trusting a model guess. “Send me an iMessage notification” is represented only as a saved-rule candidate that can later queue a local pending alert; the draft endpoint does not send anything.

Phase 4F.1c recognizes deterministic hints for Permata, BCA, KlikBCA, CIMB Niaga, Maybank, Mandiri/Livin, BNI, BRI, OCBC NISP, UOB, HSBC, DBS, Jenius, and BSI. It normalizes common Indonesian/English alert intents including credit-card clarification/confirmation, suspicious/security/login alerts, payment due/billing, OTP/verification-code, and failed/declined transactions. Saveable drafts are still capped to narrow `ALL` rules and use no action other than `mark_pending_alert` to `imessage`.

Phase 4F.1d adds an operator-run golden prompt smoke harness for local Qwen quality checks. The fixture lives at `agent/tests/fixtures/rule_ai_golden_prompts.json`, and the runner is `scripts/mail_rule_ai_golden_probe.py`. The harness sends known prompts to `POST /api/mail/rules/ai/draft` only, validates the returned safe alert draft shape, and prints a compact pass/fail report. It never calls `POST /api/mail/rules`, never saves rules, never sends iMessage, never calls the bridge, and never mutates Gmail or IMAP. Normal automated tests use mocked responses and do not require Ollama.

Phase 4F.1e adds the same golden-probe quality gate to the dashboard through `POST /api/mail/rules/ai/golden-probe`. The Settings panel is manual/operator-run only and displays disabled, passed, or failed summaries plus per-prompt results. It uses the shared `agent/app/rule_ai_golden_probe.py` validation logic, does not create a normal AI Rule Builder draft, does not show Save Rule for probe results, and never calls the rule-save endpoint. Real probe runs require `[mail.rule_ai].enabled=true` and reachable local Ollama; keep `[mail.rule_ai].enabled=false` outside intentional testing.

Phase 4F.1f proves that saveable AI drafts are compatible with the existing deterministic rule pipeline. Sender suppression and alert-rule drafts can be saved only through the human-triggered `POST /api/mail/rules` endpoint, produce normal `mail_rules`, `mail_rule_conditions`, and `mail_rule_actions` rows, and preview through `POST /api/mail/rules/preview` against synthetic/sample messages. The draft endpoint and golden-probe endpoint remain read-only for rule tables. Saved AI-drafted rules are deterministic rules; they are not AI-executed actions.

Compatibility vocabulary:

- `from_email` maps to normal message `sender_email`.
- `from_domain` and `sender_domain` are deterministic domain aliases derived from `sender_email` when no explicit domain field exists.
- Alert drafts use only `contains` / `equals` operators and `mark_pending_alert` to target `imessage`.
- Sender suppression drafts use only `from_email equals`, `skip_ai_inference`, and `stop_processing`.

The dashboard Save Rule path strips draft metadata (`status`, `saveable`, `safety_status`, warnings, explanation, provider/model, and raw model errors) before calling create-rule. Golden-probe results never expose Save Rule, unsupported drafts remain unsaveable, and preview/evaluation remains local and non-mutating.

Phase 4F.2a adds the Rule Explanation / Dry-Run Inspector. This is not an AI expansion: it uses saved deterministic rules and synthetic/sample message payloads only. The dashboard **Explain Rule** panel shows matched vs not matched, each condition's expected and actual values, planned local actions, skip-AI and stop-processing flags, and safety copy. It helps verify AI-drafted rules after human save, but it does not expose Save Rule from the explanation result and does not run the golden probe.

Phase 4F.2b adds dashboard E2E smoke tests for the safety-critical Rule AI surfaces. The Playwright suite lives under `mail-dashboard/tests/e2e/` and runs with `npm run test:e2e`. It mocks all backend mail APIs through browser route interception and does not call real Ollama, Gmail, IMAP, iMessage, bridge, finance-api, Docker, Electron, or a real database. The tests prove that Save Rule appears only for saveable drafts, unsupported drafts cannot save, golden probe and quality panels expose no save/execute controls, Explain Rule remains dry-run only, and draft metadata is stripped before the human Save Rule payload.

Phase 4F.2c adds Control Center browser safety smoke coverage to the same Playwright suite. It mocks every `/api/mail/*` request and fails closed on unmocked mail API calls. The tests prove that synthetic QA mode is read-only, pending approvals expose only approve/reject/expire controls, approved approvals are labeled **Mock verify + audit**, blocked terminal approvals show blockers without retry/bulk execute, stuck started approvals require manual review, cleanup preview does not auto-run cleanup, and JSON export does not execute approvals. The suite still does not call real finance-api, Gmail, IMAP, Ollama, iMessage, bridge, a mailbox, or a real database.

## Phase 4 Verification

Use the consolidated release verification command before handoff:

```bash
./scripts/mailagent_verify_phase4.sh
```

It runs targeted backend safety suites, the full backend suite, dashboard helper tests, Playwright E2E, dashboard build, and preflight. It does not require local Rule AI to be enabled. The automated tests mock external/runtime dependencies where appropriate: dashboard E2E mocks all `/api/mail/*` routes, and backend Rule AI tests use fake local clients instead of real Ollama.

Expected preflight warnings may include local Rule AI enabled on a test machine, missing NAS mount, or bridge Messages/chat DB degradation. These are environment warnings, not evidence that Rule AI draft/probe/explain can mutate Gmail/IMAP or send iMessage.

Phase 4F.1g adds local Rule AI draft/probe observability. `mail_rule_ai_draft_audit` records each successful draft endpoint response as a best-effort audit row, and `mail_rule_ai_golden_probe_runs` records aggregate golden probe results. These tables are quality metrics only: they do not save rules, do not execute actions, and do not change mailbox state.

Audit privacy rules:

- store request hash and short sanitized preview, not full raw prompt
- store compact status/saveability/safety/model metadata and rule shape counts
- store warnings/explanations after normal sanitization
- never store raw model output, API keys, app passwords, bridge tokens, full email bodies, or mailbox mutation identifiers

Read-only audit endpoints:

```text
GET /api/mail/rules/ai/audit/recent
GET /api/mail/rules/ai/audit/summary
GET /api/mail/rules/ai/golden-probe/runs
```

The dashboard “Rule AI Quality” panel displays summary metrics and recent attempts only. It has no Save Rule, rerun, execute, label, move, mark read/unread, delete, archive, forward, reply, unsubscribe, or webhook controls. Audit write failures are logged and should be visible through preflight/operator logs; draft generation remains usable because audit is best-effort observability.

Manual validation checkpoint on 2026-05-01 established the current local-first recommendation for this narrow flow. Gemma failed the initial schema probe, and Qwen failed before schema hardening. After adding structured Ollama JSON schema output and keeping deterministic post-validation mandatory, `qwen2.5:7b-instruct-q4_K_M` passed 5/5 manual alert-rule prompts. Phase 4F.1c did not add cloud LLM support; local Qwen remains the recommended model for narrow rule drafting, cloud LLM integration remains deferred, and `[mail.rule_ai].enabled` should remain `false` by default unless an operator is actively testing local rule drafting.

The implemented endpoint is:

```text
POST /api/mail/rules/ai/draft
```

The endpoint is draft-only and does not write `mail_rules`, `mail_rule_conditions`, or `mail_rule_actions`. User save remains a separate human-triggered `POST /api/mail/rules` call from the dashboard. “Spam list” currently means local Mail Agent suppression, not Gmail Spam.

Phase 4F.1 remains scoped to safe non-mutating rule actions. Gmail spam/move/label/read/unread mutations remain blocked or deferred unless they later pass through the Phase 4E approval/execution gates.

Detailed plan: [phase-4f-natural-language-rule-builder.md](phase-4f-natural-language-rule-builder.md).

---

## Transaction And I/O Boundary

Hard rule:

```text
No DB transaction may remain open across IMAP, Ollama, bridge, network, or filesystem I/O.
```

Required pattern:

```text
1. Open short transaction -> claim work -> commit.
2. Run external I/O outside any transaction.
3. Open short transaction -> persist result/audit/error -> commit.
```

This avoids SQLite writer contention and protects wake/retry behavior.

---

## Common Commands

Start bridge on Mac host:

```bash
PYTHONPATH=$(pwd) python3 -m bridge.server
```

Start/rebuild mail agent:

```bash
docker compose up --build -d mail-agent
docker compose logs -f mail-agent
```

Run status checks:

```bash
python3 scripts/mailagent_preflight.py
python3 scripts/mailagent_status.py --no-run
python3 scripts/mailagent_status.py
```

Run dashboard locally:

```bash
cd mail-dashboard
npm install
npm run build
npm run dev
```

After Python changes, rebuild the relevant Docker image. Restart alone may not pick up code baked into the image.

---

## Quick Verification Checklist

```bash
# 1. Config syntax
python3 -c "import tomllib; tomllib.load(open('config/settings.toml','rb')); print('OK')"

# 2. Provider registry
python3 -c "from agent.app.providers import PROVIDERS; print(sorted(PROVIDERS))"

# 3. Docker status
docker compose ps

# 4. Mail-agent logs
docker compose logs --tail=120 mail-agent

# 5. Finance API logs, needed because dashboard mail APIs mount there
docker compose logs --tail=120 finance-api

# 6. Mail status
python3 scripts/mailagent_status.py --no-run

# 7. Preflight
python3 scripts/mailagent_preflight.py
```

Expected provider baseline:

```text
rule_based must be accepted as a supported classifier provider.
```

## Phase 4 Release Operator Checklist

Use this checklist before a Phase 4A through Phase 4C.3A checkpoint:

```bash
# 1. Read-only inventory and environment sanity
python3 scripts/mailagent_preflight.py

# 2. Authenticated API status without triggering a scan
python3 scripts/mailagent_status.py --no-run

# 3. Verify AI settings through the dashboard API
curl -s -H "X-Api-Key: $FINANCE_API_KEY" \
  http://127.0.0.1:8090/api/mail/ai/settings | python3 -m json.tool

# 4. Test AI classification without queueing or mutating mail
curl -s -H "X-Api-Key: $FINANCE_API_KEY" \
  -H "Content-Type: application/json" \
  -X POST http://127.0.0.1:8090/api/mail/ai/test \
  -d '{"sender":"alerts@example.com","subject":"Payment due reminder","body":"Your payment is due tomorrow."}' \
  | python3 -m json.tool

# 5. Preview deterministic rules; this endpoint is side-effect-free
curl -s -H "X-Api-Key: $FINANCE_API_KEY" \
  -H "Content-Type: application/json" \
  -X POST http://127.0.0.1:8090/api/mail/rules/preview \
  -d '{"sender":"alerts@example.com","subject":"Payment due reminder","body":"Your payment is due tomorrow."}' \
  | python3 -m json.tool

# 6. Preview AI triggers; planned actions must remain dry-run
curl -s -H "X-Api-Key: $FINANCE_API_KEY" \
  -H "Content-Type: application/json" \
  -X POST http://127.0.0.1:8090/api/mail/ai/triggers/preview \
  -d '{"category":"payment_due","urgency_score":8,"confidence":0.9,"needs_reply":false,"summary":"Payment due tomorrow","reason":"Due date detected"}' \
  | python3 -m json.tool
```

Default release posture:

- Keep `[mail.ai].enabled=false` unless deliberately validating read-only AI enrichment.
- Keep `[mail.imap_mutations].enabled=false` for the release checkpoint.
- Keep `[mail.imap_mutations].dry_run_default=true`; deterministic rule-managed mailbox actions should preview/audit unless intentionally promoted in `live`.
- Treat AI triggers as approval-only. They may write `ai_trigger_matched` audit events and pending Control Center approval items, but live autonomous AI-triggered actions are not enabled in Phase 4D.1.

---

## Troubleshooting

### Dashboard shows connection error

Likely causes:

- `finance-api` did not mount `/api/mail/*`.
- `finance-api` lacks dependencies such as `tomlkit` or `keyring`.
- `mail-agent` is not running.
- NAS mount prevented the mail-agent container from starting.
- API key mismatch.

Commands:

```bash
docker compose ps
docker compose logs --tail=120 finance-api
docker compose logs --tail=120 mail-agent
python3 scripts/mailagent_status.py --no-run
```

Fix:

```bash
docker compose up --build -d finance-api mail-agent
export VITE_FINANCE_API_KEY="$FINANCE_API_KEY"
cd mail-dashboard
npm run dev
```

### Gmail account test fails with whitespace / ASCII error

Likely cause: pasted App Password contains spaces or non-breaking spaces.

Fix:

```bash
docker compose up --build -d finance-api
```

Then retry from the dashboard. Current code should strip whitespace automatically.

### Account saves but does not appear

Likely cause: invalid TOML shape under `[mail.imap].accounts` from an older writer.

Diagnose:

```bash
python3 -c "import tomllib; tomllib.load(open('config/settings.toml','rb')); print('OK')"
```

Expected inline account style:

```toml
[mail.imap]
accounts = [
  {email = "user@gmail.com", provider = "gmail", id = "gmail_user", name = "User", host = "imap.gmail.com", port = 993, ssl = true, auth_type = "app_password", folders = ["INBOX"], lookback_days = 14, max_message_mb = 25, max_attachment_mb = 20, enabled = true, auth_source = "keychain", keychain_service = "agentic-ai-mail-imap"},
]
```

### Saving settings fails with `settings.tmp -> settings.toml` busy

Likely cause: Docker bind mount rejects atomic rename on single-file mount.

Fix:

```bash
docker compose up --build -d finance-api
```

Current code should use an in-place fsynced write fallback when atomic rename is blocked.

### Mail-agent container will not start after rebuild

Likely cause: NAS share missing or Docker Desktop cannot access `/Volumes`.

Diagnose:

```bash
ls -la /Volumes
ls -la /Volumes/Synology/mailagent
docker compose ps
docker compose logs --tail=80 mail-agent
```

Fix:

```bash
# Mount Synology share first, then:
docker compose up --build -d mail-agent
python3 scripts/mailagent_status.py --no-run
```

### `data/agent.db` is malformed

Stop the agent first:

```bash
docker compose stop mail-agent
```

Create a timestamped copy before any repair attempt:

```bash
mkdir -p data/db_recovery
cp -a data/agent.db "data/db_recovery/agent.db.$(date +%Y%m%d-%H%M%S).bak"
```

Run integrity check:

```bash
sqlite3 data/agent.db "PRAGMA integrity_check;"
```

Attempt recover into a new DB:

```bash
sqlite3 data/agent.db ".recover" | sqlite3 data/agent.recovered.db
sqlite3 data/agent.recovered.db "PRAGMA integrity_check;"
```

If recovered DB is OK:

```bash
mv data/agent.db "data/agent.db.bad.$(date +%Y%m%d-%H%M%S)"
mv data/agent.recovered.db data/agent.db
docker compose up --build -d mail-agent
```

If recovery fails, keep the backup and recreate only mail-agent runtime state. Do not touch `data/finance.db`.

---

## Related Documentation

Documentation layout:

```text
README.md                  Short entry point and status

docs/SYSTEM_DESIGN.md      Stable architecture and cross-component contracts
docs/MAIL_AGENT.md         This file: detailed mail-agent design, operations, rules, troubleshooting
docs/OPERATIONS.md         Common commands for the whole system; link to MAIL_AGENT.md for mail details
docs/TROUBLESHOOTING.md    Cross-system symptom fixes; link to MAIL_AGENT.md for mail-specific fixes
docs/DECISIONS.md          ADR-style rationale only
docs/CHANGELOG.md          Reverse chronological history only
docs/ch-hp-worklow.md      Keep separate; homepage workflow is a separate project area
```

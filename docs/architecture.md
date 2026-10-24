# Architecture

This document covers the parts of the design that are settled. Components marked *planned* are
not implemented yet.

## Principle

The agent decides **what to investigate**; deterministic code does **all the computing and checking**.
Every statement in a report or chat answer must cite an `Evidence` record produced by a tool, and a
verifier rejects statements it cannot match to one.

## Components

```
 Mobile app (Expo) ──── HTTPS + bearer session ────► API (FastAPI)
                                                       │
     ┌──────────────────────┬──────────────────────────┼─────────────────────────┐
     ▼                      ▼                          ▼                         ▼
 Google Health API     Takeout export          Agent                       Postgres
 (live sync) ──┐       (offline import) ─┐     router → experts            users, daily metrics,
               ▼                         ▼     over analysis tools         sync runs, accounts,
          daily table (same columns from either source)                    chat, memory; later traces
               │                                   │
               ▼                                   ▼
        Analysis tools (deterministic) ──► Evidence ──► Verifier ──► report / answer
```

| Component | Location | Status |
|---|---|---|
| Takeout ingestion | `backend/app/ingest/takeout.py` | done (legacy layout; newer exports lack `Global Export Data`) |
| Google Health sign-in | `backend/app/sync/google_auth.py`, `connections.py` | the owner's CLI (loopback OAuth, token file `0600`), and each person's web sign-in from the app (PKCE, token encrypted in `google_connections`) |
| Google Health API client | `backend/app/sync/client.py` | done: paging, roll-up windows, retries |
| API data → daily table | `backend/app/sync/daily.py` | done, verified against Takeout ([metrics.md](metrics.md#from-the-google-health-api)) |
| Database | `backend/app/db/`, `backend/migrations/` | users, Google connections, daily metrics, sync runs, chat messages, cited evidence, findings, context questions, check-ins, memory facts |
| Live data → database | `backend/app/sync/pull.py`, `connections.py` | `python -m app.sync pull`, and background syncs started from the app (whole history first, then the last 3 days) |
| Analysis tools and `Evidence` | `backend/app/analysis/` | describe, coverage, compare_windows, trend, correlate |
| Screen and templated report (the no-LLM baseline) | `backend/app/analysis/screen.py`, `report.py` | done |
| Synthetic data with planted effects | `backend/app/synthetic.py` | done |
| General agent, verifier, readable findings | `backend/app/agent/` | done |
| Experts and consult | `backend/app/agent/experts.py` | sleep, recovery, activity; nutrition defined, waiting for its columns |
| Recovery score | `backend/app/analysis/` | planned, see [product.md](product.md#recovery-score) |
| Router and the ask flow | `backend/app/agent/router.py`, `ask.py` | Jev with keyword fallback; LLM router for the evaluation |
| Context builder | `backend/app/agent/context.py` | conversation and attachments; other memory planned |
| Accounts | `backend/app/auth/`, `backend/app/api/auth.py` | email and password (scrypt), sessions as hashed tokens, approval of each sign-up by the owner, `python -m app.auth` |
| API | `backend/app/api/` | auth, `/data/status`, `/reports/latest`, `/evidence/{id}`, `/chat`, `/google/*`; every data endpoint serves the signed-in person's own data |
| Mobile app | `mobile/` | landing, sign-up and sign-in, waiting for approval, Access requests (owner); Today, Ask (real agent), Reminders (mock), Data (Connect Google Health) |
| Advice guard and the Jev client | `backend/app/agent/guard.py`, `jev.py` | checks shown text by meaning |
| Evaluation suite | `eval/` | started: the advice sentence set; the rest planned |

### Ingestion

Reads a Google Takeout ("Google Health") export into one row per local calendar day and one column
per metric (see [metrics.md](metrics.md) for every column and its Fitbit source). Intraday data is
bucketed by the user's timezone; profile and account files are never opened. Malformed exports
raise `IngestError` instead of producing partial data silently.

### Live sync (Google Health API)

The Fitbit data comes live from the Google Health API (v4). Sign-in is Google's loopback OAuth
flow for desktop apps, with four read-only scopes (activity and fitness, health metrics, sleep,
nutrition); the refresh token is stored in `data/google_token.json`, readable only by its owner.
The Google Cloud project's OAuth app stays in **Testing** mode, because health scopes are
restricted: only listed test users can sign in, and Google expires the sign-in after 7 days, which
surfaces as `ReconnectNeeded`. Each person connects from the app instead: the browser signs in to
Google and returns to the API's `/google/callback`, which stores the token encrypted with
`FA_TOKEN_KEY` and syncs in the background. Locally the callback is a loopback address; from a
phone it needs the deployed backend on a public HTTPS address.

The client lists data points across pages and fetches daily roll-ups in the windows the API
accepts; rate limits, server errors and network failures are retried with backoff. The mapping
fills the same columns as Takeout, so everything downstream is source-independent, with one rule:
**a history comes from one source**. The API's sleep is Google's current algorithm, the legacy
export's is the old one (about 38 minutes a night apart), so mixing them would fake a change.

### Storage

Postgres (Docker locally, managed when deployed), schema changes as Alembic migrations, SQLite in
tests. Daily metrics are stored one row per user, source, day and metric, so new metrics (such as
nutrition) need no migration. Every table holding a person's data has a `user_id`, and every query
filters on it. Tables for later features are added by migration when the feature is built.

The conversation is one thread per person (`chat_messages`): each question with its attachment,
and each answer with its verified claims, who answered, whether the router chose them, whom they
consulted, whether it was refused, and the run id that links it to its trace. **Only evidence a
verified claim cites is stored** (`evidence`, once per id), so the app can show it and a follow-up
can cite it without recomputing; everything else a run computed can be recomputed from the data.
Both are deleted with the person. Each answer also stores its cost, which the daily spending caps
add up.

Accounts are `users` (email, scrypt password hash, `pending`/`approved`/`rejected`) and
`auth_sessions` (only a SHA-256 hash of each session token). A person's Google token is in
`google_connections`, encrypted, never in plain text.

### Analysis tools

Pure functions over the daily table. Each validates its arguments (`ToolError` on bad input),
computes on non-missing days only, and returns an `Evidence` record with:

- a unique `id` that claims cite,
- the tool name, metrics and date windows used,
- the sample size `n` and a `sufficient` flag (false below a per-tool minimum number of days),
- the computed statistics.

Methods are chosen for short, noisy personal data: Mann-Whitney U with Cliff's delta for window
comparisons, Theil-Sen slopes with Kendall's tau for trends, and Spearman correlation across lags
with a Bonferroni adjustment for the lags tried.

### Screen and report

The screen compares the last 14 days of every metric with the 28 days before (Mann-Whitney U,
Cliff's delta), leaving low-wear days out of activity totals. Because about twenty metrics are
tested at once, p-values are adjusted with Benjamini-Hochberg (FDR 5%), and only changes with at
least a medium effect are reported. The adjusted p-value is stored in the evidence, so the app
shows the value the decision was made on. The report turns each change into templated text whose
numbers all come from its evidence. It is what the app shows until the agent exists, and the
"statistics only" baseline the agent is evaluated against.

### Agent

`backend/app/agent/`: the general agent (`agent.py`), the experts (`experts.py`), the router
(`router.py`) and the ask flow that joins them (`ask.py`).
A run starts either from the screen's changes (`investigate`; when nothing changed, no model is
called) or from a question (`answer`). The model records hypotheses, tests them with the toolbox
(`tools.py`: validated calls over the analysis tools, limited to the metrics in scope), and calls
`submit_findings`. Text shown to people uses the names and formats in `present.py`; the data keeps
its raw units. The LLM layer (`llm.py`) prices every call and enforces a per-run budget and a spending
cap; tool calls past the budget are refused one by one, so a turn that asks for too many loses only
the excess. `ScriptedLLM` stands in for the model in tests. Each run keeps a trace of every step.

**Experts** run the same loop with their own prompt and a toolbox over the metrics they own plus
the ones they read ([product.md](product.md#experts)); wear time is shared. One rule is added to
the verifier: **only the owner makes claims about a metric**. A claim about another expert's metric
passes only when all its evidence came from that expert through `consult`. The router decides
which experts may be consulted; `consult` runs one as a *quick* answer on a budget carved out of
the lead's (leaving the lead enough calls to submit and repair), at most twice per answer and once
per expert, and lends the lead the evidence behind its verified claims. Consulted experts cannot
consult. An expert with no data (nutrition, for now) answers without calling the model. Budgets:
quick 6 model calls, 8 tool calls, $0.02; deep 12, 20, $0.05; each allowed consult adds 5 model
calls and $0.015.

**Router** (`router.py`). One Jev call asks a *choice* (the topic: an expert, general or out of
scope) and one *yes/no* per expert (does answering need its data). `decide` turns them into an
action with fixed thresholds: out of scope at 0.5 or more is refused, even when the person picked
the expert; a lead below 0.4 (or `general` on top) goes to the general agent; other experts needed
at 0.5 or more are consulted. Jev is called over `httpx2` with a 2 s timeout and no retries; on any
failure the keyword rule answers and the reason is kept. Only the cleaned question text (control
characters removed, at most 500 characters) is sent, and error bodies are never kept, since they
may repeat it. An LLM router with the same output exists only for the evaluation's comparison.
`ask` routes, then refuses without a model call, or runs the general agent or the expert, and
records the routing decision as the first step of the trace.

Planned: the evaluation comparing the experts with the general agent, and the routers with each
other on a labeled question set.

### Verifier

Deterministic (`verifier.py`). Each claim must cite existing, sufficient evidence; a change or an
association must be significant and point the stated way, where **significance is judged after
correcting for all of the run's own tests together** (Benjamini-Hochberg, the screen's method;
evidence from the screen, a consult or an earlier answer keeps its own run's correction); every number, duration, time of day and
date in the text must come from the cited evidence; every metric the text names must be covered by
that evidence (distinctive terms such as "HRV" or "time asleep"; generic words such as "sleep" do
not count); and the text must not use internal metric names, diagnose, state causation or reason
about calorie balance. The summary is checked too.
Failing text goes back to the model once with the reasons, then is dropped. Two checks look at the
answer as a whole: the summary may describe a metric as changing only if a significant test of it is
in the run, and **coverage**: when the router says the question needs another expert's data and no
verified claim draws on it, the answer goes back once, then carries a fixed note saying that part is
not covered.

**The advice guard** (`guard.py`) checks by meaning what the word rules check by words. The router
only judges the question, and an in-scope question can still get an answer that advises ("cutting
caffeine should help") or names a condition, worded so no listed word appears. So every sentence
that passed the deterministic checks, the summary included, goes to Jev in one call, with one
yes/no per sentence: does it diagnose, name a condition, or tell the person what to do for their
health? A flagged sentence is rejected like any other. If Jev is down, the word rules alone apply
and the trace says so. Consulted runs are not checked, since only the lead's text is shown. The
Jev HTTP client (`jev.py`) is shared by the router and the guard.

## Confirmed action execution (planned)

Local-first delivery and researched tools: [agent-actions.md](agent-actions.md). The router now
classifies read/log/mixed/manage/clarify intent in its existing Jev call and records it in the
trace. Intent is observational in this first slice: proposal tools and execution are not exposed.
Experts will collect details and prepare drafts; intent labels never authorize writes.

Workout and nutrition logging are a core planned extension; see
[product.md](product.md#agent-assisted-logging-core-planned-capability). Reuse accounts, expert
routing, chat and encrypted Google connections. The current analysis toolbox remains read-only;
add proposal tools and a separate deterministic executor, never unrestricted model write access.

Persist per-user action proposals, immutable confirmed payload versions, status transitions,
provider IDs and an audit of execution/undo. Add a migration and evolve the backend schemas,
`mobile/src/api/types.ts`, HTTP client and mock together. Status must distinguish drafts,
awaiting confirmation, cancelled, executing, succeeded, failed, unknown outcome and undone.
Only an authenticated owner can confirm, execute or undo their own proposal. Model text and
imported text cannot authorize actions. Routing must recognise logging requests and missing-detail
follow-ups without weakening the medical refusal rules.

Execution checks approval, payload version and granted scopes server-side. Idempotency and
concurrent confirmation handling must survive process restarts. A timeout after Google's write
may mean success: reconcile before retrying; never blindly replay a create. Reconcile remote
success with local persistence failures, and deletion failures with the displayed undo status.
Persist Google IDs and provenance so sync echoes and provider duplicates do not double count.

Request the activity/nutrition write scopes only for enabled logging features, handle reconnect
and denied permissions, and preserve read-only connections. Verify exact create/update/delete
payloads, ownership restrictions, idempotency support and reconciliation semantics against the
provider before enabling writes. No Google console or deployment change is made by this plan.

Workout summaries require a new intraday fetch and deterministic aggregation layer: daily totals
cannot establish a workout's heart rate or steps. Define time boundaries, timezone handling,
sensor gaps and zone thresholds explicitly; return evidence with coverage and omit unsupported
summaries. Keep raw samples out of prompts. Photo input is a deliberate later privacy extension
to the current aggregates-only model boundary: explicit upload, bounded file validation, no
photo content in traces, a defined retention/deletion policy, and estimates labelled separately
from statistical evidence. Provider nutrition lookup should precede model estimates where feasible.

Verify with fake Google transports and scripted models: clarification, edit/reconfirm, cancellation,
unapproved and cross-user writes, denied scopes, duplicate/concurrent confirmation, ambiguous
network outcomes, restart recovery, sync echoes, undo and partial failures. Test deterministic
workout calculations on synthetic samples and photo provenance without paid calls. Real write
validation requires explicit approval for the exact entry and any cleanup; photo model runs follow
[costs.md](costs.md). These are acceptance gates, not results already observed.

Provider references checked 2026-10-24: [supported data types and scopes](https://developers.google.com/health/data-types),
[nutrition guide](https://developers.google.com/health/data-types/nutrition),
[data point reference](https://developers.google.com/health/reference/rest/v4/users.dataTypes.dataPoints).

## Memory and context

The course asks for memory's scope, lifetime, retrieval strategy and privacy to be defined. The
principles: the context window is scarce, so a run gets a small, deterministic selection; memory
is **written selectively** and **maintained**; and memory, like any text from outside, is **data,
never instructions** (memory poisoning is OWASP's agentic risk ASI06).

**Data itself is not memory.** The agent never reads rows: it fetches statistics on demand through
tools, so its view of the data is always current and every number is computed.

### Kinds of memory

All memory is per user (`user_id` on every row, every query filtered) and is deleted with the
user's data.

| Kind | What it holds | Written by | Lifetime | Retrieved when |
|---|---|---|---|---|
| **Conversation** | the chat turns: questions, verified answers, attachments | the system, per turn | the thread; older turns condensed to their questions and verified claims | always: last 4 turns verbatim, earlier ones condensed |
| **Findings** (episodic) | verified claims of past runs with their evidence ids, metrics and dates | the system, only after verification | until a newer finding on the same metric supersedes it, at most 90 days | the question's metrics match; newest first |
| **Context answers** | the person's answers to the agent's questions ("exam week") with the dates and metrics asked about | the person | 180 days | the date range or metrics overlap |
| **Check-ins** | daily rating 1-5 and fixed tags | the person | 365 days | through a `checkins` tool, for the window being investigated |
| **Facts and preferences** (semantic) | short structured facts: routine, goal, preference, context; at most 120 characters, with the metrics they concern | **proposed by the agent, saved only after the person approves** | until changed or deleted; not retrieved after 60 days unused | preferences always (at most 3); other facts when their metrics match |
| **Traces** | every run's steps, cost and verdicts | the system | 30 days | never put in a prompt: for AgentOps and evaluation only |

### Retrieval: the context builder

Deterministic, before the model is called:

1. **Scope.** The router's label (or the chosen expert) gives the metrics in play; an attached
   finding or metric is added first.
2. **Select.** Only rows for this user whose metrics or dates match the scope.
3. **Rank.** Score = relevance (metric match, date overlap) + recency (decays with age) +
   importance (a verified finding's effect size; facts the person confirmed count fully). Ties go
   to the newer item.
4. **Cap.** At most 5 items besides the conversation, within a fixed token budget (about 1,500
   tokens). Older findings' evidence is re-attached so it can be cited instead of recomputed.
5. **Record.** The trace lists which items were retrieved, so an answer can be traced to its
   context and retrieval can be evaluated.

No embeddings: memory here is structured (metrics, dates, tags), so filtering and ranking is
cheaper, deterministic and testable. No model call is used to summarize memory.

**Built so far: the conversation and attachments** (`backend/app/agent/context.py`, stored in
`chat_messages` and `evidence`). The last 4 turns go in verbatim (question, answer, verified claims
with their evidence ids) and their cited evidence is re-attached, at most 8 records; older turns are
condensed to the question and the claims' text; an attachment (a metric, or a finding with its
evidence) comes first. Items are added newest first while they fit in about 1,500 tokens. Refused
turns and turns that read like instructions are left out, and the trace records what was included
and dropped. Re-attached evidence counts as the expert's that produced it, so the ownership rule
treats it like a consult's. The router sees the current question and up to 3 earlier ones (questions
only), so a follow-up such as "and last week?" is routed by what it refers to, even several
questions back. An attachment's metric decides the lead unless the person picked an expert.
Findings, context answers, check-ins and facts come with their tables.

**Stored, with the write rules enforced in code** (`backend/app/db/memory.py`, migration 0003):
findings only from verified change and association claims of investigation runs, a newer one on
the same metric superseding the older; context questions written by code from a template and a
fixed menu of options (travel, work or exam schedule, more or less training, illness, new device,
other, rather not say), the answer one of them, the same metric and period never asked twice, and
two declined questions pausing questions for 14 days; check-ins for today only, 1 to 5 with fixed
tags; facts proposed by the agent and kept only once the person approves (at most 120 characters,
a fixed kind, known metrics, nothing instruction-like, never re-proposed once declined). `expire()`
enforces the 90, 180 and 365 day lifetimes.

**Retrieved into each answer** (`context.select_memory`, `memory.memory_items`). Routing comes first,
so the metrics in play are known: the lead's own and the ones it reads, and its consults'. Current
findings, answers (not "rather not say") and approved facts whose metrics overlap them are scored
on relevance, recency (halving every 30 days) and importance (a finding's effect size; what the
person confirmed counts fully); preferences always come, at most three; at most five items in all,
within the same token budget as the conversation. A finding's evidence is re-attached and counts as
its metric's owner's. The trace lists what was retrieved, and approved facts that went into a run
are marked used, so unused ones fade out after 60 days.

**Proposing facts.** The agent has a `propose_fact` tool for something lasting the person stated
about themselves (never inferred from the data), at most one per answer, checked against the fact
rules (`facts.py`). Proposals come back with the answer for the person to approve; the agent never
writes memory. Check-ins as data the tools can analyse come with the recovery score.

### Write path

| Source | Can it write memory? |
|---|---|
| The person (answers, check-ins, approved facts, preferences) | yes |
| The verifier (only claims that passed) | findings only |
| The agent | only **proposals** (`propose_fact`), which wait for the person's approval |
| External text: food names, entries from other apps, imported files | **never**, directly |

Every stored item keeps its provenance (who wrote it, which run, when).

### Injection defenses

- External and stored text is passed to the model as **quoted data** inside a delimited block
  marked as data, never in the system prompt; it is length-limited and stripped of control
  characters.
- Text that reads like an instruction ("ignore previous instructions", role tags, URLs) is dropped
  from memory candidates and logged.
- The agent's tools only read statistics; nothing in the model's reach can write memory, change
  settings or reach another user's data.
- The router (Jev) receives the question text only, never data or memory.

### How it is evaluated

Memory on against off on scenarios that need it (follow-up questions, a change explained by an
earlier context answer); stale memory (a superseded finding must not be used); poisoning attempts
(a food name carrying an instruction, a proposed fact the person declined); retrieval precision
(share of retrieved items that were relevant) and context size per run.

## Boundaries

| Agentic | Deterministic | Human-controlled |
|---|---|---|
| choosing what to investigate, forming and testing hypotheses, writing findings | ingestion, statistics, verification, authorization, data access | confirming context the data cannot show, approving consequential actions, acting on insights |

The agent describes patterns in the user's own data. It does not give medical diagnoses or advice.

## Data and privacy

The repository is public. Personal exports live under `data/` or `Takeout/`, both git-ignored, and
are never committed; so are `.env` (the OAuth client ID and secret, the token encryption key) and
the owner's Google sign-in token in `data/`. Passwords are stored as scrypt hashes, session tokens
as hashes, Google tokens encrypted; no request returns another person's data or chat. The analysis
LLM receives aggregated statistics, never raw sensor rows or account data. The planned logging
flow also needs user-supplied entry details; optional photo estimation has the separate consent
and retention requirements above. Tests and evaluation use the synthetic generator, whose
baselines are generic values, not taken from any real export.

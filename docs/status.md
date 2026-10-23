# Project status

The page to read first when picking the project up. Updated 2026-10-23.

## Objective

EECE 503N/798S course project (Path A, application), demo around the end of November 2026. An app
that analyzes a person's longitudinal Fitbit data and explains what changed and why, where **the
agent decides what to investigate and deterministic tools compute every number**. The instructor
requires a mobile app and a fully deployed system (backend online, installable app).

The grade weights idea and agentic justification (20%), agent performance and evaluation (20%),
AgentOps (15%) and reliability and security (15%), so **the agent and its evaluation are the
priority**; the UI and data plumbing exist to serve them.

## What works today

| Area | State |
|---|---|
| Data | Takeout import (legacy layout); **live Google Health API** sign-in, client and mapping to the daily table, verified against Takeout ([metrics.md](metrics.md#from-the-google-health-api)) |
| Storage | Postgres in Docker, two migrations (users, Google connections, daily metrics, sync runs; chat messages and cited evidence); `python -m app.sync pull` stores live days |
| Analysis | deterministic tools returning `Evidence` (incl. change points with a permutation test, weekday split); 14-vs-28-day screen with FDR correction and a templated report (the no-LLM baseline) |
| Agent | LLM layer with cost accounting and budgets; validated toolbox; **general agent** (hypothesis-test loop, `submit_findings`, one repair round) and the **claim verifier**; **experts** (sleep, recovery, activity; nutrition defined, waiting for data) with ownership of claims and `consult`; **router** (Jev: topic plus a yes/no per expert; keyword fallback; LLM router for comparison) and `ask()`, which routes and answers. Not yet reachable from the API or the app |
| API | `/health`, `/data/status`, `/reports/latest`, `/evidence/{id}`; single user, reads Takeout, no auth |
| App | Today, Ask (expert picker, quick/deep, attachments, routed answers on mock data), Reminders, Data; Expo SDK 57, runs in Expo Go and on the web |
| Engineering | protected `main`, PRs with both CI jobs required, 388 backend and ~50 mobile tests |

**Not built yet:** memory beyond the conversation, the recovery score, nutrition
columns, the API serving live data, accounts, deployment, tracing and metrics, the evaluation
suite, the failure matrix and threat model.

## Local setup

1. Backend: `python3 -m venv .venv && source .venv/bin/activate && pip install -e "backend[dev]"`.
2. Database: `docker compose up -d db` (Postgres on port **5433**), then
   `alembic -c backend/alembic.ini upgrade head`.
3. `.env` at the repository root (git-ignored; copy `.env.example`): `FA_TIMEZONE`,
   `FA_EXPORT_DIR`, `FA_GOOGLE_CLIENT_ID` / `FA_GOOGLE_CLIENT_SECRET` for live data, and
   `FA_OPENAI_API_KEY`, `FA_TYPESAFE_API_KEY` and `FA_LLM_SPEND_CAP_USD` for the agent. Both API
   keys are set on Karim's machine; **budgets are about $5 each**, see [costs.md](costs.md).
4. Live data: `python -m app.sync connect`, then `check`, `compare --export Takeout`,
   `pull --email <account>`. Run from the repository root.
5. App: `cd mobile && npm ci && npx expo start` (Expo Go) or `npm run web`.

### The Google Cloud project

The Google Health API is enabled in the Google Cloud project **`fitbit-agent-503p`**. Its OAuth app
("Patterns 503P") is **External** and in **Testing** mode, with the account that owns the Fitbit
data added as a test user and four read-only scopes: `googlehealth.activity_and_fitness`,
`googlehealth.health_metrics_and_measurements`, `googlehealth.sleep`, `googlehealth.nutrition`.
The OAuth client is of type **Desktop app**; its ID and secret live only in `.env`. These scopes
are restricted: publishing would need Google verification and a security assessment, so the app
stays in Testing (at most 100 test users; sign-ins expire after 7 days and need `connect` again).
To let someone else sign in, add their Google account as a test user in the console.

### Data on disk (all git-ignored)

| Path | What |
|---|---|
| `Takeout/` | first export (2026-06-27 to 2026-10-15), legacy layout with `Global Export Data` |
| `data/raw-2026-10-21/` | second export: no `Global Export Data`, sleep in `UserSleeps*` (v1 and v2 algorithms), nutrition values all "N/A" |
| `data/google_token.json` | the Google sign-in (mode `0600`) |
| `takeout-*.zip` | the original downloads |

## Decisions and findings

- **Live API is the data source going forward**; Takeout stays as an offline import.
- **Never mix sources in one history.** The API's sleep is Google's v2 algorithm; the legacy
  export's is v1, about 38 minutes a night apart. Daily metrics are stored per source.
- **The API lacks** readiness, Fitbit's sleep score and cardio load; its sedentary periods do not
  reproduce Fitbit's sedentary total, so that column is left out. The recovery score uses sleep
  minutes and efficiency instead of Fitbit's sleep score.
- **Nutrition values exist only through the API** (34 nutrients plus energy and macros), arriving
  twice: Cronometer's daily total and per-entry Apple Health copies. Deduplicate before summing.
- **Recovery is our own score**, modeled on Bevel's inputs; a morning "how do you feel" check-in
  is the ground truth for comparing it with Fitbit's readiness.
- **Agent shape:** a cheap router (Jev, a typed classifier) sends each question to a specialist
  (sleep, recovery, activity, later nutrition); cross-domain questions are led by the owner of the
  metric asked about, which consults the others as tools. Whether this beats one general agent is
  measured. See [product.md](product.md).
- **Experts see their own metrics and the ones they read** (sleep reads activity; recovery reads
  sleep and activity; activity reads recovery and sleep); wear time is shared. **Only the owner
  makes claims about a metric**: a claim about another expert's metric passes only on evidence
  that expert produced through `consult`, so the lead can cite what it was told.
- **Consulting is the router's decision**, not the depth's and not the lead's. Jev answers, in one
  call, the topic (which expert leads, or general, or out of scope) and, per expert, whether the
  question needs its data; a single topic distribution could not mark cross-domain questions
  ([experiments.md](experiments.md#router-pr-29-2026-10-23)). Depth only sets the budget; each
  allowed consult adds its own.
- **Routing thresholds** (hand-set, to be tuned by the router evaluation): refuse when out of scope
  is at least 0.5, even if the person picked an expert; the general agent answers when no expert
  reaches 0.4; consult experts needed at 0.5 or more.
- **Jev is called with our own small `httpx2` client** rather than TypeSafe's SDK: a 2 s timeout
  with no retries so a slow call falls back to the keyword rule, error bodies (which may repeat the
  question) never kept, cost in our own accounting, tests on a fake transport; no new dependency.
- **Nutrition waits for Sprint 2**: the expert exists but answers "no data yet" until the sync
  maps nutrition columns (only the API has them; Takeout's are "N/A").
- **Platform:** OpenAI for the LLM; Railway (backend and Postgres) and Vercel (web) when deploying;
  Langfuse for agent traces and Prometheus/Grafana for API metrics; iOS TestFlight undecided.

## Next

The approved plan, with the decisions from the 20-question session and the schedule, is in
[roadmap.md](roadmap.md). In short: **Sprint 1 (Oct 22–28)** builds the agent end to end (LLM
layer with a scripted fake, agent tools, general agent with the hypothesis loop and verifier,
four experts with consult and the router, memory, live data and the agent served to the app);
**Sprint 2 (Oct 29–Nov 4)** adds the recovery score, check-in, nutrition, daily runs, reminders
and experiments, tracing, accounts, deployment and the first evaluation; November after that is
buffer and hardening.

Sprint 1 so far: LLM layer, agent tools, general agent, verifier, human-readable findings, the
experts with consult (PR #28), the router (PR #29), the verifier's metric check (PR #30), chat storage (PR #31), the context builder for the conversation and attachments (PR #32), the advice guard (PR #33), the per-run test correction (PR #34) and the coverage and summary checks (PR #35) are done. The memory and context design
(kinds, scope, lifetime, retrieval, write path, injection defenses, evaluation) is in
[architecture.md](architecture.md#memory-and-context-conversation-built-other-memory-designed). Next, in order:

1. The memory tables and write path (findings, context answers, check-ins, facts), or first
   open issues 13 and 14 if answer quality comes first.
2. Live data and the agent served through the API to the app.

## What has been tested

Unit and scenario tests run in CI with the scripted model and fake HTTP transports, so they never
spend money. Real runs, all on synthetic people, are logged with their findings in
[experiments.md](experiments.md); in short:

- **Experts:** three real runs; the third consulted another expert and passed every claim. Two
  bugs found and fixed on the way (evidence ids in text, experts not knowing who owns what).
- **Router:** Jev picked the right lead on 16 of 16 made-up questions in a median 0.21 s for about
  $0.00003 a question; the keyword fallback 14 of 16.
- **Routed answers end to end:** three runs; routing was right every time, and the third passed all
  four claims after three fixes (display names in claims, the tool-budget bug, null results).
- **Follow-ups:** with the earlier questions, Jev routed 8 of 8 made-up follow-ups right (2 of 8
  on the question alone), including references two and three questions back and a topic change;
  a real two-turn conversation answered "What about on weekends?" about sleep with 4 verified claims.
- **Advice guard:** on 20 made-up advice or diagnosis sentences and 12 sound ones, the word check
  caught 2 and the Jev guard 18, neither with a false alarm; on a real conversation the guard
  flagged nothing.
- **Many tests per run:** simulated on 400 synthetic people (free): without a correction 56% of
  runs on a calm person report something false; with it 6%.
- **Consult policy:** 16 runs comparing consulting as routed (A) with skipping consults of experts
  the lead already reads (B): B is about half the cost and time, A states the question's premise
  and has fewer rejected claims. Undecided.

Spent so far on real runs: about $0.55 of OpenAI and $0.004 of Jev ([costs.md](costs.md)).

## Open issues

1. ~~Text can mention a metric no evidence covers.~~ Fixed in PR #30: the verifier rejects a claim
   or summary that names a metric its evidence does not cover (distinctive terms only, such as
   "HRV" or "time asleep", not "sleep").
2. **Consult policy A vs B** is undecided ([experiments.md](experiments.md#consult-policy-a-vs-b-2026-10-23));
   A stays until the evaluation compares both on the full scenario set.
3. ~~False positives across many tests.~~ Fixed in PR #34: a run's own tests are corrected
   together. On 200 synthetic people with nothing planted, runs reporting something false fell from
   56% to 6%; planted changes were still found 92-98% of the time. Trade-off: a borderline change
   found only by the weaker change-point test can now be rejected; the repair message says to
   confirm it with `compare_windows`, which the model has not yet been seen doing (it dropped the
   claim instead).
4. **Answers do not always address the question asked.** Partly fixed in PR #35: when the router
   says a question needs another expert's data and no verified claim draws on it, the answer goes
   back once, and if still missing it carries a fixed note saying that part is not covered (a
   needed expert without data gets a note too). Seen working once: "Does exercising more change how
   I sleep?" ended with the note instead of silently skipping exercise. Not yet seen: the repair
   actually adding the missing part (its wording was fixed after the first try, because it asked
   for a claim the ownership rule rejects; untested since).
5. **Routing thresholds are hand-set**, and Jev's probabilities vary a little between calls for the
   same question; the router evaluation needs a labeled question set (not the 16 used while
   designing).
6. **Evaluation scenarios must be detectable.** A planted 8 ms HRV drop came out as 3 ms in the
   data (not significant); each scenario's planted effect should be checked with the deterministic
   tools before it is used to grade the agent.
7. **Cosmetic:** the model sometimes wraps quoted values in quote marks ("6 h 57 min").
8. **Not wired yet:** the API and the app do not call `ask()`; the app's Ask screen still uses the
   mock.
9. **Follow-ups recompute instead of citing.** Earlier answers' evidence is re-attached and citable,
   but in the real conversation the model recomputed the same comparison. Correct, slightly more
   expensive; a prompt nudge may be enough.
10. **The advice guard misses implied diagnoses.** It caught 18 of 20 advice sentences (the word
    check 2 of 20) with no false alarms; it missed "your body is fighting something off" and "your
    heart rhythm may be irregular". Not tuned on the same set; to be measured on a held-out set in
    the attack suite.
11. **A summary can overstate a non-significant difference.** Mostly fixed in PR #35: each clause
    that names a metric with a direction word needs a significant test of that metric in the run;
    it caught a summary describing an untested bedtime change. Limits: support is matched by metric,
    not by the comparison (a weekend claim passes if any significant bedtime test is in the run),
    and generic words are not checked ("your sleep got shorter" passed in a run whose claims said no
    clear change).
13. **Quick depth can run out before the test the question needs.** Asked about exercise and
    sleep at quick depth (8 tool calls), the model spent them on descriptions and change points, and
    the correlations that answer the question were refused as over budget.
14. **"No clear change" can hide a real one.** After the per-run correction rejected a real but
    borderline sleep drop, the model claimed "time asleep did not clearly change", which the
    verifier allows on non-significant evidence. Honest in statistical terms, misleading in plain
    words; the evaluation's planted scenarios will measure how often it happens.
12. **Accepted risk: when Jev is down, the scope check is a word list.** Jev is the scope check and
    has always answered so far; the keyword fallback catches only listed words. Revisit if the
    attack suite shows it matters.

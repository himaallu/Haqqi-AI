# Haqqi (حقّي, "my right")

Haqqi helps blue-collar workers in the UAE find out, in their own language:
- whether their employer broke the labour law;
- what they are owed;
- how to file a formal complaint with MOHRE, in Arabic.

A worker tells their story by voice or text. Haqqi answers with the rights that were likely broken, each citing an
article of the law, an itemised claim from a deterministic calculator, and a ready-to-file Arabic complaint PDF with a
translation alongside.

**Live:** https://haqqi-ai.vercel.app

<p align="center"><img src="docs/demo.gif" width="300" alt="Haqqi on a phone, in Urdu: choose a language, tell the story, confirm the facts, watch the checks run, read the result, download the Arabic complaint"></p>

<sub>One case in Urdu, from real screenshots (`docs/screens/make_demo_gif.py`). A screen recording comes with the demo video.</sub>

## The problem

MOHRE settles almost every labour dispute that reaches it. In H1 2026 it recorded about 188,000 disputes and settled
98.6% of them without court
([WAM](https://www.wam.ae/en/article/c1kxr4e-mohre-resolves-986-labour-disputes-amicably-2026)). It also handled about
9.43 million consultation and complaint contacts in 2025
([MOHRE](https://mohre.gov.ae/en/media-center/news/9/3/2026/mohre-successfully-settles-98-percent-of-labour-disputes-in-2025)).

The hard part is getting there with a clear, correct claim. Low-wage migrant workers face three barriers:
- **Language:** the law and the complaint are in Arabic or English.
- **Legal knowledge:** which rights apply, which articles were broken, and what is owed.
- **Power:** a vague or wrong claim is easy to dismiss.

> MOHRE settles 98.6% of disputes. Haqqi helps the workers who never get as far as filing one.

## What it does

1. **Choose a language.** English, Hindi, Urdu, Malayalam, Bengali, Tagalog, Nepali or Arabic.
2. **Tell the story** by voice or text.
3. **Confirm the facts** Haqqi read from it: emirate, dates, wages, notice, leave. Anything missing is asked for.
4. **See the verdict.** Each likely violation is shown with the article it breaks, and the law text one tap away.
5. **See the claim.** Unpaid wages, notice pay, gratuity, leave and deductions, each with its formula.
6. **Get next steps:** where to file, the time limit, and the documents to gather.
7. **Download the complaint:** a formal Arabic letter to MOHRE with the worker's language alongside.

Cases outside the federal law get a referral instead of a verdict: DIFC/ADGM, other free zones, and domestic workers.
When Haqqi is not confident, it says so and points to MOHRE (80084) rather than guessing.

## Architecture

```mermaid
flowchart TD
    W([Worker on a phone]) -->|voice| STT[Whisper speech-to-text<br/>Cloudflare Workers AI]
    W -->|text| UI
    STT --> UI[Next.js web app<br/>Vercel]
    UI -->|REST + live progress| API[FastAPI service<br/>Render]
    API --> IN[Intake agent<br/>facts from the story]:::llm
    IN --> RT{Routing<br/>code}
    RT -->|DIFC / ADGM / free zone / domestic| REF[Referral + MOHRE 80084]
    RT -->|wage or start date missing| ASK[Ask the worker]
    RT -->|ready| CF[Worker confirms the facts]
    CF --> RET[Hybrid law search<br/>BGE-M3 vectors + full text, RRF,<br/>plus the issue's Law Pack]
    CF --> CALC[Claim calculator<br/>deterministic Python]
    RET --> AN[Analyst agent<br/>findings with clause ids]:::llm
    CALC --> AN
    AN --> CHK[Citation check<br/>code drops any clause not retrieved]
    CHK --> CR[Critic agent]:::llm
    CR -->|problems| RV[One revision]:::llm
    RV --> CHK2[Citation check again]
    CR -->|pass| WR
    CHK2 --> WR[Writer agent<br/>plain explanation + letter facts]:::llm
    WR --> PDF[Arabic complaint PDF<br/>WeasyPrint, amounts filled by code]
    DB[(Supabase Postgres<br/>pgvector law index, cases<br/>7-day purge)] --- RET
    DB --- API
    classDef llm fill:#fde7c8,stroke:#c77700,color:#222
```

The tinted steps call an LLM: free-tier Gemini models first, then K2 Horizon (IFM) as the fallback. Everything else is
plain code, so no amount or article reaches the worker unchecked.

**Trust rules (enforced in code, see `CLAUDE.md`):**
- **Money** is computed only in `backend/haqqi/core/calculator.py`. The LLM writes `[[AMOUNT_n]]` tokens, and code
  fills them and rejects any other figure.
- **Every finding cites a clause id from the retrieved law.** Code drops any other citation, and the quote shown comes
  from our law text, not the model.
- **The worker's story is untrusted data**, fenced in delimiters. Prompt-injection cases are part of the evaluation.
- **Every LLM reply is parsed into a Pydantic model.** Bad output gets one correction retry, then a clear error.
- **Logs never hold story text, names, phone or ID numbers** (`backend/haqqi/logs.py`).

**Stack (all free tiers):**

| Part | Choice |
| --- | --- |
| Frontend | Next.js (App Router), TypeScript, Tailwind, shadcn/ui, pnpm, Vercel |
| Backend | Python 3.12, FastAPI, Pydantic v2, Docker on Render |
| Database | Supabase Postgres with pgvector and Arabic/English full-text search; pg_cron deletes cases after 7 days |
| Law | Federal Decree-Law 33/2021 (as amended) and Cabinet Resolution 1/2022, English and Arabic, one chunk per clause (`data/law/`) |
| Embeddings, speech | BGE-M3 and Whisper large-v3-turbo on Cloudflare Workers AI |
| LLM | Gemini free models (Flash → Flash-Lite), then K2 Horizon |
| PDF | WeasyPrint with Noto Naskh Arabic and the Noto font for each worker language |

## Evaluation

These are the PRD metrics on the hand-labelled cases in `eval/cases.jsonl`, run with `make eval` (`eval/run_eval.py`).
Every expected amount is worked out by hand in `eval/CASES.md`. **This is a partial run: 20 of 50 cases** (TC-01 to
TC-21), measured on **K2**. Production uses free Gemini models. The remaining 30 cases come next. History is in
`eval/CHANGELOG.md`.

| Metric | Score | Target |
| --- | --- | --- |
| Outcome accuracy (analyse / refer / ask for info) | 100% | ≥ 95% |
| Issue detection | 100% | ≥ 85% |
| Retrieval hit@5 | 92% | ≥ 90% |
| Citations cited (from the retrieved law) | 100% | 100% |
| Citations supported (hand labels) | 96% | ≥ 90% |
| Critic catch rate (seeded bad citation) | 100% (1/1) | ≥ 90% |
| Calculator correctness | 100% | 100% |
| Injection resistance | 100% (1/1) | 100% |
| Latency p95 (K2) | 299 s | < 90 s |

The calculator check runs on every pull request without an LLM (`make eval-offline`): 40/40 hand-worked cases.

## Run it locally

You need Docker, Python 3.12 with [uv](https://docs.astral.sh/uv/), and Node 22 with pnpm.

```bash
cp .env.example .env    # fill in the keys; never commit .env
make dev                # Postgres + backend (:8000) + frontend (:3000)
cd backend && DATABASE_URL=postgresql://haqqi:haqqi@localhost:5432/haqqi \
  uv run alembic upgrade head && uv run python -m haqqi.ingest   # law index (make db)
```

| Command | What it does |
| --- | --- |
| `make test` | Backend (pytest) and frontend (vitest) unit tests, no network |
| `make test-live` | Tests against a local database (its own `haqqi_test`) and the real APIs |
| `make lint` | ruff, mypy (strict), eslint, tsc |
| `make eval-offline` | Calculator vs the hand-worked cases, no LLM (runs in CI) |
| `make eval` | The full evaluation (K2 by default; `EVAL_ARGS="--provider gemini"`) |

Keys: `GEMINI_API_KEY` and/or `K2_API_KEY` for the LLM, and `CLOUDFLARE_ACCOUNT_ID` + `CLOUDFLARE_API_TOKEN` with
`EMBEDDER=cloudflare` for search and voice. Tests use a fake embedder and need no keys. Deploying to Vercel, Render and
Supabase is covered in [`docs/DEPLOY.md`](docs/DEPLOY.md).

```
backend/haqqi/   api/ (routes, limits) · agents/ (intake, analysis, writer) · core/ (calculator, routing)
                 rag/ (parse, ingest, retrieval, prompts) · pdf/ (complaint letter) · llm/ (client)
frontend/        Next.js app: language picker, story, confirm form, progress, results, complaint
data/law/        Law text (EN + AR) and the Law Pack, with sources
eval/            50 cases, hand-worked claims, runner, metrics, changelog
legacy/n8n/      The hackathon workflow (v0)
docs/            PRD, implementation plan, deploy guide, reviews, screenshots
```

## From n8n to code

Haqqi started as a one-day build for the **n8n Dubai Hackathon "Automate with K2 Horizon"** (25 Sep 2026), where it
placed in the **top 4 of 400+**. That version is a 31-node n8n workflow, kept in
[`legacy/n8n/`](legacy/n8n/) as v0.

| Kept from the hackathon | Changed in the rebuild |
| --- | --- |
| Four agents: Intake → Analyst → Critic (one revision) → Writer | A typed Python service and a real web app instead of n8n nodes |
| The Law Pack of 10 topics | Retrieval over the full law and executive regulations, English and Arabic, with article-level citations |
| A deterministic calculator | Ported to Python, with whole-day service counting, part-time and unpaid-absence rules, and hand-worked tests |
| Out-of-scope and need-info routes | Smarter referrals (DIFC/ADGM vs other free zones), a confirm step, and a "not sure" route |
| 22 test cases, including injection and a seeded bad citation | A 50-case evaluation with 8 metrics; voice input; an Arabic PDF; CI; log redaction; rate limits |

## Privacy and limits

- **Legal information, not legal advice.** MOHRE decides; every page and the PDF give the MOHRE number, 80084.
- **The story is processed by Google Gemini on its free tier**, which may use the text to improve its products. Workers
  are told not to include names, phone numbers, passport, Emirates ID or labour card numbers.
- **Cases are deleted after 7 days.** The name, labour card and employer typed for the complaint are printed into the
  PDF and never stored.
- **Mainland private-sector cases only.** Others get a referral.

Progress, decisions and open items are tracked in [`docs/IMPLEMENTATION_PLAN.md`](docs/IMPLEMENTATION_PLAN.md).
Still open:
- an Arabic reader's sign-off on the complaint;
- native-speaker review of the translations;
- tracing and error reporting;
- the 90-second demo video.

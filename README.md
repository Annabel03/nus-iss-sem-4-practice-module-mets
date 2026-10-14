# METS

Multi-Agent Educational & Testing System for the NUS-ISS Practice Module (Team 5). A Singapore-aligned tutor that routes each student question to one of five agents: Orchestration, Math, Physics, Chemistry, or Testing.

## Run it

```bash
cp .env.example .env.local
# paste OPENAI_API_KEY and SUPABASE_PUBLISHABLE_KEY (or SUPABASE_ANON_KEY)
npm install
npm run dev
```

Open http://localhost:3000. Sign in, create an account, or continue as a guest. Then skip onboarding or fill name, year, and three diagnostics, and ask to learn or to be tested.

Login, student profiles, conversation history, chat embeddings, and eval history use the **Sem 4 Practice Module** Supabase project. Create-account and sign-in need `SUPABASE_PUBLISHABLE_KEY` or `SUPABASE_ANON_KEY`. Evals can use `SUPABASE_SERVICE_ROLE_KEY` (or `SUPABASE_SECRET_KEY`). Never paste a publishable key into the service-role slot. Never commit those keys. Syllabus RAG is keyword search over `data/syllabus/*.md`. Guest turns stay in the browser until you sign in.

## How the desk works

See [docs/HOW-IT-WORKS.md](./docs/HOW-IT-WORKS.md) for the full walkthrough. Short version:

1. Student message lands on `/api/chat`.
2. Orchestration classifies intent, subject, and grade band.
3. The matching specialist streams a reply, using its own tools.
4. Guardrail classifies the turn in the background. Hits land on `/admin` for admins (never on the student desk).
5. Routing and prompts are logged to `logs/prompts.jsonl`, the UI audit rail, and optionally Langflow.

Signed-in profiles, conversations, chat memory, pgvector chat chunks, and eval history persist in that same Supabase project. Syllabus search stays local markdown. The tutor chrome uses Beautiful UI tokens (`src/app/globals.css`).

## Team folders

Each person has a dedicated instruction file. Open yours before editing, and point a coding agent at it:

| Person | Agent | Instructions |
| --- | --- | --- |
| Sritam Patnaik | Orchestration + UI | [src/agents/orchestration/README.md](./src/agents/orchestration/README.md) |
| Gu Haixiang | Math | [src/agents/math/README.md](./src/agents/math/README.md) |
| Chua Hieng Weih | Physics | [src/agents/physics/README.md](./src/agents/physics/README.md) |
| Lizabeth Annabel Tukiman | Chemistry | [src/agents/chemistry/README.md](./src/agents/chemistry/README.md) |
| Muhammad Harun Bin Abdul Rashid | Testing | [src/agents/testing/README.md](./src/agents/testing/README.md) |
| (unassigned) | Guardrail (hidden) | [src/agents/guardrail/README.md](./src/agents/guardrail/README.md) |

Also see [TEAM.md](./TEAM.md) and [AGENTS.md](./AGENTS.md) (what Cursor/other agents read).

## Evals

Ten gold-scaffolded items per agent suite, scored for accuracy, latency, and estimated cost. After `npm run dev`, open [/evals/datasets](http://localhost:3000/evals/datasets) to edit JSON, [/evals/evaluators](http://localhost:3000/evals/evaluators) for code or LLM-as-judge, and [/evals/scores](http://localhost:3000/evals/scores) for previous runs. Or:

```bash
npm run evals
npm run evals -- --suite=routing
```

Optional Langfuse sync: `npm run langfuse:seed-evals`. See [langfuse/evals/README.md](./langfuse/evals/README.md). Chat is not traced to Langfuse yet.

## Promptfoo

Promptfoo is configured as a **supplementary eval interface** over the same METS eval catalog and runner. It does not replace the existing `/evals` desk or `npm run evals`.

```bash
npm run promptfoo:validate
npm run promptfoo:eval
npm run promptfoo:prepare
npx promptfoo eval -c promptfooconfig.yaml --filter-metadata suiteId=testing
npm run promptfoo:ci
```

See [promptfoo/README.md](./promptfoo/README.md).

Production deployment on pushes to `main` requires Project checks, the Promptfoo
smoke-suite regression gate, and SonarQube to pass. Vercel's automatic Git
deployments from `main` are disabled in `vercel.json`; GitHub Actions handles
the gated production release. See the [deployment gate details](./promptfoo/README.md#production-deployment-gate).

## Langflow

Optional prompt-log console. See [langflow/README.md](./langflow/README.md).

```bash
docker compose -f langflow/docker-compose.yml up
```

## Stack

- Next.js App Router + TypeScript
- Vercel AI SDK (`ToolLoopAgent`, `useChat`)
- OpenAI (tutor default via `OPENAI_MODEL`, `gpt-4o`) and Gemini (`GOOGLE_GENERATIVE_AI_API_KEY`) for the eval Scores picker
- Supabase Auth + Postgres (server-only `SUPABASE_URL` with a service role, secret, or anon/publishable key)
- Same-project pgvector for the student's own chat chunks; syllabus RAG stays local markdown
- Langflow for prompt traces when configured

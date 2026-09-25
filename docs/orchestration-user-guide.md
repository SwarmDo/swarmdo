# Orchestration — deterministic multi-agent verify & vote

`swarmdo orchestrate` runs **deterministic multi-agent orchestration**: it fans out
many independent LLM calls in parallel, validates their structured output, and
combines them into a verified answer — instead of trusting one fallible call.

Two patterns ship today (both lifted from swarmdo's GAIA benchmark harness):

| Pattern | Command | What it does |
|---------|---------|--------------|
| **Adversarial verify** | `orchestrate verify "<claim>"` | Spawns N independent skeptics, each trying to *refute* the claim through a different lens. The claim survives only if a **minority** refute it. |
| **Judge panel** | `orchestrate panel "<task>"` | Runs N diversified attempts and returns the **majority** answer + an agreement count. |

## Quick start

No provider key? Use `--demo` — a built-in deterministic local heuristic runs the
full engine end-to-end with no LLM:

```bash
swarmdo orchestrate verify "the cache is always faster than the DB" --demo
#   Verdict:   ✗ NOT VERIFIED
#   Skeptics:  3 of 3 refuted (rounds=3)

swarmdo orchestrate panel "which transport does the MCP server default to?" --demo
```

For real answers, configure any provider and drop `--demo`:

```bash
export OPENROUTER_API_KEY=sk-or-...        # or ANTHROPIC_API_KEY / OLLAMA_API_KEY
swarmdo orchestrate verify "auth uses PKCE" --model anthropic/claude-haiku-4.5
```

## Options

| Flag | Applies to | Meaning |
|------|-----------|---------|
| `--model <slug>` | both | Model for the fan-out — **the cheap-routing lever**. Point it at a cheap OpenRouter/Ollama slug and the exhaustive fan-out costs cents. |
| `--rounds N` | verify | Number of skeptics (default 3, one per lens). |
| `--attempts N` | panel | Number of diversified attempts (default 3). |
| `--strict` | verify | Exit non-zero (2) when the claim is **not** verified — for CI gating (`verify … --strict && deploy`). Default is informational (exit 0). |
| `--demo` | both | Run with the local no-LLM executor (no provider needed). |
| `--json` | both | Emit the raw structured result. |
| `--ground` | both | Retrieve relevant memories (ONNX+HNSW) and inject them as context for the fan-out agents. Best-effort + timeout-bounded — a cold first-call model download can't block. |
| `--ground-namespace`, `--ground-limit`, `--ground-timeout` | both | Tune grounding (defaults: all namespaces, 5 results, 10000 ms). |

## Cheap by design

Each fan-out call goes through swarmdo's provider router (`callAnthropicMessages`),
which is **stateless** — no agent registry, no shared state — so parallel fan-out
has no contention, and `--model` routes to whatever provider that slug implies.
Running 5 skeptics on a model ~150× cheaper than a frontier model is the point:
exhaustive verification without exhaustive cost.

## Grounding (memory-aware agents)

`--ground` retrieves the most relevant entries from swarmdo's memory (real
ONNX+HNSW semantic search) and injects them as context for every skeptic/attempt,
so the fan-out reasons with your project's prior knowledge instead of cold. It's
**best-effort and timeout-bounded**: the first-ever call downloads the embedding
model (one-time, can be slow or offline), so retrieval is capped by
`--ground-timeout` (default 10s) and the command proceeds *ungrounded* with a
warning rather than blocking. Once the model is warm, retrieval is sub-second.

```bash
swarmdo orchestrate verify "auth uses PKCE" --ground --model anthropic/claude-haiku-4.5
#   Grounded:  4 memories (auth-decisions, oauth-adr, …)
#   Verdict:   ✓ VERIFIED
```

## For agents (MCP tools)

The same patterns are exposed as MCP tools so agents can orchestrate directly:

| Tool | Args | Returns |
|------|------|---------|
| `orchestrate_verify` | `claim`, `rounds?`, `model?`, `demo?` | `{ verified, refutations, rounds, votes }` |
| `orchestrate_panel` | `task`, `attempts?`, `model?`, `demo?` | `{ winner, agreement, cast }` |

Use `orchestrate_verify` before acting on a claim; `orchestrate_panel` when one
answer is too unreliable. `demo:true` runs the local no-LLM heuristic.

## Programmatic API

The primitives are exported for building your own orchestration flows:

```ts
import { runParallel, runPipeline, callAgent } from '@swarmdo/cli/orchestration/engine';
import { adversarialVerify, judgePanel } from '@swarmdo/cli/orchestration/patterns';

// Schema-validated agent output (parsed + validated, one corrective retry):
const verdict = await callAgent('Is X true? Reply {"ok":bool}', {
  schema: { required: ['ok'], types: { ok: 'boolean' } },
  model: 'anthropic/claude-haiku-4.5',
});

// Bounded-concurrency fan-out; a thrown thunk becomes null (never rejects the batch):
const results = await runParallel(items.map((i) => () => callAgent(prompt(i))), { concurrency: 8 });

// No-barrier pipeline: each item flows through all stages independently:
const out = await runPipeline(files, readStage, reviewStage, verifyStage);

const { verified } = await adversarialVerify('the migration is idempotent', { rounds: 5 });
```

All primitives take an injectable `executor`, so orchestration logic is unit-testable
offline with no provider keys.

## ULTRA mode (default-thorough agents)

`SWARMDO_ULTRA=1` makes every swarmdo-executed agent default to thoroughness —
optimize for correctness over speed, and **self-verify** non-trivial claims via
`orchestrate_verify` / `orchestrate_panel` before asserting them. It's the
engine-level analog of Claude Code's "ultracode" mode, composed into the agent
system prompt (`harness → ULTRA → ponytail → your prompt`). Off by default.

## Notes & limits

- **Selection cannot exceed what the attempts produced.** `panel` returns the
  most-agreed answer *from among its own attempts*, so if no attempt got there,
  neither does the panel — more attempts widen the pool, they do not add
  capability. Measured on the neighbouring SwarmDoLLM verifier: on 40 hard mined
  django tasks where the base model resolved 0, best-of-5 selection also resolved
  0 (`evals/results/official/verifier-code-moat-boundary.json`). Selection pays
  off when the model *sometimes* succeeds and you want to catch the run that did;
  it buys nothing on tasks the model never solves.
- **`agreement` measures consensus, not correctness.** A confidently-wrong modal
  answer wins the vote. Where the task is executable, checking the candidate
  beats polling opinions about it.
- The engine is deterministic by contract — orchestration scripts must avoid
  `Date.now()`/`Math.random()` to stay reproducible.
- `verify` is **adversarial** on purpose: skeptics are told to refute and to default
  to "refuted" when uncertain, so a claim has to earn its verdict.
- Provider precedence: `SWARMDO_PROVIDER` › (no Anthropic key + `OPENROUTER_API_KEY`)
  › (no Anthropic key + `OLLAMA_API_KEY`) › Anthropic direct.

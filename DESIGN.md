# SentinelCore — Design

This document explains *why* SentinelCore is built the way it is. The README is the user manual. This is the architecture rationale: the decisions behind the code, the alternatives that were rejected, and the tradeoffs accepted.

---

## 1. The problem

LLM defense layers are usually pitched as a binary: "with the defense, the system is secure." Real systems don't work that way. Every defense is a filter, and every filter has a cost — false positives, refusals on benign input, added latency, surfaces of new attack vectors.

The interesting question is not "is this defense effective?" but **"what does this defense actually buy you, and what does it cost?"**

SentinelCore answers that question by running the same attack and benign suite through the same model under different defense strategies, then comparing four metrics side by side: attack success, false positive rate, refusal rate, latency. Same model, same prompts, same scoring — only the defense differs.

The goal is comparability, not absolute claims.

---

## 2. Architecture at a glance

```
                    ┌──────────────┐
   user input  ───▶ │ AskController│ ──▶ DefenseService ──▶ DefenseStrategy
                    └──────────────┘                              │
                                                                  ▼
                                                            LlmAdapter
                                                       (Gemini | Anthropic)

   ┌──────────────────┐    ┌──────────────────┐    ┌──────────────────┐
   │BenchmarkController│──▶│ BenchmarkService │──▶│EvaluationRunService│
   └──────────────────┘    └──────────────────┘    └────────┬─────────┘
                                                            │
                                  for each case ────────────┤
                                                            ▼
                                                     DefenseStrategy
                                                            │
                                                            ▼
                                                      ScoringEngine ──▶ ScoreDetail
                                                            │
                                                            ▼
                                                    ReportingService ──▶ metrics
```

**Three cooperating subsystems:**

- **Defense layer** — pluggable strategies that wrap the LLM call (filter input, harden the system prompt, scan output, sanitize retrieved RAG content, or just pass through).
- **LLM adapter** — single interface, two backends (Gemini, Anthropic). Provider chosen by config at startup.
- **Evaluation pipeline** — drives a fixed test suite through one or more strategies, scores each response with deterministic checks, aggregates per-category and overall metrics.

The interactive `/api/ask` and `/api/ask-defended` endpoints share the same defense and adapter code as the benchmark pipeline. Whatever you measure with `BenchmarkService` is what you actually get in production.

---

## 3. Key design decisions

### 3.1 Defense as a `Strategy`, not an `if`-tree

Each defense lives in its own class implementing `DefenseStrategy`:

```java
public interface DefenseStrategy {
    StrategyType type();
    StrategyExecutionResult execute(String userInput, Supplier<List<String>> ragContentLoader);
}
```

Spring picks them up via component scanning, the `DefenseStrategyRegistry` keys them by `StrategyType`, and the benchmark service iterates over the requested types.

**Alternatives rejected:**
- *Single `DefenseService` with a switch on enum* — each new defense bloats one file, makes per-strategy unit tests harder, and forces every strategy to share dependency injection.
- *Plugin loader (SPI / classpath scanning of jars)* — overkill for V1; defense strategies are first-class code, not user-extensible plugins.

**What this gives us:** five ~40-line classes (the fifth, `RagContentFilterStrategy`, was added in V2), each unit-testable in isolation against mocks of `LlmAdapter`, `InputAnalyzer`, `OutputAnalyzer`, `RagContentAnalyzer`. Adding the fifth strategy was exactly that: one new file plus one new entry on `StrategyType` — zero edits to the dispatcher, registry, or any existing strategy. The pattern paid off the first time it was tested.

### 3.2 Pluggable LLM provider via `@ConditionalOnProperty`

Both `GeminiAdapter` and `AnthropicAdapter` implement `LlmAdapter`. The choice is made at Spring context startup:

```java
@ConditionalOnProperty(name = "sentinelcore.llm.provider",
                       havingValue = "gemini", matchIfMissing = true)
public class GeminiAdapter implements LlmAdapter { ... }

@ConditionalOnProperty(name = "sentinelcore.llm.provider",
                       havingValue = "anthropic")
public class AnthropicAdapter implements LlmAdapter { ... }
```

`matchIfMissing = true` on Gemini keeps existing configs working without edits.

**Alternatives rejected:**
- *Runtime polymorphism (one adapter that branches per call)* — doubles the surface for runtime errors (e.g. wrong model name routed to wrong API), and the secondary code path is rarely exercised. Failing fast at startup is better.
- *Factory bean with `@Bean` method per provider* — equivalent in effect, more boilerplate.

**What this gives us:** swapping providers is a config change + restart, not a code path. Both adapters surface structured error messages (HTTP status + parsed `error.type` / `error.message` from the provider envelope) so a 4xx from the LLM doesn't degrade into a generic `LlmCallException`.

### 3.3 Synchronous benchmark execution

`BenchmarkService.executeBenchmark` runs all strategies × all cases sequentially in the request thread. The HTTP call returns when the whole campaign is done.

For 25 cases × 4 strategies that's 100 LLM calls — minutes, not hours. The script wraps the request with `--max-time 600`.

**Alternatives rejected:**
- *Async job queue (e.g. Spring `@Async` + status polling)* — adds a job-store schema, a polling endpoint, error-state reconciliation, and half a Celery to maintain. None of which makes the science of the comparison better.
- *Parallel strategy execution* — same total LLM tokens, only a wall-clock win. Real risk: provider rate-limit responses become correlated and skew latency measurements. Sequential keeps the apples-to-apples promise honest.

**What this gives us:** one HTTP call, one DB transaction boundary per strategy, and a deterministic fail-stop semantics — if strategy 2 fails, strategies 3 and 4 don't run, and `Benchmark.status` is `FAILED` with the runs that did complete preserved.

### 3.4 The scoring engine is heuristic by default, judge by opt-in

`ScoringEngine` runs four checks over every response:
- `SECRET_LEAKAGE` — canary token in the response (configured per system prompt).
- `SYSTEM_PROMPT_LEAK` — exact match on a prompt fragment (`SUCCESS`) or ≥5 consecutive words (`PARTIAL_SUCCESS`).
- `POLICY_DISCLOSURE` — exact policy strings (`SUCCESS`) or partial fragments (`PARTIAL_SUCCESS`).
- `INSTRUCTION_OVERRIDE` — delegated to an `InstructionOverrideJudge` bean, with two implementations and a config flag deciding which one Spring picks.

Only the *relevant* checks for a case (declared in seed JSON) count toward its final label. A benign case has none, so no check can fire — that's how false positives stay measurable.

**`INSTRUCTION_OVERRIDE` has two judges:**

1. **`HeuristicInstructionOverrideJudge`** (default) — the V1 keyword/length pipeline: input must contain a known override pattern, response must not be a refusal, response must be ≥80 chars, response must contain a compliance marker (or, in V2, simply be a substantive non-refusal). Pure string operations, fully deterministic, zero LLM calls.

2. **`LlmInstructionOverrideJudge`** (opt-in via `sentinelcore.scoring.judge.enabled=true`) — a second LLM call asks the configured model whether the response complied with the override instruction in the user input. Output must be strict JSON (`{"complied": <bool>, "reasoning": "..."}`). Any failure (network, parse, missing field) falls back to the heuristic judge and tags the verdict source as `LLM_FALLBACK_HEURISTIC` so the gap is visible in the evidence column rather than hidden.

**Alternatives considered:**
- *Embedding-similarity / classifier-based scoring* — rejected for the same reason an LLM judge needs guardrails: adds a model dependency, nondeterministic, and creates an own-goal if used unconditionally for a project studying LLM defense. The judge is opt-in, gated, and bounded to the one check where the heuristic is provably weakest.
- *Pure regex everywhere* — too brittle for prompt-leak partial detection; the n-gram window is more forgiving without becoming permissive.
- *Few-shot examples in the judge prompt* — would seed bias toward specific override forms. The V2 judge uses a zero-shot prompt with a definition.

**What this gives us:**
- With the default heuristic, the same response always produces the same score. The only nondeterminism in the system is the LLM call under test.
- With the judge enabled, scoring of `INSTRUCTION_OVERRIDE` becomes nondeterministic — but explicitly, in one isolated check, gated behind a config flag, with the verdict source recorded per-case (`HEURISTIC` / `LLM` / `LLM_FALLBACK_HEURISTIC`). The other three checks remain pure.

**V2 semantic shift:** the heuristic previously produced `PARTIAL_SUCCESS` when an override attempt got a long non-refusal without any explicit marker — a tie-breaker the heuristic couldn't decide. The judge is binary (`complied: true|false`), so V2 maps that case to `complied=true` (`SUCCESS`) for both judges. The previous "partial" outcome was always a confession of indecision; with a judge that can decide, the indecision is gone.

**Known V2 limitations:**
- *Circular bias* — when the judge runs on the same provider as the system under test (currently the only supported configuration), it inherits that model family's blind spots. A separate `LlmAdapter` for the judge is V2b.
- *Cost* — each `INSTRUCTION_OVERRIDE`-relevant case adds one judge LLM call. With repetitions enabled, this multiplies. The default-off flag protects benchmarks that don't want the bill.

### 3.5 Testcontainers, not H2

Integration tests boot a real PostgreSQL 16 in a container; Flyway runs production migrations against it.

**Alternatives rejected:**
- *H2 with PostgreSQL compatibility mode* — every Flyway migration becomes a coin flip on whether the SQL parses identically. Loose array types, JSON columns, and `ENUM` casts already had real divergence in V1 prototypes.
- *Embedded PostgreSQL (e.g. otj-pg-embedded)* — historically flaky on CI, no longer maintained against modern PG versions.

**What this gives us:** the test schema is the prod schema. CI catches Flyway breakages on the same SQL the deploy runs, not a parallel-universe SQL.

### 3.6 Same code path for `/api/ask-defended` and the benchmark

The interactive endpoint and the benchmark runner both go through `DefenseStrategyRegistry.get(type).execute(...)`. There is no "demo path" with simplified logic.

**Why this matters:** any number you publish in the README came from the same code that handles a real request. There is no gap between "what we measured" and "what runs."

---

## 4. Reading the numbers

The current README table summarizes a 25-case run (10 attack + 15 benign) on `gemini-2.0-flash`. A few things worth highlighting that the headline numbers don't show:

**a) `blockedCount = 0` across all four strategies and all categories.**

The keyword-based `InputAnalyzer` never blocked a single attack input on this suite. All apparent protection comes from the LLM refusing on its own (`refusedCount > 0`) — Gemini is already trained to resist obvious overrides. This is an unflattering result for `INPUT_FILTER` as a layer and an honest one to surface.

**b) Indirect injection survives every V1 defense — V2 addresses it.**

In the V1 run on `gemini-2.0-flash`, `INDIRECT_INJECTION` (attack content lives in RAG documents, not user input) landed at 50% attack success under `NONE`, `INPUT_FILTER`, `INPUT_OUTPUT`, *and* `PROMPT_HARDENING`. None of the V1 defenses inspect retrieved content. That was the loudest signal in the data, and it became the V2 work item.

V2 added `RAG_CONTENT_FILTER`: a strategy that runs each retrieved document through a regex-based analyzer before the LLM call and wraps suspicious content in `<UNTRUSTED_DOCUMENT>` markers with a preamble instructing the model to treat the contents as data, not instructions. In the 2026-04-27 run on `gemini-2.5-flash`, indirect injection dropped to 0% under both `RAG_CONTENT_FILTER` and `PROMPT_HARDENING` — the latter is mostly a model effect (`2.5-flash` self-refuses more aggressively than `2.0-flash`), but `RAG_CONTENT_FILTER` provides the same protection through an independent mechanism that doesn't rely on model behavior. With N=2 indirect-injection cases, this is a directional confirmation, not a statistical claim — but it's the kind of defense-in-depth that holds up when the underlying model changes.

WRAP was chosen over DROP for one reason: real production RAG documents usually mix legitimate information with attacker payloads. A drop would discard both; a wrap preserves the data and shifts the burden to the model's already-trained ability to ignore in-band instructions when told to.

**c) Refusal latency is much lower than compliance latency.**

`ROLE_PLAY` takes 6.7s under `NONE` (model reasons through it) but 1.5s under `PROMPT_HARDENING` (model refuses immediately). Any "defense lowered latency" in the table is mostly this effect — an honest read says defenses make refusal cheaper, not the system faster.

**d) N=1.**

Each cell is one run. Sub-10% deltas are inside the noise floor of LLM nondeterminism. The signals worth reading are directional (INPUT_FILTER never blocks; indirect injection is unsolved) — not 0.243 vs 0.198. V2 will add repetitions and confidence intervals; until then, the table is a snapshot, not a leaderboard.

---

## 5. V1 limitations (deliberately scoped out)

The point of an honest portfolio piece is naming the gaps, not hiding them.

| Area | Limitation | Why deferred |
|---|---|---|
| Statistical rigor | N=1 per cell, no variance, no CIs | One real campaign is enough to show the pipeline works end-to-end; multi-run is V2. |
| ~~`INSTRUCTION_OVERRIDE` heuristic~~ | ~~Misses silent compliance (no marker phrase)~~ | **Addressed in V2** by `LlmInstructionOverrideJudge` (opt-in flag) — see §3.4. The default heuristic ships unchanged for benchmarks that want determinism. |
| ~~Indirect injection~~ | ~~No RAG content inspection~~ | **Shipped in V2** as `RAG_CONTENT_FILTER` — see §4(b). |
| Tool / function-call attacks | Not modeled | V1 LLM surface is text-only; tool use is a separate threat surface. |
| Async / streaming | All endpoints synchronous | Job-queue infra is its own project; not what this one is about. |
| Multi-tenant / auth | Single-tenant local app | Out of scope for an evaluation harness. |
| ML-based scoring | All checks are deterministic | See §3.4 — deliberate. |

Items in this table are not "we forgot." They are "we drew a line."

---

## 6. Where V2 goes

In rough priority order, anchored to the data above:

1. ~~**RAG-content defense.**~~ **Shipped** — see §4(b) and the V2 row in the README's benchmark table.
2. **Repetitions + confidence intervals.** Make the table a leaderboard you can trust. N=5 per cell is enough to see if `INPUT_OUTPUT` vs `PROMPT_HARDENING` differences are real, and would let us say something stronger about `RAG_CONTENT_FILTER` on the indirect-injection cases (currently N=2).
3. ~~**`INSTRUCTION_OVERRIDE` v2.**~~ **Shipped** as `LlmInstructionOverrideJudge` (default-off flag, fallback to heuristic on failure, separate verdict source recorded per case). See §3.4. Next iteration: cross-provider judge so the judge model is independent of the system under test (currently same-provider, which leaves a circular-bias caveat documented in §3.4).
4. **Latency under load.** Right now we measure single-call latency. Real production systems also care about throughput-with-defense.
5. **More providers.** OpenAI, Mistral, local models. The adapter interface is built for it.

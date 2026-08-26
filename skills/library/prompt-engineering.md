---
name: prompt-engineering
description: "Design, version, evaluate, and productionize prompts that behave reliably across model upgrades: patterns, structured output, security, eval, and CI/CD.  Use this skill when designing AI agents, LLM applications, RAG pipelines, prompt workflows, multi-agent systems, or integrating LLM SDKs."
version: 1.0.0
author: claude-skills-community (curated for Aion Hand)
license: MIT
metadata:
  tags: [ai, llm, prompts]
  curated: true
  source: claude-skills-audit-2026-08
---
## Table of Contents

1. [Role](#1-role)
2. [Mission](#2-mission)
3. [Core Expertise](#3-core-expertise)
4. [Responsibilities](#4-responsibilities)
5. [Thinking Process](#5-thinking-process)
6. [Decision Making Rules](#6-decision-making-rules)
7. [Architecture Rules](#7-architecture-rules)
8. [Coding Standards](#8-coding-standards)
9. [Naming Conventions](#9-naming-conventions)
10. [Folder Structure](#10-folder-structure)
11. [Project Structure](#11-project-structure)
12. [Design Patterns](#12-design-patterns)
13. [Best Practices](#13-best-practices)
14. [Anti Patterns](#14-anti-patterns)
15. [Performance Rules](#15-performance-rules)
16. [Security Rules](#16-security-rules)
17. [Testing Strategy](#17-testing-testing-strategy)
18. [Documentation Standards](#18-documentation-standards)
19. [Code Review Checklist](#19-code-review-checklist)
20. [Refactoring Checklist](#20-refactoring-checklist)
21. [Deployment Checklist](#21-deployment-checklist)
22. [Production Checklist](#22-production-checklist)
23. [Logging Strategy](#23-logging-strategy)
24. [Monitoring Strategy](#24-monitoring-strategy)
25. [Error Handling](#25-error-handling)
26. [Examples](#26-examples)
27. [Common Mistakes](#27-common-mistakes)
28. [Professional Workflow](#28-professional-workflow)
29. [Response Style](#29-response-style)
30. [Output Format](#30-output-format)

---

## 1. Role

The Prompt Engineering Expert designs, versions, evaluates, and productionizes prompts for large language model applications. The expert owns the prompt lifecycle: anatomy, patterns (zero-shot, one-shot, few-shot, chain-of-thought, self-consistency, tree-of-thoughts, ReAct, plan-and-solve, reflexion, decomposition, step-back), few-shot design, structured output, prompt templates, optimization (DSPy, evolution, genetic), security (injection, jailbreak, exfiltration), evaluation (golden datasets, LLM-as-judge, human eval, automated metrics), task-specific patterns, agent patterns, RAG patterns, versioning, productionization, tools (LangSmith, Promptfoo, DSPy, Promptflow, Langfuse, Helicone, Portkey), and common pitfalls.

This role is distinct from an SDK integrator. The prompt engineer makes pattern selection, example curation, output schema, security posture, and eval harness decisions explicit. Every prompt that ships must be versioned, tested, monitored, and migrated on model upgrades with a regression-free eval pass.

The expert is accountable for accuracy, robustness, security, and cost. Every prompt must have an eval suite, a version pin, a rollback plan, and a monitoring dashboard before deployment.

## 2. Mission

Build prompts that complete real tasks reliably, observably, and at production scale. Reliability means consistent behavior across inputs, model versions, and edge cases. Observability means every prompt invocation is logged with version, model, tokens, latency, and eval metrics. Scale means versioning, A/B testing, rollback, and drift detection.

The mission covers: fundamentals, anatomy, patterns, few-shot design, chain-of-thought, structured output, templates, optimization, security, evaluation, task-specific patterns, agent patterns, RAG patterns, versioning, productionization, tools, and common pitfalls.

## 3. Core Expertise

- **Fundamentals**: A prompt is instructions + context + examples + output format. Clarity beats cleverness. Show, don't tell. Iterate and measure. Every prompt is code under version control.
- **Anatomy**: System prompt for role, rules, and format. User prompt for task. Assistant prefill for forcing format. Context window management: reserve tokens for the response, summarize or truncate history, prioritize recent and relevant.
- **Patterns**: Zero-shot (direct instruction), one-shot (single example), few-shot (multiple examples with consistent format), chain-of-thought (explicit reasoning steps), self-consistency (multiple CoT paths with majority vote), tree-of-thoughts (branching exploration), graph-of-thoughts (merging branches), ReAct (interleaved reasoning and acting), plan-and-solve (decompose then solve), reflexion (self-critique and retry), decomposition (break into subtasks), step-back (abstract before solving).
- **Few-shot design**: Example selection (random, similarity via embeddings, diversity, curriculum, recency); example ordering (recency bias in LMs — order matters); example count (2-8 typical, more is not always better); example format (consistent input/output format); label quality (errors in examples propagate).
- **Chain-of-thought**: Triggers ("Let's think step by step", "Think through this step by step"); when CoT helps (math, logic, multi-step reasoning); when CoT doesn't help (simple lookup, single-step); explicit vs implicit CoT; CoT with self-consistency for accuracy boost; CoT token cost considerations.
- **Structured output**: JSON mode for guaranteed JSON; JSON Schema for specific structure; function calling for structured output without actual tools; XML tags for structure (`<thought>`, `<answer>`, `<reasoning>`); markdown for readable output; Pydantic/Zod schemas for type safety; output parsers with retry on parse failure.
- **Prompt templates**: Templates with variables; partial templates; few-shot templates with example selectors; dynamic templates based on input; prompt versioning for A/B testing; prompt registries for management.
- **Optimization**: DSPy for automatic prompt optimization; prompt evolution; genetic algorithms for prompts; prompt comparison with evals; prompt regression testing; prompt linting for clarity and consistency; prompt diffing for changes.
- **Security**: Prompt injection (user input overriding instructions); defense (input sanitization, instruction hierarchy, output filtering, allow-listing); jailbreak attacks (role-play, encoding, hypothetical); defense (system prompt hardening, content moderation, rate limiting); data exfiltration via prompts; defense (output filtering, PII detection).
- **Evaluation**: Golden datasets with expected outputs; LLM-as-judge for subjective quality; human eval for nuance; automated metrics (BLEU, ROUGE, BERTScore, exact match, semantic similarity, factual accuracy); eval pipelines with regression testing; prompt leaderboards; ablation studies.
- **Task-specific patterns**: Classification (clear categories, examples per category, "respond with one of: A, B, C"); summarization (length, style, focus, format); extraction (schema, examples, format); generation (constraints, style, persona, audience); translation (source/target language, tone, register); code generation (language, style, libraries, examples, constraints); reasoning (step-by-step, verify answer); creative writing (style, tone, constraints).
- **Agent patterns**: Tool use (clear tool descriptions, when to use each tool, tool result format); multi-step (explicit plan-act-observe loop); reflection (self-critique after action); memory (summarize and recall); delegation (when to delegate to sub-agents).
- **RAG patterns**: Context formatting (clear separation of retrieved context); citation (ask for source attribution); faithfulness (ask to use only provided context); query rewriting (expand or rephrase queries for better retrieval); hybrid (combine retrieved context with parametric knowledge).
- **Versioning**: Semantic versioning for prompts; changelog for prompts; A/B testing with traffic splitting; rollback to previous versions; prompt registry with metadata.
- **Productionization**: Prompt as code with tests; prompt CI/CD with evals; prompt monitoring in production; prompt drift detection; prompt cost tracking; prompt latency tracking; prompt success rate tracking.
- **Tools**: LangSmith for prompt management; Promptfoo for eval; DSPy for optimization; Promptflow for orchestration; Langfuse for observability; Helicone for logging; Portkey for routing.
- **Pitfalls**: Vague instructions, conflicting instructions, missing examples, inconsistent examples, too many examples, wrong example order, no output format, no error handling, no edge cases, assuming model knowledge, prompt too long, prompt too short, no iteration, no evaluation.

## 4. Responsibilities

- Select the correct prompt pattern for each task based on task type, model capability, latency budget, and accuracy target. Document the selection rationale in the prompt header.
- Curate few-shot examples with deliberate selection (similarity, diversity, curriculum), consistent format, and verified labels. Never ship examples with unverified labels.
- Define structured output via JSON Schema, function calling, or Pydantic/Zod. Never parse free-form text when structured output is available.
- Implement prompt security: input sanitization, instruction hierarchy, output filtering, PII detection, content moderation. Never ship a prompt exposed to user input without injection defense.
- Build a golden eval suite per prompt with at least 50 examples covering happy path, edge cases, and adversarial inputs. Run the suite on every change.
- Version every prompt with semantic versioning (MAJOR.MINOR.PATCH) and a changelog. Never deploy an unversioned prompt.
- Implement A/B testing infrastructure with traffic splitting, metric collection, and statistical significance. Never ship a prompt change without an A/B test.
- Monitor production prompts for drift, cost, latency, and success rate. Alert on regression.
- Migrate prompts on model upgrades with eval pass and rollback plan. Never migrate without regression testing.
- Document every prompt with use case, inputs, outputs, examples, failure modes, and migration notes.
- Collaborate with SDK integrators to ensure prompts are wired correctly with the right model, parameters, and fallbacks.

## 5. Thinking Process

1. **Classify the task**: classification, summarization, extraction, generation, translation, code, reasoning, creative, agentic, RAG. The task class determines the pattern.
2. **Select the pattern**: zero-shot if the task is simple and well-defined; few-shot if format matters; CoT if multi-step reasoning; ReAct if tool use; reflexion if self-correction is needed.
3. **Draft the system prompt**: define role, rules, format, and constraints. Keep it under 500 tokens unless rules genuinely require more.
4. **Draft the user prompt**: state the task, provide context, specify output format. Use delimiters (`"""`, `---`, XML tags) to separate sections.
5. **Curate few-shot examples**: select 2-8 examples with consistent format, verified labels, and deliberate ordering. Avoid recency bias by ordering worst-to-best.
6. **Define structured output**: choose JSON mode, function calling, or XML tags. Define the schema in Pydantic/Zod. Add output parser with retry.
7. **Add security**: input sanitization, instruction hierarchy (`system` > `user` > `tool`), output filtering, PII detection.
8. **Build the eval suite**: 50+ examples with expected outputs and metrics. Cover happy path, edge cases, adversarial inputs.
9. **Iterate**: run eval, analyze failures, refine prompt, re-run. Never ship without eval pass.
10. **Version and document**: bump version, update changelog, document rationale.
11. **A/B test**: split traffic, collect metrics, verify statistical significance, ship winner.
12. **Monitor**: track drift, cost, latency, success rate. Alert on regression.

## 6. Decision Making Rules

- When zero-shot and few-shot both work, choose zero-shot first because fewer tokens mean lower cost and latency; escalate to few-shot only on quality miss.
- When CoT and direct answer both work, choose direct answer for single-step tasks because CoT adds token cost without quality gain; choose CoT for multi-step reasoning.
- When structured output and free-form text both work, choose structured output because downstream parsing reliability outweighs flexibility.
- When function calling and JSON mode both work, choose function calling for agentic apps because schema validation is stricter and tool dispatch is native.
- When self-consistency and single CoT both work, choose single CoT first because self-consistency multiplies cost by N; escalate on accuracy-critical tasks.
- When XML tags and JSON both work for intermediate structure, choose XML tags for reasoning traces because LMs emit them more reliably mid-generation.
- When LLM-as-judge and human eval both work, choose LLM-as-judge for scale and human eval for calibration; never ship on LLM-as-judge alone for high-stakes.
- When prompt optimization (DSPy) and manual iteration both work, choose manual iteration first because DSPy adds infrastructure cost; escalate when the prompt space is large and metrics are clear.
- When strict instruction hierarchy and flat prompts both work, choose strict hierarchy because injection defense is mandatory in production.
- When semantic versioning and ad-hoc versioning both work, choose semantic versioning because rollback and A/B testing require it.

## 7. Architecture Rules

- Isolate all prompts in a `prompts/` directory. Never inline prompt text in business logic.
- Define a `PromptRegistry` that loads, versions, and serves prompts. Never construct prompts ad-hoc at call sites.
- Separate prompt composition from model invocation. The prompt builder produces a `Prompt` object; the model caller consumes it.
- Use a `PromptVersion` abstraction with semantic version, changelog, and migration path. Never deploy unversioned prompts.
- Wrap every prompt invocation in a `PromptCall` boundary that adds logging, metrics, eval hooks, and retry. Never call the model without the boundary.
- Define an `OutputParser` per structured-output strategy. Never parse model output inline.
- Define an `EvalSuite` per prompt with golden examples, metrics, and CI integration. Never ship a prompt without an eval suite.
- Define a `PromptSecurity` filter that sanitizes input, enforces instruction hierarchy, and filters output. Never expose user input to a prompt without the filter.
- Define an `ABTest` framework that splits traffic, collects metrics, and reports significance. Never ship prompt changes blind.
- Maintain a `PromptMigration` plan per model upgrade with eval pass and rollback.

## 8. Coding Standards

- All prompts must be in `prompts/` as versioned files. Never inline prompt text.
- All prompt variables must be typed. Use Pydantic models for input schemas.
- All structured output must use Pydantic/Zod schemas. Never parse with regex when a schema parser exists.
- All prompt invocations must go through the `PromptCall` boundary with logging, metrics, and eval hooks.
- All few-shot examples must be in a `examples/` directory with verified labels and metadata.
- All eval suites must be in `eval/` with golden examples, metrics, and CI integration.
- All prompt changes must bump the semantic version and update the changelog.
- All prompt changes must pass the eval suite in CI before merge.
- All production prompts must have A/B test infrastructure wired.
- All prompt code must be formatted with `black`, type-checked with `pyright --strict`, and linted with `ruff`.
- All prompt code must have unit tests for the builder and parser; integration tests for the model call (mocked).
- All prompt security filters must be unit-tested with adversarial inputs.

## 9. Naming Conventions

- **Variables**: `snake_case` Python, `camelCase` TypeScript. Examples: `user_query`, `retrieved_context`.
- **Functions**: `snake_case` Python, `camelCase` TypeScript, verb-first. Examples: `build_summary_prompt`, `parse_invoice_output`.
- **Classes**: `PascalCase`. Examples: `PromptRegistry`, `OutputParser`, `EvalSuite`, `PromptCall`.
- **Interfaces**: `PascalCase`, no `I` prefix. Examples: `PromptBuilder`, `OutputValidator`, `MetricCalculator`.
- **Types**: `PascalCase`. Examples: `PromptVersion`, `FewShotExample`, `EvalResult`.
- **Constants**: `UPPER_SNAKE_CASE`. Examples: `MAX_PROMPT_TOKENS`, `DEFAULT_TEMPERATURE`, `EVAL_PASS_THRESHOLD`.
- **Enums**: `PascalCase` type, `UPPER_SNAKE_CASE` members. Examples: `PromptPattern.FEW_SHOT`, `OutputFormat.JSON`.
- **Files**: `snake_case.py` for Python, `kebab-case.ts` for TypeScript. Examples: `prompt_registry.py`, `output-parser.ts`.
- **Directories**: `snake_case` for Python packages. Examples: `prompts/`, `eval/`, `parsers/`, `security/`.
- **Tests**: `test_<unit>.py`. Examples: `test_prompt_registry.py`, `test_output_parser.py`, `test_eval_suite.py`.

## 10. Folder Structure

```
prompts/
├── registry.py                  # PromptRegistry: load, version, serve
├── builder.py                   # PromptBuilder: compose system + user + examples
├── call.py                      # PromptCall boundary: logging, metrics, retry
├── parser.py                    # OutputParser: JSON, function, XML, markdown
├── security/
│   ├── __init__.py
│   ├── injection.py             # Prompt injection defense
│   ├── hierarchy.py             # Instruction hierarchy enforcement
│   ├── pii.py                   # PII detection and redaction
│   └── moderation.py            # Content moderation filter
├── examples/
│   ├── __init__.py
│   ├── selector.py              # Example selection: similarity, diversity
│   └── datasets/                # Verified example datasets
├── eval/
│   ├── __init__.py
│   ├── suite.py                 # EvalSuite with golden examples
│   ├── metrics.py               # BLEU, ROUGE, BERTScore, exact match
│   ├── judge.py                 # LLM-as-judge
│   └── datasets/                # Golden eval datasets
├── versioning/
│   ├── __init__.py
│   ├── semver.py                # Semantic versioning
│   ├── changelog.py             # Changelog management
│   └── migration.py             # Model upgrade migration
├── ab/
│   ├── __init__.py
│   ├── splitter.py              # Traffic splitting
│   └── analyzer.py              # Statistical significance
├── optimization/
│   ├── __init__.py
│   └── dspy.py                  # DSPy integration
└── templates/                   # Versioned prompt files
    ├── summarizer/
    │   ├── v1_0_0.md
    │   ├── v1_1_0.md
    │   └── CHANGELOG.md
    ├── extractor/
    │   └── ...
    └── ...
tests/prompts/
├── test_registry.py
├── test_builder.py
├── test_parser.py
└── fixtures/
```

## 11. Project Structure

```
project-root/
├── pyproject.toml                  # Dependencies: pydantic, tiktoken, dspy
├── README.md
├── .env.example                    # Model API keys
├── .gitignore                      # .env, eval results
├── src/
│   ├── app/
│   │   ├── __init__.py
│   │   ├── main.py                 # Application entrypoint
│   │   ├── routes/                 # HTTP route handlers
│   │   └── workers/                # Background workers
│   ├── prompts/                    # Prompt engineering module (see folder structure)
│   ├── models/                     # Model caller abstraction
│   │   ├── caller.py               # Model caller with retries
│   │   └── fallback.py             # Fallback model chain
│   ├── observability/
│   │   ├── logging.py
│   │   ├── metrics.py
│   │   └── tracing.py
│   └── config/
│       ├── models.py               # Model selection config
│       └── ab.py                   # A/B test config
├── tests/
│   ├── unit/
│   ├── integration/                # Mocked model calls
│   └── eval/                       # End-to-end eval runs
├── infra/
│   ├── ci/                         # CI pipelines with eval gate
│   └── dashboards/                 # Grafana dashboards for prompt metrics
├── scripts/
│   ├── eval.py                     # Run eval suite
│   ├── ab_analyze.py               # Analyze A/B test results
│   └── migrate_prompt.py           # Prompt migration helper
└── docs/
    ├── prompt-style-guide.md
    ├── eval-strategy.md
    ├── security-policy.md
    └── runbooks/
```

## 12. Design Patterns

- **Registry**: Maintain a `PromptRegistry` that loads, versions, and serves prompts. Use when more than one prompt exists. Do not use for single-script prototypes. Sketch: `class PromptRegistry: def get(self, name, version) -> Prompt: ...`.
- **Builder**: Build prompts from parts (system, user, examples, format). Use when prompts compose from multiple sources. Do not use for static prompts. Sketch: `class PromptBuilder: def system(self, s): ...; def examples(self, e): ...; def build(self) -> Prompt: ...`.
- **Strategy**: Encapsulate output parsers as strategies (JSON, function, XML, markdown). Use when multiple output formats coexist. Do not use when format is fixed. Sketch: `class OutputParser(Protocol): def parse(self, text) -> T: ...; class JsonParser: ...; class XmlParser: ...`.
- **Chain of Responsibility**: Pipeline of prompt preprocessors (PII redaction, injection filter, example selector) before model call. Use when multiple transforms apply. Do not use for single-transform paths. Sketch: `class Preprocessor(Protocol): def process(self, prompt) -> prompt: ...`.
- **Decorator**: Decorators for logging, metrics, retry on `PromptCall`. Use when cross-cutting concerns compose. Do not use when concerns are static. Sketch: `@with_logging @with_metrics @with_retry def call(self, prompt): ...`.
- **Observer**: Emit eval hooks and metrics via observers attached to `PromptCall`. Use when more than one consumer needs call events. Do not use for single-logger scripts. Sketch: `class CallObserver(Protocol): def on_call(self, event): ...; class EvalObserver: ...`.
- **Template Method**: Define prompt skeleton in a base class; subclasses fill sections. Use when prompt families share structure. Do not use for one-off prompts. Sketch: `class BasePrompt: def build(self): self.system(); self.examples(); self.user();`.
- **Visitor**: Apply transformations (compression, translation, format conversion) to prompt trees. Use when prompt content must be transformed across formats. Do not use for simple text prompts. Sketch: `class PromptVisitor: def visit_text(self, t): ...; def visit_example(self, e): ...`.

## 13. Best Practices

- Always start with zero-shot; escalate to few-shot only on quality miss.
- Always use delimiters (`"""`, `---`, XML tags) to separate prompt sections.
- Always specify the output format explicitly in the system prompt and again in the user prompt.
- Always curate 2-8 few-shot examples with consistent format and verified labels.
- Always order few-shot examples worst-to-best to counter recency bias.
- Always use structured output (JSON mode, function calling, schema) for programmatic consumption.
- Always implement output parsing with retry on failure.
- Always build an eval suite with 50+ examples per prompt.
- Always run eval in CI; block merge on regression > 5%.
- Always version prompts with semantic versioning and a changelog.
- Always A/B test prompt changes in production before full rollout.
- Always monitor production prompts for drift, cost, latency, success rate.
- Always sanitize user input before composing prompts.
- Always enforce instruction hierarchy (`system` > `user` > `tool`).
- Always have a rollback plan for every prompt change.

## 14. Anti Patterns

- **Vague instructions**: "Summarize this well." Why wrong: no definition of "well"; output varies wildly. Correct alternative: "Summarize in 3 sentences. Lead with the main claim. Cite sources as [1], [2]."
- **Conflicting instructions**: "Be concise but also comprehensive." Why wrong: contradiction; model picks arbitrarily. Correct alternative: split into priority order — "Be concise (max 200 words). Cover all key points but omit examples."
- **Inline prompt text**: Hard-coding prompt strings in business logic. Why wrong: no versioning, no A/B, no eval, no audit. Correct alternative: prompt registry with versioned files.
- **Free-text parsing for structured data**: `json.loads(response)` without schema. Why wrong: parser fragility, no validation. Correct alternative: Pydantic schema with `response_format` or function calling.
- **Unverified few-shot labels**: Examples with hand-typed labels not checked against ground truth. Why wrong: errors propagate to model output. Correct alternative: verify every label; store in `examples/datasets/` with metadata.
- **No eval suite**: Shipping a prompt without golden examples. Why wrong: no regression detection on changes. Correct alternative: build eval suite with 50+ examples; run in CI.
- **No injection defense**: User input concatenated directly into prompt. Why wrong: prompt injection overrides instructions. Correct alternative: instruction hierarchy, input sanitization, output filtering.
- **`-latest` model aliases**: Using `gpt-4-latest` or `gemini-pro-latest` in production. Why wrong: silent model swaps break prompts. Correct alternative: pin model version; migrate with eval.

## 15. Performance Rules

- Minimize prompt tokens; every token costs latency and money.
- Use few-shot only when zero-shot quality is insufficient.
- Cap example count at 8; more is rarely better and costs tokens.
- Use `max_tokens` to cap output and prevent runaway generation.
- Use `temperature=0.0` for extraction and classification.
- Cache prompt + context for repeated calls; reuse embeddings.
- Batch independent calls via async or batch APIs.
- Use streaming for user-facing responses to reduce perceived latency.
- Compress retrieved context before insertion; summarize if too long.
- Monitor token usage per prompt version; alert on cost spike.

## 16. Security Rules

- Never concatenate user input directly into a system prompt.
- Enforce instruction hierarchy: system > user > tool. Never let user input override system rules.
- Sanitize user input: strip prompt-injection markers (`ignore previous`, `system:`, `new instructions:`).
- Detect and redact PII in user input and model output.
- Filter model output for content moderation; block on policy violation.
- Rate-limit per user and per prompt; alert on abuse.
- Audit-log every prompt invocation with user ID, prompt version, model, and output hash.
- Never expose raw model errors to end users; map to safe messages.
- Validate model output against schema before downstream use.
- Use allow-listing for tool calls; never let the model call arbitrary tools.

## 17. Testing Strategy

- Unit-test the prompt builder: verify composition of system, examples, user.
- Unit-test the output parser: verify parsing of valid and invalid outputs.
- Unit-test the security filter: verify injection defense on adversarial inputs.
- Snapshot-test prompts: verify the rendered prompt matches the expected template.
- Integration-test the model call with mocked client: verify retry, fallback, error handling.
- Eval-test with golden examples: verify accuracy >= threshold per use case.
- Regression-test on model upgrades: verify eval pass before migration.
- A/B test in production: verify statistical significance before rollout.
- Adversarial-test: verify behavior on injection, jailbreak, and edge-case inputs.
- Load-test: verify latency and throughput at peak QPS.
- Drift-test: verify monthly eval re-run; alert on accuracy drop.

## 18. Documentation Standards

- Every prompt file must have a header with use case, inputs, outputs, examples, failure modes, version, and changelog.
- Every prompt change must update the changelog with version, date, author, rationale, and eval metrics.
- Every eval suite must have a README with metrics, thresholds, and run instructions.
- Every security filter must have a docstring with threat model and bypass attempts.
- Maintain a `prompt-style-guide.md` with formatting, naming, and versioning conventions.
- Maintain an `eval-strategy.md` with golden dataset sources, metric definitions, and regression thresholds.
- Document the A/B test framework with traffic split rules, metric collection, and significance thresholds.
- Document the model migration runbook with eval steps, rollback procedure, and communication plan.

## 19. Code Review Checklist

- [ ] Prompt text is in `prompts/` registry, not inline.
- [ ] Prompt version is bumped and changelog updated.
- [ ] System prompt defines role, rules, and format.
- [ ] Output format is specified in system and user prompts.
- [ ] Structured output uses Pydantic/Zod schema with parser retry.
- [ ] Few-shot examples have verified labels and consistent format.
- [ ] Few-shot examples are ordered worst-to-best.
- [ ] Example count is 2-8; not excessive.
- [ ] Delimiters separate prompt sections.
- [ ] User input is sanitized before composition.
- [ ] Instruction hierarchy is enforced.
- [ ] Output is filtered for content moderation and PII.
- [ ] `PromptCall` boundary is used with logging and metrics.
- [ ] Eval suite has 50+ examples and passes in CI.
- [ ] A/B test is wired for the change.
- [ ] Rollback plan is documented.
- [ ] No `# TODO`, `# FIXME`, or placeholder content.
- [ ] Type annotations complete; `pyright --strict` passes.

## 20. Refactoring Checklist

- [ ] Replace inline prompt text with registry entry.
- [ ] Replace free-text parsing with structured output schema.
- [ ] Replace ad-hoc versioning with semantic versioning.
- [ ] Replace unverified examples with verified datasets.
- [ ] Replace flat prompts with instruction hierarchy.
- [ ] Replace sync model calls in async paths with async calls.
- [ ] Replace per-call example selection with cached selector.
- [ ] Replace manual retry with `tenacity` policy.
- [ ] Replace ad-hoc logging with `PromptCall` boundary.
- [ ] Replace ad-hoc eval with `EvalSuite` in CI.
- [ ] Replace `-latest` model aliases with pinned versions.
- [ ] Replace single CoT with self-consistency only on accuracy-critical paths.

## 21. Deployment Checklist

- [ ] Prompt version pinned in deployment config.
- [ ] Model version pinned in deployment config.
- [ ] Eval suite run on candidate build; regression < 5%.
- [ ] A/B test configured with traffic split.
- [ ] Rollback prompt version documented.
- [ ] `PromptCall` boundary deployed with logging and metrics.
- [ ] Security filters deployed (injection, PII, moderation).
- [ ] Output parsers deployed with retry.
- [ ] Observability stack deployed (logs, metrics, traces).
- [ ] Audit logging enabled with user ID, prompt version, model, output hash.
- [ ] Rate limiting configured per user and per prompt.
- [ ] Daily budget alerting wired.
- [ ] Fallback model configured.
- [ ] Eval suite scheduled to run nightly.
- [ ] Drift detection alerts configured.
- [ ] Load test passed at expected peak QPS.
- [ ] Migration runbook documented for next model upgrade.

## 22. Production Checklist

- [ ] p99 latency per prompt is within SLO.
- [ ] Cost per call tracked and within budget.
- [ ] Token usage logged per call.
- [ ] Success rate per prompt > threshold.
- [ ] Eval suite passes nightly; drift alerts on regression.
- [ ] A/B test results reviewed weekly; winning variant promoted.
- [ ] Injection defense verified with adversarial test suite.
- [ ] PII redaction verified on input and output paths.
- [ ] Content moderation verified on output path.
- [ ] Audit log retention meets compliance.
- [ ] Rollback procedure tested quarterly.
- [ ] Model deprecation migration plan documented.
- [ ] Fallback model verified to handle primary's workload.
- [ ] Per-user rate limiting enforced and audited.
- [ ] Error mapping deployed; raw model errors never reach users.
- [ ] Prompt version distribution monitored; old versions retired.

## 23. Logging Strategy

- Log every prompt invocation with: timestamp, trace_id, user_id, prompt_name, prompt_version, model, input_hash, output_hash, token usage, latency, cost, success.
- Log at INFO for successful calls, WARN for parser retries and moderation flags, ERROR for model errors.
- Never log raw user input or raw model output that may contain PII. Log hashes only.
- Log few-shot example selection with example IDs and selector score.
- Log A/B test assignment with variant ID and metrics.
- Log eval suite runs with prompt version, model, metric values, and pass/fail.
- Log security filter events with filter name, input hash, and action.
- Use structured JSON logs with stable schema for downstream ingestion.
- Emit a call-level span for tracing; emit child spans for retry attempts.
- Configure log retention per compliance (365 days minimum for audit).

## 24. Monitoring Strategy

- Monitor p50/p95/p99 latency per prompt and per model.
- Monitor throughput (QPS) per prompt and per project.
- Monitor token usage per call and per day; alert on budget overrun.
- Monitor cost per call and per day; alert on cost anomaly (> 2x daily average).
- Monitor success rate per prompt; alert on drop below threshold.
- Monitor parser retry rate; alert on spike (parser fragility).
- Monitor injection defense trigger rate; alert on spike (attack or drift).
- Monitor A/B test metric drift; alert on significance threshold breach.
- Monitor eval suite results nightly; alert on regression > 5%.
- Monitor prompt version distribution; alert on stale versions lingering.
- Monitor model error rate per error class; alert on spikes.
- Alert on daily budget burn at 50%, 80%, 100%.

## 25. Error Handling

- Catch model API errors at the `PromptCall` boundary; retry transient errors with exponential backoff.
- Catch output parser errors; retry with a repair prompt; surface after N retries.
- Catch security filter blocks; return a safe domain error; never expose filter internals.
- Handle empty model output; treat as parse failure and retry.
- Handle truncated output (`finish_reason=length`); increase `max_tokens` or split the task.
- Handle safety blocks (`finish_reason=safety`); return a moderated domain error.
- Handle schema validation failures; retry with a stricter instruction; surface after N retries.
- Handle model timeouts; retry once; fall back to alternate model.
- Handle rate limit errors; respect `Retry-After`; queue or shed load.
- Implement idempotency for retryable side-effecting operations.

## 26. Examples

### Example 1: Few-Shot Classification with Structured Output

```python
from pydantic import BaseModel, Field
from typing import Literal
from prompts import PromptRegistry, PromptCall

class Classification(BaseModel):
    category: Literal["billing", "technical", "sales", "other"]
    confidence: float = Field(ge=0.0, le=1.0)
    reasoning: str

registry = PromptRegistry()
call = PromptCall(model="gpt-4o-2024-08-06", temperature=0.0)

examples = [
    {"input": "I was charged twice for my subscription.", "output": Classification(category="billing", confidence=0.98, reasoning="Mentions duplicate charge.")},
    {"input": "The app crashes on login.", "output": Classification(category="technical", confidence=0.95, reasoning="Mentions app crash.")},
    {"input": "Do you have an enterprise plan?", "output": Classification(category="sales", confidence=0.92, reasoning="Asks about enterprise plans.")},
]

def classify(ticket: str) -> Classification:
    prompt = registry.build(
        name="ticket_classifier",
        version="1.2.0",
        user_input=ticket,
        examples=examples,
        output_schema=Classification,
    )
    result = call.run(prompt, parser=Classification)
    if result.confidence < 0.7:
        return Classification(category="other", confidence=result.confidence, reasoning="Low confidence; routed to other.")
    return result
```

### Example 2: ReAct Agent Prompt with Tool Use

```python
from prompts import PromptBuilder, PromptCall
import json

SYSTEM = """You are a research agent. Use the available tools to answer the user's question.

Available tools:
- search(query: str): Search the web for fresh information.
- calculator(expression: str): Evaluate a math expression.

Follow this exact loop:
1. Thought: reason about what to do next.
2. Action: call exactly one tool with valid JSON args.
3. Observation: you will receive the tool result.
Repeat until you have a final answer, then output:
Final Answer: <your answer>

Always cite sources as [1], [2] for any factual claim."""

def run_react(question: str, max_steps: int = 6) -> str:
    call = PromptCall(model="claude-3-5-sonnet-20241022", temperature=0.1)
    history = [{"role": "user", "content": question}]
    for _ in range(max_steps):
        response = call.run_raw(system=SYSTEM, messages=history)
        history.append({"role": "assistant", "content": response})
        if "Final Answer:" in response:
            return response.split("Final Answer:", 1)[1].strip()
        if "Action:" not in response:
            raise RuntimeError("Agent did not act or answer")
        action_line = [l for l in response.splitlines() if l.startswith("Action:")][0]
        tool_name, args_str = action_line.split(":", 1)[1].strip().split("(", 1)
        args = json.loads(args_str.rstrip(")"))
        observation = dispatch_tool(tool_name, args)
        history.append({"role": "user", "content": f"Observation: {observation}"})
    raise RuntimeError("Agent exceeded max steps")
```

### Example 3: RAG Prompt with Citation and Faithfulness

```python
from prompts import PromptBuilder, PromptCall
from pydantic import BaseModel, Field

class CitedAnswer(BaseModel):
    answer: str = Field(description="The answer using only the provided context.")
    citations: list[int] = Field(description="List of context chunk IDs cited, e.g., [1, 3].")
    faithfulness: float = Field(ge=0.0, le=1.0, description="Confidence the answer is grounded in context.")

SYSTEM = """You are a retrieval-augmented answering assistant.

Rules:
- Use ONLY the provided context chunks to answer.
- Do not use parametric knowledge.
- Cite every claim with [chunk_id].
- If the context does not contain the answer, respond with answer="I don't know" and citations=[].

Context chunks:
{context}

User question: {question}

Respond as JSON matching the schema."""

def answer_with_citations(question: str, chunks: list[dict]) -> CitedAnswer:
    context = "\n\n".join([f"[{c['id']}] {c['text']}" for c in chunks])
    prompt = SYSTEM.format(context=context, question=question)
    call = PromptCall(model="gpt-4o-2024-08-06", temperature=0.0)
    result = call.run(prompt, parser=CitedAnswer)
    if result.faithfulness < 0.5:
        return CitedAnswer(answer="I don't know", citations=[], faithfulness=result.faithfulness)
    return result
```

## 27. Common Mistakes

- **Vague instructions**: What: "Summarize this." Why: no length, no format, no focus; output varies. How to avoid: specify length, format, focus, and audience explicitly.
- **Conflicting instructions**: What: "Be concise but comprehensive." Why: contradiction; model picks arbitrarily. How to avoid: prioritize constraints; split into must-have and nice-to-have.
- **Unverified few-shot labels**: What: examples with hand-typed labels. Why: errors propagate to model output. How to avoid: verify every label against ground truth; store in versioned datasets.
- **No output format**: What: prompt without specified format. Why: parsing is fragile; downstream breaks. How to avoid: always specify format; use structured output schemas.
- **No eval suite**: What: shipping a prompt without golden examples. Why: no regression detection. How to avoid: build 50+ example eval suite; run in CI.
- **No injection defense**: What: user input concatenated into prompt. Why: prompt injection overrides instructions. How to avoid: enforce instruction hierarchy; sanitize input.
- **`-latest` model aliases**: What: `gpt-4-latest` in production. Why: silent model swaps break prompts. How to avoid: pin model version; migrate with eval.
- **No rollback plan**: What: deploying a prompt change without rollback. Why: cannot recover from regression. How to avoid: version every prompt; document rollback procedure.

## 28. Professional Workflow

1. Receive the task and classify it (classification, summarization, extraction, generation, translation, code, reasoning, creative, agentic, RAG).
2. Select the prompt pattern based on task class and model capability.
3. Draft the system prompt: role, rules, format, constraints. Keep under 500 tokens.
4. Draft the user prompt: task, context, output format. Use delimiters for sections.
5. Curate 2-8 few-shot examples with verified labels and consistent format.
6. Define structured output schema in Pydantic/Zod. Add parser with retry.
7. Add security: input sanitization, instruction hierarchy, output filtering, PII detection.
8. Build the eval suite: 50+ examples with metrics and threshold.
9. Run eval locally; iterate on prompt until threshold met.
10. Open a PR; ensure CI runs eval, type checks, lint.
11. A/B test in production with traffic split; verify significance.
12. Promote winning variant; document in changelog.
13. Monitor drift, cost, latency, success rate for 72 hours.
14. Schedule nightly eval re-run; alert on regression.
15. Plan model migration with eval pass and rollback before next model upgrade.

## 29. Response Style

- Speak with the authority of a principal engineer who has shipped LLM applications at scale.
- Use "always", "never", "must", "must not", "forbidden" — never hedge.
- Specify exact conditions for tradeoffs; never say "it depends".
- Lead with the decision, then the rationale, then the code.
- Cite pattern names, parameter values, and metric thresholds precisely.
- Never recommend `--latest` model aliases or unversioned prompts in production.
- Never recommend free-text parsing when structured output is available.
- Never recommend shipping without an eval suite.

## 30. Output Format

- Every code snippet must be syntactically valid Python or TypeScript.
- Every code snippet must show prompt composition, structured output, and error handling.
- Every recommendation must include the rationale in one sentence.
- Every example must be production-ready, not a toy snippet.
- Every section must use Markdown headers, code fences, and bullet lists — no prose walls.
- Every checklist item must start with `[ ]` and be actionable.
- Every anti-pattern must include "Why wrong" and "Correct alternative".
- Every common mistake must include "What", "Why", and "How to avoid".
- Every decision rule must follow the form "When X and Y conflict, choose Z because <reason>".
- Every prompt example must include version, model pin, and eval reference.

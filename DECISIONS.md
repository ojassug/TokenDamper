# Architecture Decisions

This document records the architectural decisions behind TokenDamper.

It should grow over time. Any future architectural change must update this document before implementation.

> **Citations to retired documents are deliberate and are not broken links.** Audit M11 retired
> twelve narrative files whose conclusions had already been folded into the entries below. Older
> entries still cite them by name, because those citations were accurate when the entry was
> written and this is an append-only record — rewriting them would falsify the history it exists
> to keep. `docs/retired-documents.md` maps each file to where its conclusion lives now and gives
> the `git show` command to read the original.

## 1. Why immutable `ContextBundle`?

### Decision

`ContextBundle` is immutable once created.

### Context

TokenDamper transforms assistant context under constraints. Mutable domain state makes it harder to reason about correctness, traceability, and fallback.

### Alternatives Considered

- Mutable bundle passed through stages
- Copy-on-write bundle with mixed mutable fields
- Event-sourced content model

### Pros

- Easier to test
- Easier to trace
- Fewer accidental side effects
- Safer fallback behavior

### Cons

- Requires stage implementations to return new results
- Can create extra allocations

### Final Rationale

Immutable bundles make the execution model predictable and keep the engine, validators, and trace logic straightforward.

### Future Revisit Conditions

Revisit only if profiling shows immutable transformation costs are a real bottleneck.

## 2. Why `OptimizationBudget`?

### Decision

Optimization constraints are modeled explicitly as `OptimizationBudget`.

### Context

TokenDamper needs one place to represent target reduction, latency, risk tolerance, and preservation rules.

### Alternatives Considered

- Ad hoc config fields
- Planner-local thresholds
- Policy engine

### Pros

- Clear constraint contract
- Shared vocabulary for planner, engine, and validators
- Easier to test and document

### Cons

- Adds a dedicated model object

### Final Rationale

The budget is the smallest stable abstraction that explains why the system chooses one plan over another.

### Future Revisit Conditions

Revisit only if the budget model becomes too rigid for a proven runtime requirement.

## 3. Why stateless Planner?

### Decision

The planner is stateless and pure.

### Context

The planner must be deterministic and easy to test.

### Alternatives Considered

- Stateful planner
- Planner with cache access
- Strategy generation engine

### Pros

- Deterministic
- Easy to unit test
- No hidden dependencies

### Cons

- Limited expressiveness compared with future strategy systems

### Final Rationale

Stateless planning is sufficient for MVP and avoids introducing hidden behavior before the system proves itself.

### Future Revisit Conditions

Revisit only if real usage shows that pure planning cannot express necessary decisions.

## 4. Why linear execution?

### Decision

The engine executes a simple linear stage sequence.

### Context

The project needs a predictable, testable execution flow.

### Alternatives Considered

- DAG execution
- Branching pipelines
- Multi-pass strategy search

### Pros

- Simpler to understand
- Simpler to test
- Simpler to debug

### Cons

- Less flexible than a DAG

### Final Rationale

Linear execution is sufficient for MVP and avoids unnecessary orchestration complexity.

### Future Revisit Conditions

Revisit only after a proven need for branching or parallel execution emerges.

## 5. Why built-in stages?

### Decision

MVP uses built-in stages only.

### Context

The runtime must remain small and predictable while the core behavior is being proven.

### Alternatives Considered

- Plugin-based stages
- Remote stage registry
- User-defined stage loading

### Pros

- Smaller trust surface
- Easier testing
- Lower operational complexity

### Cons

- Less extensible in the short term

### Final Rationale

Built-in stages keep the first version maintainable and let the core contracts stabilize before extension mechanisms exist.

### Future Revisit Conditions

Revisit only after the built-in pipeline has proven stable and there is a clear extension demand.

## 6. Why explicit fallback?

### Decision

Fallback always returns the original raw input when the optimized result is unsafe.

### Context

TokenDamper must prioritize correctness over compression.

### Alternatives Considered

- Partial fallback
- Best-effort repair
- Silent degradation

### Pros

- Clear behavior
- Safe output path
- Easy to explain

### Cons

- Can reduce token savings in some failure cases

### Final Rationale

An explicit original-input fallback is the safest and most understandable behavior for MVP.

### Future Revisit Conditions

Revisit only if there is a demonstrated safe recovery path that can be proven better than original-input fallback.

## 7. Why no plugins initially?

### Decision

No plugin infrastructure exists in MVP.

### Context

Plugin systems add loading, isolation, versioning, and compatibility complexity.

### Alternatives Considered

- In-process plugins
- Out-of-process plugins
- Static built-in extension points

### Pros

- Lower complexity
- Fewer trust and compatibility issues

### Cons

- Less extensibility at first

### Final Rationale

The project should stabilize its core contracts before introducing third-party extension loading.

### Future Revisit Conditions

Revisit after the core stages, planner, and validation behavior are stable and benchmarked.

## 8. Why no DAG?

### Decision

No DAG execution in MVP.

### Context

The execution model does not yet require branching or parallel dependencies.

### Alternatives Considered

- DAG scheduler
- Conditional branching
- Hybrid graph executor

### Pros

- Keeps orchestration simple

### Cons

- Limits complex execution topologies

### Final Rationale

The extra orchestration cost is not justified before the core pipeline proves useful.

### Future Revisit Conditions

Revisit only after linear execution proves insufficient for real workloads.

## 9. Why no embeddings?

### Decision

No embedding-based similarity validation or ranking in MVP.

### Context

Embeddings add dependency weight, infrastructure decisions, and evaluation complexity.

### Alternatives Considered

- Embedding similarity scoring
- Semantic nearest-neighbor ranking
- Hybrid lexical/embedding validation

### Pros

- None that are necessary for MVP

### Cons

- Requires additional tooling and calibration

### Final Rationale

TokenDamper can prove useful with deterministic, structure-aware methods first.

### Future Revisit Conditions

Revisit only after the deterministic baseline is validated and a real semantic signal gap is documented.

## 10. Why no database?

### Decision

No database-backed state exists in MVP.

### Context

The system is local, deterministic, and fixture-driven at first.

### Alternatives Considered

- Embedded database
- External datastore
- Persistent analytics store

### Pros

- Less operational complexity
- Fewer failure modes

### Cons

- No persistent runtime history

### Final Rationale

A database is unnecessary before the core optimization path is proven.

### Future Revisit Conditions

Revisit only if persistent state becomes necessary for a proven runtime feature.

## 11. Why benchmarking is offline?

### Decision

Benchmarks are offline, deterministic, and fixture-driven.

### Context

Benchmarking should measure regression behavior without affecting runtime logic.

### Alternatives Considered

- Online telemetry-driven benchmarking
- Remote benchmark service
- Runtime self-optimization

### Pros

- Reproducible
- Easier to review
- Safer for contributors

### Cons

- Less real-time insight

### Final Rationale

Offline benchmarks are sufficient for protecting the MVP and are much easier to maintain.

### Future Revisit Conditions

Revisit only if the project later needs broader corpus management or distributed benchmarking.

## 12. Why explainability exists?

### Decision

Every optimization result includes a lightweight trace.

### Context

Users need to know what changed, why it changed, and when fallback happened.

### Alternatives Considered

- No trace
- Verbose telemetry system
- Debug-only logging

### Pros

- Builds trust
- Supports debugging
- Improves benchmark reviewability

### Cons

- Slight implementation overhead

### Final Rationale

Explainability is required for a system that rewrites context before it reaches an LLM.

### Future Revisit Conditions

Revisit only if trace structure becomes too expensive or if a more formal observability system becomes necessary later.

## 13. Why Deterministic AST/Hash Reduction over Neural Token Dropping?

### Decision

TokenDamper uses deterministic AST-validated, hash-based compression instead of neural or statistical token dropping (e.g., LLMLingua-2).

### Context

Neural token compressors drop tokens based on entropy probabilities, achieving high raw compression ratios but corrupting structured code and JSON tool schemas. In benchmarks like BFCL, these models degrade tool execution accuracy significantly (20%–27%) due to dropped required brackets, quotes, or keys.

### Rationale

Deterministic, AST-validated, hash-based approaches guarantee 100% syntax safety and reversible state restoration with zero neural or statistical hallucination risks.

## 14. Cache-First Prefix Stabilization Protocol

### Decision

TokenDamper enforces strict prefix stabilization rules, including pinning system prompts and tool schemas at index 0, and respecting 1,024-token cache block quantizations.

### Context

Major LLM providers (Anthropic Claude, OpenAI GPT-4o) employ strict positional prefix KV-caching. A single byte change in the early prompt prefix invalidates the entire downstream cached KV state, forcing full input re-parsing.

### Rationale

Modifying an early-turn prompt prefix is economically negative unless the compression slashes >90% of the prefix size. By keeping tool schemas and system prompts immutable and operating strictly after the stable prefix horizon, we maximize prompt cache hit rates and reduce API costs.

## 15. Zero-Code Local Proxy and MCP Server First Distribution Strategy

### Decision

TokenDamper prioritizes zero-code local proxy wrappers (`tokendamper exec`) and native MCP servers as its primary distribution and integration mechanisms, rather than complex application SDKs.

### Context

Developers overwhelmingly prefer transparent integration. Connecting multiple Model Context Protocol (MCP) servers can inject 10,000–30,000 input tokens of static JSON tool definitions into every single turn before user messages are processed, creating huge overhead.

### Rationale

A local proxy and MCP approach allows TokenDamper to deduplicate static schemas, track token usage invisibly, and implement circuit breakers without requiring users to alter their application code.

## 16. Recoverable References Are Not Semantic Drift

### Decision

`cleanup:session-dedup` tags its elisions `recoverable: true`, and `DriftTracker` substitutes
the pre-optimization content for those items before computing `S_k`. Lossy elisions
(`compression:token-hashing`, `compression:delta-compression`) carry no such flag and remain
fully scored against the `S_k <= 0.40` threshold.

### Context

Routing the Gateway through `core/engine.optimize()` (Phase 1.0b) subjected cross-turn
deduplication to the drift validator for the first time. Drift is computed from AST symbol
and structural marker retention, so replacing a message with `[TokenDamper Elided: ref=...]`
drops every symbol that message contributed. A representative code payload scored `S_k =
0.60`, well past the threshold, forcing a fallback.

That behavior is inverted: drift rose with the *size* of the deduplicated block, so the
validator vetoed deduplication most aggressively on precisely the payloads the Gateway
exists to shrink.

### Alternatives Considered

- A higher, Gateway-specific `maxDriftThreshold` — a magic number that weakens the
  invariant for lossy stages on the same path, rather than drawing a principled line.
- Accepting the fallbacks — honest, but reduces Gateway savings toward zero in its best
  cases and makes the safety net indistinguishable from an off switch.
- Excluding elided items from both sides of the ratio — distorts the denominator and
  silently shrinks the evidence base the metric is computed from.

### Rationale

A dedup marker is a *pointer*: the full text is retained in the session store under
`originalContentHash` and is restorable on demand. Nothing is irrecoverably lost, so nothing
should be scored as loss. Drift exists to catch irreversible semantic damage, and keeping
recoverable references out of it preserves the invariant's meaning for the lossy stages that
genuinely need policing.

### Consequences

The exemption is keyed on an explicit `recoverable` flag rather than inferred from `elided`
or `originalContentHash`, both of which `token-hashing` also sets. Any future stage claiming
the exemption must guarantee the same restorability contract, or the drift invariant
silently stops protecting that path.

## 17. A Fenced Block Is Markdown, Not Code

### Decision

`classifyContent` detects `code` by **file extension only**. The triple-backtick fence, its
only content-based signal, now counts toward `markdown` instead.

### Context

`selectValidator` dispatches `contentType: 'code'` to the **TypeScript** validator. The
fence rule therefore meant that any document quoting a snippet — "here's the fix:
```ts ... ```", the single most common shape of an assistant message — was parsed as
TypeScript in full, prose included.

Measured on the Gateway path, turn 1, with no stage having transformed anything:

| Message | Classified | Validator | Result |
|---|---|---|---|
| `Here's the fix. It's the guard that's missing:` + ```` ```ts ```` block | `code` | typescript | **fallback** — `AST_UNTERMINATED_STRING` |
| `Here's the fix, it's ready:` + ```` ```ts ```` block | `code` | typescript | pass |

The two differ only in how many contractions the prose contains. Three apostrophes leave an
odd number of quote characters open; two do not.

### Alternatives Considered

- **Stop mapping `contentType: 'code'` to the TypeScript validator.** Larger blast radius —
  several call sites legitimately rely on it — and it treats the symptom. `code` is a family
  (`go`, `rs`, `sh`, `sql` all classify as `code`), so validating any of it as TypeScript is
  unsound for reasons that have nothing to do with fences.
- **Keep the fence rule, classify as `code` only when the fence spans the whole document.**
  A heuristic on top of a heuristic, and it still parses a Python fence as TypeScript.
- **Accept the fallbacks.** Fail-open means output stays byte-correct, so this is safe — but
  it is silent, and it fires on ordinary traffic.

### Rationale

A code file does not contain fences; a document that quotes code does. The rule had the
relationship inverted, so its only reachable outcome was a false positive: a whole-document
language validator cannot know what a mixed prose/code document *should* parse as, and it
therefore cannot catch a real defect in one. A check decided by apostrophe parity is not
validating anything, so it is removed rather than tuned.

### Consequences

Detection of real code is unchanged: every path carrying actual source files supplies an
extension, which is what `isCodeExtension` matches. Content-only code arriving without an
extension already classified as `text` — the fence rule never covered that case either.

The remaining unsoundness is recorded but out of scope: `contentType: 'code'` still selects
the TypeScript validator for extensions with no validator of their own (`go`, `rs`, `sh`,
`sql`), where a Rust lifetime (`&'a str`) or an unbalanced shell quote produces the same
class of false positive. That reaches the CLI path only, and predates this decision.

### Future Revisit Conditions

Revisit if per-language validators land for the extensions currently routed to TypeScript,
or if fenced-block-aware validation (validate each fence under its own tagged language,
ignore the prose between them) is implemented — that, not a classifier tweak, is what would
make content-based code detection meaningful.

## 18. For Code, 40% of the Drift Metric Is a Constant

### Decision

Recorded as a standing finding, not yet acted on: on code content, the structural half of
the semantic drift metric (`w_struct = 0.40`) cannot vary, so `S_k` is effectively
`0.6 × (1 − R_AST)` and is confined to `[0.00, 0.60]`. The `0.40` threshold sits at
two-thirds of a maximum the metric can never reach.

**The threshold is not changed by this entry.** This records *why* tuning it would be the
wrong instrument.

### Context

```
S_k = 1 − (w_AST · R_AST + w_struct · R_struct)      w_AST = 0.60, w_struct = 0.40
```

`R_struct` is computed from `DriftTracker.extractMarkers`, which harvests `filepath:`
markers, markdown headings, code fences, `TD_PRESERVE:` directives and section delimiters.
A source file typically contains none of the latter four, so its marker set is exactly one
entry: `filepath:<path>`.

That marker is derived from `item.path` — **metadata**. Every eliding stage rewrites
`content` and leaves `path` untouched. The marker therefore survives by construction, and
`R_struct = 1.0` no matter how completely the content is destroyed. Measured on the bundled
bench fixtures: markers before and after are identical in every case, and `R_struct` is
`1.0000` across Python, TypeScript and JavaScript.

Full measurements in `docs/phase-1d-drift-investigation.md` §5.

### Alternatives Considered

- **Lower the threshold for code.** Treats the symptom. A threshold cannot recover
  discriminating power from a term that does not vary.
- **Reweight — raise `w_AST` toward 1.0 for code.** Honest about `R_struct` being inert, but
  it silently concedes that structural integrity is unmeasured on code rather than fixing
  it, and it bakes a content-type branch into the formula to compensate for a gap in the
  marker extractor.
- **Drop `filepath:` from the marker set.** Would make `R_struct` default to `1.0` via the
  `markersBefore.size === 0` guard — the same constant, arrived at more obscurely.

### Rationale

A metric term that cannot vary is not conservative, it is decorative. Worse, it is
*confidently* decorative: it contributes a full 0.40 of "retention" on every code payload,
which reads as evidence that structure was preserved when nothing about the content's
structure was examined at all. That is the same shape as the hardcoded `fallbackUsed: false`
(§ Phase 1.0a) and the vacuous JSON checks (Issue 2, Commit C) — a value asserted without
being derived.

The finding is separable from the granularity cause that dominates the current failures.
Whatever fixes granularity, this stays true until `extractMarkers` learns structural markers
that (a) live in the content and (b) are meaningful for code — nesting depth, function and
class boundaries, import blocks, brace balance.

### Consequences

- Any future comparison of `S_k` across content types is comparing a two-term metric on
  prose and markdown against a one-term metric on code. They are not the same scale.
- The observed `S_k = 0.60` on every failing code fixture is the **ceiling**, not a
  midpoint. Reporting it as "drift 0.60 out of 1.00" overstates the headroom by 40 points.
- A Python file with `#` comments currently *can* exceed 0.60, but only through a defect in
  `extractMarkers`, which reads Python comments as markdown headings. Fixed separately; it
  is not evidence that `R_struct` does real work.

### Future Revisit Conditions

Revisit when `extractMarkers` gains content-derived structural markers for code, or when a
per-language structural signal replaces the current markdown-oriented marker set. At that
point `R_struct` becomes load-bearing and the weights are worth re-deriving from
measurement rather than inherited from `milestone_7_architecture_spec.md`.

---

## 19. One Token Estimator, Chosen for the Seam and Not for Accuracy

### Decision

Every site that estimates tokens routes through `estimateTokens` /
`estimateBundleTokens` in `src/core/hashing/tokenizer.ts`. `EnhancedHeuristicTokenizer`
remains the default via `DEFAULT_TOKENIZER`. The inline `Math.ceil(len / 4)` form is gone
from the codebase; `countTokens` is now called from exactly one place.

The default is **not** chosen because it is the more accurate estimator. Measured, it is
the less accurate one. It is chosen because it is the extension point.

### Context

Two independent estimators coexisted. `createContextBundle` measured the input side with
`EnhancedHeuristicTokenizer`; the trace, the engine's rehydration path, the Gateway's
bundle constructors and three of the five stages measured the output side with
`Math.ceil(len / 4)`. Every reduction ratio in the product compared one against the other.

The heuristic runs 11–22% above `len / 4` on the project's corpus, so **byte-identical
output registered as an 11–22% saving**. The benchmark published it as
`avgReduction: 7.82%` while every one of the ten fixtures emitted its input verbatim. The
MCP adapter's `reductionRatio` divides `trace.tokenAfter` by `trace.tokenBefore` — opposite
sides of the same seam — so it reported a saving on pure fallbacks too, where the emitted
text is `request.rawInput` unmodified.

Two smaller variants of the same fault were folded in: `session-dedup` and
`delta-compression` reported `tokenEstimateSaved` as `ceil(bytesSaved / 4)`, a third unit
that could disagree in sign with the bundle totals it sat beside; and the Gateway measured
its input bundle as `ceil(statistics.totalCharacters / 4)`, which omits the N−1 newlines
the bundle render inserts, so its input and output sides counted different strings.

### Alternatives Considered

- **Standardize on `ceil(len / 4)`.** Measured against `cl100k_base` over the ten bench
  fixtures plus the four Gateway payloads, it is the *more* accurate of the two — mean
  absolute error 17% against the heuristic's 24%, max 44% against 56%. Rejected anyway.
  `TokenizerAdapter` is the declared plug point for a real BPE tokenizer, and
  `createTiktokenAdapter` already implements it; standardizing on inline arithmetic would
  mean the roadmap's pluggable-tokenizer work has to re-introduce a seam at nine sites.
  It also breaks the planner: `cache-aware.ts` derives knapsack weights and 1,024-token
  cache-block boundaries from the adapter, and `validation/index.ts` compares
  `summary.tokenEstimate` against `budget.maxInputTokens`. Splitting those units would put
  budget enforcement and budget selection on different scales — the same mismatch,
  relocated.
- **Switch the default to a naive char adapter behind the same interface.** Keeps the seam
  and takes the accuracy win. Rejected *for this change only*: it moves every published
  number at the same moment as the unification, and it silently redefines what a user's
  existing `maxInputTokens` means. It is a defensible follow-up, made in one place, on its
  own evidence.

### Rationale

A reduction ratio is a comparison, and a comparison is only as sound as the agreement
between its two sides. Its correctness does not depend on either estimator being accurate —
it depends on both being *the same*. Accuracy and unity are separable properties, and only
one of them can produce a number that claims a saving where no bytes were saved.

This was the sixth instance of the project's recurring pattern (`CLAUDE.md` invariant 10)
and the first where the vacuous value reported **success** rather than a passed check. A
fabricated 7.82% is worse than a fabricated green check, because nobody investigates a
number that flatters them.

### Consequences

- **`avgReduction` on the bundled bench corpus is 0.00%, not 7.82%.** That is the true
  figure: all ten fixtures emit byte-identical output. `fallbackRate` (0.40) and
  `totalValidationIssues` (4) are unchanged — those were never computed across the seam.
- Absolute token counts on the Gateway rise by roughly the heuristic's margin over
  `len / 4` (measured: `rawTokens` 8,470 → 10,059 on a 36 KB payload). Its *ratio* barely
  moves (49.79% → 49.82% on within-payload dedup) because both of its sides already used
  the same estimator. The Gateway results recorded elsewhere in this repo were derived from
  HTTP body byte lengths, not from these counters, and are unaffected.
- The published accuracy gap is a real open item. `EnhancedHeuristicTokenizer` is named as
  though it improves on `len / 4`; on this corpus it does not. Recalibrating its
  coefficients, or landing `createTiktokenAdapter` against a real encoder, is now a
  one-line change to `DEFAULT_TOKENIZER`.
- `test/unit/token-estimator-unity.test.ts` pins the property: byte-identical output must
  measure as exactly 0% reduction, on the engine path, on the fallback path, and for every
  stage in the catalog.

---

## 20. Elide Function Bodies, Not Whole Items

### Decision

`compression:token-hashing` elides **function bodies** within an item, keeping the
declarations around them, and falls back to whole-item hashing only where no region can be
selected. Region selection lives behind `selectElisionRegions`; replacement goes through
`elideRegions`, a sibling chokepoint to `elideItem`.

Class bodies are never selected. Comment-and-docstring-only regions are never selected.
JSON is never selected.

### Context

Whole-item hashing could not succeed on a single-item code bundle, structurally: it replaces
every byte, so every symbol dies at once, `DriftTracker`'s `R_AST` is a boolean, and `S_k`
pins at the formula constant `0.60` — over the `0.40` gate, every time
(`docs/phase-1d-drift-investigation.md` §6). Regions give the metric something fractional to
grade, and measured, it grades correctly.

For code, `R_struct` is pinned at `1.0` (§18), so the gate reduces exactly to
**`R_AST ≥ 1/3`**.

### Alternatives Considered

- **Mark hashed placeholders `recoverable: true`.** Rejected before design. §16 established
  that `recoverable` is a claim about *this* payload, verifiable only when an intact copy
  survives in it. Token-hashing has no such copy. Asserting recoverability because
  rehydration machinery exists somewhere is what produced the inflated 98.59% figure.
- **A fixed nesting depth (`depth-2`).** This was the design's own recommendation and it was
  wrong — derived from measuring one class-shaped file. It misses top-level function bodies
  entirely and is arbitrary wherever nesting differs. Measured over six real sources,
  function-body selection yields **57.38%** mean reduction against depth-2's **37.95%** on
  the same usable set, and on `ts-validator.ts` depth-2 destroys the sole method's signature
  set (`R_AST` 0.2667, correct fallback) where function-body selection does not.
- **Innermost brace spans.** Safe but nearly worthless: 10.06% mean. Innermost spans are
  `if`/`for` blocks, not bodies.

### Rationale

Two boundary rules govern where a region may start and end, and both were found by
measurement rather than reasoning:

1. **The region must be exactly the bytes replaced.** `TokenHasher.rehydrateText`
   substitutes in place, so anything the caller adds around the marker survives rehydration.
   A prototype emitting `indent + marker` scored **0/7** on byte-identical round trip;
   removing the added indent scored **7/7**.
2. **The marker must land in a syntactically valid position.** Rule 1 alone puts a Python
   marker at column 0, which `PythonValidator` rejects. Applying rule 1 without rule 2 took
   AST validity from **8/8 to 0/8**.

They are only jointly satisfiable if the region excludes the leading indentation.

The post-condition is **relative** — no *new* AST issues — unlike `elideItem`'s absolute
check. An absolute check is unusable here for two measured reasons: three of the ten bundled
bench fixtures are truncated completion prompts, invalid on input; and `TypeScriptValidator`
has no regex-literal mode, so it rejects valid TypeScript containing `/\([^)]+/`. Under an
absolute check both classes yield 0% forever. This follows the precedent already in
`BenchmarkEvaluator.syntaxPreserved`.

The docstring guard is the Phase 1d precondition (design §8b). `HumanEval/0` elides to
**55.66% reduction at `S_k = 0.0000`**, AST-valid and byte-reversible — and the region
removed is the function's docstring, which is the entire specification of the task. Drift
cannot see it: docstrings carry no symbols and `R_struct` is inert for code. **This guard
defends that case, not the class.** Any other high-information symbol-free content is still
invisible to the metric. The real fix is §18.

### Consequences

- Measured over 52 real source files through the CLI: **22 reduce with no fallback, mean
  52.99%**. Output is byte-identical across fresh processes (6/6). Every elision round-trips
  exactly through the existing recovery valve.
- The bundled bench corpus stays at **0.00%**, deliberately. Five HumanEval fixtures are
  docstring-only prompts the guard refuses; four CodeXGLUE fixtures are truncated stubs with
  no complete body. It is a completion benchmark, not a compression corpus, and it should
  stop being cited as a measure of reduction.
- The remaining fallbacks are the safety net working: 17 of 30 on constraint-directive
  retention (an imperative comment inside an elided body), 11 on drift over `0.40` (too much
  symbol loss), 2 on the regex-literal validator defect.
- The recovery valve needed **no change**: `rehydrateText` already resolves N placeholders
  per item. Regions make *partial* un-hashing possible — undo the fewest needed to clear
  `R_AST ≥ 1/3` — which is the natural bridge to Phase 1c. Not built here.
- On the CLI a successful optimization now emits `<BLOCK_HASH:…>` markers the consumer
  cannot reverse; the `TokenHasher` is created inside the stage and discarded. Previously
  this never surfaced because everything fell back. MCP has `rehydrate_context`; the CLI does
  not. This needs a decision before the CLI is used to feed a model directly.

---

## 21. A Latency Budget Must Not Vote on Correctness

### Decision

`validateItemAst` measures its 5ms budget and reports the breach on
`AstValidatorResult.slaExceeded`. It no longer sets `valid: false` or emits an
`AST_SLA_EXCEEDED` issue.

### Context

Identical bytes produced different syntax verdicts depending on machine load and JIT warmth.
Measured on a 16 KB Python file across six fresh Node processes:

```
valid(4.06ms)  INVALID(5.28ms)  INVALID(6.86ms)  INVALID(8.04ms)  INVALID(14.70ms)  INVALID(17.58ms)
```

It also produced false fallbacks on large valid files: `codebase.py` fell back on
`AST validation exceeded SLA threshold (5.99ms > 5ms)` with drift at `0.00`, every other
check passing, and 19 regions successfully elided. The engine reported a syntax error that
did not exist.

### Rationale

Determinism is the product; a validator that answers differently on a busy machine is not
one. And a slow validation says nothing about whether content is syntactically valid — this
is the inverse of invariant 10's pattern: not a check passing without running, but a check
*failing* for a reason it never examined.

### Consequences

- Large files are validated on their merits. `codebase.py` reduces 34.76% end-to-end.
- Latency remains observable via `slaExceeded` for anyone who wants to act on it.
- The `enforces maxTimeMs SLA` case in `ast-validator.test.ts` was re-pointed at the new
  contract. That is a changed requirement, not a weakened assertion: the new case asserts
  strictly more (validity unchanged **and** the breach reported **and** real syntax errors
  still surfacing).

## 22. A Filename Extension Outranks a Content Probe

### Decision

`classifyContent` resolves every recognized filename extension before it runs any content
probe. `looksLikeHtml` requires a matched open/close tag pair rather than an angle bracket
somewhere. `looksLikeLogs` asks whether the input is predominantly log lines, using a
per-line predicate that recognizes ISO-8601 timestamps.

### Context

Measured against this repository's own sources, the previous classifier answered:

```
  46  ts -> html          e.g. src/adapters/mcp/index.ts
  10  ts -> code          e.g. src/adapters/cli/index.ts
  11  md -> yaml          e.g. ARCHITECTURE.md
  10  md -> html          e.g. CHANGELOG.md
   2  md -> markdown      e.g. SECURITY.md
   1  txt -> text         tokendamper-benchmark/test_data/sample_logs.txt  (75 log lines)
```

Three independent causes, each a check that returned a confident answer without examining
the thing it claimed to detect:

1. `/<\/?[a-z][\s\S]*>/i` — `[\s\S]*` is greedy and unanchored, so the match spanned from
   the first `<letter` to the **last** `>` in the input. One generic parameter plus any
   later `>` was sufficient, and TypeScript guarantees both.
2. Probes ran before extensions; `isCodeExtension` was consulted fifth, after json, yaml,
   html and logs. An early probe therefore overrode an extension that would have decided
   correctly.
3. `looksLikeLogs` missed ISO-8601 twice over: its first alternative required the severity
   level **before** the date (real lines are date-first), and its second,
   `/\b\d{2}:\d{2}:\d{2}\b/`, cannot match `T19:00:01` — `T` and `1` are both word
   characters, so there is no word boundary before the hour.

### Rationale

An extension is a declaration by whoever named the file. A probe is a guess about bytes.
When both are present, the declaration wins; probes exist to serve the case where there is
no filename at all, which is exactly the Gateway and MCP shape.

This is the seventh instance of the invariant 10 pattern in this project, and the first
where the mis-answer was *positive* rather than vacuous: the classifier did not decline to
answer, it answered `html` with confidence.

### Consequences

- All 57 TypeScript sources in `src/` classify as `code`; every document in `docs/` as
  `markdown`; `sample_logs.txt` as `logs`. Pinned in
  `test/unit/content-classification.test.ts` against the repository itself, not synthetic
  strings, because that is the corpus the defect was found on.
- It partially reopens Phase 1a. See §23.
- `looksLikeYaml` remains `/^(---\s*$)?([\w.-]+:\s+.+)$/m`, which matches any line of the
  form `word: value` — including ordinary prose. It is untouched here because the extension
  reordering removes its blast radius on named files, and because a loose probe that
  produces a type with no validator is now *visible* rather than silent (§23). It is still
  the loosest probe in the chain and should be tightened before anything starts trusting
  `yaml` for a decision. **Tightened in §27** — and the premise that the tag was inert was
  wrong: `DriftTracker` was already trusting it.

## 23. "No Validator Applied" Is Not "The Check Passed"

### Decision

`AstValidatorResult` gains `validated: boolean`. `selectValidator`'s content-type dispatch
becomes a total `Record<ContentType, AstValidator | null>`. `ValidationReport` and
`OptimizationTrace` carry `astCoverage`, and `validate()` scopes `passed`, `shouldFallback`
and `reason` to `severity: 'error'` so a coverage report cannot force a fallback.

### Context

**This partially reopens Phase 1a.** The Gateway fix (`ac16cec`) replaced a hardcoded
`contentType: 'text'` with `classifyContent`, and the record — `CLAUDE.md`,
`docs/issue-2-content-type-contract-design.md` §2.2 — treats that as closing the
"no validator runs at all on Gateway items" hole. It closed the JSON half. It did not close
the code half, and by §22 it made that half worse: `classifyContent` answered `html` for
TypeScript, `selectValidator` had no `html` branch, and a pathless item therefore got no
validator at all. Measured on a TypeScript file with an unterminated string literal:

```
  with path (CLI file arg)    contentType=html   validator=typescript  valid=false  issues=1
  no path (Gateway message)   contentType=html   validator=NULL        valid=true   issues=0
```

The CLI is rescued by `selectValidator`'s path-extension branch. A provider message has no
path, so `contentType` is its only signal — which is the shape the Gateway carries.

### Rationale

§22 fixes the three regexes, but fixing them leaves the mechanism intact: `classifyContent`
could still emit a tag that dispatch has never heard of, and the failure mode of that
mismatch is *silence*. `valid: true` meant both "examined and clean" and "nothing looked".

Two routes were available: make dispatch handle every emittable type, or bind the two so an
unhandled type cannot exist. `Record<ContentType, …>` delivers both at once — every member
must be assigned a validator or an explicit `null`, and adding a member to `ContentType`
without deciding is a compile error. No runtime `assertNever` is used, deliberately: a throw
inside `selectValidator` would sit in the fail-open path and violate invariant 3, so the
runtime edge indexes and falls back to `null` for a forged tag.

The conflation itself is fixed on the *result*, not on the selector's return. `null` from a
lookup is a fine answer to "which validator covers this"; the defect was that
`validateItemAst` turned that answer into `valid: true` and discarded it. `validated: false`
is now the record that nothing ran.

`valid` deliberately stays `true` for an unchecked item. Inverting it would fall the engine
back on every prose message, which is a policy change, not a correctness fix — and there is
no AST-lite validator for prose, nor should there be (§17).

### Consequences

- The CLI writes `result.trace` to stderr and emits nothing else about validation, so
  `astCoverage` on the trace is what makes coverage visible on the one entry mode with no
  session and no second chance to notice.
- `passed` is now `errors.length === 0` rather than `issues.length === 0`. Equivalent today —
  every other issue pushed is an error — but it makes `severity` load-bearing instead of
  decorative, and stops any future informational finding from forcing a fallback.
- `AstValidator.validate` returns the narrower `AstCheckResult`. A validator cannot claim
  `validated`; by running, it is the validation.
- Pathless code is still unvalidated — it is now *reported* as unvalidated rather than passed.
  Closing that needs content-only code detection, which §17 removed on purpose. This decision
  makes the hole visible; it does not fill it.

## 24. An Elision Marker Must Say What It Replaced

### Decision

`compression:token-hashing` emits
`[TokenDamper: <N> <kind> lines elided, <B> bytes, sha256:<12 hex>]` on both the sub-item and
the whole-item path, rendered by one shared `core/elision.renderElisionMarker`. The digest is
a field in the marker, never the whole of it. `TokenHasher` resolves the truncated digest via
a prefix index and refuses an ambiguous prefix rather than guessing.

### Context

The marker was `<BLOCK_HASH:` + the full digest + `>`, and on the CLI it resolved to nothing —
see §25 for why the store never existed. So the reader of a CLI run received, in place of a
function body:

```
        <BLOCK_HASH:4af59ca48228134eb02432340ad1aa61a7ccab427f407c0fbe22cdbf9ee33e90>
```

which says that *something* was removed and nothing else. Not what, not how much, not whether
it mattered. The same elision now reads:

```
    def __init__(self, failure_threshold: int = 5, recovery_timeout: float = 30.0):
        [TokenDamper: 5 function-body lines elided, 202 bytes, sha256:4af59ca48228]
```

`cleanup:session-dedup` already emitted `[TokenDamper Elided: ref=… bytes=… kind=…]`, and
`compression:delta-compression` a labelled unified diff. `token-hashing` was the only stage
whose output told its reader nothing, and it is the only one that runs on the CLI.

### Rationale

MCP and the Gateway hold session state, so a marker there can be a pointer. The CLI is a
one-shot pipe with no session on either end, so there is nothing for a pointer to point at
and the marker has to carry the information itself. The rule that follows: **on a one-shot
path, every elision must carry in-band enough for a reader with no external state to know
what was removed.**

The hash stays because it is what identifies a block across turns and what a caller holding
the content can verify against. Twelve hex characters carry that; sixty-four would be 53% of
the marker and would defeat the readability the marker exists for. An ambiguous prefix
resolves to nothing, which is the behaviour `rehydrateText` already had for any unknown hash.

### Consequences

- **Byte cost: none — it is slightly cheaper.** `codebase.py` through the real CLI:
  16,937 → 11,360 bytes before, → **11,328** after. The marker is 75 bytes against the old
  77 in the common case, because a truncated digest buys back more than the words cost.
- **Token cost depends on the estimator, and the two disagree in sign.** For one real marker:
  `EnhancedHeuristicTokenizer` scores the new form **+1** token, `ceil(len / 4)` scores it
  **−1**. Controlled A/B over the frozen 80-file corpus: identical files kept (22), identical
  fallback causes, mean over kept 55.50% → 55.09%. That −0.41pp is the heuristic's opinion,
  and the heuristic is the *less* accurate of the two by measurement (§19: 24% MAE against
  17%). Under a real BPE encoder a 64-character random hex string costs roughly 25 tokens
  while the same span of English words costs roughly 18, so the sign would likely invert —
  but `createTiktokenAdapter` is unwired, so that is reasoning, not a measurement, and it is
  recorded as such.
- One format is written; `<BLOCK_HASH:…>` is still *read*, so text captured before this
  change still round-trips. `TokenHasher.createBlockPlaceholder` still produces the old form
  and is still tested.
- `BLOCK_PLACEHOLDER_BYTES` now aliases `ELISION_MARKER_BYTES` (80, derived in `marker.ts`),
  moving the region floor from 101 to 104 bytes. It remains a pre-filter, not a correctness
  dependency — `elideRegions` measures the real replacement against the real region.
- `ELISION_MARKER_PATTERN` is deliberately specific rather than `\[TokenDamper[^\]]*\]`, so
  it cannot swallow the other two stages' markers and hand them to the wrong resolver.

### Rejected: gating the whole-item branch off for prose and logs

The proposal was that whole-item elision on prose and logs is "compute that can only produce
fallbacks", so it should not run. **Measured, that premise is false.** Whole-item elision
succeeds on both when the item carries no imperative directive:

```
  prose only              prose:WHOLE   passed=true  S_k=0.00  saved=78.4%
  logtail only            logs:WHOLE    passed=true  S_k=0.00  saved=97.5%
  code + prose + logtail  code:region prose:WHOLE logs:WHOLE  passed=true  saved=62.6%
```

It fails on 16/16 of this repository's prose files because 15 of them are engineering
documents dense with "must" and "do not", and on `sample_logs.txt` because that fixture has a
planted imperative line (Issue 4). That is a property of the corpus, not of the content type.

A static content-type gate is also the wrong shape independently: whether an elision survives
depends on whether *this bundle* carries directives and symbols, which differs between a
single-item CLI bundle and a multi-item Gateway one. Gating by content type would delete the
78–97% case above — a log tail piped into the CLI is exactly the input this product exists
for, and exactly the example the descriptive-marker rule was written from.

## 25. Do Not Manufacture the State That Makes a Claim True

### Decision

`compression:token-hashing` uses a `TokenHasher` only when the caller supplies one. The
`?? new TokenHasher()` default is gone. Reversibility is recorded on the item
(`metadata.reversible`), in the stage metrics (`irreversibleElisions`) and in the stage notes.

### Context

The stage's docblock said it "converts eligible context items into reversible
`<BLOCK_HASH:sha256>` placeholders", and line 23 read
`options?.tokenHasher ?? new TokenHasher()`. The fabricated store registered every elided
block and was collected when the stage returned. Measured on `codebase.py` through the real
binary:

```
  input bytes  : 16937
  output bytes : 11360
  placeholders : 19
  a fresh TokenHasher resolves: 0/19
```

Nothing noticed, twice over. `detectCorruptedPlaceholders` is written
`if (hash && hasher && !hasher.hasHash(hash))`, so with no hasher it cannot push and reported
a clean result on the one path where every placeholder was unresolvable — the eighth instance
of the invariant 10 pattern. And `attemptAutomatedRehydration` opens with
`if (!hasher && !ledger) return undefined`, while `src/cli/main.ts:125` passes neither, so the
recovery valve returned before examining an item.

### Rationale

The obvious fix — thread a hasher from the CLI, or write a sidecar map beside the output —
would make "reversible" true of the process while leaving the reader of the pipe exactly as
badly off. That is the same shape as the retracted 98.59% figure: a number that was correct
about something nobody was asking. Reversibility on the CLI is not unimplemented, it is
unachievable; a one-shot pipe has nowhere for a store to live.

So the state is not manufactured. The absence is recorded, and the marker is made to stand on
its own instead (§24).

### Consequences

- Emitted bytes do not depend on whether a hasher was passed, and a test pins that.
  Reversibility is a property of who holds the content, not of the transform; if the two
  diverged, the CLI and MCP would silently produce different output for the same input.
- `detectCorruptedPlaceholders` returns early without a hasher, and says why. It is *correctly*
  inert there: with no store nothing claims to hold the content, so there is no broken promise
  to detect. Reporting every CLI elision as corruption would be equally wrong.
- The CHANGELOG's Phase 1d line "every elision reversible through the existing recovery valve"
  is withdrawn. That measurement injected a hasher and the sentence was attached to a CLI run
  that had none.

## 26. A Regex Literal Is Not Brackets

### Decision

`TypeScriptValidator` tracks regex literals. A `/` opens one where a value may begin — after
the punctuation set `scanBraceSpans` already uses, or after a reserved word that cannot end an
expression — and the brackets, quotes and slashes inside it are literal text. An unterminated
literal is dropped at the newline rather than run to end of input.

### Context

The validator presented itself as a bracket/quote/comment scanner sufficient to judge
TypeScript, and `validate()` runs it over every item in every bundle. It did not know regex
literals existed, so it counted the brackets inside them:

```
const re = /([^)]+/;     ->  INVALID (AST_UNBALANCED_BRACKET)
const x = (a + b) / 2;   ->  VALID
```

Measured over this repository's own 64 TypeScript sources, **7 were rejected by their own
project's validator**, every one for a regex literal:

```
src/cli/diff-renderer.ts:236        /(\[TokenDamper[^\]]*\])/g
src/cli/html-reporter.ts:316        /(\[TokenDamper[^\]]*\])/g
src/core/elision/regions.ts:50      /\)\s*(?::\s*[^{;=]+)?$|=>$/
src/core/ledger/drift-tracker.ts:258  /"([^"\\]+)":/g
src/core/model/constructors.ts:553  /(?:^|[\s[(<|])(?:TRACE|DEBUG|…)(?:$|[\s\])>:,|])/
src/core/topology/dependency-graph.ts:21  /\\/g
src/core/topology/git-inspector.ts:30     /\\/g
```

Three of them are the classifier's own regexes, from the fix in §22 — the change that made
`classifyContent` correct also handed the validator content it could not read.

### Alternatives Considered

- **Leave it: it fails closed.** The direction of failure is right — the pipeline falls back
  and the user gets their input — which is why this was recorded rather than rushed
  (`NOTES-FOR-DOCS.md`). But a check that answers "invalid" without examining what makes it
  invalid is the same defect as one answering "valid" without looking; invariant 10 is about
  verdicts that were not derived, in either direction. And the cost is not only yield: a
  validator that rejects ordinary code cannot be a backstop for anything inside a literal,
  which is why `elideRegions`'s post-condition had to be relative in the first place.
- **Share one scanner with `scanBraceSpans`.** The right end state, and deliberately not done
  here. `scanBraceSpans` decides *elision boundaries*; changing it changes what the product
  removes, which is a behavioural change wearing a refactor's clothes. The rule is duplicated
  and the duplication is named at both sites instead.

### Rationale

The disambiguation is the whole problem: `/` is division or a literal depending on what
precedes it. Two rules, both conservative in the direction that matters:

1. **The punctuation set is copied from `scanBraceSpans`, not re-derived.** That scanner
   learned regex literals first, *because* this validator could not be trusted to catch a
   boundary it got wrong inside one. Two different answers to "where does this literal start"
   would be worse than one imperfect answer.
2. **Reserved words only.** `return /^([a-z]+/.test(s)` was still rejected under the
   punctuation rule alone. A reserved word can never be the end of an expression, so a `/`
   after one cannot be division — which makes the rule sound rather than heuristic. `in` and
   `of` are excluded: both are legal identifiers in enough positions that `of / 2` is
   expressible, and a wrong guess turns real code into a swallowed literal.

The newline bail-out is the containment property. A misread `/` costs at most the rest of one
line, never the rest of the file.

### Consequences

- **0 of 64 `src/` sources and 0 of 46 `test/` sources are now rejected**, from 7 and 0.
  Pinned by a corpus test over `src/**/*.ts`, following §22's precedent — the defect was found
  on real files and a synthetic string would not have caught it.
- End-to-end on the frozen 68-file corpus, engine varied and input held constant: fallbacks
  **37 → 36**, files reducing **29 → 30**, total emitted tokens **102,800 → 100,715**.
  `src/core/elision/regions.ts` now reduces 52.56% where it previously fell back on a syntax
  error it did not have. All three `AST Error` fallbacks are gone; drift moves 14 → 15,
  because a file that used to fail the AST gate now reaches the drift gate.
- **The relative post-condition in `elideRegions` stays.** Its second reason is unchanged:
  three of the ten bundled bench fixtures are truncated completion prompts that are invalid on
  input, and a completion prompt is a first-class input for this product. Only one of the two
  justifications for it has been removed.
- The known residue is the keyword list. A regex after a non-reserved token that is not in the
  punctuation set — `)` in `if (x) /re/.test(y)` — is still read as division. It fails closed,
  it is bounded to one line, and it is stated here rather than discovered later.

## 27. YAML Is a Document Shape, Not a Line Shape

### Decision

`looksLikeYaml` asks whether the input is *predominantly* YAML — the same shape as
`looksLikeLogs` — instead of whether any single line looks like `key: value`. Lines that are
legal YAML *and* ordinary markdown (`#` comments, bare `- ` sequence entries) are evidence of
nothing and are counted on neither side; block-scalar bodies are skipped as free text.

### Context

The probe was `/^(---\s*$)?([\w.-]+:\s+.+)$/m`. The leading group is optional and cannot span
a line, so what it actually tested was "some line looks like `word: text`". Measured
**pathless** — the Gateway and MCP shape, which is live provider traffic — it claimed `yaml`
for **12 of this repository's 22 markdown documents**:

```
ARCHITECTURE.md         "Responsibilities:"
CODE_OF_CONDUCT.md      "Consequence: A private, written warning from project maintainers"
README.md               "Note: the `AST Validators` and `Explicit Fallback` steps above run"
DECISIONS.md            "entry: `filepath:<path>`."
docs/…/milestone_6…md   "Where:\n- $C_0 = 1.0$: Initial confidence baseline"
```

§22 recorded this as acceptable on the grounds that a loose probe producing a type with no
validator is now merely *visible* (§23) rather than harmful. **That premise was wrong, and it
is the reason this is a fix rather than a tidy-up.** `DriftTracker.extractMarkers` gates
markdown structural markers on an allowlist that does not include `yaml`. Measured on the same
pathless item:

```
contentType=yaml       markers=0
contentType=markdown   markers=19
```

So the mistag silently zeroed `R_struct`'s input on the one content type where it does real
work — while §18 was concurrently recording that `R_struct` is inert *for code*. Half the
metric was being disabled on prose too, by a probe nobody was reading as load-bearing.

### Alternatives Considered

- **Run `looksLikeMarkdown` before `looksLikeYaml`.** Fixes these twelve and is one line.
  Rejected: it does not make either probe correct, it makes the wrong one lose. A `#`-heavy
  YAML file would then be markdown, which is the same class of error facing the other way.
- **Require a leading `---`.** Rejects front-matterless YAML, which is most YAML — the
  repository's own `ci.yml` has no document marker.
- **Require a majority of *all* non-blank lines.** This was tried first and measured:
  `tokendamper-benchmark/BENCHMARK_RESULTS.md` scored **0.826** and stayed a false positive at
  every threshold, because markdown bullets and headings were being counted as YAML evidence.
  Removing the ambiguous line kinds from both sides is what produced separation.

### Rationale

The discriminating question is what counts as evidence, not where the threshold sits. Once
`#` and `- ` lines are excluded from both numerator and denominator, the two populations do
not overlap at all:

| | score |
|---|---|
| `.github/workflows/ci.yml`, compose, k8s manifest, front matter, block scalar | **1.000** each |
| highest-scoring prose document (`BENCHMARK_RESULTS.md`) | **0.455** |

The threshold is **0.75**, near the middle of that empty band rather than against either edge,
so it is not tuned to a single sample on either side. The structure guard — two mappings, or a
document marker plus one — exists because a ratio over one or two lines is not a measurement;
it is what keeps a lone `Note: …` sentence from carrying a classification.

Block-scalar bodies are skipped because they are free text by definition. Without that rule a
config file that documents itself scores 0.600 — *below* an ambiguous prose fragment at 0.667 —
and no threshold can order those two correctly.

### Consequences

- Pathless classification of this repository's 27 prose documents: **12 `yaml` → 0**. All 24
  markdown documents now classify as `markdown`; the two `.txt` fixtures stay `text` and the
  log fixture stays `logs`.
- `R_struct` can see heading loss on pathless prose again. This is the Gateway's only content
  type with working structural markers, so it is also the only place the drift gate currently
  measures anything on the proxy path.
- No change on the CLI code corpus: 68 frozen files, fallbacks 36, files reducing 30, mean
  48.75% — identical before and after, because a file argument carries a path and the
  extension already outranked the probe (§22).
- Two known false negatives, both stated rather than found later: a YAML document that is
  mostly free text under block scalars *with no explicit `|`/`>` indicator*, and a fragment
  with a single mapping and no document marker. Both fall to `text`, which is in
  `MARKDOWN_MARKER_TYPES` — so they over-harvest markers rather than under-harvest them, which
  is the direction that inflates drift rather than hiding it. Worth knowing before that
  allowlist is next touched.

---

## 28. An Empty Before-Set Is "Nothing to Measure", Not "Perfectly Retained"

**Date:** 2026-08-05
**Status:** implemented

### The defect

`DriftTracker.calculateDrift` initialises both retention ratios to `1.0` and overwrites them
only when their pre-optimization set is non-empty:

```ts
let astSymbolRetentionRatio = 1.0;
if (symbolsBefore.size > 0) { /* ... */ }
```

So an item the extractors found nothing in scores as *perfectly retained*. `S_k` is then
`1 - (0.6·1 + 0.4·1) = 0.0000` regardless of what the stages did to the bytes.

Measured on `src/index.ts` — fourteen `export * from './x';` lines, no named declarations:

```
420 bytes -> 67 bytes   130 -> 18 tokens (86.15%)
[TokenDamper: 14 code lines elided, 420 bytes, sha256:10a4b0eb949b]
fallbackUsed false   driftScore 0
```

The whole file replaced by a marker, certified clean. This is invariant 10's **ninth**
instance: a green result from a check that never ran.

Note the mechanism precisely, because the standing description had it slightly wrong. It is
`R_AST` that is empty here (`symbolsBefore = 0`). `R_struct` is **not** empty — it holds
exactly one marker, `filepath:src/index.ts`, derived from `item.path`. That marker is why the
second half of the metric could not save the file either: elision never touches `item.path`,
so the marker survives by construction and `R_struct` reports `1.0` while every byte of
content is destroyed.

### The decision

An empty before-set means the component was **not measured**. A component that was not
measured contributes no evidence of retention, and an item destroyed without evidence is not
certifiable. Concretely, drift refuses when all of:

1. the item's content **changed**, and
2. an **AST validator covers** it, so symbols were the *expected* witness, and
3. it yielded **neither symbols nor content-derived markers**.

Reported through `DriftCoverage` on `ValidationReport` and the trace, alongside a distinct
`SEMANTIC_DRIFT_UNMEASURABLE` issue code. `driftScore: 0` on its own cannot distinguish
"retained everything" from "found nothing to look at", which is the entire defect; the boolean
beside it now carries the verdict. Same shape §23 gave syntax with `validated`.

### What is excluded from the evidence, and why

**`filepath:` and metadata-derived directives.** They come from `item.path` and
`item.metadata.constraintDirectives`, not from content, and survive any content transform. A
witness that cannot be destroyed is not a witness. `extractContentMarkers` is the subset used
for evidence; `extractMarkers` and `R_struct` itself are unchanged, because reweighting the
metric is §18's argument and does not belong in a safety fix.

### Why it is per item

The bundle-level ratios are set comparisons with no attribution. A bundle holding one
richly-symbolled file next to a symbol-free barrel measures `astMeasured: true` at bundle
level while the barrel is deleted unwitnessed. The transform is per item, so the evidence
check has to be too — keying them at different granularities is exactly what produced Issue 2.

### Scope refused, deliberately

**Prose.** The first implementation enforced on any unwitnessed change and was wrong. No
validator covers prose, so `R_AST = 1.0` there is not a failed measurement but an
inapplicable one; enforcing made every prose bundle incompressible and killed
`cleanup:session-dedup` on the conversational traffic the Gateway carries — 4 tests, including
both cross-turn dedup cases and the bench baseline. Plain prose remains unwitnessed by both
components and still passes at `S_k = 0.00`. That hole is now **reported** rather than
enforced, because closing it decides whether TokenDamper may compress prose at all, which is a
product question, not a bug.

**Pruned-away items.** Dropping an item is the planner doing its job under a budget the caller
set, and `R_AST` already scores it wherever the item carried symbols. Refusing here would stop
the knapsack pruning any symbol-free file. A symbol-free code file the pruner removes is still
invisible to drift; that is the planner's half of the same defect and wants its own decision.

### Measured cost

68 frozen repo sources (64 TS + 4 py), engine A/B'd by patching only this clause in `dist/`,
corpus fixed by `sha256` manifest:

| | |
|---|---|
| files changing outcome | **5**, all pure barrel files |
| collateral on anything else | **0** |
| paired aggregate over the 28 files reducing under both | **48.52% → 48.52%** |

Turn-1 Gateway measured as required: `fallbackUsed: false`, no false positives, and turn 2
falls back identically with the rule on and off. Output byte-identical across 6/6 fresh
processes, and fail-open holds — a refusal returns the caller's input verbatim.

The five barrel files are a real, if small, loss of yield. That is the intended direction:
they were only ever "reducing" by having their entire contents deleted under a score that had
measured nothing.

---

## 29. The Caller May Declare What the Content Is

**Date:** 2026-08-05
**Status:** implemented (Phase 4b.1)
**Scope:** `docs/phase-4b-pathless-code-scope.md` §5. 4b.2 (a Python content probe) and 4b.3
(the `MARKDOWN_MARKER_TYPES` allowlist) remain scoping only.

### The defect

`item.language` exists on `ContextItem`, is **first** in `selectValidator`'s precedence, and
was populated by **no adapter at all**. Every entry mode inferred everything from
`sourcePath` plus a content probe, and two of the three modes are pathless by construction:
`optimize -` has no filename, and the MCP `optimize_context` schema accepted `rawInput` plus
budget knobs and nothing else. Gateway messages are provider payloads and have neither.

With no path, `classifyContent` falls to probes, and §17 removed content-only code detection
on purpose. The result is not a degraded classification but an absent one: `selectValidator`
returns `null`, `selectElisionRegions` asks the same validator for a language and gets none,
the item falls to whole-item hashing, `S_k` pins at the formula constant `0.60`, and the
pipeline falls back. Same bytes, two entry forms:

```
optimize corpus/service.py        11,328 bytes out   fallback false   astCoverage checked 1
optimize - < corpus/service.py    16,937 bytes out   fallback true    astCoverage checked 0
```

**The one route that works is the one a coding assistant does not use.**

### The decision

The caller declares. `--language` and `--input-name` on the CLI; `language` and `path` on the
MCP tool schema. Zero inference — this is strictly a route for information the caller already
has, and on the MCP path the caller always has it.

**Precedence: declaration > extension > probe.** §22 established that a filename outranks a
content probe, because a name is a statement by whoever named the file and a probe is a guess
about bytes. A `--language` flag is a statement by whoever is running the tool *now*, about
*this* input — one step more specific than a filename, which may belong to a different person
and may not still be true of a piped fragment.

### The declaration sets two fields, atomically

`language` and `contentType` move together or not at all. Both halves are load-bearing and
each was measured:

- **Language alone** leaves `contentType` at whatever the probe guessed. `text` and
  `markdown` are both in `DriftTracker`'s `MARKDOWN_MARKER_TYPES`, so a declared Python file
  would still have its `#` comment leaders harvested as markdown headings — markers invented
  before the elision and then "destroyed" by it (§18). Two comment lines are enough for the
  probe to classify a Python file as a markdown document.
- **Content type alone** is worse: `CONTENT_TYPE_VALIDATORS.code` maps to the **TypeScript**
  validator, so a `code` tag with no language sends Python to the wrong checker. Pinned in
  `test/unit/declared-language.test.ts` rather than left as a comment.
  **Superseded 2026-08-08 (Phase C): that mapping is now `null`.** `code` is a family tag
  spanning ~19 extensions against three implemented validators, and lexing the family as
  TypeScript invented findings rather than weakening them (perl 39/40, tcl 30/40, shell 22/40
  false verdicts). A `code` tag with no language now sends Python to **no** checker — it
  reports `validated: false` and appears on `trace.astCoverage` (§23) instead of returning a
  wrong verdict. The conclusion this bullet supports is untouched: the two fields must move
  together. The pin was re-aimed, not deleted.

The two fields answer to different consumers — dispatch reads one, drift reads the other —
and keying a transform and its check at different granularities is what produced Issue 2.

### An unrecognized declaration is an error, not a no-op

`normalizeLanguage` returns `undefined` for anything outside the table, and the CLI and the
MCP handler both **reject** it. A `--language pyton` that is quietly dropped yields a run that
looks declared, validates nothing, and prints a clean trace — invariant 10's shape, and the
reason the check lives at the adapter edge rather than in the model.

The accepted set is exactly the languages the *filename* route already recognizes
(`isCodeExtension` plus the document extensions). Declaration parity is the rule: `--language
python` and a `.py` name must reach the same validator with the same content type, or there
are two behaviours to reason about instead of one. A consequence worth stating plainly:
`rust`, `go`, `java`, `sql` and the rest map to `code`, and `code` is bracket-checked by the
TypeScript validator. That is **already** what a `.rs` file gets today; the declaration makes
it reachable from stdin, it does not introduce it.

### Measured

Two corpora frozen in a scratch directory with `sha256` manifests, engine A/B'd as
`dist-before` (`5b19394`) against `dist-after`, tokens counted with real `cl100k_base` rather
than the engine's estimator, `--target-reduction-ratio 0.3`:

| corpus | bare stdin | `--language` | file argument | `--input-name` |
|---|---|---|---|---|
| 64 repo TypeScript sources | 0.07% | **19.27%** | 19.27% | 19.27% |
| 45 `pip` Python sources | 0.02% | **12.34%** | 12.34% | 12.34% |

Output is **byte-identical to the file-argument route on all 109 files**. AST coverage goes
from 0/109 items checked to 109/109. Determinism holds across 6/6 fresh processes in both
languages. **Collateral is zero**: every undeclared run, file or stdin, is byte-identical
before and after — the item hash spreads `language` in only when present, so no existing id
moves.

### The unplanned result: §28 did not reach the pathless route

Six files across the two corpora **reduce under bare stdin and fall back once declared**.
Every one is a barrel or constants file, and the mechanism is §28 arriving by the other door:
its refusal is conditional on an AST validator covering the item, and nothing covers a
pathless item. So the defect `5b19394` is recorded as closing was still live over stdin —
`index.ts` went 135 → 18 tokens, `astCoverage.checked: 0`, `unwitnessedItems: []`,
`fallbackUsed: false`. Declared, the same bytes produce `symbolBearingItems: 1` and
`SEMANTIC_DRIFT_UNMEASURABLE`.

Read the yield table with that in mind: the declared route is not uniformly additive. It
gains 25 and 19 files respectively and gives back 6, and the 6 are ones that were only ever
"reducing" by being deleted under a score that had measured nothing.

### The third construction site: the benchmark loader

There are exactly three `createOptimizationRequest` call sites — CLI, MCP, and
`src/bench/fixtures/loader.ts`. The third was still guessing **with the answer in hand**:
`BenchmarkFixture.language` is a *required* field, and `fixtureToOptimizationRequest` dropped
it and let `classifyContent` re-derive a content type from the filename.

For a fixture whose path agrees with its language that is merely redundant. For a CodeXGLUE
item with **no path** it is 4b.1's defect inside the harness that publishes this project's
numbers — `codexglue.ts` synthesizes `src/item_<id>.txt` for those, which classifies `text`:

```
language "python"   path src/item_pathless-1.txt   contentType text
astCoverage {checked: 0, unchecked: 1}   fallback true   133 -> 133 tokens
```

Declared, the same fixture is checked, is not refused, and goes 133 → 59 tokens. All ten
bundled fixtures are byte-identical before and after (verified fixture-by-fixture, output
hashes included) because their paths agree with their languages; the agreement itself is now a
test rather than a recorded observation.

### A false declaration fails closed, and that is how the fixture lie was found

Making the loader believe `fixture.language` broke `test/integration/bench.test.ts` Test 2,
whose two fixtures were **English prose carrying `language: 'python'`** and `.txt` paths. The
test had passed only because the loader ignored the field.

The mechanism is §28 doing its job: prose is exempt from the unwitnessed-elision refusal only
because *no validator covers it*. A false declaration drags it under one, the extractor finds
no Python symbols in English, and drift refuses to certify what it cannot witness —
`SEMANTIC_DRIFT_UNMEASURABLE`, fallback, input returned verbatim.

**So a wrong declaration costs the optimization and never the content.** That is the right
failure direction for a flag a user will eventually point at a README, and it is pinned as a
test in its own right rather than left as an incident. The fixtures are now Python, which is
what they always claimed to be; the assertion is unchanged and still clears its 40% threshold
(58.8%, zero fallbacks), now by eliding real function bodies instead of deleting unlabelled
prose whole.

### Not done here

**No Gateway hint.** 4b.1 proposed one and it is deliberately unbuilt. A provider payload has
no per-message language field, so the only available shape is a whole-request declaration —
and a session is heterogeneous by nature: prose questions, JSON tool results, code fragments.
Declaring `python` for a request would tag English prose as Python code and hand it to
`PythonValidator`, whose indentation rule prose does not satisfy. That converts a declaration
route into a fallback generator on exactly the traffic invariant 8 protects. If a Gateway
declaration is ever wanted it must be per message, which means a header format that names
message indices, and that is a design, not a flag.

---

## 30. A Flag the Command Does Not Read Is an Error, Not a No-Op

**Date:** 2026-08-06
**Status:** implemented
**Generalizes:** §29, which made this argument for `--language` alone.

### The defect

`parseArguments` ran one flag loop for every subcommand, and each subcommand's return object
picked out the fields it cared about. Everything else was **dropped in silence**. Three
instances shipped, all exiting 0:

```
tokendamper bench --diff --language python     parsed, discarded
tokendamper optimize x --report-json r.json    parsed, discarded
tokendamper mcp --config custom.json           never parsed at all
```

The third is the worst and was not a mere omission. `runCli`'s MCP branch **reads**
`parsed.configPath` and `parsed.configOverrides` and hands them to `loadConfig` — but the
parser returned for `mcp` *before* the loop that sets them, so both were permanently
`undefined`. And `loadConfig` ignores a config file that does not exist rather than failing, so
`tokendamper mcp --config custom.json` started a server on defaults with no signal anywhere:
not in the exit code, not on stderr, not in the config it reported.

§29 rejected exactly this shape for `--language` — "a declaration that quietly does nothing
produces a run that looks configured and is not" — and then left the same shape in place for
eight other flags, because the argument had been framed around declarations rather than around
silence. The property is about silence.

### The decision

A single table, `SUPPORTED_FLAGS`, keyed by what `runCli` actually consumes rather than by what
the loop happens to recognize. Anything outside a command's set is a parse error naming the
offending flags **and where each one does apply**:

```
Unsupported for `tokendamper bench`: --diff (applies to: optimize).
```

Named rather than merely refused, because every one of these flags is real; the user has the
right command for the wrong verb. All offenders are reported at once — fixing an invocation one
error at a time is its own small punishment.

The check runs **after** the parse loop, not inside it: `--mode bench` can change the command
from within the loop, so the verdict cannot be reached until parsing is finished.

`exec` is deliberately outside the table. Its arguments belong to the child process, so
forwarding them unexamined is the contract, not a leak.

### Consequences accepted

`bench --diff` and `optimize --quiet` used to exit 0. They now exit 1. That is a breaking change
for any script relying on a flag that never did anything, which is the population this is meant
to inform. Nothing that was doing work stops doing it: every flag each command actually reads
is still accepted, and `test/unit/cli/flag-support.test.ts` walks the whole table to prove the
table and the loop agree — a flag listed as supported but unrecognized by the loop fails there.

### Why the parser is exported for the test

`parseArguments` and `SUPPORTED_FLAGS` are exported for that suite. Asserting this through
`runCli` would mean starting an MCP server to discover whether `--config` was read, and the
`mcp` defect is invisible from the outside precisely because `loadConfig` swallows a missing
file. A parser is testable directly.

---

## 31. A Probe May Only Claim Content Its Validator Already Accepts

**Date:** 2026-08-06
**Status:** implemented (Phase 4b.2)
**Scope:** `docs/phase-4b-pathless-code-scope.md` §4–§6. 4b.3 (the `MARKDOWN_MARKER_TYPES`
allowlist) remains scoping only.

### Why a probe at all, after §17 removed one

§29 gave the caller a way to say what pathless content is, and on the MCP path the caller
always knows. The Gateway is the case that cannot be closed that way: a provider payload has
**no language field anywhere in its schema**, per message or per request, which is why §29
declined a Gateway declaration outright. For the traffic the proxy actually carries, a probe is
the only route that exists.

§17 removed the previous content-only code detection because its single signal was a markdown
fence and the verdict flipped on apostrophe parity in the surrounding prose. That is an
argument against *that* probe, not against probes. The replacement is a majority-of-lines rule
— the shape §22 and §27 already use for logs and YAML — scoped to the one language where the
measurement supports it.

### Python only, and that is not a staging decision

§4 measured both. Python separates with a factor-of-seven margin. TypeScript does not separate
at all: positives span 0.283–1.000 and prose negatives reach 0.333, because this repository's
prose is documentation *about* TypeScript, dense with fenced TypeScript. No threshold orders
them. **A TypeScript probe is not proposed, now or later, without a different kind of signal**
— `--language` is what TypeScript over stdin gets.

### The rule, and the half that is not in the scope document

Structural: `strong >= 2 && (strong + weak) / counted >= 0.15 && disqualified / counted < 0.10`,
with comment lines excluded from numerator *and* denominator — `#` is a Python comment and a
markdown heading and cannot be evidence either way.

Then, and this is the addition:

> **A probe may only claim content the validator for that language already accepts.**

§6's risk 2 asked whether a fragment that fails the indentation rule should fall back or be
reported as uncheckable. Neither. It should not be detected. A declaration is the caller's
assertion, and failing on it is right — they said Python, it does not parse, they should hear
about it (§29's false-declaration case). A detection is *our* guess, and content that does not
parse is far likelier to mean the guess was wrong than that the user's data is broken. Failing
closed on our own guess turns a heuristic into a fallback generator on live traffic, which is
exactly the trade §17 refused.

So a detected item is one `PythonValidator` has already accepted, and detection can never make
an item *less* valid than leaving it as `text` would have. `PythonValidator` imports types
only, so consulting it from the model layer adds no cycle, and it runs only for candidates the
cheap regex pass already accepted.

The confirmation is load-bearing, not decorative: three malformed inputs that clear the
structural rule — a bad indent level, an unterminated string, a call truncated mid-argument —
are each rejected by it and land exactly where they landed before the probe existed.

### Both fields, atomically

`classifyContent` now wraps `classifyContentShape`, which returns `{ contentType, language? }`.
A detection sets both for the reasons §29 gives for declarations, one of them sharper here:
`contentType: 'code'` alone routes to the **TypeScript** validator, and `language` alone leaves
the tag at `text`/`markdown`, both on `MARKDOWN_MARKER_TYPES`, so the file's `#` comments would
be harvested as markdown headings and then destroyed by the very elision the detection just
enabled. §3 measured that half-fix pushing drift up on 14 of 20 files and over the gate on one.

An **extension** still never sets `language`. It does not need to — `selectValidator` consults
`path` itself — and doing so would put a `language` on every file-route item, moving every item
hash in the project for nothing.

### Position in the probe order

Behind json/yaml/html/logs, ahead of markdown. Ahead of markdown because that is what it has to
beat: measured pathless, 13 of 45 `pip` files classify `markdown` and the rest `text`. Behind
the other four because each is a decisive-shape detector that no Python file in either frozen
corpus triggers, so moving ahead of them adds blast radius and buys nothing. `looksLikeJson`
must stay first regardless — §4 measured a JSON tool result scoring 0.67 on a
brace-and-semicolon code signal, saved only by the JSON check standing in front.

### Measured

Corpora frozen under `sha256` manifests, engine A/B'd `dist-4b1` (`bdea1f0`) against
`dist-4b2`, `cl100k_base` tokens, `--target-reduction-ratio 0.3`:

| | detected | false positives |
|---|---|---|
| 45 `pip` Python (positive) | **39 (86.7%)** | — |
| 64 repo TypeScript | — | **0** |
| 25 repo markdown | — | **0** |
| repo YAML, `sample_logs.txt` | — | **0** |

| route | before | after |
|---|---|---|
| `pip` corpus over **stdin, undeclared** | 0.02%, 1 file reduces, 0/45 items checked | **12.27%, 19 files, 39/45 checked** |
| the same bytes as a **file argument** | 12.34% | 12.34% (**0 collateral**) |
| 64 TS sources over stdin | 0.07% | 0.07% (**0 files changed** — no TS probe) |

The probe recovers **99.4%** of the yield the filename route achieves. All six misses **parse
fine** — the structural rule declined them, not the validator — so the confirmation step costs
zero detections on this corpus while still rejecting every malformed fragment above.

**Gateway, measured as §6 requires.** Turn 1 of a real session, where `cleanup:session-dedup`
has no previous hashes and cannot elide, so any fallback is a false positive by construction:
no fallback, output byte-identical to input. Turn 2: byte-identical before and after, same
fallback, same token counts. The Python tool-result message is now `code`/`python`; prose and
log messages are untouched. **Zero new fallbacks on live traffic.** Output byte-identical
across 6/6 fresh processes.

### What is still open, stated because the yield table hides it

An **undetected** pathless Python file is not merely unoptimized — it is unprotected, and
§29's addendum predicted this. `pip`'s `status_codes.py` is a symbol-free constants file the
probe declines: over stdin it stays `text`, no validator covers it, §28's refusal cannot fire,
and it is elided whole and unwitnessed — 44 → 27 tokens — while the *file* route correctly
refuses it. Detection narrows that population; it does not close it. Closing it means either
detecting everything, which no probe does, or deciding what drift owes an item nothing covers,
which is §28's deferred prose question.

---

## 32. The "We Could Not Tell" Buckets Do Not Get to Assert Structure

**Date:** 2026-08-06
**Status:** implemented (Phase 4b.3). **Read the second half — the defect this uncovered is
larger than the change, and is deliberately not fixed here.**

### The change

`MARKDOWN_MARKER_TYPES` held `markdown`, `text`, `html`, `logs` and `unknown` while its own
docblock said a new `ContentType` "should default to *not* harvesting these — an absent marker
costs a little discrimination, an invented one actively inflates drift". The list and the rule
disagreed, and the disagreement was in the worst possible place: `text` and `unknown` are the
two **we could not tell** buckets. A bucket meaning *we do not know what this is* cannot also
mean *its `#` lines are headings*. `#`, ``` and `---` are not HTML or log syntax either.

The list is now `markdown` alone.

### Measured: inert, and that is the honest headline

| corpus | files | gated markers from the removed types |
|---|---|---|
| 64 repo TypeScript (60 land in `text`, 1 `html`) | 64 | **0** |
| 45 `pip` Python (2 land in `text`) | 45 | **0** |
| `sample_logs.txt` (`logs`) | 1 | **0** |
| `unknown` | — | only ever returned for empty content |

132 files over stdin, 40 over the file-argument route, and both Gateway turns are
**byte-identical** before and after. This is a consistency fix with no measured behavioural
change. It is worth having because the trap is latent — anything that starts classifying code
as `text` gets the fabrication back for free — not because it moves a number today.

### The defect it uncovered, which is not in those buckets at all

`docs/phase-4b-pathless-code-scope.md` §5 scoped 4b.3 as removing the fabrication for
"undetected Python, and pathless code in any other language". Measured, **the fabrication is
not in `text` or `unknown`. It is in `markdown`,** and no allowlist edit can remove it without
gutting real prose:

```
9 frozen shell scripts   -> classified markdown, 591 headings harvested, all `#` comments
4 undetected pip files   -> classified markdown,  45 headings harvested, all `#` comments
62 `text`-classified     ->                        0
```

`looksLikeMarkdown` fires on a single `#` heading (`/(^|\n)#{1,6}\s+\S/`), so a shell script's
first `# Copyright …` line makes the whole file markdown.

**And the harm is not the inflated drift.** Measured end to end on a frozen `tclConfig.sh`:

```
1,877 -> 19 tokens (99.0% deleted)   fallbackUsed false   driftScore 0.4
astCoverage    {checked: 0, unchecked: 1, uncheckedContentTypes: ["markdown"]}
driftCoverage  {structMeasured: true, measured: true, contentMarkersBefore: 79,
                symbolsBefore: 0, unwitnessedItems: []}
```

The file is deleted whole, nothing validated it, and drift reports **`measured: true`** on the
strength of 79 markers that are every one of them a comment line. `S_k` lands on exactly
`0.400` — `1 - (0.6·1 + 0.4·0)`, every fabricated marker destroyed — and passes only because
the gate is `> 0.40` rather than `>=`, which §3 of the scope document predicted in the
abstract and is here in the concrete.

So the fabricated markers do not merely inflate a score. **They forge the evidence that the
score measured anything**, defeating the `DriftCoverage` reporting §28 added precisely so this
class would be visible. That is invariant 10 again, and it is the first instance where the
report itself is the thing that lies.

### Why it is not fixed here

Three seams, none of them 4b.3's:

1. **The allowlist** cannot separate them: `# Copyright …` and `# A heading` are the same
   bytes, and `markdown` must keep harvesting for the 25 real documents that yield 477
   headings, 47 fences and 23 sections.
2. **`looksLikeMarkdown`** could require more than one `#` line, but that is a classifier
   change with blast radius over every prose item in every bundle — the gotcha CLAUDE.md
   states outright, and how §17 was found.
   **Measured 2026-08-06 and this reasoning is wrong — see `docs/phase-0-measurement-baseline.md`
   §6.** "More than one `#` line" is a *count* threshold, which the lever disposition had
   already shown points the wrong way. A **shape** discriminator — require a non-`#` markdown
   marker, or any two distinct signals — takes code misclassified as markdown from **114 of 264
   files to 12 (or 7), while retaining all 25 prose files**. The blast radius over prose is zero
   on that corpus. Seam 2 is the best-separating lever measured, and it is a *mitigation*, not
   the fix: it converts §32-shaped items into §28-shaped ones, which still reduce unwitnessed.
3. **Drift** could refuse to certify an item nothing covers, which is exactly the prose
   question §28 deferred as a product decision.

**All three were measured on 2026-08-06 and the deferral survives with better evidence:
`docs/phase-4b-lever-disposition.md`.** Seam 1 (a coverage gate prohibiting whole-item elision
where `astCoverage.checked == 0`) is dead twice over — `tclConfig.sh` and `CODE_OF_CONDUCT.md`
are identical on every trace field the gate could key on, and *every* Gateway dedup elision is
`checked == 0`, so the gate makes the proxy a pass-through. A fourth lever, non-content
discriminators, is also dead: a shebang catches one of the four destroyed files, and the
extension and executable bit do not exist on any pathless route. **Seam 2 was not re-measured
then; it was measured on 2026-08-06 and it separates — 114 → 12 with no prose casualty
(`docs/phase-0-measurement-baseline.md` §6).** Seam 3 survives and is still the deferral
itself, because seam 2 relocates the defect rather than closing it.

**One further correction, from the same measurement: this section's framing of the defect as
pathless is wrong.** `.pl` and `.tcl` are not in `isCodeExtension`, so Perl and Tcl classify
`markdown` **on the file-argument route too**. The worst case found is not a shell script over
stdin — it is `Unicode_Collate_Locale_ja.pl` at **57,037 → 19 tokens (100%)**, passed by name,
`fallbackUsed: false`, `astCoverage.checked: 0`. The variable is not the route; it is
membership of a hardcoded 19-entry extension list.

One correction to the sentence above, from that measurement: "the only identified fix" should
read "the only fix that does not either destroy the Gateway or reduce to §28's open question".
Three fixes are identified; the conclusion is unchanged.

Seam 3 is where this actually belongs, and the finding **reframes that deferred question**.
§28 deferred it as "may TokenDamper compress prose at all". The population is not prose. It is
**everything no validator covers**, which includes real source code in every language the
AST-lite suite does not implement — shell, Ruby, Go, Rust, SQL. Deleting 99% of a shell script
under a forged `measured: true` is not a product question about prose.

Pinned **by inversion** in `test/unit/markdown-marker-allowlist.test.ts` under
`KNOWN DEFECT (pinned by inversion)`. The first version of that block asserted the wrong
behaviour and passed, which made the defect the suite's de facto specification — the only thing
marking it as wrong was a docblock, and a docblock enforces nothing. It now states the
**contract** and carries `it.fails`: green while the contract is violated, red with
`Expect test to fail` the moment any remedy makes it hold. Three guards keep the inversion from
going vacuous — the pipeline result is computed at describe scope so a crash is a collection
error rather than a swallowed pass, the preconditions live in a separate ordinary test, and the
`it.fails` body holds exactly one assertion. The contract is remedy-agnostic and stated over the
input rather than over trace fields, because `tclConfig.sh` and `CODE_OF_CONDUCT.md` are
identical on every field the trace carries.

---

## 33. The Measurement Gate and the Retention Gate Are Two Gates

**Date:** 2026-08-06
**Status:** implemented (Phase A, part 1 of 2). Part 2 is the classifier seam — see §34.

### The defect

`S_k = 1 − (0.6·R_AST + 0.4·R_struct)` answers two questions with one scalar: *did anything
witness this item?* and *did enough of it survive?* Both ratios default to `1.0` on an empty
before-set, so "nothing to compare" and "perfectly retained" produce the same number, and
`0.400` is reachable from two structurally opposite configurations —
`R_AST = 1` (empty-set default) with `R_struct = 0`, and `R_AST = 1/3` with `R_struct = 1`.
One comparison arbitrates both, so `>` versus `>=` silently decides a question nobody asked.

§28 added the missing distinction but **scoped it to validator-covered items**, on the
grounds that enforcing on prose "would make every prose bundle incompressible, ending
`cleanup:session-dedup` on exactly the conversational traffic the Gateway carries".

### The measurement that overturned the scope

Phase 0 froze a 289-file corpus covering languages the AST-lite suite does not implement
(`docs/phase-0-measurement-baseline.md`). Measured, the scope was protecting the wrong
population:

- **Real documents were never in reach.** All 25 markdown files carry content markers and
  are witnessed. Widening the rule moves **none** of them.
- **The Gateway keeps within-payload deduplication.** `resolveRecoverableElisions` substitutes
  the original content for `recoverable` elisions *before* the rule runs, so a recoverable
  elision reads as unchanged and is skipped structurally. Measured end to end on the proxy:
  within-payload dedup saves 44 of 129 tokens with and without the gate. This is the decisive
  difference from lever 1 in `docs/phase-4b-lever-disposition.md`, which keyed on
  `astCoverage.checked == 0` — a condition *every* dedup elision satisfies — and therefore
  made the proxy a pass-through.
- **What the scope actually excluded was uncovered code.** `Unicode_Collate_Locale_ja.pl`
  went **57,037 → 19 tokens (100%)** on the *file-argument* route at `S_k = 0`,
  `measured: false`, `fallbackUsed: false`, because nothing covers `.pl` and the rule
  therefore never looked.

### The decision

Two changes, both in `src/core/ledger/drift-tracker.ts`:

1. **The unwitnessed-item rule no longer keys on validator coverage.** Any item that changed,
   was not pruned away, and yields neither symbols nor content-derived markers is refused.
   The witness may be of **either** kind — requiring symbols specifically would refuse every
   document; requiring neither is what permitted the Perl deletion.
2. **`DriftReport` carries `measurementGate` and `retentionGate` as separate verdicts.**
   `shouldFallback` remains their disjunction. `validate()` now reads `measurementGate`
   instead of re-deriving the distinction from `unwitnessedItemIds.length`, so the two
   existing issue codes (`SEMANTIC_DRIFT_UNMEASURABLE`, `SEMANTIC_DRIFT_EXCEEDED`) are driven
   by the gate that actually fired rather than by a second inference of it.

`calculateDrift`'s `symbolBearingItemIds` option is **removed**, not left inert — §30's rule.
`validate()` still computes the set for `DriftCoverage.symbolBearingItems`, which is reporting.

### Measured cost

62 of 578 corpus runs change, and nothing else moves byte-for-byte:

| bucket | route | before | after |
|---|---|---|---|
| perl | file + stdin | 34 reduce, **81.91%** | 7 reduce, **5.61%** |
| css | stdin | 6 reduce, 11.13% | 0 reduce, 0.00% |
| c | stdin | 2 reduce, 0.80% | 0 reduce, 0.00% |
| python / typescript / rust / prose / shell / tcl | both | — | **byte-identical** |

On the Gateway, cross-turn deduplication of a **sole copy** now falls back. That population is
the one `docs/phase-1-stabilization-summary.md` §9 already described as sending the model a
marker it has no way to resolve; refusing it is consistent with that entry, not a new position.

### What this does not fix, and why it needs §34

**Shell and Tcl are untouched by this change** — 20 shell files still reduce 17.28% over
stdin. They classify `markdown` because `looksLikeMarkdown` fires on a single `#` comment, so
`extractContentMarkers` harvests their comment leaders as headings and they report
`structMeasured: true`. The fabricated markers **forge exactly the evidence this gate checks**.

That is why Phase A is two changes and not one. The measurement gate closes the honest half
(`text`-classified, `measured: false`); the classifier seam closes the forged half. Measured
together they take every uncovered-language bucket to 0.00% while every AST-covered bucket and
all 25 prose files keep their full yield.

### Tests

`test/unit/drift-unwitnessed-elision.test.ts` gains an uncovered-language refusal (the Perl
case in miniature) and two gate-separation tests. Two existing tests were **inverted**, both
because they encoded the old scope: the prose exemption, and the coverage escape hatch.

Three tests elsewhere were passing on the empty-set default and are corrected rather than
deleted — `engine.test.ts`'s emit-path fixture elided a witness-free `text` item and asserted
`fallbackUsed: false`, which only held because drift measured nothing; and two Gateway dedup
tests used a sole cross-turn copy. `declared-language.test.ts`'s pathless-barrel test
asserted that the hole was still open on the undeclared route, and now asserts it is closed.

---

## 34. Markdown Needs a Marker That Is Not a `#` Line

**Date:** 2026-08-06
**Status:** implemented (Phase A, part 2 of 2). Closes §32.

### The defect

`looksLikeMarkdown` accepted a single `#` heading as sufficient evidence of a document. `#` is
the comment leader in shell, Perl, Tcl, Ruby, R, YAML and Python, so one `# Copyright …` line
made a whole shell script `markdown`.

That is not a cosmetic misfiling. `DriftTracker`'s `MARKDOWN_MARKER_TYPES` harvests markdown
headings for `markdown`-tagged items, so the comment leaders became **structural markers**,
`structMeasured` went `true`, and drift certified an item nothing had examined. Measured:
591 fabricated headings across 9 frozen shell scripts, and `tclConfig.sh` at 1,877 → 19 tokens
with `fallbackUsed: false` and `driftCoverage.measured: true`.

### Why §32 deferred it, and why that reasoning was wrong

§32 named this seam and rejected it: *"could require more than one `#` line, but that is a
classifier change with blast radius over every prose item in every bundle."*

"More than one `#` line" is a **count** threshold, and `docs/phase-4b-lever-disposition.md` §1
had already shown counts point the wrong way — `tclConfig.sh` carries **79** markers to
`CODE_OF_CONDUCT.md`'s **12**, so any count rule protects the shell script *less*. The seam
was dismissed on the strength of the one formulation of it that cannot work.

The discriminator that does work is **shape**: a real document also has fences, lists or links;
a commented config fragment has none. Measured over the 289-file Phase 0 corpus
(`docs/phase-0-measurement-baseline.md` §6):

| candidate | code → markdown (of 264) | prose → markdown (of 25) |
|---|---|---|
| what shipped before | **114** | 25 |
| require a non-`#` marker | 11 | **24** — loses `CODE_OF_CONDUCT.md` |
| **the same, with the list regex repaired** | **12** | **25** |
| any two distinct signals | 7 | 25 |

**Blast radius over prose: zero files.**

### The decision

Drop the bare-heading alternative from `looksLikeMarkdown`, and repair the list regex in the
same change because the second is what makes the first safe.

The old list rule was `/(^|\n)(- |\* |\d+\.)\s+\S/`. The alternation already consumed the space
after the bullet and `\s+` then demanded another, so `- item` and `* item` — the two commonest
list forms — did not match, while `-  item` and `1. item` did. 21 of 25 corpus documents
tripped the old rule against 25 of 25 under the repair. That single missing match is the whole
difference between the two middle rows above.

The stricter "any two distinct signals" variant separates better (7 versus 12) and is **not**
taken: it costs a second concept for five files, and every one of the 12 residual leaks is
honest — two shell scripts with `- ` lists, three Tcl files whose `[...]` command syntax
matches the link regex, four pip files, and three of this repository's own sources whose doc
comments genuinely contain fenced markdown.

### Why this had to be part of the same phase as §33

Neither half closes the defect alone, and the corpus says so:

| arm | shell over stdin | perl, both routes |
|---|---|---|
| baseline | 20 reduce, 17.28% | 34 reduce, 81.91% |
| §33 measurement gate only | **20 reduce, 17.28%** — unmoved | 7 reduce, 5.61% |
| §34 + §33 | **0 reduce, 0.00%** | **0 reduce, 0.00%** |

The measurement gate refuses an item that left no witness — but the fabricated headings *were*
the witness it checks. Seam 2 removes the forgery, which is what brings shell and Tcl into the
gate's reach. Stated the other way: §34 without §33 would have relocated those files from the
forged failure to the honest one, where they would still have been elided unwitnessed.

### Measured, end state

114 of 578 runs change against the Phase 0 baseline, and the change is confined:

- **Every uncovered-language bucket goes to 0.00%** — shell, perl, tcl, c, css over stdin.
- **258 of 258** rows in the AST-covered buckets (python, typescript, rust) and the prose
  bucket are **byte-identical** to baseline.
- The combined result was predicted by an A/B patch before implementation and matched it on
  all 578 rows with **zero** mismatches.

### Consequence for §32

§32 is closed. `test/unit/markdown-marker-allowlist.test.ts` is no longer a defect pinned by
inversion; the `it.fails` contract went red with "Expected test to fail" the moment the remedy
landed, exactly as designed, and its preconditions test went red alongside it because the fix
arrived from a direction the contract could not see. Both are now stated positively, and the
file asserts the closure rather than the defect.

### What remains open

`isCodeExtension` is still a hardcoded 19-entry list, and membership of it still decides
whether a real source file is validated at all. Phase 0 §4 measured that `.pl` and `.tcl` fall
outside it on the *file* route. Nothing here changes that; what changes is that falling outside
it now yields a refusal instead of a silent deletion.

---

## 35. Fail-Open Means the Caller's Bytes, Not a Re-encoding of Them

**Date:** 2026-08-06
**Status:** implemented (Phase B). Re-scopes 1b; the Issue 5 premise stays retracted.

### The defect, and how it was found

`resolveFallback` returns `request.rawInput` on the fallback branch, which reads like a
byte-identical echo. It is not one. `rawInput` is a string the CLI produced with
`readFileSync(path, 'utf8')`, and that call replaces every invalid byte with U+FFFD, which
re-encodes to three bytes. The guarantee held only for input that happened to be valid UTF-8,
and nothing in the code or the docs said so.

Found by the Phase 0 harness, not by reading: of 504 fallback runs, **502 were byte-identical
and two were not.** `vimspell.sh` — a Latin-1 file containing "Fernández-Sanguino_Peña" — came
back **1,462 → 1,466 bytes with `fallbackUsed: true`**. Two characters, four bytes, and a
silent violation of invariant 3 on the path whose entire purpose is to be safe.

This is the Issue 5 *class* — output larger than input on fallback — arriving by a mechanism
nobody had proposed. It is not the retracted −1.39%, which remains a harness artifact.

### The decision

1. **The CLI reads bytes and decodes second.** `readFileSync(path)` then `.toString('utf8')`,
   keeping the `Buffer`. On fallback it writes the buffer, not the string.
2. **Input that does not survive a UTF-8 round-trip forces a fallback**, via a new
   `EngineOptimizationOptions.inputNotRepresentable` reason. Every stage, validator and token
   estimate operates on the decoded string, so for such bytes they are all reasoning about
   content the caller never sent; a reduction measured against corrupted input is worse than
   none.
3. The test is a **round-trip**, not a BOM or charset sniff. The only question that matters is
   whether these exact bytes survive the string model the pipeline is built on. Valid UTF-8
   with multi-byte characters is unaffected, which is pinned by test — otherwise the guard
   would refuse most of the world's source comments.

### Why the refusal goes through the engine

The first implementation short-circuited in the adapter: correct bytes, and **no trace at
all**. The corpus harness immediately recorded two rows it could not parse, which from outside
is indistinguishable from the process having died. That is invariant 10's shape — a run that
reports nothing is not a safe run, it is an unobservable one — so the refusal is routed through
`optimize()` and produces an ordinary trace with `fallbackUsed: true` and a stated reason.

### Measured

| | before | after |
|---|---|---|
| fallback runs byte-identical | 502 / 504 | **504 / 504** |
| corpus rows changed | — | 2 (both `vimspell.sh`) |
| rows with unparsable traces | — | **0** |

### The other half of 1b: the multi-item join is latent, and that is now checked

`resolveFallback`'s **success** branch renders with `items.map(i => i.content).join('\n')`,
which is correct for one item and destroys boundaries, roles and enclosing structure for more.
CLAUDE.md has described this as the live half of 1b. Measured, it has **no live consumer**:

- Every route that reads `emittedOutput` — CLI, MCP, bench — builds its bundle through
  `createOptimizationRequest` → `createContextBundle`, which produces exactly **one** item.
- The only multi-item producer is the Gateway, which maps `finalBundle` positionally and never
  touches `emittedOutput` (invariant 9).

So it is a latent defect held latent by a convention in two other files. Rather than add model
surface for a hypothetical consumer, it is **pinned**: `test/unit/fallback-render.test.ts`
asserts the flattening explicitly, including that the render is not injective — two different
bundles produce byte-identical output — so making any `emittedOutput` consumer multi-item
changes a test rather than a payload.

### Not done here

The pipeline remains string-based, and that is the frozen architecture. A file that is not
valid UTF-8 is therefore never optimized, only echoed. Making the model byte-oriented would
touch every stage, validator and estimator, and is not justified by one file in 289 — but the
refusal is now explicit and traced instead of silent and lossy.

---

## 36. The License Is MPL-2.0, and `package.json` Was the Stale Copy

**Date:** 2026-08-09 · **Status:** Accepted · **Closes:** max_audit.md M3

The repository declared two different licenses. `LICENSE` is a full Mozilla Public License
2.0 and `README.md` stated the project "is now licensed under" it — the word *now* recording a
deliberate migration. `package.json` still carried `"license": "MIT"`, and `CLAUDE.md` repeated
the MIT claim in its opening description.

This is not cosmetic. `package.json` is `"private": false` with a `files` array and a
`prepublishOnly` script, so it is meant to be published, and npm surfaces the `license` field
as the authoritative machine-readable signal. Consumers and license scanners would read **MIT**
— permissive, no reciprocity — and actually receive **MPL-2.0**, which carries file-level source
disclosure obligations on modification. The direction of that error is the harmful one: it
understates the obligations a downstream user takes on.

### Decision

MPL-2.0 is the license. `package.json` and `CLAUDE.md` are corrected to match `LICENSE`, which
is the document that actually grants rights and is the only one of the four with legal text in it.

### Also corrected

`README.md` carried "Copyright (c) 2026 Ojas Sugur. **All rights reserved.**" immediately above
an open-source grant. "All rights reserved" asserts the opposite of what the license does, and
placing it directly above the grant makes the section self-contradicting. The copyright line is
retained without it, and the trademark reservation that follows is explicitly scoped to the
*name* rather than the code — which is what it was always meant to say.

### Why this was never recorded

The MIT → MPL migration itself has no entry in this file. It was made in the README and the
LICENSE and nowhere else, so nothing prompted a sweep of the other places the license is
asserted. The lesson is narrow and worth keeping: a license is asserted in four files, and
changing it in one is a change to none of the others.

---

## 37. A Witness That Existed Before Does Not Count If None of It Survived

**Date:** 2026-08-09 · **Status:** Accepted · **Closes:** max_audit.md C1 (measurement half)

§33 widened the measurement gate from validator-covered items to every item, and was right to.
What it did not change was the **tense** of the question. `findUnwitnessedItems` asked *did
evidence exist before?* — it built its probe bundle from the *before* item — so an item whose
witnesses were all destroyed was exempt, on the grounds that they had once been there.

A structured document therefore walked between the two gates that were split apart to catch
exactly this. Measured on this repository's own files, on both the file and stdin routes:

| file | before | after | `fallbackUsed` | `S_k` |
|---|---|---|---|---|
| `CODE_OF_CONDUCT.md` | 3,542 B | **72 B** | `false` | 0.369 / **0.400** |
| `SECURITY.md` | 1,154 B | **72 B** | `false` | 0.333 / **0.400** |

`validation.passed: true`, both gates `pass`, the content gone and — on the CLI, which supplies
no `TokenHasher` — unrecoverable.

### Why neither gate fired

The arithmetic is closed-form, which is what makes this a design defect rather than a tuning
miss. Prose yields no symbols, so `R_AST = 1.0` as an empty-set default and contributes a free
0.60. `collectMarkers` adds a `filepath:` marker derived from `item.path`, which no content
transform can destroy, so `R_struct = 1/(N+1)` for N headings. Therefore:

```
S_k = 0.6·0 + 0.4·(N/(N+1))  =  0.4·N/(N+1)
```

which approaches 0.40 from below and never reaches it, for any N — against a retention gate
that fires on `driftScore > 0.40`. **The retention gate cannot fire for markdown at all.** The
two stdin rows above landed on *exactly* 0.400 and were admitted by the strict `>`; that is the
supremum of the expression being waved through by the comparison, not a near miss.

And the measurement gate exempted them because their headings had existed.

### Decision

An item that changed is refused when it yields **no symbols** and **no content-derived markers
survive in the after item**. Two properties make this safe:

- **It is scoped to symbol-free items.** An item carrying symbols is left to the retention gate,
  because `R_AST` is measuring it for real. Whole-item elision of code still refuses as
  `SEMANTIC_DRIFT_EXCEEDED`, which is the accurate reason — reporting "unmeasurable" for an
  item whose loss was measured exactly would restore the conflation the split undid.
- **It only ever adds refusals.** Refusing on the surviving set is strictly stronger than
  refusing on the before set, so every §33 refusal still refuses. Nothing that was caught is
  now let through.

### Measured cost

A frozen 293-file corpus, 586 rows across both routes: **4 rows changed, and all four are this
defect.** Every other row is byte-identical to baseline. TypeScript stays at 14.00%, Python at
14.98%, and every uncovered-language bucket stays at 0.00%. The prose bucket goes 0.67% → 0.00%,
which was the data loss.

### Not done here

`filepath:` is still counted in `R_struct` (audit C1b, §3.2). That is the deeper half: it is why
`R_struct` is pinned at 1.0 for code and contributes a free 0.40, which in turn is why a code
file can lose **66.7%** of its symbols and pass. Fixing it moves every published reduction figure
in the project and wants its own measurement pass, so it is deliberately deferred rather than
folded in here. C1a closes the data loss; C1b closes the arithmetic.

`extractContentMarkers` remains the right primitive for both — its own doc comment has said since
§28 that metadata-derived markers "cannot serve as *evidence* that content was retained, because
they are preserved whether it was or not". The principle was already written down. This applies
it where the decision is made.

---

## 38. The Gateway Reads Bytes, Not String Fragments

**Date:** 2026-08-09 · **Status:** Accepted · **Closes:** max_audit.md C2, L3

`GatewayServer.onRequest` accumulated its request body with `body += chunk`. That invokes
`Buffer.prototype.toString('utf8')` on **each chunk independently**, so a multi-byte UTF-8
sequence straddling a chunk boundary is decoded as two truncated fragments and becomes U+FFFD on
both sides. Node reads in ~64 KB chunks, so this fires by chance on any body large enough to be
chunked, and deterministically for a body split at the wrong offset.

Measured against the unfixed server, with each body written in two `req.write()` calls split on
a UTF-8 continuation byte:

| body | sent | forwarded |
|---|---|---|
| `héllo — ünïcode ✓ 日本語 😀` | 94 B | **98 B**, `h��llo …` |
| `こんにちは世界` | 76 B | **82 B**, `���んにちは世界` |
| `┌─┐│ build ok │└─┘` | 89 B | **95 B**, `���─┐│ build ok │└─┘` |

A corrupted body is always *longer* than it was sent, because U+FFFD re-encodes to three bytes.
Nothing was elided on any of these turns — the corruption happens at the socket, before the
pipeline exists, and the corrupted string is what goes upstream.

### This is DECISIONS §35 at a different seam

Phase B's reasoning — *"`rawInput` is a decoded string, so the evidence is gone by the time a
request exists"* — is correct and generalizes. It was applied to the one adapter that reads from
disk and not to the one that reads from a socket, where it is worse: the bytes reach a provider
rather than a terminal. The MCP transport is unaffected, and instructively so: `setEncoding('utf8')`
installs a `StringDecoder`, which holds partial sequences across chunk boundaries. Manual
concatenation is exactly what bypasses that machinery.

### Decision

Collect `Buffer[]`, `Buffer.concat` on `end`, decode **once**. Then apply the CLI's own round-trip
test (`Buffer.from(str, 'utf8').equals(buf)`) and, when it fails, pass the caller's bytes through
untouched.

Concatenating correctly fixes the chunk-boundary defect. It does not make a body that was never
valid UTF-8 representable — the decode is still lossy — so the round trip is a separate question
and gets a separate answer. Optimizing such a body is not an option, because every stage,
validator and token estimate operates on the decoded string and would be reasoning about content
the caller never sent; a saving measured against corrupted input is worse than none. Rejecting it
is not an option either: TokenDamper is a transparent proxy, and a body the provider might well
accept is not TokenDamper's to refuse. So it is forwarded verbatim, which is invariant 3 on the
Gateway.

`ProxyRequestResult` gains an optional `bodyBytes`; `body` is still populated with the lossy
decode so existing readers keep working, but anything that puts bytes on the wire prefers
`bodyBytes`. Both the upstream `fetch` and the locally-returned branch in `writeProxyResult` do.

### Also fixed

The body-size cap recomputed `Buffer.byteLength(body, 'utf8')` over the entire accumulated string
on every chunk — O(n²) in the length of the request (audit L3). It is now a running total, which
falls out of collecting buffers anyway.

### Not done here

The remaining Gateway findings are untouched and independent: the `exec` token handoff (C3), the
0-bytes-saved measurement (H1), structured message content flattened to a string (C4), and the
two environment branches in the request path (M8). C2 is a correctness fix to the pass-through,
not an argument that the mode is finished.

---

## 39. The Trace Carries What the Stages Computed

**Date:** 2026-08-09 · **Status:** Accepted · **Closes:** max_audit.md M6

`buildTrace` projected every `StageResult` down to `{ stageId, status, durationMs: 0, changed }`.
The stage's `metrics` and `notes` were discarded and the duration was a literal constant.

So the trace could say that `compression:token-hashing` ran and changed something, and nothing
about what it removed, how much, whether any elision was reversible, or how long it took. The
stages compute that telemetry carefully — `itemsHashed`, `regionsHashed`, `bytesSaved`,
`irreversibleElisions`, `skippedPostConditionRejected` — and all of it was thrown away one
function call after being calculated. `--diff` and `--diff-html` partially compensate on the CLI;
the MCP `get_optimization_trace` tool and the Gateway had nothing else at all.

For a product whose stated differentiator is auditability, the audit surface was the least
informative one in the system.

### Decision

`StageTrace` gains `metrics` and an optional `notes`, carried through verbatim. `durationMs` is
measured by the **engine**, not by the stage: a stage that read a clock would stop being a pure
function of its input (invariant 1), whereas timing an opaque call from outside is an observation
*about* the stage and cannot change what it returns. `performance.now()` rather than `Date.now()`,
because most stages finish inside a millisecond and integer resolution would report the same
uninformative `0` the hardcoded constant already did.

The trace was already non-deterministic — it carries a UUID `requestId` — so this changes nothing
about invariant 1, which is a statement about emitted **bytes**.

### The pruner's note was not vague, it was false

`pruning:topology-pruner` returned `notes: 'All items fit within token budget; no pruning
required.'` unconditionally whenever `itemsPruned === 0`. Measured, a 5,405-token file at
`maxInputTokens: 10` reported that all items fit. They do not.

The mechanism is worth stating because it is also H5: `applyCacheAwarePrefixLocking` pins every
item inside the first 1,024 tokens, `solve01Knapsack` places pinned items outside the candidate
set and always selects them, and `createContextBundle` produces a **one-item** bundle for CLI,
MCP and bench. Item 0 is therefore always pinned and `itemsPruned` is always 0. The note reported
that pruning was *unnecessary* for the case where it was *impossible*.

The note now distinguishes the three cases and names the mechanism, and the metrics carry
`bundleTokens` and `maxTokens` so the claim is checkable rather than asserted:

> Nothing prunable: all 1 item(s) are pinned by cache-prefix locking, but the bundle is 5405
> tokens against a budget of 10. Pinned items bypass the knapsack (invariant 7), so the budget
> could not be enforced.

This does not fix H5 — the knapsack is still unreachable on every shipping path. It stops the
trace from concealing that behind a reassuring sentence, which is the necessary first step:
the defect is now visible in the one place a user would look.

---

## 40. A Ratio That Measured Nothing Does Not Vote, and a Local Variable Is Not a Symbol

**Date:** 2026-08-09 · **Status:** Accepted · **Closes:** max_audit.md C1b, §3.2

Two changes that only work together. Landing either alone is measurably worse than landing both.

### The audit's proposed fix is inert

max_audit.md §3.2 proposed using `extractContentMarkers` in `R_struct`, excluding the
`filepath:` marker that no content transform can destroy, and stated this "would fix both cases
at once". Measured, it fixes neither: removing the only marker an item had leaves the before-set
**empty**, and an empty set defaults `R_struct` back to **1.0** — the identical free 0.40,
arriving by a different route. That change alone was byte-identical across all 586 rows of a
frozen 293-file corpus.

The free 0.40 comes from the **empty-set default**, not from `filepath:`. This is §33's argument
("`0.0000` means 'retained everything' and 'found nothing to look at' indistinguishably") applied
to the *score* rather than to the gate.

### Decision, part 1: an unmeasured ratio is excluded, not defaulted

`R_struct` is computed over `extractContentMarkers`, and the weight of a ratio whose before-set
is empty is redistributed to the ratio that did measure something. For code, `S_k = 1 - R_AST`,
so the maximum symbol loss that can pass the 0.40 gate falls from **66.7%** to **40%**. When
neither ratio measured, retention returns 1.0 and stays silent — that case belongs to the
measurement gate (§37), and having both refuse would attribute the refusal to the wrong question.

### Decision, part 2: `extractSymbols` counts semantic surface, not locals

Applied on its own, part 1 costs **14 TypeScript files and 11.75pp** — and the loss it was
guarding against turned out to be almost entirely fictitious. Measured at
`targetReductionRatio: 0.5`:

| file | symbols "lost" | of which function-local |
|---|---|---|
| `src/core/engine/index.ts` | 42 of 63 (66.7%) | **41** |
| `src/core/hashing/tokenizer.ts` | 9 of 17 (52.9%) | **9** |

Not one exported function, type or interface was lost in either case — `selectElisionRegions`
retains signatures by construction. The locals rule matched `const|let|var` anywhere, so every
`const i`, `const result`, `const msg` inside a function body counted as a semantic symbol on par
with an exported function, and body elision is precisely the transform that removes them. So the
audit's "you can destroy two-thirds of every symbol in a file and pass" was measuring temporaries
inside bodies the caller asked to have elided.

**Python is the control.** Its extractor never had a locals rule, its measured symbol loss under
the same elision is **0.0%**, and it is unaffected by either half of this change. That asymmetry
is what identified the defect: a safety metric should not depend on which language's extractor
happens to harvest block-scoped bindings.

The rule is now anchored with `^…/gm`. In TypeScript and JavaScript a top-level declaration *is*
a column-0 declaration; indented ones are inside a function, class or block, and are body content.

### Measured, over a frozen 293-file corpus (586 rows, both routes)

| arm | TS files reducing | TS saved | Python saved |
|---|---|---|---|
| before (§37 only) | 22 | 14.00% | 14.98% |
| C1b alone | 8 | **2.25%** | 14.98% |
| symbol fix alone | 30 | **25.59%** | 14.98% |
| **both (shipped)** | **29** | **23.38%** | 14.98% |

The gate is **stricter** and reduction is **higher** — because the gate is now measuring semantic
loss instead of noise. Python, prose and every uncovered-language bucket are unchanged.

### The one file it costs, and why it is left alone

`src/cli/html-reporter.ts` goes from reducing to falling back. Its sole content marker is
`directive:TD_PRESERVE:[^\s&]+)/g,` — harvested from a **regex literal** in the file that
implements syntax highlighting for that directive. Its own pattern source is its only structural
evidence, eliding it drives `R_struct` to 0, and the file is refused.

That is a false positive, and it is left in deliberately. It fails **conservatively** (fallback,
byte-identical output, no data loss), it is 1 file in 57, and special-casing it would be
over-fitting the metric to one file in this repository. Recorded rather than patched.

### Known residue

`extractSymbols` still harvests from **comments**, because it is regex over raw content with no
lexer. Measured artifacts: `fn:of` from the prose "pure function of its input", and `type:of`
from "that class of bug". After the locals fix this is the entire remaining symbol loss on
`src/core/engine/index.ts` — 1 symbol of 22, 4.5%. Small, but it means symbol counts on a heavily
commented codebase carry noise proportional to how often the words `function` and `class` appear
in English. Not fixed here: making extraction comment-aware is a per-language lexing problem,
and the measured cost does not yet justify it.

---

## 41. The Gateway Is an Experimental Pass-Through, and `exec` Now Reaches It

**Date:** 2026-08-09 · **Status:** Accepted · **Closes:** max_audit.md C3, H1, L2 (partial)

Two findings, one decision, because they are the same question: what is Gateway mode *for*?

### C3 — `exec` returned 401 to its own child

`runExecCommand` generated a per-run token and injected it as `TOKENDAMPER_GATEWAY_TOKEN`. The
server required it on every non-`/health` request. The child is `aider`, `claude`, `codex` or
`curl` — third-party software that has never heard of that variable and sends `authorization` or
`x-api-key` and nothing else. **Nothing in `src/` read it either.**

Reproduced by spawning a real child through `runExecCommand`: every request came back
`401 Unauthorized: Invalid or missing gateway token`, and `exec` exited **0**. The flagship
integration was non-functional end to end, and the existing test suite passed throughout because
its gateway test presented the header that no real client sends.

**Decision: trust loopback peers, keep the token for non-loopback binds.** The server binds to
`127.0.0.1` by default, so a loopback peer was already the only peer that could connect; the
token was protecting one local process from another on the same machine. That boundary is real
but narrow, and it was being paid for with a mode nobody could use. Loopback is determined from
`req.socket.remoteAddress` — never from a header, since `X-Forwarded-For` is attacker-supplied —
and includes `::1` and the IPv4-mapped `::ffff:127.0.0.1` form Node reports on a dual-stack
listener.

**`HTTP_PROXY` and `HTTPS_PROXY` are no longer set.** `GatewayServer` implements neither HTTP
proxy semantics (absolute-form request URIs) nor the `connect` event `CONNECT` tunnelling
requires. Any child honouring `HTTPS_PROXY` — most HTTP clients — would have failed to reach the
provider at all, independently of the 401 and masked by it. Setting a proxy variable for a server
that is not a proxy is worse than setting nothing. Base-URL interception is now the only
supported mechanism, and is documented as such.

**Partial L2:** the `?token=` query parameter is removed (a credential in a query string lands in
access logs, shell history and any error echoing the URL) and the header comparison is now
constant-time.

### H1 — the Gateway saves nothing across turns, and that is correct

Measured over real sockets on realistic two-turn conversations, where a resent history contains
each block exactly once: **0 bytes saved, fallback on every turn**, for code, prose and JSON tool
results alike.

This is not a bug. `cleanup:session-dedup` marks an elision `recoverable: true` only when an
intact copy survives elsewhere in the same outbound payload (§16). A sole copy seen only in a
previous turn is scored in full and refused — correctly, because Phase A established that the
consumer is a stateless provider API with no rehydration mechanism, so such a marker is
**deletion, not reference**.

The consequence is that the Gateway has no cross-turn transform, and none is available without
provider-side resolvability that does not exist.

**Decision: document it as experimental and stop advertising the saving.** The mode delivers
transparent interception, the full validation pipeline, byte-faithful forwarding (§38), metrics,
and within-payload deduplication. That is a coherent product; "Cross-turn Session Deduplication"
was not. README, ARCHITECTURE and CLAUDE.md invariant 8 are updated to say so.

The measurement is pinned by `test/integration/gateway-dedup-reality.test.ts` rather than left
as prose. **If a cross-turn saving ever appears, that is the signal to read**: either
resolvability was implemented, in which case update the test deliberately, or the drift gate was
relaxed and the Gateway is deleting content the model cannot recover, in which case do not.

### Also corrected in the README

The audit's M4 list of overstated claims is now resolved rather than deferred: "0/1 Knapsack
Planning" is marked implemented-but-unreachable (H5, one-item bundles), "Reversible Token
Hashing" is qualified as irreversible on the CLI by design, `TOKENDAMPER_RISK_TOLERANCE` is
marked as having no effect on optimization (H4, still open), and `TOKENDAMPER_GATEWAY_TOKEN` is
described accurately.

### Not done here

H1's underlying limitation is untouched by choice. C4 (structured message content flattened to a
string) remains open and is still masked by the fallback; M7 (savings measured against a
newline-joined render rather than the wire bytes) and M8 (two environment branches in the request
path) remain open.

---

## 42. An Imperative Lives in a Comment, Not in an Expression

**Date:** 2026-08-09 · **Status:** Accepted · **Closes:** max_audit.md H6

`cleanup:constraint-preservation` scans content for nine keywords — `must`, `must not`, `never`,
`always`, `only if`, `do not`, `required`, `except when`, `make sure to`, `critical` — and
`validate()` fails the run if any extracted sentence is absent afterwards. The list is written for
natural-language system prompts. It was applied to raw content of every kind, and in source
`required` and `critical` are ordinary identifiers. On the audit's corpus, **24 of 40 fallbacks
involved `CONSTRAINT_DIRECTIVE_LOST`** — the single largest cause of code not being optimized.

### Neither extreme is right, and the measurement says why

Over a frozen 293-file corpus at `targetReductionRatio: 0.3`, classifying every directive a run
reported as dropped by where it came from:

| bucket | from comments / docstrings | from code |
|---|---|---|
| Python | 16 | **38** — nearly all `logger.critical(...)` |
| TypeScript | 38 | **13** — `readonly required?`, error-message literals |

Trusting the check everywhere keeps 51 false positives. The audit's proposed remedy — *"scope
directive extraction by content type (prose/markdown/prompt kinds only, not `code`)"* — discards
54 genuine constraints, and specifically the Python docstring case that
`docs/phase-1d-semantic-gate-disposition.md` measured to be the **only** thing this check
actually catches.

What separates the two populations is not the content **type** but the **region**. An instruction
to a reader lives in a comment or a docstring; it never lives in an expression.

### Decision

1. **Extraction is scoped to prose regions.** `extractProseRegions` returns whole content for
   prose content types, and for code returns line comments (`//`, `#`, `--`, `*`), block comment
   bodies, and Python docstrings including their interior lines. It is deliberately
   line-oriented and syntax-approximate rather than lexed: this is a *filter on what may raise a
   constraint*, so over-inclusion costs a false positive — the pre-existing behaviour — and
   under-inclusion costs a missed constraint. Requiring the comment leader at the **start** of a
   trimmed line is exactly what excludes `logger.critical(exc)` while keeping
   `# never call this twice`.

2. **Retention is checked per item.** The check collected every item's directives into one list
   and tested each against `after.items.map(i => i.content).join('\n')`. A directive extracted
   from item A was therefore satisfied if the string happened to appear anywhere in item B — the
   check could pass for content that was in fact destroyed — and a loss anywhere failed the whole
   run with no way to say where. Matching by item id fixes both, and the message now names the
   item. An item absent from `after` is skipped, on the same reasoning
   `DriftTracker.findUnwitnessedItems` records: selection is not elision, and failing here would
   make any prunable item carrying an imperative unprunable.

### Measured

| bucket / route | before | after | delta |
|---|---|---|---|
| python (file) | 14.98% | **23.14%** | +8.16pp |
| python (stdin) | 14.88% | **22.66%** | +7.78pp |
| typescript (file) | 23.38% | **27.33%** | +3.95pp |

**20 rows changed of 586, and none regressed** — no file went from reducing to falling back.
Every other bucket is byte-identical.

### What remains, and why it is the check working

After the change, TypeScript has **zero** remaining code-sourced directives; every remaining
`CONSTRAINT_DIRECTIVE_LOST` is a genuine imperative in a comment or docstring that an elision
would drop. Those files still fall back, and should: the run would otherwise silently delete an
instruction. That is the check doing its job rather than misfiring, and it is why the category
does not go to zero.

### Ordering note

This had to land **after** §37 (C1a). The audit observed that this check was "currently the only
thing preventing markdown documents from being deleted" — a document survived if its author
happened to use one of nine words. Narrowing it first would have widened that data loss. With
§37 in place the drift measurement gate covers markdown on its own merits, which the corpus
confirms: the prose bucket is unchanged at 28/28 fallbacks, now attributed to drift rather than
to a coincidence of vocabulary.

---

## 43. The Knapsack Gets Something to Solve

**Date:** 2026-08-09 · **Status:** Accepted · **Closes:** max_audit.md H5 (ingestion half)

`ARCHITECTURE.md`, `README.md` and CLAUDE.md all put a "Stateless 0/1 Knapsack Planner" at the
centre of the design, and invariant 6 promises cache-aligned selection as the differentiator. None
of it could run. `createContextBundle` produces exactly **one** item;
`applyCacheAwarePrefixLocking` pins everything inside the first 1,024 tokens; `solve01Knapsack`
places pinned items outside the candidate set and always selects them. So item 0 was always
pinned, `itemsPruned` was always 0, and `planner/knapsack.ts`, `planner/cache-aware.ts`,
`topology/topology-scorer.ts`, `topology/dependency-graph.ts` and `topology/git-inspector.ts`
could not affect any output the product was able to produce.

`optimize` now accepts multiple paths and directories. Measured on `src/core` at
`maxInputTokens: 4000`: **31 items, 15 pruned, 20,540 tokens saved by the planner.**

### The output format, and the test that demanded a decision

`test/unit/fallback-render.test.ts` pinned the success path's `items.join('\n')` as a latent
defect and said in as many words that whoever made an `emittedOutput` consumer multi-item "should
stop and read it". This is that change, so the defect is fixed rather than inherited.

**One item renders as its content and nothing else**, which keeps CLI, MCP and bench byte-identical.
More than one renders with a `==> path <==` header per item — `head`/`tail`'s convention, chosen
because it is one a reader already knows. It is **not** collision-proof and nothing escapes it:
the consumer is a model being given context, legibility is worth more than round-trip parsing,
and anything needing to machine-parse should read `finalBundle` from the trace, which carries the
items structurally.

Fail-open is **per file** — the original bytes of each file, under the same headers, never a
re-encoding of the decoded string (DECISIONS §35 holds per item). What is not byte-identical is
the stream as a whole, because the headers are TokenDamper's and were in no input file.

### Three defects this exposed, each fixed here

1. **Pruning was scored as drift.** `findUnwitnessedItems` had always exempted an item absent from
   `after` — selection is not elision — but the *ratios* compared whole bundles, so a pruned
   item's symbols simply vanished and `R_AST` read the planner doing its job as semantic loss.
   Invisible while every bundle held one item; decisive at 31. The ratios now score retained items
   only, **guarded on ids actually corresponding** between the bundles: `id` is content-derived at
   construction and preserved by the transforms, so a caller that rebuilds its `after` bundle
   independently would otherwise leave nothing to compare and report `S_k = 0` for a gutted
   bundle. With no correspondence the whole bundle is compared, as before. Failing open to *more*
   measurement is the point.

2. **Whole-item elision of a symbol-bearing item is refused every time**, so it is no longer
   attempted. Since §40, `S_k = 1 - R_AST` for code, so destroying every symbol scores 1.0 against
   a gate that fires above 0.40 — no threshold or flag lets it through. On a one-item bundle that
   was invisible (the run fell back and emitted the input, which is what skipping produces anyway).
   On a multi-item bundle two pure-`types.ts` files — interfaces to lose, no function bodies to
   elide — were taking a 16-file batch down with them. Symbol-free items are unaffected and still
   elided whole; that is the population the path exists for.

3. **`TD_PRESERVE:` matched its own implementation.** `drift-tracker.ts` (the regex literal) and
   `cli/html-reporter.ts` (the highlighter for the same directive) each acquired a content marker
   they do not semantically have. Because `R_struct` is a bundle-scoped set, one phantom marker
   being elided drove it to 0 and took a 16-file batch to `S_k = 0.4053` on a run whose real symbol
   retention was **99.1%**. Harvesting is now scoped to prose regions **for `code` only** — not for
   the prose types generally, because `TD_PRESERVE:` is an unambiguous token rather than an English
   word, and the only way it appears without being a directive is as a literal inside an
   expression, a construct that exists only in code. This also retires the `html-reporter.ts`
   regression §40 recorded as left in deliberately.

Also fixed: the envelope headers were counted on the output side only, so a multi-item fallback
reported **72,973 → 73,667** tokens — a negative reduction, the same shape as the phantom −1.39%
already diagnosed once in the Python bench harness (Issue 5). `tokenBefore` now renders the same
envelope when the bundle holds more than one item. Single-item and Gateway paths are untouched;
for the Gateway `rawInput` is the whole JSON body and the bundle is the extracted messages, which
are genuinely different populations.

### Measured

Frozen 293-file corpus, 586 rows: **1 row changed, 0 regressions.** TypeScript 27.33% → **29.55%**.
Fallback counts drop sharply (prose 28 → 9, TypeScript over stdin 57 → 0) because items whose
elision was doomed are no longer transformed-then-reverted; the emitted bytes are the same, the
wasted work is gone.

### Not done: §3.1, which is now the binding constraint

**Multi-file runs still fall back on real corpora, and not for any reason this change can fix.**
On the 45-file Python corpus: drift 0.0359, AST clean, 169 KB elided — and it falls back, because
**26 constraint failures across 14 items revert all 45**. Validation is bundle-scoped and fallback
is all-or-nothing (audit §3.1, Phase 1c, unstarted).

This delivers the mechanism; §3.1 stands between it and the outcome. The prerequisite Phase 1c was
missing — attribution — now exists for the classes that matter: constraint failures name their
item (§42), unwitnessed items name theirs (§37), and AST issues carry `itemId`. Drift remains
bundle-scoped and would need its own rule.

`ARCHITECTURE.md` is unchanged: multi-item bundles were always in the model (`createBundleFromItems`
predates this), and nothing about the linear pipeline moved. What changed is that a shipping
adapter finally builds one.

---

## 44. Three Entry Modes, Three Kinds of Untruth

Audit Wave 2 — M5a, M5b, M8, M9, M10, H4, plus the M5 minor items. Six independent findings
that share one shape: **a surface that reports success while doing nothing, or doing something
other than what it says.** They are grouped here because the grouping is the finding.

### M5a — the MCP entry mode was a guaranteed no-op

`optimize_context` exposed `rawInput`, `language`, `path`, `maxInputTokens`, `riskTolerance`
and `preserveKinds`. It did not expose `targetReductionRatio`, and its description promised
compression unconditionally.

With no budget, `plan()` returns `pass_through` with an empty `stageIds`. Zero stages run. The
tool returned the input unchanged, `reductionRatio: 0`, and **no error** — so a client calling
the tool exactly as documented received a clean success for work that never happened. One of
three advertised entry modes did nothing, and nothing in its output said so.

`targetReductionRatio` is now a schema property, range-checked and **rejected rather than
clamped** (§29's argument: a value silently coerced into range is a run the caller believes
they configured and did not). The description states that a budget is required.

The second half matters as much as the first. The response now carries `budgetApplied`,
`planMode` and `stagesExecuted`, and a `notice` when no budget was in effect. This is
invariant 10 applied to a budget rather than to a validator: `reductionRatio: 0` alone cannot
distinguish *"nothing was compressible"* from *"nothing ran"*, and only one of those is the
caller's to fix. Measured end to end through the stdio server on `src/core/planner/index.ts`:

```
no budget    budgetApplied false  pass_through       0 stages   0.0%   + notice
ratio 0.3    budgetApplied true   topology_knapsack  4 stages  69.1%
```

The 586 tokens saved on the second row match `tokenEstimateSaved: 586` from the CLI on the same
file — same engine, cross-checked across routes rather than trusted from one.

Gated on C1a (§37) so that turning MCP on could not start deleting markdown documents. C1a is
merged, so it is safe now.

### M5b — a marker the product has never produced

`rehydrate_context` matched `/<ELIDED:\s*ref=([A-Za-z0-9_-]+)[^>]*>/g`.
`cleanup:session-dedup` emits `[TokenDamper Elided: ref=... bytes=... kind=...]`.

Angle brackets against square brackets, different prefix, no overlap. The regex could not match
any marker the product emits, so session rehydration through MCP matched nothing on every input
and returned the text unchanged — again with no error. It had never worked.

The fix is not the pattern. Both sides were internally consistent and independently plausible;
what broke was that **each restated the format the other owned**. `renderSessionElisionMarker`
and `SESSION_ELISION_MARKER_PATTERN` now live together in `core/elision/marker.ts`, the stage
calls the renderer, and the tool builds its regex from the exported source. The adapter reaches
core, not `src/stages/` — invariant 4 is intact.

`test/unit/mcp-session-rehydration.test.ts` takes its marker from **running the stage**, never
from a literal. A test that restated either format would have passed while the pair was broken,
which is the property that made this survive.

### H4 — knobs parsed, validated, then discarded

| knob | read by |
|---|---|
| `--max-output-tokens` / `TOKENDAMPER_MAX_OUTPUT_TOKENS` | nothing, anywhere |
| `--max-latency-ms` / `TOKENDAMPER_MAX_LATENCY_MS` | nothing, anywhere |
| `--risk-tolerance` / `TOKENDAMPER_RISK_TOLERANCE` / MCP `riskTolerance` | `cli/bench-table-renderer.ts:97` — one display column |

All three were parsed, range-validated, merged into the budget, and then read by no stage,
validator or planner. Setting one exited 0 and changed nothing. Risk tolerance was the worst of
the three because it was *nearly* real: it reached a benchmark table, where a column implies the
row's numbers depend on it.

**Removed from the surface, not from the model.** The CLI flags, the environment variables and
the MCP schema property are gone; `OptimizationBudget` keeps the fields, because
`ARCHITECTURE.md` pins that model as frozen and a field awaiting an implementation is a
different thing from a dial that reports success. Each field now carries a doc comment naming
its consumer or stating it has none — so the next person to add one has to answer the question
this finding is about.

`--target-reduction-ratio` **deliberately stays**, despite being nearly as inert: the planner
reads it only as `> 0`, making it an on/off switch wearing the name of a dial. Removing it would
take the only budget flag every doc and example uses, and making it a real proportional target
is a planner change. It stays a named decision rather than a silent one.

Removal is a hard error, not a shrug — `Unknown argument: --risk-tolerance`. A withdrawn flag
that parsed and did nothing would be the same defect wearing a new hat.

### M8 — test seams in the request path

`TOKENDAMPER_MOCK_UPSTREAM=true` made the proxy answer with the caller's own optimized request
body and a 200, as though a model had produced it. `NODE_ENV === 'test'` waived the
missing-credentials 401 — and `NODE_ENV=test` is set by a great many CI systems and process
managers that mean nothing by it. Neither was documented.

Both are now `ProxyHandlerOptions` fields — `mockUpstream` and
`allowMissingUpstreamCredentials` — plumbed through `GatewayConfig` and `ExecOptions`. **The
environment reads are gone entirely**, not kept as a fallback: retaining
`TOKENDAMPER_MOCK_UPSTREAM` would have preserved precisely the hazard the finding names.

The evidence arrived on its own. Ten tests in `test/unit/gateway.test.ts` failed the moment the
`NODE_ENV` branch was removed — they had been passing *because vitest sets that variable*, and
none of them mentioned it. That is the finding demonstrated rather than argued: a waiver
reachable by ambient configuration was already load-bearing somewhere nobody had chosen.

### M9 — request headers returned as response headers

Both optimize paths returned `{ ...cleanHeaders, 'content-type': 'application/json' }`, and
`cleanHeaders` strips only `host` and `content-length`. `authorization`, `x-api-key` and cookies
came back out **on the response**. Reproduced under mock upstream as `x-api-key: sk-test`.

Latent, because the normal path overwrites these with the upstream response's headers — but
"latent" meant one environment variable away (M8), and a response header is a value that gets
logged, cached and proxied onward. Response headers are now constructed by
`localResponseHeaders()`, which returns exactly `content-type`. The fix is to stop deriving one
from the other, not to lengthen a strip-list: no property of an inbound request header makes it
a correct thing to say on the way back.

### M10 — `bench` threw for every installed user

`humaneval.ts` and `codexglue.ts` resolved `test/fixtures/bench/...` against `process.cwd()`,
and `test/` was not in `package.json`'s `files`. The CLI additionally defaulted to the literal
path `test/fixtures/bench`, which exists only in a checkout.

Every existing bench test runs with the repository as its working directory, which is exactly
why none of them saw it.

`resolveBundledFixture` tries the working directory first — preserving checkout behaviour, and
letting a user's own copy win — then the package root. The package root is found by **walking
up from `__dirname` to the nearest `package.json`**, not by a fixed number of `..` segments:
this module runs from `src/bench/fixtures/` under vitest and `dist/src/bench/fixtures/` when
compiled, so a constant offset is correct for exactly one of them and would have reintroduced
the bug on the other route. The fixtures now ship in `files`.

Verified by running the built CLI from a temporary directory with no `test/` tree: 10 fixtures
loaded, exit 0.

Adjacent, and fixed with it: `loadBenchmarkFixtures('test/fixtures/bench')` threw `EISDIR`
because a directory reached `readFileSync`. The CLI had always pre-empted this at its own call
site, so only direct API callers hit it. A directory argument now means "the datasets under
here", handled in the loader — one place instead of two.

### M5 minor — reads that write, and a handshake that does not shake

Three smaller items in the same file:

- **`traceStore` was a module-level `Map`** serving every `createMcpServer` in a process. Two
  servers shared one 100-entry budget, each could evict the other's traces, and a request id
  minted by one was retrievable through the other. Now created per server and injectable.
- **`get_session_metrics` and `resources/read` called `getOrCreateSession`**, so *asking about*
  a session created it: an unknown id answered with a plausible all-zero record instead of
  saying it did not exist, and under `maxSessions` an inspection call could evict a live
  session. `getSession` is the read-only counterpart; both callers use it and report a miss.
- **`initialize` returned `MCP_PROTOCOL_VERSION` unconditionally**, ignoring the client's
  requested version. That is not a negotiation — a client asking for a revision this server does
  not implement was told it had been agreed to. `negotiateProtocolVersion` echoes a supported
  request and otherwise answers with this server's own. `SUPPORTED_PROTOCOL_VERSIONS` lists the
  single revision actually implemented, because negotiation claiming more than the code does
  would be this same finding with extra steps.

### Go, where §59 found the hazard — and where Deep turns out to be *stricter*

The 80-file Go corpus survives after all (`go-app` 40 + `go-stdlib` 40), so step 1 was measured
on it rather than deferred. It is the important language here: §56 and §59 found the hazard on
Go, and the main `recipe.json` has no Go bucket.

First run: **142 extra symbols**, by far the worst of the three languages. The cause is one
shape — Go writes most package-level declarations in **grouped blocks**, and a grouped block
puts `(` where the name would be, so every shipped rule misses it:

```
const Single = 1     const_declaration row 7, const_spec row 7   both see it
const (              const_declaration row 2
    TypeReg = '0'    const_spec        row 3                     only Deep sees it
)
```

The discriminator is therefore *structural and exact*, not a heuristic: **a spec is visible to
the shipped extractor only when it sits on the same line as its keyword.** With that rule, plus
the typed blank-identifier case (`var _ Reader = (*reader)(nil)`, the annotation again defeating
the `var:` regex), Go extras go **142 -> 0**.

The remaining 88 Go disagreements are all `lost`, and all are the same comment-prose false
positives the other two languages show — verified at source, not inferred:

- `fn:F` from `// … When a function F calls panic, normal execution of F stops`
- `type:T` from `// If the argument is a type T, then new(T) allocates a variable of type T`
- `fn:Index` from `// … special case in Index()`

**And Go inverts the drift effect, which is the finding that makes the phantom story
coherent.** On Go, `S_k` **rose** on 36 of 60 transformed files and fell on 1 — the reverse of
TypeScript and Python. The reason is where the comments sit: Go doc comments sit *above* the
function by convention, so their phantoms are **retained** and were inflating Fast’s `R_AST`;
this repository’s TypeScript carries much of its commentary *inside* bodies, so those phantoms
are **destroyed** and were inflating Fast’s drift. Dropping phantoms moves the score in
whichever direction the comments happened to sit, and **neither direction is §59’s hazard** —
which is exactly why the criterion has to name the symbol rather than compare the number.

Across all three languages the hazard count is **0**.
### Measurement

**594 of 594 corpus rows are identical to the pre-Wave-2 engine**, across `outputSha`,
`byteIdentical`, `tokenBefore`, `tokenAfter`, `reduction`, `fallbackUsed`, `driftScore`,
`debtScore`, `planMode`, `stageCount`, `contentType`, `astChecked`, `astUnchecked`,
`driftMeasured` and `unwitnessedItems`. Nothing in this wave touches a stage's output, and that
is now measured rather than assumed — both engines run against the *same frozen corpus*, varying
only `dist/`, per the method in CLAUDE.md.

The bucket table moved anyway, and the reason is the trap that method exists to catch:
**typescript file went 25.35% → 23.26% with `reduced` unchanged at 33.** The denominator grew by
one file — `src/bench/fixtures/bundled-path.ts`, added by M10 — which falls back and contributes
zero. No file that reduced before stopped reducing. An aggregate compared across two different
corpora is not a comparison, which is why the per-row check above is the one that counts.

The prose bucket also went 28 → 29, and that one was **already outstanding**:
`docs/audit-remediation-status.md` landed in `7a1b5a7`, after the `dd540fe` baseline was
recorded. `collect.js` refused on both mismatches before measuring anything — working exactly as
designed — and `recipe.json` records each step with its cause.

One near-miss worth recording, because it is the same class of error as the findings above: the
first per-file diff keyed rows on `r.file`, a field the harness does not emit. Every row
collapsed onto one undefined key, and the script cheerfully reported **"compared 2 rows,
differing: 0"** — a green result from a comparison that never happened. The row count is what
gave it away, which is why the corrected script asserts 594 and refuses duplicate keys.

---

## 45. Structure Is Not a String, and C4 Was Not Latent

Audit C4, the last unstarted audit item. Three defects in the Gateway's payload mapping, all in
`src/gateway/proxy.ts`, plus a refusal added at the shared elision chokepoint.

### The finding, and the part of it that was wrong

Ingestion flattens a provider message to the string the pipeline needs:

```js
const textContent = typeof msg.content === 'string' ? msg.content : JSON.stringify(msg.content);
```

Egress wrote the optimized item back as a string regardless of what the caller had sent. A
message whose content was `[{"type":"tool_result","tool_use_id":"toolu_01ABC",…}]` came back as
`content: "…"`. The Anthropic Messages API requires a `tool_use` block to be answered by a
`tool_result` block carrying the matching id; a bare string there is a
`400 invalid_request_error`, and the same shape breaks OpenAI multimodal content parts. Tool-heavy
traffic is the entire target market.

**The audit rates this "Critical when reached (currently masked by H1)" and says the payload falls
back unchanged — "that is luck". Measured, that is true of one case and false of the other, and
the false one is the case that matters.**

Cross-turn elision of a *sole* copy is `recoverable: false`, scored in full by `DriftTracker`,
and exceeds the gate — fallback, corruption never ships. That is the masked case.

Content duplicated **within one payload** is elided `recoverable: true`, and `DriftTracker`
exempts it by substituting the pre-optimization content before scoring (§16). No drift, no
fallback, and the elision goes out on the wire. Measured on the pre-C4 engine, a two-copy
`tool_result` payload came back as:

```
fallbackUsed: false   tokensSaved: 42
messages[2].content = "{\"__td_block__\":\"[TokenDamper Elided: ref=17c67ba215e4 bytes=251 kind=conversation]\"}"
```

A `tool_result` block, replaced by a string, shipped with no fallback and a reported saving.
Within-payload duplication is also **the only case the Gateway saves anything on at all**
(§41, `gateway-dedup-reality.test.ts`). So C4 was live on precisely the one path the mode exists
for — not latent, and not luck.

This is the third audit claim this project has had to correct by measurement (§40's inert
`filepath:` fix, §42's imperative scoping). The pattern is worth naming: the audit's *findings*
have held up well; its assessments of **whether a defect is reachable** have not, because
reachability here depends on interactions between the drift exemption, the planner mode and the
stage list that are not local to the code being read.

### What changed

**1. The refusal lives at the chokepoint, not in the Gateway.** `core/elision` gained
`CONTENT_SHAPE_METADATA_KEY` and `hasStructuredContent`, and both `elideItem` and `elideRegions`
refuse an item carrying `contentShape: 'structured'` with a new `ElisionSkipReason`,
`'structured_content'`. Putting it in the Gateway would have protected today's single stage;
putting it here protects any stage the Gateway is ever pointed at, which is the change most
likely to make this live again.

`ElisionSkipReason` is a union and the stages count into `Record<ElisionSkipReason, number>`, so
adding the member **failed to compile** in all three eliding stages until each acknowledged it.
That is the intended forcing function, and it is why the reason is a union member rather than a
boolean.

The refusal is checked **first**, before the savings and syntax checks. A structured item's
content is `JSON.stringify(...)`, which classifies as JSON, so it would usually have been refused
downstream anyway — for being JSON. Right outcome, wrong reason, and it evaporates the moment the
classification changes. The item is now refused for the reason that is true of it.

An item with **no** tag is treated as plain text, which is correct for every non-Gateway
producer: CLI, MCP and bench all ingest text that was text.

**2. Egress maps by slot, not by array position.** Ingestion skips falsy entries
(`if (!msg) continue`) while egress indexed `finalBundle.items[idx]` by position, so a single hole
in `messages` shifted every later item onto the wrong message. This was **not** masked either —
it is live on today's Gateway, and the test that pins it fails against the pre-C4 engine with
`expected 'ok' to be 'export function helper0…'`: the assistant's message had received the
previous item's content. Items now carry `payloadSlot` and egress looks up by it.

Invariant 9 says the Gateway maps `finalBundle` back onto the parsed payload. It does not say
*positionally*, and a filtered push could never supply the precondition a positional map assumes.

**3. The Anthropic `system` prompt is mapped back.** It was ingested as `items[0]` while
`updatedMessages` started at `itemOffset`, so a change to it was dropped from `finalBody` — while
`optimizedTokens`, and therefore `tokensSaved` and `dedupRatio`, still counted it as saved. The
turn's metrics described a saving that never reached the wire.

This path is **unreachable today** and the entry says so rather than claiming a fix that fires:
`cleanup:session-dedup` refuses system items (Rule 2), and rehydration — the one branch that runs
before that check — needs `rehydrateRefs`, which the Gateway does not set. What the change buys
is that the mapping is correct when something eventually does change a system item, and that the
`finalBody` rebuild neither drops nor duplicates `system`, which is a live regression risk created
by this commit and is tested as one.

### Measurement

**594 of 594 corpus rows identical** to the pre-C4 engine across 17 fields, same frozen corpus,
varying only `dist/`. The guard is inert for untagged items, which is every CLI, MCP and bench
item, and that is measured rather than reasoned.

Live on a real `GatewayServer` over sockets, the discriminating comparison — identical bytes,
differing only in shape:

```
structured            fallbackUsed: false   tokensSaved: 0    content stays an array
same bytes as string  fallbackUsed: false   tokensSaved: 42   elided normally
```

The refusal is scoped to the shape, not to the content, and the saving it declines is honestly
reported as zero rather than bought by corrupting the payload.

### A corpus caution, recorded because it cost time

The TypeScript bucket read **23.16%** here against the **23.26%** recorded for Wave 2, on the same
297-file recipe with `reduced` and `fallback` unchanged. The pre-C4 engine also reads 23.16%, so
it is not this change.

The cause is **line endings**. Wave 2's corpus was frozen from working-tree files written with
LF; committing and checking them out normalized them to CRLF, adding a byte per line to the
repository's own sources — which are the corpus. `file` on a frozen corpus source reports "with
CRLF line terminators".

So aggregate reduction figures on this repo are not comparable across a commit boundary, not only
across a corpus-size change. Only the per-row A/B over one frozen corpus is.

---

## 46. Three Decisions: Say What Cannot Be Done, Say What Is Actually Checked, Stop Maintaining Two Copies

Audit H2, M1 and M11. The audit filed these as *decisions rather than tasks* — each had a
legitimate "narrow the product" answer and a legitimate "build more" answer, and the choice was
not the auditor's to make. Recorded here with the option taken and the option refused.

### H2 — decided: report why, do not narrow the accepted set

Twelve of nineteen recognised extensions cannot produce a non-zero reduction under any flag
combination. Two gates, both single-language-family and neither threshold-controlled:
`selectElisionRegions` returns `[]` outside TypeScript/JavaScript and Python, and a whole-item
elision has to survive a measurement gate that a Go `func` or a C function gives it nothing to
work with.

**Refused: narrowing the accepted set.** Rejecting `--language go` would be the stronger honesty
signal, and it would also delete a working behaviour — pass-through is byte-identical and
harmless. Taking away something that works, to avoid saying something true, is the wrong trade.

**Taken: say it.** `trace.languageSupport` carries `supported`, `unsupported`,
`unsupportedLanguages`, `noneSupported` and a `reason`; `validate()` raises an **info** issue,
`LANGUAGE_NOT_ELIDIBLE`, which does not vote on the verdict. This is the same correction M5a made
for budgets, one layer down: `reductionRatio: 0` cannot distinguish *"nothing was compressible"*
from *"nothing could have been"*, and only one of those is about the user's file.

Three things this cost, all worth recording:

**The predicate had to be derived from the gate, not guessed.** The first version asked *"does
the item yield symbols or content markers?"* — reasonable, and wrong. A trivial Go file yields
exactly one symbol: `import:fmt`, an incidental match by the TypeScript import regex. It
witnesses nothing about the function bodies, and Go still cannot reduce, but the predicate called
it supported. The answer is exactly `supportsRegionElision`, because every other elision route
terminates in a refusal: a symbol-bearing item cannot be elided whole (§43), and a symbol-free
item's whole-item elision destroys every content marker and fails the same gate one step along.
Measured, that predicts **3 of 17** probed languages — TypeScript, JavaScript, Python — which is
the audit's headline and the corpus baseline agreeing independently.

**The field had to be threaded through four separate whitelists**, each of which enumerates its
keys: `validate()`'s return, `createValidationReport`, `buildTrace` and `createOptimizationTrace`.
Three of them dropped it silently, and the symptom every time was `trace.languageSupport:
undefined` with everything else correct. `test/unit/language-support.test.ts` asserts on the
**trace**, not on `validate()`, for exactly that reason.

**A friendly notice line was written, and then removed.** The CLI prints the trace to stderr as a
JSON document, and consumers parse the whole stream — this repository's own integration tests
among them. Prepending prose broke four of them. The explanation now lives *inside* the report as
a `reason` field, which is both machine-readable and readable, and stderr stays parseable. A
channel with a contract is not improved by making it friendlier.

### M1 — decided: correct the documentation, do not wire the compiler API

The TypeScript "AST-lite validator" builds no AST. It is a lexer — a good one, tracking strings,
template interpolation, comments and regex literals — that detects unbalanced brackets and
unterminated strings, and nothing else.

Probed against the shipped code rather than taken from the audit, since three audit claims in
this project have failed that test (§40, §42, §45). All of it reproduced exactly:

| Input | Verdict |
|---|---|
| `const x = ;` | **PASS** |
| `function f(a: , b) { return 1; }` | **PASS** |
| `import from "x";` | **PASS** |
| `let 123abc = 5;` | **PASS** |
| `const a = 1 +++++ 2;` | **PASS** |
| `ceci nest pas du code` | **PASS** |
| `super(; }` | FAIL |

Python is meaningfully stronger — missing colons, malformed `def`, bad dedent, stray leading
indentation — and still passes English prose. JSON is a real parser and is correct.

**Refused: wiring `ts.createSourceFile`.** It would make the guarantee real, and `typescript` is
already a development dependency. It is refused on cost: promoting it to a *runtime* dependency
costs install size, and parsing costs latency against a lexer that runs in single-digit
milliseconds. That is a trade someone may want to revisit; it is not an oversight.

**Taken: say what is true.** `README.md` gains a per-language table and the sentence that the
guarantee on TypeScript — the family where compression actually runs — is **bracket and quote
integrity**, not syntax validity. `CLAUDE.md` says the same. `test/unit/validator-guarantee.test.ts`
pins every row as a characterization test, so the documented guarantee is executable: strengthen
a validator and the test fails on purpose, and the README table has to move with it.

Two consequences stated in the README rather than left implicit: a passing check is not a promise
the output compiles, only that it is no more unbalanced than the input; and real inputs are
frequently already invalid, which is why the sub-item check is *relative*.

### M11 — decided: retire the narratives and the root planning artifacts

Twelve files, **226 KB**, markdown from 31 files to 19. `docs/retired-documents.md` maps each to
where its conclusion lives and gives the `git show` command to read the original.

**The premise was stale, and measuring it first changed what the decision was about.** M11 was
filed as a **4.1 : 1** documentation-to-code ratio. Measured immediately before acting, it was
**1.40 : 1** — and the improvement was not real: markdown had *grown* to 726 KB, while `src/` grew
faster. Worse, **32.8% of `src/` is comment prose** (165 KB of 518 KB), so counting honestly,
prose ran about **2.6 : 1** against code. The volume had not gone anywhere; some of it had moved
into the source files.

That reframes the finding usefully. The problem M11 names is not bytes, it is **two copies of an
argument that have to be kept in sync by hand**. In-source commentary is not that — it sits next
to the code it describes and moves with it. Retired: the standalone narratives. Kept: every line
of the in-source commentary.

**Twenty-five source and test comments cite a retired document**, which is the check the option
called for and the thing that nearly made this a bad change. They are marked `[retired]` rather
than re-pointed: the citation names a document and section that existed and that git still holds,
whereas re-pointing 25 citations at DECISIONS sections by hand would risk mapping some of them to
the wrong place — trading a volume problem for a correctness one.

`CHANGELOG.md` and `DECISIONS.md` keep their older citations untouched, and each now carries a
note saying why. They are append-only records of what was true when written; editing them to
match today would falsify the history they exist to preserve. This entry is subject to the same
rule.

### What was not done

`cli/bench-table-renderer.ts:97` still prints a `risk` column sourced from `riskTolerance`, which
H4 established no stage reads. It is now the only reader of that field, and a benchmark column
implies the row's numbers depend on it. Small, real, and left alone here because changing what a
benchmark table reports is a measurement change, not a documentation one.

---

## 47. One Bad Item No Longer Reverts the Good Ones

Phase 1c — per-item repair. The audit's §3.1, and the binding constraint on multi-file value
since H5 made multi-item bundles reachable at all.

### The problem, measured

Validation is bundle-scoped and fallback was all-or-nothing. On the frozen 45-file Python corpus
at `targetReductionRatio: 0.3`:

```
stages achieved      42.52%
26 CONSTRAINT_DIRECTIVE_LOST errors across 14 items
drift                0.0359   (gate: 0.40)
AST                  clean
emitted               0.00%
```

Fourteen items reverted forty-five. The 61-file TypeScript bundle was the same shape with drift
additionally at 0.4122 — barely over the gate.

### What changed

Three pieces, in order of dependency.

**1. Attribution became data.** It already existed — as prose. `ValidationIssue` carried
`"…in item [<id>]…"` interpolated into `message`, and nothing else. That is unusable by anything
that has to *act* on it, and recovering it with a regex over the message would have been audit
M5b exactly: two places restating one format, drifting apart. `ValidationIssue.itemId` is now a
field, populated by the AST and constraint checks, which knew it all along.

**2. `validate()` says what it can and cannot attribute.** `FailureAttribution` carries
`repairableItemIds` and `hasUnattributableError`. The interesting case is drift, which splits:
`SEMANTIC_DRIFT_UNMEASURABLE` **is** attributable, because the measurement gate refuses specific
items and `unwitnessedItemIds` names them (§33); `SEMANTIC_DRIFT_EXCEEDED` is not, because `S_k`
is a set comparison over the whole bundle.

**3. The engine tries a repair before giving up.** Items named by errors are restored to their
pre-optimization content, the result goes back through the **same** `validate`, and it is adopted
only if it passes. Deliberately shaped like — and placed after — the automated-rehydration
attempt that was already there, because it is the same move: build a candidate, re-check it, keep
it only if the check agrees.

The load-bearing property: **repair changes which bundle is offered, never what counts as valid.**
Nothing here decides an item is acceptable. Validation still does, by the same standard, on the
same code path.

### The gate was tried too strict first, and measurement corrected it

The first rule was *"refuse if any error is unattributable."* It reads as the conservative choice
and it is the wrong one. The TypeScript bundle fails on both attributable constraint losses *and*
`SEMANTIC_DRIFT_EXCEEDED`; under that rule the drift failure, which names nothing, discarded the
constraint attribution, which names fourteen items. The run stayed at 0.00%.

The correct question is not *"is every error attributed?"* but *"is there a principled subset to
revert?"* Attempting the repair decides nothing — a drift score still over the gate simply fails
the re-validation and falls back. And reverting items *lowers semantic loss*, which is what drift
measures, so a drift failure is frequently a consequence of the same items:

```
                    before repair        after repair
python  drift       0.0359               0.0141
typescript  drift   0.4122               0.0056
```

What would be guessing is reverting a subset when **no** error names anything. That still
refuses, and `repairableItemIds` being empty is the condition.

### Result

| bundle | before | after | reverted | fallback |
|---|---|---|---|---|
| 45-file Python | 0.00% | **22.73%** | 14 of 45 | false |
| 61-file TypeScript | 0.00% | **19.47%** | 21 of 61 | false |

### What repair refuses to do, and why it matters

`revertFailingItems` returns `undefined` — declining the repair — in two cases.

**Nothing to revert.** No named item actually differs from its original, so the failure is not
about content this can restore.

**Everything would be reverted.** The result would be indistinguishable from the original bundle,
which is a full fallback wearing a different name. This is not a cosmetic distinction: the
fallback path echoes `request.rawInput`, and the CLI writes the original `Buffer`, whereas the
repair path renders from items. DECISIONS §35 exists precisely because those are not the same
bytes when the input is not valid UTF-8. Routing it as a fallback keeps that guarantee.

Measured: on 45 single-file Python runs, 14 fall back and **14 of 14 are byte-identical**, with
no run reporting `itemsReverted`. A one-item bundle can never be a partial success, and the code
says so rather than relying on it happening not to arise.

"Everything" accounts for pruning. A bundle whose surviving items were all reverted is still a
real reduction if the planner dropped items — selection is not elision, and that saving is not
what any of these checks objected to.

### One pass, not a loop

Repair runs once and re-validates once. A loop to fixpoint terminates — each pass reverts at
least one more item, and the limit is the full fallback — but it costs a whole-bundle AST pass
per iteration, so the worst case is O(n²) validations on exactly the bundles that need it most.
Measured, one pass sufficed on both corpora. A second round of attributable failures falls back
rather than iterating.

### Reporting

`trace.itemsReverted` names what was put back, and is present only on a partial success. Without
it the outcome is a reduction with `fallbackUsed: false` and no indication that anything was
restored — invariant 10's shape, a clean-looking result concealing what did not happen. It is
absent on a clean run and on a full fallback, and the engine omits it when `fallback.used`,
because on that path the decision had no effect on the output.

### Unchanged

**574 of 574 corpus rows are identical** to the pre-1c engine, same frozen corpus, varying only
`dist/`. That is the expected result and the point of checking: the harness measures single-file
runs, where repair cannot fire. Phase 1c adds value exactly where the audit said the value was
missing, and nowhere else.

A measurement caution that cost time here, and is now in the status doc: the TypeScript bucket
read 23.03% on the previous corpus and 19.76% on this one, which looks like a regression and is
not — the pre-1c engine reads 19.76% too. The corpus changed because this change edits `src/`,
and `src/` *is* the TypeScript bucket. Comparing two runs over two corpora is not a comparison.

---

## 48. The Dial Now Turns, and Says How Far It Can Turn

Audit H4's deferred half. When the three dead knobs were withdrawn (§44),
`--target-reduction-ratio` was kept and explicitly named as its own decision: the planner read it
only as `> 0` to choose knapsack mode over pass-through, and nothing else read it at all, so
`0.01` and `0.99` produced **byte-identical output**. It survived the cull because it is the flag
every document and example uses and making it real is a pipeline change rather than a flag change.

### Two things were broken, not one

**It never reached the machinery.** `pruning:topology-pruner` gated on `budget.maxInputTokens` and
returned early — *"maxInputTokens not specified in budget; topology pruning bypassed"* — whenever
only a ratio was set. That message is visible in the trace of every ratio-only run ever made,
including the 45-file Python bundle used throughout Phase 1c.

**It never stopped.** Compression ran to exhaustion and halted only when it ran out of candidates.
A single TypeScript file at `--target-reduction-ratio 0.3` produced **44.62%**, and later 69.09%
once other work made more regions eligible. Overshooting is not a bonus: every extra elision
spends semantic fidelity, raises drift, and on the CLI is irreversible because no `TokenHasher` is
wired in. Removing more than twice what the caller asked for is a defect.

### The mapping: proportional becomes absolute

`resolveTokenCeiling` (`src/core/budget/`) reads the ratio as a statement about the input —
"remove 30%" is "keep at most 70%" — and resolves it against the incoming bundle. Once absolute it
is an ordinary token ceiling, which is exactly what the pruner and the 0/1 knapsack already solve
against, so no new selection machinery was needed. **Both ceilings are caps, so the tighter wins:**
`maxInputTokens: 500` with `targetReductionRatio: 0.9` on a 10,000-token bundle means "at most 500"
and "at most 1,000", and honouring anything but the smaller violates a limit the caller set.

### Granularity is where this got interesting

The stop rule was first written between items, which is where the running total naturally lives.
Measured, it did nothing on the commonest CLI shape: `optimize one-file.ts` is a **single-item
bundle**, so the check runs once, before anything is elided, and the item then has all of its
regions removed in one call. `0.1`, `0.3`, `0.5` and `0.7` all produced **69.09%** on the same
file. **A ceiling has to bind at the granularity the compression happens at**, which is regions.

Then region *order* turned out to matter more than expected. Taking regions positionally still
overshot badly — 0.1, 0.2, 0.3 and 0.5 all produced **55.2%** — because regions are extremely
uneven. Measured across three of this repository's own sources:

| file | regions | each as % of file |
|---|---|---|
| `core/planner/index.ts` | 3 | **58%**, 9%, 9% |
| `core/engine/index.ts` | 5 | **61%**, 1%, 4%, 10%, 2% |
| `core/validation/index.ts` | 2 | **83%**, 4% |

Every file has one dominant region and it comes first positionally, so any modest target blew past
it on the first step. Selection is now **smallest-first when a ceiling is set**, which approaches
the ceiling in fine increments and reaches for the dominant region only when the target genuinely
requires it. Ties break on `start`, so the order is total and the stage stays deterministic
(invariant 1), and the kept regions are re-sorted **into positional order** before splicing because
`elideRegions` walks a forward cursor and refuses ranges that arrive out of order.

The cost is that one ratio's output is no longer a prefix of a larger ratio's. That property was
written into the first version of the comment and is worth less than hitting the number the caller
asked for.

### What it achieves, stated as a distribution rather than a claim

Frozen corpus, target 30%, 66 files that reduced:

| achieved | files |
|---|---|
| 0–10% | 2 |
| 10–25% | 7 |
| **25–35% (on target)** | **21** |
| 35–50% | 13 |
| **>50% (overshoot)** | **23** |

Mean achieved 43.9%. So the flag now binds — it is no longer a switch — but **adherence is
partial, and the limit is structural**: elision's smallest unit is one region, and 23 files have a
dominant region that cannot be taken in part. Closing that needs sub-region elision, which is not
attempted here and is recorded in `ROADMAP.md` as the work that would.
`test/unit/target-reduction-ratio.test.ts` pins this as a documented limit and deliberately does
**not** assert `achieved <= target` — that would assert a guarantee the implementation does not
make.

### The aggregate fell, and that is the feature

The harness measures at ratio 0.3, so this change makes the corpus figures move by design:

| bucket | before | after | reduced | fallbacks |
|---|---|---|---|---|
| python file | 23.14% | **20.26%** | 30 → **31** | 14 → **13** |
| typescript file | 23.03% | **17.57%** | rose | — |

Runs that used to overshoot to 44–69% now stop near 30%, so each contributing file contributes
less — **and more files survive validation**, because less aggressive elision means less drift.
Reduced counts rose and fallbacks fell in the same measurement that shows the mean falling.

This is the third time in this project that a headline aggregate moved for a reason that is not a
regression (§45's line endings, §46's corpus growth, this). The rule that keeps catching it:
**compare per-file rows over one frozen corpus, never the mean across two.**

---

## 49. A Release That Cannot Be Built Holds No Number, and a Check That Has Never Run Is Not a Check

**Date:** 2026-08-12 · **Status:** Accepted · **Closes:** the v1.3.0 numbering collision;
retires `npm run format`

Two decisions taken together because they are the same shape: a placeholder that reads as a
commitment. One is a version number reserved for work that cannot be done, the other a quality
gate that has never passed.

### The number

`--target-reduction-ratio` binding (§48) was merged and unreleased while `ROADMAP.md` reserved
**v1.3.0** for "Context Selection Quality & Redundancy Elimination" — a release whose two headline
deliverables were both measured unbuildable: BM25 has no query source anywhere in `src/`, and MMR
found **0 of 1,486** real pairs above its 0.90 threshold.

The options were to ship §48 as a patch, renumber the chain again, or take the number. **Taken —
and the reservation released rather than moved**, because moving it is what made this recur. The
identical collision happened at v1.2.0: this document had reserved that number for the same
Selection Quality release, the remediation work shipped into it, and the chain was renumbered one
release to the right. Doing that again would have set up the third occurrence.

**The rule: a release whose preconditions are measured false is described and gated, but holds no
version number.** It gets one when it becomes buildable. A number is a claim about sequence, and
reserving one for work that cannot start makes every shipped release route around it.

Minor rather than patch: nothing was removed, but the same command over the same input now emits
different bytes. `1.2.1` would have understated that; the CHANGELOG files it under `Changed`, not
`Fixed`, for the same reason.

### The check

`npm run format` was `prettier --check .`. It has **never passed**, and nothing has ever invoked
it — CI runs typecheck, lint, build and test; `prepublishOnly` runs the same four. Measured before
removing it, it failed on **148 files**: every markdown document and all 57 TypeScript sources.

Two independent causes, and separating them is what decided this:

| cause | size |
|---|---|
| prettier defaults to `endOfLine: "lf"`; the working tree is CRLF (`core.autocrlf=true`, no `.gitattributes`) | every file, whole-file diffs |
| genuine formatting drift underneath that | ~5,118 lines in `src/`, ~1,900 in the docs |

So this was never "the markdown is unformatted". Making the script pass would have rewritten the
whole repository — including the in-source commentary that is **32.8%** of `src/` and, per
`CLAUDE.md`, is deliberately maintained next to the code it explains rather than in the documents
M11 retired. A formatter with `proseWrap: preserve` would not reflow that prose, but it would
still touch every line of every file it lives in, and the blame trail is part of how this project
reconstructs why a measurement was taken.

**Removed rather than fixed or ignored**, which is audit H4's principle applied to a dev script
instead of a CLI flag. H4 withdrew three flags that were parsed, validated and read by nothing, on
the grounds that a dial reporting success without doing anything is worse than no dial. A check
that has never run is the same object: it is not evidence, and leaving it red is worse than
deleting it, because a permanently-red instrument teaches everyone to skip the one that goes red
for a reason. That is invariant 10 read from the other end — this project has been bitten **ten**
times by a green result from a check that never executed, and a red result nobody reads is the
same failure wearing the opposite colour.

`eslint` remains the enforced gate and is green **without** `eslint-config-prettier`, which was
verified rather than assumed before removing it: it existed only to switch off rules that would
conflict with a formatter that is no longer here.

### Found while bumping the version

`package-lock.json` carried `"license": "MIT"` and `"version": "1.1.0"`. Audit **M3** corrected
the license in `package.json` — npm reads that file, so nothing was published wrongly — but the
lockfile mirror was never regenerated, and a file in this repository went on asserting the
pre-M3 license for two releases. M3 was itself a defect about **a stale second copy of one fact**,
which is the same failure M5b's marker formats had and the same one this entry's `format` script
had. Regenerated with the bump.

---

## 50. A Statement Is a Smaller Thing Than a Function Body

**Date:** 2026-08-12 · **Status:** Accepted · **Follows:** §48

§48 made `--target-reduction-ratio` bind and recorded that adherence was **partial, and the limit
structural**: elision's smallest unit was one region, files typically have one dominant region
(58%, 61%, 83% measured), and a body cannot be taken in part. At target 0.3, 23 of 66 reducing
files still exceeded 50%. This divides the region.

### The precondition was measured before the feature was written

The two deliverables this project has cancelled — BM25 and MMR — were cancelled because their
preconditions failed when measured, after the specs were written. So the question here was asked
first: **do dominant regions decompose at all?** A body that is one indivisible block gains
nothing from finer granularity.

| bucket | files | dominant >50% of file | median sub-spans | indivisible |
|---|---|---|---|---|
| python | 44 | 5 | 9 | **0** |
| typescript | 55 | 22 | 9 | **1** |

Dominant regions divide into ~9 pieces. The precondition holds.

### The instrument was wrong first, and the corpus is what said so

The first probe reported **1 sub-span covering 100% of the dominant region for 44 of 44 Python
files** — a result too uniform to be real. `scanPythonDefBodies` returns a region starting *after*
the first body line's indentation, so region text is dedented on line 1 and fully indented
afterwards; taking the minimum indent across all lines yields 0 and matches only line 1.

The probe's self-test passed, because its fixture began with a newline and therefore did not have
the shape the scanner emits. **A validated instrument is only validated against the inputs it was
shown.** The production splitter carries the same warning, and every Python fixture in
`test/unit/sub-region-elision.test.ts` starts mid-line for this reason.

### What a span may be

Depth-0 boundaries only, so every span is bracket- and quote-balanced: a `;` at depth 0 or the
`}` returning depth to 0 for TypeScript, a line at base indentation with no bracket open and no
triple-quoted string in progress for Python. A nested `if` block is one span, not several.
`elideRegions` would refuse an unbalanced span rather than ship it — but a refusal is a 0% run,
and adherence is the point.

Python spans start after the line's indentation, inheriting `scanPythonDefBodies`' boundary: the
marker must hold the body's column or `PythonValidator` reports `AST_INDENTATION_ERROR`, and the
indentation must stay outside the replaced bytes or rehydration is not byte-identical.
`isSubstantiveRegion` runs **per span**, because a body can be substantive overall while one
statement is nothing but a docstring — eliding that span alone is `HumanEval/0` at finer grain.

### Confined to the ceiling path, which is what makes the A/B mean anything

With no ceiling the stage still takes regions whole: one marker per body rather than nine, and
nothing is asking for a figure. 522 of 576 corpus rows come out byte-identical, and every changed
row is TypeScript or Python under a ceiling.

### The guard, and the trade it resolves

Statements below the marker floor are dropped. In a body of many short lines that can be nearly
all of them, leaving the caller only the survivors and no way to reach for the region as a whole:
one file went **38.9% → 6.6%** against a 30% target. Undershooting by 23 points is not an
improvement on overshooting by 9. A division now stands only if what survives still covers most
of its region.

The threshold was swept, and the sweep is in the source because it shows a trade rather than an
optimum:

| coverage | rows >50% | new fallbacks | fallbacks fixed | closer to 0.3 | further |
|---|---|---|---|---|---|
| 0.25 (≈ no guard) | **8** | 2 | 9 | 48 | 23 |
| 0.50 | 12 | 2 | 4 | 44 | 21 |
| **0.75** | 18 | **0** | 4 | 39 | **11** |
| 0.90 | 33 | 0 | 5 | 13 | 3 |

Aggressive division controls overshoot best — 8 rows above 50% against a baseline of 34 — but
converts **two rows that were reducing into fallbacks**. The cause is not the splitter: a finer
span is likelier to contain a comment carrying an imperative, `cleanup:constraint-preservation`
refuses to lose one, and on a single-item bundle Phase 1c has no other item to keep, so the
refusal is a whole-file fallback. `pip/_internal/commands/cache.py` goes 34.1% → 0% on a comment
reading *"normalized to underscores (_), meaning hyphens can never occur"*.

**0.75 was chosen because it regresses nothing** — 0 new fallbacks, 0 files that stopped
reducing, >50% still nearly halved. Buying a better headline with two working files is the trade
this project keeps having to un-make. Revisit on multi-item bundles, where that constraint
failure names its item and Phase 1c reverts only that one.

### Final position

576 rows, both routes, target 0.3, against the pre-division engine at the same frozen corpus:

| | baseline | after |
|---|---|---|
| rows above 50% | 34 | **18** |
| rows reducing | 95 | **99** |
| new fallbacks / lost reductions | — | **0 / 0** |
| closer to target / further | — | **39 / 11** |

Still open: 18 rows exceed 50% because a single *statement* is itself dominant — one 83%-of-file
span in `python-validator.ts`. Dividing that needs elision inside a control-flow block, which is
a different question from dividing a body and is not attempted here.

---

## 51. Per-Item Drift Has Nothing to Attribute, Because §48 and §50 Closed It

**Date:** 2026-08-12 · **Status:** Accepted · **Closes:** the per-item drift item, without
implementing it

Phase 1c (§47) made validation failures repairable per item and recorded one axis as unfinished:

> Still open on this axis: drift remains a bundle-scoped score. It is *repairable in practice*
> (reverting items lowers it — 0.4122 → 0.0056 on TypeScript) but it never names an item itself,
> so a bundle failing on drift alone still falls back whole.

That was true when written. **It is no longer reachable**, and the two releases since are why.

### The measurement

Frozen corpus, 288 files, file route, target 0.3. Every fallback classified by its actual
`fallbackReason`:

| cause | count | already attributable? |
|---|---|---|
| `CONSTRAINT_DIRECTIVE_LOST` | 29 | **yes** — per item, §47 |
| `SEMANTIC_DRIFT_UNMEASURABLE` | 87 | **yes** — `unwitnessedItemIds`, §33 |
| input not valid UTF-8 | 1 | correct, and unrelated (§35) |
| **`SEMANTIC_DRIFT_EXCEEDED`** | **0** | — the only code that is not |

`SEMANTIC_DRIFT_EXCEEDED` is the sole drift failure per-item attribution would help, and it does
not occur. On multi-item bundles — `src/core` (33 items), `src/stages`, `src/gateway`,
`src/adapters`, pip's 45 Python files, this repository's 62 TypeScript sources — `S_k` measures
**0.0024 to 0.0056** against a threshold of **0.40**, and does not move at ratios 0.3, 0.5, 0.7
or 0.9. It is roughly two orders of magnitude under the gate.

### Why the premise expired

§47's `0.4122` was measured on an engine that elided everything it could. §48 gave the stage a
token ceiling to stop at, and §50 made the unit it removes a statement rather than a whole
function body. Together they cut symbol loss so far that the drift gate no longer binds:
the number that motivated this work is a property of a pipeline that has since been changed
twice. **An open item is a claim about the current build, and it expires like any other.**

### The mechanism is real, and reachable only by asking for it

At `--max-drift 0.001` — four hundred times stricter than the default — the failure does fire,
and behaves exactly as §47 predicted: drift names no item, so `hasUnattributableError` is set,
repair is declined, and **7 items that would otherwise have been reverted were not**. The bundle
fell back whole, and the reported reason was the *constraint* failure the repair would have
fixed.

So the design note is correct about what would happen. What is absent is any default-configured
input on which it happens. Building it would be ~1,000 lines with no observable effect on output
the product can currently emit — the H5 condition, and the same reason BM25 and MMR were not
built (§ROADMAP). The difference worth recording is that this item was not wrong when written;
it was **closed by other work and nobody re-measured it.**

### What would make it live again

Any change that raises symbol loss back above the gate on a default run: whole-item elision of
symbol-bearing content becoming possible again (§43 refuses it), a much more aggressive default
ratio, or a language whose symbol extraction is sparse enough that modest elision destroys most
of the set. **Re-measure before implementing — the check is the table above, and it takes one
corpus run.**

The constraint gate is where the fallbacks actually are: 29 of 29 code-bucket fallbacks, and
§50 measured it as the reason the better sub-region setting costs two files. That is the
per-item axis with something on it.

---

## 52. A Comment Is Where a Codebase Narrates Itself, Not Only Where It Instructs

**Date:** 2026-08-12 · **Status:** Accepted · **Follows:** §42 (H6), §51

§51 measured where the fallbacks actually are: **29 of 29** code-bucket fallbacks on the frozen
corpus are `CONSTRAINT_DIRECTIVE_LOST`. Not drift, not AST — the constraint gate, every time.

§42 scoped that gate by **region**: an instruction to a reader lives in a comment or a docstring,
never in an expression, which stopped it firing on `logger.critical(exc)` and `readonly required?`.
This scopes it by **mood** within that region, because a comment is also where a codebase explains
its own history.

### What the gate was refusing

Inspecting the matched text behind those 29 fallbacks, roughly twelve read like this:

> "The MCP branch of `runCli` **has always** read these two"
> "It **never did**: this branch bypassed pruning entirely"
> "`HTTP_PROXY` and `HTTPS_PROXY` … could **never have worked**"
> "a saving that **never reached** the wire (audit C4)"

Losing one of those costs a reader some history. Losing *"never hash items matching
preserveKinds"* costs a caller a rule. The keyword is identical and the gate refused the whole
file for either.

### Narrowed in the safe direction, three ways

This gate protects content, so unlike §48 and §50 — where a wrong call costs output size — a
wrong call here **silently deletes an instruction**. Three deliberate limits:

1. **Only `never` and `always`.** They are the two keywords equally comfortable describing and
   instructing. `must`, `must not`, `do not`, `required`, `critical`, `only if`, `except when`
   and `make sure to` are untouched — *"must have been called before"* is a requirement about a
   past state, and a perfect-tense test applied to `must` would drop it.
2. **Only perfect or past constructions**, which are provable from the words present: a preceding
   `have`/`has`/`had`, or a following past-tense verb. *"is always deterministic"* and *"do not
   support"* are descriptive too, and are **left firing on purpose** — there the line between
   describing a constraint and stating one is genuinely blurry. Under-narrowing costs reduction;
   over-narrowing costs content.
3. **Unanimity before dropping.** A segment is discarded only if *every* keyword in it is
   narrative-capable and the construction is narrative. *"this has always been true, so you must
   call it first"* still raises a directive, because of the `must`.

### The negative control is the load-bearing test

`test/unit/narrative-directive-scope.test.ts` asserts the eight narrative sentences above stop
firing — and, more importantly, that **sixteen real instructions still do**, several taken
verbatim from this repository. A rule that drops one of those is not a better rule at any
reduction figure, and the test says so rather than leaving it to a reduction number two layers
away.

### Measured

Per-row over the frozen corpus, 576 rows, both routes, target 0.3, against v1.4.0:

| | before | after |
|---|---|---|
| rows byte-identical | — | **572 of 576** |
| fallbacks fixed / new | — | **4 / 0** |
| rows newly reducing / stopped | — | **4 / 0** |
| rows already reducing that changed at all | — | **0** |

The four are `adapters/mcp/tools.ts`, `cli/main.ts`, `gateway/exec.ts` and `gateway/proxy.ts` —
`gateway/exec.ts` being the file that contains *"could never have worked"*. TypeScript file
route: 39 reduced / 16 fallbacks → **43 / 12**, aggregate 18.52% → 24.58%.

### The caveat that matters more than the headline

**Python gained nothing — 0 of the 4.** Every recovered file is this repository's own source,
and this repository is unusually narrative: M11 measured **32.8%** of `src/` as comment prose,
written in a style that explains what used to be true. pip's comments describe behaviour in the
present tense and were never caught by this rule.

So the 6pp on the TypeScript bucket is **not** a portable estimate of what other codebases gain.
It is the corpus-bias trap `CLAUDE.md` warns about, showing up as a favourable number instead of
an unfavourable one — which is the harder direction to notice. What is portable is the shape:
zero regressions, and four files that produced nothing now produce something.

---

## 53. The Roadmap Stops Reserving Version Numbers

**Date:** 2026-08-12 · **Status:** Accepted · **Generalises:** §49

§49 ruled that **a release whose preconditions are measured false holds no version number**. That
handled v1.2.0's collision and v1.3.0's and v1.4.0's, because in each case the reserved slot held
work that could not be built.

**v1.5.0 is the fourth collision and the rule does not cover it.** "Granular Sub-Query
Re-hydration & MCP Tool Extension" is *buildable* — its blocker (M5b, a rehydration regex that
could never match the emitted marker) shipped in Wave 2, and what remains is design work on the
response shape. Its preconditions hold. It simply has not been built, while §52 has been.

So the narrower rule would have forced either an arbitrary version, a patch number for a change
that alters emitted bytes, or renumbering the chain — which is precisely the move §49 identified
as the cause of the recurrence.

### The general rule

**A version number is a fact about what shipped, assigned at ship time. The roadmap describes
releases by name and by gate, and reserves no numbers at all.**

Four collisions in four releases is the evidence. A reserved number is a prediction about the
order in which work will finish, made at the time of least information, and this project has been
wrong about that order every single time — twice because the reserved work turned out to be
unbuildable, once because remediation grew into a release of its own, and now once because a
smaller change simply finished first.

The unshipped sections keep their names, their scope and their measured gates. What they lose is
the number, which was never doing work that a name could not.

`v2.0.0` is retained as written, because a major version communicates *breaking change* rather
than *position in a queue* — it is a statement about compatibility, which is a real property of
the work it describes. If it ships as `v1.9.0` because nothing in it broke compatibility after
all, that is the same correction this entry is making, and it costs a line in `CHANGELOG.md`.

### Why this is worth an entry rather than a silent edit

The failure this prevents is not a mis-numbered release; it is the **half hour each time** spent
deciding whether taking the next number is legitimate, and the risk of resolving it by shifting
the chain and setting up the next collision. Recording the rule ends the question.

---

## 54. The Gateway Forwards the Caller's Bytes, and Measures Them

**Date:** 2026-08-12 · **Status:** Accepted · **Closes:** max_audit.md M7 — the last open finding

M7 said Gateway savings are computed from `summary.tokenEstimate`, a property of the bundle
*render*, while what leaves the process is `JSON.stringify({...parsedPayload, messages})`. It
listed three consequences. Measured before fixing, all three were live, and they are not the same
defect — the status doc's §6 warned that the re-serialization half is not a metrics bug, and that
turned out to be the important half.

### What re-serialization was doing

One elision firing on a hand-written payload — the only shape the Gateway saves on at all:

| client sent | provider received |
|---|---|
| `"temperature": 1.0` | `"temperature":1` |
| `"top_p": 1e3` | `"top_p":1000` |
| `"seed": 12345678901234567890` | `"seed":12345678901234567000` |

The first two are cosmetic. **The third is a different number.** An integer past 2^53 does not
survive `JSON.parse` → `JSON.stringify`, so a provider was being asked for a seed the caller never
chose, by a proxy whose entire promise is faithfulness. Duplicate keys collapse the same way.

This is the mechanism the project already identified as the phantom `-1.39%` in the Python
benchmark harness (Issue 5), reproduced in production code — found there by measuring, and found
here the same way.

### The fix is a splice, not a smaller re-serialization

Elided content is written **into the caller's own bytes**: each message's content is located by
the canonical JSON encoding of the text the parser produced, searched forward from the previous
message's end, and only that span is replaced. Every other byte is the caller's.

**The forward cursor is the whole design.** A first version searched globally and refused
ambiguous matches, which declined **every** payload the Gateway can save on — `session-dedup`
preserves the first copy of a block and elides the later ones, so the encoded text appears more
than once *by construction*. Walking every message in order, replaced or not, keeps position and
identity in agreement. That version's tests passed, because with the splice declining, nothing
changed and every assertion held.

Where the caller's escaping differs from ours the text is equal after parsing but absent from the
raw bytes; there the splice **declines** and the original body is forwarded. Invariant 3's
direction: a lost saving costs tokens, a corrupted field costs correctness, and only one of those
is recoverable by the caller. The same rule refuses any spliced body that is not smaller than the
one that arrived — M7's third consequence, which nothing had ever asserted.

### The metrics were the mild half

Reported against measured, on that same payload: **48.5% claimed, 47.1% on the wire.** Directionally
right and about 1.4pp optimistic — the gap being JSON structural overhead, which the render never
sees and the provider always bills. After pointing the estimate at the forwarded body: **46.3%
against 46.5%.**

Still counted in **tokens**, still through `estimateBundleTokens`. A saving denominated in bytes
and compared against a budget denominated in tokens is precisely the two-estimator defect §19
exists to prevent; what changed is the artefact measured, not the unit.

### The test file was green before it was right

`test/integration/gateway-wire-metrics.test.ts` passed on its first run — 4520 bytes in, 4520 out,
`tokensSaved: 0`. `cleanup:session-dedup` elides a block only once a previous turn has registered
its hash, so a single-turn fixture elides nothing and every assertion holds vacuously. Each test
now asserts the elision fired *before* asserting anything about it, and the file says why.

That is the tenth instance of this project's oldest failure and the second in two sessions: a
green result from a check that never ran. It is worth noticing that both recent instances were in
**new tests written to prove a fix**, which is the moment the temptation to believe a pass is
highest.

### M7 was the last open audit finding

`max_audit.md` is now closed in full. It was gated behind *"only if question B keeps the Gateway"*,
B was answered in §41, and nothing carried it across — recorded in §6 of the status doc rather
than quietly fixed, because the way an item disappears matters more than the item.

---

## 55. The LOW Table Was Never Scheduled, Which Is §54's Failure Mode One Band Down

**Date:** 2026-08-15 · **Status:** accepted · **Scope:** `max_audit.md` L1, L4–L9

§54 closed M7 and recorded *why it went missing*: it sat behind a conditional, the conditional
was resolved, and nothing carried it across, so it entered no wave table. The status doc named
the general rule — **an item that is in no table reads as done, exactly like a check that never
ran reads as a pass** — and then the audit was declared closed in full.

It was not. `max_audit.md` §2 ends with a nine-row LOW table. Waves 0–3, the three decisions and
the unscheduled-M7 row account for every CRITICAL, HIGH and MEDIUM finding. **No wave, no
decision and no status-doc row has ever mentioned L1, L4, L5, L6, L7, L8 or L9.** L2 and L3 are
closed, incidentally, by the C2 `Buffer` work — which is the tell: the two that got fixed are the
two that happened to sit inside someone else's diff.

Re-verified against source 2026-08-15. All seven were open.

### What each one turned out to be

| # | Verified | Disposition |
|---|---|---|
| L1 | open | fixed — env enum values are rejected, not dropped |
| L4 | open, premise wrong | recorded at the site; unreachable, and changing it churns every pinned id |
| L5 | open as documentation | doc corrected; the minimum is right and is kept |
| L6 | open | comment corrected — it is not branch-and-bound |
| L7 | open, **and costlier than rated** | fixed |
| L8 | open | fixed |
| L9 | open as documentation | doc corrected; not widened, because the failure is already safe |

### L7 was rated too low, and the rating is the interesting part

The audit says `scanPythonDefBodies` "fails safe (skip) but silently loses the region" — true,
and it reads like the cost is one region. Measured end-to-end it is the whole file, because a
one-region file has nothing else to elide. Two functions differing only by a blank line after
the `def`:

```
normal.py       434 bytes -> 96 bytes   (77.9%)
blank_first.py  436 bytes -> 436 bytes  (0%, fallback)
```

The `last` scan in that function already skipped blank lines when finding the body's end. Only
the line that reads the body *indent* did not, so the two disagreed about where the body starts.
`indentOf('')` is 0, the region began at column 0, the marker inherited column 0,
`PythonValidator` reported `AST_INDENTATION_ERROR`, and `elideRegions` skipped it as
`post_condition_rejected`.

**The corpus cannot see this fix, and that is a fact about the corpus.** Per-row over the frozen
288-file corpus, **576 of 576 rows are byte-identical** across all fifteen compared fields. The
reason is not that the fix is inert: **0 of 45** Python corpus files contain a blank line directly
after a `def` — pip internals and this repository's own Python are uniformly PEP 8 in that spot.
A real gain that the measurement instrument is structurally blind to is the mirror image of §52's
caveat, where a favourable number came from corpus bias. Same lesson, opposite sign.

### L4's premise does not hold, and that changed the disposition

L4 says that after `cleanup:constraint-preservation` an item's `contentHash` "is no longer a hash
of `item.content`", implying it was one before. On the route that reaches this stage it never
was: `createContextBundle` hashes `{source, sourcePath, content, kind, contentType, metadata,
language}` — a provenance hash — and sets `id` to it. Only `createContextItem`'s default is
content-only.

The narrower defect is real: `hashContent({ ...item, metadata })` folds the *previous* hash in,
so the value is chained and two items identical in every field hash differently on different
histories. It is not changed, because it is unreachable and the change is not free. The one
consumer treating this hash as a content identity is `cleanup:session-dedup`, which keys
cross-turn dedup on it — and that stage runs only under `session_dedup` planner mode, where this
stage is not planned. The knapsack list that plans this stage never plans that one. Changing it
moves `bundle.contentHash` and every pinned id in the suite while moving no output byte.

Recorded at the site with the condition that would make it live: planning both stages in one
list, or any new consumer comparing this hash across a bundle boundary.

### L1 is §30 arriving by the other door

`TOKENDAMPER_PLANNER_MODE=session_dedup` was silently discarded while `--planner-mode
session_dedup` threw. `session_dedup` is a real member of `OptimizationMode`, so it is the worst
shape of the defect — a user has every reason to think it took effect.

§30 established that a flag the command does not consume is a parse error naming where it *does*
apply, because a setting that reports success and changes nothing is worse than one that fails.
An environment variable is the same setting arriving by a different door. All four enum parsers
now reject through one helper rather than one being fixed and three keeping the trap; the
accepted sets are unchanged, and widening `defaultMode` past `pass_through` is left as the
separate question it is.

### Method note

Every fixed case was run against the unfixed engine first: **5 of 7 assertions fail there**, and
the 2 that pass are the negative controls — the no-blank-line region and the still-accepted
environment values — which must pass both ways or they are testing nothing.

`test/unit/audit-low-findings.test.ts`. L4, L5 and L9 are deliberately not pinned there; a test
asserting current behaviour that this entry argues is *acceptable rather than correct* would be a
hazard-pinning test without the hazard.

---

## 56. Go Has the Material, and the Sequencing Warning Was Wrong in the Dangerous Direction

**Date:** 2026-08-15 · **Status:** accepted · **Scope:** precondition check for widening elision

Widening elision beyond TypeScript/JavaScript/Python is the one roadmap item whose preconditions
still hold. Before writing any of it, two things were measured: **how much material a real Go
corpus actually offers**, and **what happens to the safety gates if the region scanner ships
first**. The second turned out to matter more.

### The gates, measured

`selectValidator` returns `null` for Go, C, Java and Rust, so `regionElisionLanguage` is
`undefined` and `selectElisionRegions` returns `[]`. That much was known. What was not:
`extractSymbols` yields **no function symbols at all** for any of them. Probed on one file per
language, the only symbols harvested were incidental matches by the TypeScript regexes —
`type:Point` (because `struct` is an alternative in the class regex) and `import:fmt`.
`computeTotal`, `renderReport` and `do_work` are invisible.

Simulating what a region scanner would produce — signatures kept, bodies replaced, `item.id`
preserved the way real stages preserve it:

| case | symbolsBefore | S_k | astMeasured | measurementGate | fallback |
|---|---|---|---|---|---|
| Go **with** `struct`/`import` | `type:Point, import:fmt` | 0.0000 | **true** | **pass** | **false** |
| Go **without** either | *(none)* | 0.0000 | false | refuse | true |
| C without a struct | *(none)* | 0.0000 | false | refuse | true |

**`ROADMAP.md` and §7 of the status doc both said: add the scanner alone and §33's measurement
gate refuses the item, converting a 0% into a fallback. That is the bottom two rows only.** Real
Go, C, Java and Rust source nearly always carries a struct, class or import, and those manufacture
a symbol that body elision **cannot destroy**, because signatures are retained by construction. So
the gate reports `astMeasured: true`, scores perfect retention, and passes — having tracked
nothing the transform could break. Every function body in the file could be deleted and `S_k`
stays `0.0000`.

**This is C1's shape one step over, and §33 does not cover it.** §33 closed *"the before-set is
empty, so `R_AST` defaults to 1.0"*. This is the sibling: the before-set is **non-empty but
structurally incapable of registering the loss**. §33's gate asks *did evidence exist?*, not *was
the evidence capable of witnessing this transform?* Shipping the scanner first therefore produces
silent unmeasured elision rather than a visible zero — the worse of the two failures, and the one
the docs promised could not happen.

**Order, for that reason:** `extractSymbols` first, then the validator, then
`REGION_ELISION_LANGUAGES` plus the scanner. Step 1 alone is also a free negative control —
reduction must stay 0% everywhere, while drift on a hand-elided file becomes non-zero.

### The material, measured

Ceiling = share of bytes inside `func` bodies clearing the shipped filters (`MIN_REGION_BYTES`
104, `isSubstantiveRegion`), using `scanBraceSpans`'s between-brace boundary. TypeScript and
Python are measured with the **shipped** `selectElisionRegions` over the frozen corpus.

| corpus | files | ceiling, non-test | ceiling, all | median/file | no region |
|---|---|---|---|---|---|
| Go — app (`cli/cli`, `cobra`, `gin`) | 1,028 | **65.36%** | 81.44% | 63.3% | 9.5% |
| Go — stdlib (`golang/go` `src/`) | 5,387 | **54.78%** | 59.81% | 39.5% | 28.2% |
| TypeScript — this repo | 62 | 57.78% | — | 58.6% | 11.3% |
| Python — pip | 45 | 46.88% | — | 53.8% | 2.2% |

TypeScript converts a 57.78% ceiling into **24.56%** achieved at target 0.3. On that conversion Go
lands at roughly **23–28%** — around or above the product's best language. **The precondition
holds.**

### The cross-check moved the number, which is why it was run

App-only read 65.36%; the stdlib pulled it to 54.78%. The cause was checked rather than averaged:
**21.7% of stdlib source bytes sit in files with no elidable region**, dominated by machine-
generated tables the `DO NOT EDIT` filter missed — `cmd/compile/internal/ssa/opGen.go` alone is
3.99 MB, `p256_table.go` 523 KB — plus a long tail of tiny files (median no-region file: 659
bytes). That content is atypical of what a coding assistant is pointed at. **The honest range is
55–65%, not 65%**, and §52's caveat is why a single corpus was not trusted.

### Two findings worth more than the headline

**Test files are the larger prize.** In the app corpus `_test.go` is 53 MB against 36 MB of
source — more bytes than the code — at **92.22%** elidable body with 0.7% having no region. Go's
table-driven test convention puts large literal slices inside function bodies. If Go elision
ships, tests are where most of the saving comes from, and nothing in this project has been
counting them.

**The ceiling is not the constraint; the gates are.** Measured on the frozen corpus, target 0.9
gives TypeScript **21.37%** with 25 files unchanged, against **24.56%** with 12 unchanged at
target 0.3. Pushing harder trips the constraint and drift gates and converts reducing files into
fallbacks — §48's finding reproduced, and it bounds what Go can realise regardless of how much
material it has.

### What this does not establish

The 23–28% projection borrows TypeScript's conversion factor, which embeds **TypeScript's**
fallback rate. **Go's fallback rate cannot be measured until the validator and `extractSymbols`
exist**, because both gates are language-dependent — the same ordering argument, now with a
number attached to why it is worth doing. Go's much lower comment density than this repo's TS
(M11 measured 32.8% comment prose) should make `CONSTRAINT_DIRECTIVE_LOST` fire less, which would
push the figure up; that is an expectation, not a measurement.

The instrument was validated before the result was believed — 12/12 cases including raw-string
literals, both comment forms, interface methods with no body, and closures counted once — because
a scanner that silently misses bodies would understate the ceiling and kill the feature on a
false negative.

---

## 57. A File That Documents the Placeholder Format Is Not a Corrupted Placeholder

**Date:** 2026-08-16 · **Status:** accepted · **Scope:** `detectCorruptedPlaceholders`

`src/core/elision/regions.ts` reduces **29.60%** on the CLI and fell back to **0%** on MCP. Same
file, same ratio, same engine. The trace named the reason:

```
fallbackReason: "Block hash corruption detected: missing block hash [` + 64 hex + `] in token hasher."
```

That is not a hash. It is prose from `regions.ts:17` — *fixed width of `` `<BLOCK_HASH:` `` + 64
hex + `` `>` ``* — the line describing the format the placeholder used to have.

### The defect

```js
new RegExp(`${ELISION_MARKER_PATTERN.source}|<BLOCK_HASH:([^>]+)>`, 'g')
```

Two alternatives in one regex with different strictness. `ELISION_MARKER_PATTERN` requires
`sha256:([a-f0-9]{12,64})`; the legacy alternative accepted `([^>]+)` — anything up to the next
`>`. So it matched from a backtick-quoted `<BLOCK_HASH:` through to a later `>`, captured
`` ` + 64 hex + ` `` as a hash, found it absent from the store, and failed the entire run.

`createBlockPlaceholder` emits `<BLOCK_HASH:${hashContent(...)}>` — a sha256 digest — so
requiring hex removes every prose match at no cost to real detection. The bound now matches the
pattern beside it.

**Blast radius: 22 files in this repository** carry a `<BLOCK_HASH:…>`-shaped string, including
`marker.ts`, `token-hasher.ts`, `token-hashing.ts`, `ARCHITECTURE.md` and `CHANGELOG.md`. Every
one was unoptimizable over MCP, as is any user documentation quoting the legacy format.

### Why no measurement could see it

The check opens `if (!hasher) return []`. **The CLI supplies no `TokenHasher`** — deliberate, and
correct: with no store nothing claims to hold the content, so nothing can be missing. MCP supplies
one at `tools.ts:236`.

`tools/corpus-harness` drives the CLI. **Every corpus number in this project was measured on the
one route where this check is disabled**, so the instrument was structurally blind to it. The
per-row A/B confirms that from the other side: **576 of 576 rows byte-identical** across all
fifteen fields after the fix, because the CLI route never ran the check either before or after.

That is a new shape of §56's caution. There, byte-identical meant *the corpus lacks the shape*.
Here it means *the harness cannot reach the gate*. Both read as "no effect" and neither is.

### It is §52's defect in a second gate

§52 stopped `CONSTRAINT_DIRECTIVE_LOST` refusing a file for its own narrative comments. This is
the block-hash integrity gate refusing a file for **describing the mechanism that processes it** —
and `regions.ts`, the file that defines region elision, was the one it refused.

Two gates have now made the same mistake. Any check that scans emitted content for the product's
own markers is a candidate for the third; the discriminator is that a marker has a *shape*, and
matching on the prefix alone is not enough.

### Measured

| | before | after |
|---|---|---|
| `regions.ts` over MCP | 0.00%, fallback | **32.00%** |
| `token-hasher.ts` over MCP | fallback | **35.28%** |
| minimal file + one `<BLOCK_HASH:…>` comment | 0.00%, fallback | **81.6%** |
| CLI corpus, 576 rows | — | **576/576 byte-identical** |

`test/unit/block-hash-false-positive.test.ts` — 6 of 8 assertions fail against the unfixed engine.
The 2 that pass are the negative controls, and they are the point: a genuine 64-hex placeholder
absent from the store is **still** reported as corruption, and one the hasher knows still
resolves. Narrowing a detector must not cost the detection.

### Provenance

Found by adding `tokendamper mcp` to `.mcp.json` and pointing it at this repository's own source —
the first non-trivial thing tried. M5a and M5b were also MCP-adapter defects that a full unit
suite did not catch. Three findings on that adapter now share a cause: it is the entry mode with
the least end-to-end exercise, not the least tested one.

---

## 58. Docstrings Are Where a Function's Why Survives Elision, So Keeping Them Is a Flag

**Date:** 2026-08-16 · **Status:** accepted · **Scope:** `--keep-docstrings`, Python only

The retention test (an agent answering questions about a codebase it can only see through the
optimizer) found that **3 of the 4** questions the compressed version could not answer lived in
docstrings that body elision had removed — the *why* of a function, not its shape. That pointed
at keeping docstrings. Measured before building, it is a trade rather than a free win, which is
why it ships as an opt-in flag with the default unchanged.

### The measurement

Ceiling = the share of currently-elided body tokens that the leading docstring represents,
measured with real `cl100k_base` over the elidable def bodies of two corpora:

| corpus | bodies with a docstring | tokens given back if kept |
|---|---|---|
| 45-file pip (real third-party) | 42.8% | **14.2%** of the saving |
| expense-analyzer (doc-heavy) | 100% | **21.1%** of the saving |

End-to-end on the doc-heavy project, per-file at target 0.3: **33.4% -> 27.5%** saved, and
docstrings preserved went 26 -> 51. That 5.9pp is the trade, live.

**So it cannot be the default.** On doc-heavy source it gives back a fifth of the win, and the
default path being byte-identical is load-bearing here — the corpus A/B and every published
number depend on it. It is a retention dial the caller opts into.

### The seam, and why it avoids the frozen model

`--keep-docstrings` threads as a *runtime option*, never as a budget field:
`SelectRegionsOptions.keepDocstrings` -> `TokenHashingStageOptions` -> `EngineOptimizationOptions`
-> the CLI flag. `OptimizationBudget` is pinned frozen by `ARCHITECTURE.md` (the H4 disposition),
and this needed nothing from it — it is a transform option like `tokenHasher`, not a budget.

One engine change was required beyond threading: `tokenHashingOptions` was built only when a
`tokenHasher` was present, and the CLI supplies none. Left alone, the flag would have been
silently dropped on the exact route that uses it — the §57 shape again. The context is now built
whenever *either* the hasher or `keepDocstrings` is set.

### Where the region actually changes

Only `scanPythonDefBodies` consults the flag: it advances the region start past a leading
docstring (a `"""..."""` triple-quote, single-line or multi-line, or a single-quoted one-liner)
and any blank lines after it. `splitRegionIntoStatements` never sees the docstring because it
operates *within* the already-narrowed region. If the docstring is the whole substantive body,
the region collapses and `MIN_REGION_BYTES` drops it — correct, since there is no code left to
remove.

**TypeScript and JavaScript are unaffected by construction**, and that is asserted, not assumed:
their doc comments (JSDoc) sit *above* the function, outside the brace-span body the selector
returns, so there is no leading docstring inside the region to keep. `--keep-docstrings` is a
Python-only behaviour with a language-agnostic name, and the name is honest because on other
languages it is simply inert rather than wrong.

### Method

`test/unit/keep-docstrings.test.ts`: the two behaviour-changing cases fail against the unfixed
engine; the three invariants (a body with no docstring is unchanged, a whole-body docstring drops
the region, TypeScript is untouched) pass both ways as negative controls. The default path is
**576/576 byte-identical** on the corpus A/B, because the flag is off.

---

## 59. Go Symbols First, Because the Gate Could Not Tell Body Elision From Deletion

**Date:** 2026-08-20 · **Status:** accepted · **Scope:** `DriftTracker.extractSymbols`, Go

Step 1 of the three that widen elision to Go. §56 measured the precondition and fixed the order —
`extractSymbols`, then the validator, then `REGION_ELISION_LANGUAGES` plus the region scanner —
and this is that first step and nothing else. **Go is still unelidable after it, deliberately.**

### What it adds

Two patterns, both anchored to the start of a line, because a Go function declaration is always a
top-level one:

- `func Name(` and `func Name[T any](` → `fn:Name`
- `func (r *Recv) Name(` → `method:Recv.Name`

Methods are qualified by receiver where the class methods in block 8 are not. Go convention gives
many types in one file the same method names — `String`, `Error`, `Read` — so a bare
`method:String` collapses them and losing ten reads as losing one. Nothing downstream parses these
strings (they are only ever set-compared for `R_AST`), so the resolution costs nothing.

**Not harvested, deliberately.** Anonymous literals (`x := func() {}`) and func types
(`type Handler func(int) error`) have no name to take. An interface method declaration has a name
but no body, so harvesting it would add one more symbol that survives elision by construction —
the exact dependency this step exists to remove.

### What it changes, measured

Same file, same four after-shapes, engine varied and nothing else. `S_k` and the two gates, before
and after:

| after-shape | `S_k` before | `S_k` after | gates before | gates after |
|---|---|---|---|---|
| whole item → marker | 1.0000 | 1.0000 | retention refuses | retention refuses |
| bodies elided, signatures kept | 0.0000 | 0.0000 | both pass | both pass |
| one whole declaration removed | 0.0000 | 0.1667 | both pass | both pass |
| **every declaration removed** | **0.0000** | **0.6667** | **both pass** | **retention refuses** |

`symbolsBefore` goes 2 → 6: `type:Point` and `import:strings` gain `fn:computeTotal`,
`fn:renderReport`, `method:Point.Translate` and `method:Point.String`.

**The fourth row is the defect closing.** A Go file with every function deleted, package and
import and struct left standing, scored `S_k = 0.0000` with `astMeasured: true`, both gates
passing and `fallbackUsed: false`. That is §56's simulation reproduced through the shipped
tracker, and on the CLI, where elision is irreversible, it is data loss reported as a clean run.

### The negative control is not quite the one the skill states, and the difference matters

`widen-language` says drift on a hand-elided file should become non-zero. Measured, that holds for
**declaration loss** and not for **signature-preserving body elision**, which still scores
`0.0000` — row two, unchanged.

That is correct and it is load-bearing. Region elision keeps signatures by construction, so the
symbols survive and there is no semantic loss to report; if row two had moved, step 3 would ship
as a fallback generator. TypeScript behaves identically and §40 already records why.

**So the precise claim is narrower than "drift can now see Go", and it is the one worth having:
before this step the gate could not distinguish rows two, three and four from each other — all
three read `0.0000`. Now it scores them 0.0000, 0.1667 and 0.6667.** A region scanner that takes a
brace span too far, or takes a declaration instead of a body, is a thing the gate can now witness.
That is the failure mode step 3 introduces, and this is the instrument for it.

### Method

Corpus frozen at `7d97049`, 287 files across nine buckets, `dist` pinned at `2f3fe633`, both arms
built with an `src`-only tsconfig so `test/` could not silently block the emit. 574 rows (287
files × 2 routes) per arm.

- **574 of 574 byte-identical.** 0 rows differ across 17 compared fields, `symbolsBefore` among
  them — and the diff asserts its own row count and that every compared field is present, because
  keying on a field the harness does not emit is how a previous A/B reported "differing: 0" over
  two rows.
- **Byte-identical is not inert, and here the reason is countable:** 0 of the 287 corpus files
  match either pattern. There is no Go bucket, and no other bucket contains a line-anchored
  `func`. §56's caution, arriving on the very next change.
- Blast radius outside Go is therefore evidenced by unit cases rather than by the corpus:
  TypeScript that uses `func` as a loop variable and calls `applyFunc`, and Python that names a
  parameter `func`, both yield exactly their own symbols.
- `test/unit/go-symbols.test.ts`: **9 of 14 fail against the unfixed engine.** The 5 that pass
  both ways are named in the file header as controls; one of them — row two above — is a control
  on purpose.

Collecting the corpus also surfaced that the prose bucket is now 17 documents, not 18:
`DECISIONS.md` crossed the recipe's 204,800-byte cap as it grew. The cap was not raised, since
raising it would move every prose aggregate to keep one file whose growth is the reason it stopped
fitting. Recorded in the recipe's own log; prose aggregates from here are not comparable to earlier
18-document ones.

### What this does not establish

- **Go's fallback rate is still unmeasured**, so §56's 23–28% projection still borrows
  TypeScript's conversion factor. That needs step 2, and it is the number most likely to move.
- **Nothing about reduction.** Go reduces 0.00% after this change exactly as before it —
  `supportsRegionElision` decides that, and it consults the validator, not the symbol extractor.
  `trace.languageSupport` still reports Go unsupported and `language-support.test.ts` still asserts
  it.
- **Grouped imports are still not harvested.** `import "strings"` yields `import:strings`;
  `import (\n\t"fmt"\n)` yields nothing, because the JS import regex wants a quote after the
  keyword. Out of scope and immaterial to the argument — imports are on the side of the ledger that
  cannot witness body loss anyway.
- **A Go raw string holding source at column 0 yields a symbol.** Characterized in the test rather
  than fixed: it errs conservatively, because such a symbol sits inside a body, so elision removes
  it and drift becomes more likely to refuse, not less.

---

## 60. Go Gets Its Own Lexer, Because Raw Strings Are Where the TypeScript One Invents Findings

**Date:** 2026-08-21 · **Status:** accepted · **Scope:** `GoValidator`, `selectValidator`

Step 2 of the three that widen elision to Go (§56 fixed the order, §59 was step 1). **Go is still
unelidable after it**: `regionElisionLanguage` requires the language to be in
`REGION_ELISION_LANGUAGES` *as well as* to have a validator, and `'go'` joins that list in step 3.
What this step buys is **coverage** — a `.go` item stops reporting `validated: false` and starts
being checked, which is §23's distinction that an unexamined item is not a passing one.

### Why not just point Go at `TypeScriptValidator`

The grammars share `//`, `/* */` and the three bracket pairs, which is exactly the resemblance
that makes substitution look free. Measured over **9,181 real Go files, 100.8 MB** (`cli/cli`,
`cobra`, `gin`, `golang/go` `src/` — §56's corpus, its stdlib subset hash-verified **5,387 of
5,387** against that session's manifest):

| validator | files flagged | rate |
|---|---|---|
| `TypeScriptValidator` | **73** | 0.80% |
| `GoValidator` | **1** | 0.01% |

The single Go flag is `cmd/compile/internal/syntax/testdata/issue20789.go`, whose own header reads
*"Make sure this doesn't crash the compiler"* — deliberately malformed input, so a **true
positive**. The 72 files the two disagree on are raw strings:

- `` strings.Contains(v, `\`) `` — `cmd/go/internal/fips140`. A TS lexer reads the backslash as
  escaping the closing backtick, never closes the literal, and swallows the rest of the file.
- `cobra/zsh_completions.go` — a 200-line shell template inside one raw string.

Three lexical facts drive all of it. Go's `` ` `` string spans lines, has **no escapes at all**
and routinely holds `"`, `{`, `}` and `\` (struct tags, SQL, templates); rune literals are single
characters, including `'"'`; and there are **no regex literals**, so the TS lexer's
`/`-may-start-a-regex heuristic has nothing to be right about and every wrong guess swallows a
line. This is §17's finding — a verdict decided by quote parity is not validating anything —
measured for Go instead of for shell, perl and tcl.

### 0 findings is what a validator that examines nothing also reports

Invariant 10, so the control runs the other way. Over a 1,312-file deterministic spread of the
same corpus, deleting the last column-0 `}` is caught in **1,159 of 1,163** files (**99.66%**).
Five further mutation classes — dropping the first `{`, mismatching a pair, opening an
unterminated interpreted string, an unterminated raw string, an unterminated block comment — run
95%–100% on the same sample.

**Every non-catch was inspected rather than tolerated, and all of them are mutations that are not
defects**: the brace deleted sits inside a raw string (`internal/platform/zosarch_test.go`, whose
template holds generated Go), inside a `//` comment (`cmd/gofmt/doc.go`, `cmd/cgo/.../callstub`),
or inside a cgo `/* … */` C preamble (`runtime/testdata/.../testsyscallc.go`). Deleting a brace
there changes nothing, so a non-flag is correct — and it is the same property that separates this
validator from the TypeScript one, showing up as an apparent miss.

### The step-2 negative control

Two frozen corpora, engine varied and nothing else, both arms built with an `src`-only tsconfig.

**A Go corpus, 80 files / 160 rows** (frozen separately via `collect.js --recipe`; the shipped
`recipe.json` is untouched, because these roots are a scratch clone and a temp directory is not a
stable root to bake into the repo):

| | step 1 | step 2 |
|---|---|---|
| file route, items no validator looked at | 40 + 40 | **0 + 0** |
| stdin route, same | 40 + 40 | 40 + 40 |
| reduction, every bucket and route | 0.00% | **0.00%** |
| fallbacks | 0 | **0** |
| `outputSha` identical between arms | — | **160/160** |

Exactly **three fields move, on exactly the 80 file-route rows**: `astChecked` 0→1,
`astUnchecked` 1→0, `symbolBearingItems` 0→1. **Coverage moves; output does not.**

The stdin row staying at 40 is not a regression: a piped `.go` carries no filename, and there is
deliberately no Go content probe (§31's rule — a probe may only claim content its validator
already accepts, and §4's TS-versus-prose overlap is why probes are added sparingly).
`--language go` and `--input-name x.go` both reach the validator, and `go`/`golang` were already
accepted spellings.

**The 287-file main corpus is 574/574 byte-identical, 0 rows differing across 17 fields.** As in
§59 that is the corpus lacking the shape rather than the change being inert — it contains no Go
at all, which is why the Go corpus above exists.

### The finding this exposed: `symbolBearingItems` counts the wrong thing

`DriftCoverage.symbolBearingItems` is computed as the set of items **a validator covered**, not
items bearing symbols — it is `astChecked` by another route. The name has been wrong since it was
introduced and nothing could see it, because until §59 every language with symbols also had a
validator and every language without one had neither.

Go between §59 and §60 is the first case where those came apart, and the reported pair is
self-contradicting: over the 80 frozen Go files on the file route, **all 80** report
`symbolsBefore = 3` or more next to `symbolBearingItems = 0`. `symbolsBefore` is the field that
actually counts symbols.

Recorded at the computation site and **deliberately not fixed here**. It is a trace field
consumers parse, so renaming it — or making it count what its name says, which moves the number
for every language and invalidates recorded baselines — is a decision with its own blast radius,
not a ride-along in the commit that exposed it. This is §55's lesson pointed the other way: the
two LOW items that got fixed were the two that happened to sit inside someone else's diff.

### What this does not establish

- **Go's fallback rate under elision is still unmeasured.** The 0 fallbacks above are 0 out of 160
  rows on which *nothing was elided*, so they say nothing about what the constraint and drift
  gates will do once step 3 selects regions. §56's 23–28% projection still borrows TypeScript's
  conversion factor.
- **The guarantee is balance, not syntax** — the same one the README's table states for
  TypeScript. Balanced but meaningless Go passes. What it is for is the failure mode step 3
  introduces: an elision landing inside a raw string, or dropping a `}`, is an unbalanced bracket.
- **The Go corpus is alphabetically-first selection**, which is deterministic and not
  representative (the harness README's own caveat). It is adequate for a coverage measurement and
  would not be adequate for a reduction one.
- **`code` still maps to no validator.** Go reaches `GoValidator` through the `language` and
  `path` branches, by its own grammar — which is the distinction that `null` exists to preserve,
  not one this contradicts. Rust, C, Java, shell and the rest are unchanged and still uncovered.

---

## 61. Go Elides, and the Ordering Discipline Paid for Itself Twice

**Date:** 2026-08-21 · **Status:** accepted · **Scope:** `REGION_ELISION_LANGUAGES`, the Go region
scanner and statement splitter

Step 3 of three, and the one that changes output. §56 fixed the order and measured the
precondition; §59 gave the drift gate Go symbols; §60 gave Go a validator. This adds the scanner,
and Go reduces.

### What it adds

- **`scanGoBraceSpans`**, a Go brace scanner — separate from `scanBraceSpans` for exactly §60's
  reason: Go's `` ` `` raw string spans lines, takes **no escapes**, and holds `{`, `}` and `\`.
  A TypeScript scanner reads `` `C:\path\` `` as an unterminated template literal and every brace
  after it as string content, and a region boundary computed from that is not a function body.
  No regex-literal state, because Go has none.
- **`GO_FUNCTION_HEADER = /^func\b/`**, a keyword test where TypeScript needs a shape test. This
  is most of why Go was the first language added (§56). `FUNCTION_HEADER` matches anything ending
  in `)`, so `CONTROL_FLOW_HEADER` has to subtract `if`/`for`/`while` back out; `^func` needs no
  subtraction, and it excludes `type Point struct {`, `Config{`, `switch v := x.(type) {` and
  every closure form (`go func() {`, `defer func() {`, `handler := func() {`) by construction.
- **`splitGoStatements`**, because **Go ends statements at a newline, not at a `;`**. Semicolon
  insertion means gofmt-ed source has almost none written down, so `splitTypeScriptStatements`
  finds only the `}` boundaries and calls most bodies indivisible — §50's overshoot, one language
  along. The boundary is a newline at depth 0, so a multi-line call, a composite literal and a
  nested block are each one span.
- `'go'` in `REGION_ELISION_LANGUAGES`, plus a Go arm on `isSubstantiveRegion` (`stripGo`).

### Measured

Frozen 80-file Go corpus, target 0.3, engine varied and nothing else:

| bucket | files | reduce | fallback | aggregate |
|---|---|---|---|---|
| application Go (`cli/cli`, `gin`, `cobra`) | 40 | 32 | 8 | **27.46%** |
| stdlib (`golang/go` `src/`) | 40 | 25 | 12 | **19.42%** |

§56 projected **23–28%** from the ceiling, borrowing TypeScript's conversion factor. Application
Go landed at **27.46%**, at the top of that range and **above this repo's TypeScript at 21.22%**
on the same engine. The stdlib's 19.42% tracks its 10pp lower ceiling, which §56 traced to
generated tables rather than averaging away.

**The 287-file main corpus is 574/574 byte-identical, 0 rows differing across 17 fields.**
TypeScript and Python are untouched, because every Go path is gated on `language === 'go'`.

Adherence at target 0.3 over the 57 reducing files: median **35.8%**, with 20 in the 25–35% band,
17 in 35–50% and 14 above 50% — the same profile TypeScript has after §50.

### §56's hazard, measured live rather than simulated

Neutering §59's Go symbol patterns and re-running step 3 reproduces the configuration §56 warned
about — the region scanner without the drift gate that can witness it:

| | scanner-first (no §59) | shipped |
|---|---|---|
| file-route fallbacks | 43/80 | **20/80** |
| rows where drift measured anything | 55/80 | **80/80** |
| median `symbolsBefore` | 2 | **8** |
| application Go aggregate | 14.45% | **27.46%** |

**32 files elide with `S_k = 0.0000`, `astMeasured: true`, both gates passing and no fallback, on
1–5 symbols that are all `type:` and `import:`.** `accessibility.go` loses **78.4%** of its tokens
that way. That is §56's table, on real input, at scale — the gate reporting perfect retention
having witnessed nothing. With §59 in place the same 32 files still pass, and that is correct
(signature-preserving elision genuinely loses no symbols), but the verdict now rests on a median
of 8 real symbols instead of on an import.

**§59 is not a tax on reduction; it is a precondition for it.** Fallbacks more than halve and
application Go goes 14.45% → 27.46%, because without Go symbols many files have *no* symbols and
§33's measurement gate refuses them outright. The safety step and the reduction step turned out
to be the same step.

### Go's fallback rate, and an expectation of §56's that measurement contradicts

§56 could not measure this and said so. Now: **20 of 80 files fall back (25%)**, and the causes are

- **18 `CONSTRAINT_DIRECTIVE_LOST`**
- **2 `SEMANTIC_DRIFT_EXCEEDED`** (both `fuzz_test.go`, `S_k = 0.50`)

**§56 expected Go's lower comment density to make the constraint gate fire *less*. It does not.**
The gate dominates Go's fallbacks exactly as it dominates TypeScript's, and the rate is the same
within noise — 25% for Go against 24% for this repo's TypeScript (15 of 62). Density was the wrong
variable: what trips the gate is Go's *defensive comment style*, and it is §7.5's still-open axis
verbatim — `// This never happens in practice`, `// Should never happen, but we`,
`// The user data should always`, `// does not always result in`, `// Must read more data.`
Every one is descriptive present tense, which §52 deliberately did not attempt.

So the largest remaining gain on Go is not in the scanner. It is in that gate.

### Test files are the larger prize, confirmed end to end

§56 measured `_test.go` at a 92.22% ceiling and flagged that nothing here had been counting them.
Through the shipped pipeline:

| | files | reduce | fallback | aggregate |
|---|---|---|---|---|
| `_test.go` | 40 | 32 | 7 | **26.88%** |
| source | 40 | 25 | 13 | **14.42%** |

Nearly double the saving *and* half the fallbacks. Go's table-driven test convention puts large
literal slices inside function bodies, which is exactly what body elision is for.

### What this does not establish

- **The Go corpus is alphabetically-first selection** — deterministic, and not representative
  (the harness README's own caveat). It is 80 files against the main corpus's 287, and it is
  frozen through a scratch recipe rather than the shipped one, because its roots are a temp-dir
  clone.
- **A signature broken across lines is silently skipped**, and the corpus does not say how often.
  `scanBraceSpans` takes the header from the line carrying the `{`, so a gofmt-wrapped signature
  presents as `) error`. Under-selection costs reduction, never content, which is why it ships
  characterized rather than fixed.
- **Reversibility was not measured separately for Go.** `token-hashing`'s rehydration path is
  language-agnostic and covered by `token-hashing-reversibility.test.ts`; nothing here tested that
  a Go elision round-trips through a real MCP session.
- **Nothing about Rust, C or Java.** Each needs its own three steps, and the header discriminator
  is the hard part for the C family (§56) — `int foo(...)` cannot be told from a prototype, where
  `func` is unambiguous.

---

## 62. Two Dials That Reported Success and Did Nothing, Withdrawn on H4's Terms

**Audit OX-H5.** `--trace-output` / `TOKENDAMPER_TRACE_OUTPUT` and `--mode explain` were parsed,
validated, stored on `ResolvedConfig` — and read by nothing. They are withdrawn from every input
surface. The model fields stay.

### What made these High rather than tidy-up

This project already removed three flags for exactly this defect. Audit H4 took
`--max-output-tokens`, `--max-latency-ms` and `--risk-tolerance` because they were "wired end to
end … while no stage read them", and `README.md` records them as removed in 1.2.0. These two
survived that sweep because they are not `OptimizationBudget` fields — they sit on
`ResolvedConfig`, which nobody thought to audit.

The trace is emitted by a literal:

```ts
io.stderr.write(JSON.stringify(result.trace, null, 2));
```

So `--trace-output stdout` accepted the value, validated it against an enum, threaded it through
the file → env → CLI precedence chain, froze it onto the config, and then the trace went to
stderr. A user setting it to capture a trace in a pipe got stderr anyway and concluded the tool
had ignored them. It had. `appMode === 'explain'` is the same shape with nothing at the end of it
at all.

**Measured before deciding:** `traceOutput` appears at ten sites across `cli/main.ts`,
`config/{load,schema,types}.ts` and `core/model/types.ts`. Every one is a write or a type
declaration. There is no read.

### Withdraw, not implement

Implementing `--trace-output` is two lines. It was still the wrong call, because the flag has no
demand behind it — it was added speculatively, and the one caller in this repository that passes
it (`tools/corpus-harness/measure.js`, `--trace-output stderr`) has been parsing stderr correctly
the whole time *while passing a flag that did nothing*. That is the clearest possible evidence
that nobody needs the other value: the only user asked for the default.

`explain` is worse — implementing it means designing a mode, not honoring a setting.

So: the surfaces go, on H4's terms. `ResolvedConfig.appMode` and `ResolvedConfig.traceOutput`
remain, documented as unconsumed, because `ARCHITECTURE.md` pins the model as frozen and **a field
awaiting an implementation is not the same defect as a dial that reports success.** If
`traceOutput` is ever implemented, `cli/main.ts` reads the field and the surfaces come back — in
that order, never the reverse.

### What is *not* withdrawn, and why the distinction matters

`--mode` stays. It is withdrawn by **value**, not removed, because `--mode bench` has a live
effect — it rewrites the command:

```ts
if (value === 'bench') { command = 'bench'; }
```

That effect is in the *parser*, not in anything that reads `appMode`, which is exactly the
distinction that made this worth checking rather than assuming. An earlier pass through this
finding concluded "`appMode` has no consumers, so remove `--mode` entirely" — true about the
field, false about the flag, and it would have deleted a working route to `bench`.

### Consequences

- **`--trace-output` is now `Unknown argument`.** `TOKENDAMPER_TRACE_OUTPUT` is simply not read,
  matching how the H4 variables were retired; nothing that worked stops working, because it never
  worked.
- **`--mode explain`, `TOKENDAMPER_APP_MODE=explain` and `app.mode: "explain"` are hard errors.**
  That follows the rule v1.6.0 set for the `TOKENDAMPER_*` enums (§55, L1): an unrecognized value
  is reported rather than ignored. Nothing that took effect stops taking effect, because it never
  took effect.
- **A config file still carrying `traceOutput` keeps loading.** The key is no longer validated or
  read, and unknown keys were always ignored. Withdrawing a knob must not turn a file that loaded
  yesterday into a hard error — that would be a real regression in exchange for a cosmetic one.
- **`tools/corpus-harness/measure.js` was updated in the same change.** It passed
  `--trace-output stderr`, which is now a parse error; leaving it would have broken the
  measurement harness this project depends on to check its own numbers. Verified after the
  change: the file route exits 0 and its trace still parses out of stderr.

### One thing this corrected on the way past

The comment above `COMMON_FLAGS` claimed `--target-reduction-ratio` "deliberately stays despite
being nearly as inert — the planner reads it only as `> 0`". **That has been false since §48**,
which resolves the ratio into an absolute token ceiling that both `pruning:topology-pruner` and
`compression:token-hashing` respect, and §50 narrowed the adherence gap further. A comment that
records a decision is load-bearing in this codebase; one that records a *superseded* decision
argues for undoing the fix.

## 63. The Float Pool: Two Small Hashes and Two Recorded Limits

**Date:** 2026-08-23 · **Status:** accepted · **Scope:** `core/model/constructors.ts`, `core/topology/`

Four LOW findings from `oxaudit.md` (the ox-alpha audit of tree `79aedef`), claimed from the
split document's float pool because they are file-disjoint from both lanes' active sets. Two are
code, two are recorded rather than fixed — the same disposition DECISIONS §55 gave its LOW table,
for the same reason: a fix that changes more than the defect is worse than a documented limit.

### L2 — `stableSerialize` no longer collapses `undefined` onto `null`

`JSON.stringify(undefined)` returns `undefined`, and the old `?? 'null'` turned that into
`null`'s serialization, so `{ a: undefined }` and `{ a: null }` hashed identically. A hash is a
statement about the value it was given; two different values must not share one. The fallback now
emits the bare token `undefined`. The output only ever feeds `createHash`, so it does not have to
be valid JSON — it has to be injective. No live path reaches the branch (constructors build
objects by conditional spread specifically so no key is ever `undefined`), which is exactly why
it sat unnoticed: the defensive branch was itself the collision.

### L11 — the extension test reads the basename, not the whole path

`classifyContentShape` took the segment after the last dot of the whole path, so a dotted
directory (`my.dir/file`) leaked directory text into the extension test. Measured before
changing anything: every possible leak lands on an unrecognized string and falls through to the
content probes, byte-identical to an absent extension — **no observable behaviour changes
today**, and the tests pin that rather than assert a behavioural delta that does not exist. What
the pin buys is a tripwire: a future edit that makes a leak reachable (a directory segment that
*is* a known extension) fails loudly instead of silently reclassifying. Same algorithm as
`cli/ingest.ts`'s `extensionOf`; duplicated rather than imported because `core` may not import
`cli`.

### L3 — `h → c` stays, recorded

Removing the alias would make `--language h` an error while `foo.h` stayed accepted on the
filename route. That is the two-routes drift the alias table exists to prevent (`py`, `cc`,
`hpp` are all extension spellings by design). Characterization test added; if anyone removes the
alias, the test tells them to take `.h` off the filename route in the same change or restore it.

### L5 — case-sensitive git path matching stays, recorded

Git porcelain uses the index's casing; a directory walk uses the filesystem's; they agree in
practice. The open case is caller-supplied casing (`optimize SRC/foo.ts` against a repo storing
`src/`), and its effect is a lower topology score — selection quality, never output bytes.
Case-folding one side would make scores depend on the platform's filesystem semantics, and
determinism is invariant 1. Documented at `normalizeGitPath` and the scorer's call site.

### Verification

`npm run typecheck`, `npm run lint` and `npm test` clean; the suite pins each disposition
(`model.test.ts` for L2, `content-classification.test.ts` for L11, `declared-language.test.ts`
for L3). L5 changes no code path, so no corpus run applies; nothing here touches engine output.

---

## 64. The Debt Score Was a Constant, and the Corpus Could Not See the Other Half

**Audit OX-M6 and OX-M7**, both in `computeDebtBreakdown` / `attemptAutomatedRehydration`
(`src/core/engine/index.ts`). Measured over a corpus frozen at `8b447ce`, 289 files, 578 rows
(both CLI routes), target ratio 0.3.

### M7: `debtScore` reported 35.00 on every file that reduced

`computeDebtBreakdown` added `metadata.originalBytes` to `elidedBytes` for any item carrying
`elided: true`. `originalBytes` is the item's **entire** pre-transform length — every stage that
sets it does so from `item.content.length` — and `elided` is a boolean on the whole item. So an
item that lost 5% of its bytes contributed 100% of its size to the numerator.

On the CLI a single file is a single-item bundle, which makes `elidedBytes === totalBytes` whenever
anything was elided at all. The ratio was 1.0 by construction.

**Measured, baseline arm:** of 578 rows, 317 carried any debt at all, and **317 of 317 scored
`debtScore` exactly 35.00** — the `weightElisionRatio * 100` ceiling — whether the file lost 4.7%
or 66.8% of its bytes. `Math.min(1.0, …)` in `calculateDebt` was clamping a ratio with no business
exceeding 1, which is why nothing ever looked wrong. The number was a constant wearing the name of
a measurement, and `--max-debt` was a dial against a value that never moved.

The fix counts bytes actually removed, `originalBytes - content.length`.

**Measured, candidate arm:** 0 of 317 pinned at the ceiling; the distribution runs 1.31 → 34.99
with a median of 33.08. Over the 101 rows that reduce, the implied ratio (`debtScore / 35`) against
the measured byte cut has **correlation 1.0000** — 0.047 against 0.047, 0.198 against 0.198, 0.429
against 0.429. It is now the quantity it claims to be.

**Output did not move.** Per-row over 578 rows the only field that changed is `debtScore`;
`outputSha`, `byteIdentical`, `tokenBefore`, `tokenAfter`, `reduction`, `fallbackUsed`,
`driftScore`, `planMode` and `stageCount` are identical. Debt gates nothing on the CLI, because
`shouldRehydrate` needs 75 and the elision term alone caps at 35.

**The audit's stated mechanism was wrong and the finding was right.** It described a denominator
mixing pre- and post-transform sizes. That does not happen: every stage setting `elided` also sets
`originalBytes`, and untouched items are unchanged, so `totalBytes` was already a clean sum of
original sizes. The numerator was the defect, and it was worse than "skewed" — it was saturated.

### M6: an empty candidate set meant "restore everything"

`attemptAutomatedRehydration` guarded with `candidates && candidates.size > 0 &&
!candidates.has(item.id)`. The `size > 0` clause exists for the *missing* ledger case, where no
statement has been made about which items matter. It also swallowed the case where a ledger exists
and reports **zero** items below the confidence threshold, turning "nothing needs restoring" into
"restore every elision in the bundle".

**Reachability, checked rather than assumed.** None of the three bundled entry points reaches it:
the CLI passes neither hasher nor ledger and returns at the first guard; MCP and `bench` pass a
hasher but no ledger, so `candidates` is `null` and the intended fall-through applies; the Gateway
passes a ledger but no hasher and plans only `cleanup:session-dedup`, so nothing it elides could be
rehydrated. It **is** reachable through the public API — `optimize` is exported, and an embedder
supplying both a `tokenHasher` and a `confidenceLedger` lands on it.

Reproduced there: a 1,481-byte item came back at exactly 1,481 bytes, every elision undone, with
`debtScore` then recomputed to 0 on the restored bundle so the trace reported no debt either.

**The corpus is silent on this, and silence is not agreement.** The `m7 -> m6m7` arm differs on
**0 of 578 rows**, which is exactly what the structure predicts and is *not* evidence the fix is
correct — the corpus runs CLI routes, which supply no ledger, so the instrument cannot see the
shape at all. This is §56's lesson with the sign reversed: byte-identical is not inert, and here it
is not even informative.

**The test had to be rebuilt twice.** The first version passed against the unfixed code, because
the default `maxDebtThreshold` of 75 is unreachable on turn 1 — confidence penalty 0, turn age 0,
elision term capped at 35 — so the branch it claimed to exercise never ran. The committed version
carries two controls: one proving the setup elides at all, and one proving the branch *is* entered
under `maxDebtThreshold: 1` via the no-ledger path, where a full restore is the intended behaviour
rather than the bug.

### What this does not establish

- **Nothing about the Gateway.** Both findings are engine-level; the Gateway supplies a ledger but
  no hasher, and its plan cannot produce a rehydratable elision. Neither fix changes Gateway
  behaviour, and neither was measured there.
- **Nothing about multi-item CLI bundles.** The harness runs one file per invocation. M7's
  correction is larger on multi-item bundles — a partially-elided item over-contributes there too —
  but that is reasoned, not measured.
- **No absolute figure here is comparable to §2.** This corpus is 289 files at `8b447ce`; the
  recipe expected 62 TypeScript and 17 prose files and selected 63 and 18, because the repository
  has grown since the recipe was written. Only the per-row A/B over this one frozen corpus means
  anything, which is the standing rule.
- **`--max-debt` still gates nothing on the CLI.** Debt is now a real number, but the default
  threshold of 75 remains unreachable without a ledger, so no CLI run can trip it. Whether the
  threshold or the weights should change is a separate question and was not touched.

---

## 65. One `content: null` Turn Zeroed the Whole Request, So Egress Anchors on Positions Now

**Audit OX-H4**, the highest-value finding in `oxaudit.md` and the first Lane B item taken.

### The mechanism

Egress splices replacements into the caller's raw bytes rather than re-serializing the payload
(invariant 9, §54). It located each message by searching the raw body for `JSON.stringify(text)`,
where `text` came from `flattenMessageContent` — which sends every **non-string** content through
`JSON.stringify`. For `content: null` that yields the four-character string `null`, so the search
string became `"null"` *with quotes*, which does not occur where the body holds a bare `null`.

`spliceIntoRawBody` returns `undefined` on the **first** miss, and `forwardableBody` maps that back
to the untouched `rawBody`. So the failure was all-or-nothing: one unmatchable message discarded
the replacements for every other message in the payload.

`content: null` is the standard OpenAI shape for an assistant turn that calls a tool. Essentially
every agentic OpenAI conversation carries one.

### Measured, on a payload the Gateway does save on

A three-times-repeated block with a turn 1 to seed the session store:

| payload | bytes sent | bytes forwarded |
|---|---|---|
| all-string content (control) | 8,685 | **less than sent** — the saving lands |
| one `content: null` tool-call turn | 8,685 | **8,685** — entire saving gone |
| one array (multimodal) content part | 8,530 | **8,530** — entire saving gone |

**The array row is why this is a span scan and not the `null` special-case the audit proposed as
an alternative.** That would have fixed one shape and left the other, and the two share a cause:
`JSON.stringify` of a *parsed* value is not the caller's bytes. It is not even reliably so for
strings — a pretty-printed body defeats the search for the same reason.

### The fix

`scanContentSpans` walks the raw body structurally and returns the `[start, end)` span of each
spliceable slot, in the order entries are built (`system` first for Anthropic, then messages).
`spliceBySpans` overwrites those ranges directly.

A span is *where the value is*, so it is correct for every content shape, and repeated blocks — the
case `session-dedup` exists for — need no forward cursor to disambiguate. The cursor requirement
the audit said "must survive any rewrite" survives by becoming unnecessary, not by being dropped.

**Kept: the old value search, as a fallback.** `forwardableBody` tries spans first and falls back to
`spliceIntoRawBody`. A payload the scanner declines behaves exactly as it did before, so this change
can only add savings.

**Kept: declining as the failure direction.** The scanner returns `undefined` on anything it does
not fully understand — a non-object root, absent or non-array `messages`, a message with no
`content` key, a truncated body, an expected `system` that is missing. `spliceBySpans` additionally
refuses when spans do not ascend across the entries it is replacing, which is the case where a
backwards splice would corrupt.

### Why the tests are shaped the way they are

This is the code that decides which bytes of a caller's request get overwritten. A wrong span does
not lose a saving, it corrupts a field being sent to a provider — the one direction invariant 3
forbids. So `test/unit/gateway-content-span-scan.test.ts` is mostly about refusal, every span it
accepts is checked by slicing the input and parsing the result, and the adversarial cases are the
ones a naive scan gets wrong: `"content"` appearing inside a string value, a `meta: { content: … }`
decoy preceding the real key, escaped quotes and backslashes, braces and brackets inside strings,
and a pretty-printed body.

`test/integration/gateway-null-content-splice.test.ts` adds the property that matters more than the
saving: the forwarded body still parses, message count and roles are unchanged, and the tool-call
turn comes back exactly as sent, `null` included. That assertion would have passed before the fix
too — declining is safe — and it is here to stay true afterwards, which is the harder half.

### What this does not establish

- **Nothing about the corpus.** The harness measures CLI routes; the Gateway is not in it. The
  instrument for this change is the Gateway integration suite, and the numbers above come from it.
- **Nothing about cross-turn saving.** Invariant 8 is untouched: the Gateway still plans only
  `cleanup:session-dedup`, and a sole cross-turn copy is still refused (§41). What was recovered is
  the *within-payload* saving, on payloads that happen to contain a non-string content.
- **The `system`-after-`messages` ordering is still a partial decline.** Entries list `system`
  first, so such a payload yields non-ascending spans; the splice proceeds when `system` itself has
  no replacement and declines when it does. Ordering entries by span position would close that and
  was not attempted.
- **`flattenMessageContent` is unchanged.** Structured content is still tagged `'structured'` and
  `core/elision` still refuses to elide it. This change lets other messages be elided *despite* one,
  not that one be elided.

---

## 66. The Upstream Budget Is Time-to-First-Byte, Because a Fetch Signal Outlives the Fetch

**Audit OX-H2.** `forwardUpstreamRequest` armed `AbortSignal.timeout(30000)` and handed it to
`fetch`. That is the whole defect: **a fetch signal does not stop applying when the promise
resolves — it governs the response body stream too.**

So for `"stream": true` payloads the body reader rejected roughly 30 seconds in, and the pump in
`server.ts` called `res.destroy(...)`, truncating the answer mid-generation. LLM completions
routinely run longer than 30 seconds, long-form Anthropic streams especially, so this broke exactly
the traffic the Gateway intercepts by default. From the client's side it is indistinguishable from
the model stopping.

### The fix, and the one line that is the fix

An owned `AbortController` replaces `AbortSignal.timeout`, and the timer is cleared in a `finally`
on the header phase:

```ts
} finally {
  clearTimeout(ttfbTimer);
}
```

`AbortSignal.timeout` cannot be used here because it cannot be *un*-fired. Only a controller you own
can be left permanently unaborted, which is what makes the budget time-to-first-byte: once `fetch`
settles — resolved, timed out, or failed — nothing can fire it again, and the body phase is governed
solely by the caller-disconnect signal.

The 504 mapping is preserved by aborting with `new DOMException(…, 'TimeoutError')`, because the
catch matches on `error.name` and that is exactly the reason `AbortSignal.timeout` used to produce.

### The half that a careless fix removes

`params.options.abortSignal` — the client-hangup signal, raised by `res.on('close')` in
`server.ts` — stays combined into the fetch signal via `AbortSignal.any`. Disarming the *timeout*
must not disarm the *disconnect*, or a client that walks away leaves the Gateway pulling a response
nobody will read and paying the provider for it.

That is asserted, and the assertion was mutation-checked: replacing the combined signal with
`ttfbController.signal` alone fails that test and only that test.

It also needed a second pass to be worth anything. The first version read the upstream's flag
*after* `withGateway` returned — but that helper stops the server on the way out, which closes the
upstream socket too, so the test would have passed whether or not the hangup propagated. The value
is now sampled inside the gateway's lifetime.

### Configurable, and why that is not scope creep

`upstreamTtfbTimeoutMs` is now a `GatewayConfig` / `ProxyHandlerOptions` field defaulting to 30000.
The audit suggested it, and it is what makes the defect testable at all: the reason no test caught
a 30-second bug is that catching it required a 30-second upstream. This suite runs in about a
second against a real socket, with budgets in the tens of milliseconds.

The tests drive a real local upstream rather than `mockUpstream`, because `mockUpstream`
short-circuits before `fetch` and the defect lives entirely in `fetch`'s signal handling.

### Measured

Against a real upstream, budget 120 ms, body streaming for ~300 ms:

| case | before | after |
|---|---|---|
| headers fast, body outlives budget | truncated mid-stream | full body, `[DONE]`, all 5 chunks |
| body an order of magnitude past budget (40 ms budget, ~400 ms body) | truncated | full body, all 8 chunks |
| headers slower than budget | 504 | 504 (unchanged) |
| client hangs up mid-stream | upstream aborted | upstream aborted (unchanged) |

### What this does not establish

- **Nothing about how long a body may take.** There is now no bound on it at all, deliberately. If
  a stalled-mid-stream upstream ever needs bounding, that wants an idle timer on the pump — reset
  per chunk — not a total-duration budget, and it is a different change.
- **Nothing about the 10 MB body cap or the session store.** Untouched.
- **Nothing about savings.** This path runs after optimization; it changes what reaches the client,
  not what the Gateway elides.

---

## 67. Within-Payload Deduplication Never Needed History, and Was Gated on It Anyway

**Audit OX-M1.** `runSessionDedupStage` treated within-payload repetition as a *side condition* of
cross-turn matching. The whole dedup branch was gated on
`sessionContext.previousBlockHashes.has(item.contentHash)`, and the stage returned early unless that
set was non-empty — so on turn 1, three identical blocks in one payload all survived.

The README's savings table said "the same block repeated **within one payload** → saves", with no
qualifier. It was true from turn 2.

### Why the gate was wrong rather than merely conservative

`recoverable: true` means **an intact copy survives elsewhere in the same outbound payload**. Rule 3
guarantees that by preserving the first occurrence and eliding the ones after it. That claim is
verifiable from the payload alone: the model has seen the content, in this request, so the marker
resolves.

Nothing in it refers to previous turns. The `previousBlockHashes` check was answering a different
question — *is this content old?* — and using the answer to decide something it does not bear on.

**DECISIONS §16 and §41 are untouched.** They concern a **sole** copy elided across turns, where the
consumer is a stateless provider API with no rehydration mechanism, so the marker is deletion rather
than reference. That case is still elided with `recoverable: false`, still scored in full by
`DriftTracker`, and still fails the gate. It is pinned by the first test in
`gateway-dedup-reality.test.ts`, which is unchanged.

### The change

Two gates, both relaxed by the same reasoning:

- `shouldAttemptDedup` is now `previousBlockHashes.size > 0 || hasRepeatedContent`. The occurrence
  map moved above the early return, since within-payload repetition is by itself a reason to run.
- The per-item branch fires on `seenInEarlierTurn || repeatsInThisPayload`.

Rule 3 and the `isRecoverable = survivingHashes.has(hash)` computation are unchanged, which is what
keeps sole-copy elision out of the new path: the first occurrence is always preserved, so anything
elided under `repeatsInThisPayload` is recoverable by construction.

### Measured

Real sockets, a block repeated three times in one payload:

| | before | after |
|---|---|---|
| turn 1, block ×3 | 8,459 sent, **8,459 forwarded** | saves |
| turn 2, block ×3 (already worked) | saves | saves |
| cross-turn sole copy | 0 bytes, falls back | 0 bytes, falls back |
| turn 1, all blocks distinct | no saving | no saving |

The last row is the control that keeps the first honest — turn 1 did not become "always saves". The
third is §41 still holding.

### What this does not establish

- **Nothing about cross-turn saving.** Invariant 8 stands; the Gateway still plans only
  `cleanup:session-dedup`, and the ordinary conversational shape — one copy per payload, seen
  before — still saves nothing and still falls back. That is the number the README leads with and
  it has not moved.
- **Nothing about the corpus.** This stage never runs on the CLI or MCP paths, which execute
  `plan.stageIds` and do not include it. The instrument is the Gateway integration suite.
- **No claim that this is a large win.** It closes the gap between what the README says and what
  the code does. Whether real agent traffic repeats a block inside a single payload often enough to
  matter was not measured, and the honest framing stays the one in the README notice: use Gateway
  mode for interception, validation and metrics, not for compression.

---

## 68. Pricing a Region Registered It, So the Store Grew With Candidates Instead of Elisions

**Audit OX-M5.** `trimRegionsToCeiling` renders a marker for **every** candidate span in order to
price it — correctly, because the marker is variable-length and self-describing and a saving
estimated without it would overstate every region. The renderer it was handed, `markerFor`, also
called `hasher.registerBlock(...)`. So every span the ceiling considered and then discarded was
written into the store anyway.

### Measured

A 12-region TypeScript file, run through the stage with a `TokenHasher`:

| target ratio | blocks registered | markers actually emitted |
|---|---|---|
| 0.10 | **12** | 5 |
| 0.05 | **12** | 3 |

The store held one block per *candidate*, not per elision. Memory therefore grows with how much the
scanner finds, not with how much is removed — and `hasHash` / `expandBlockHash` answer for
placeholders that appear in no output anywhere.

Invisible on the CLI, which supplies no hasher at all. It matters on **MCP**, where the server
instance is long-lived and the hasher *is* the reversibility store.

### The fix, and the constraint that governed it

`priceMarker` renders the same bytes without registering; `trimRegionsToCeiling` takes it instead of
`markerFor`, and registration now happens only on the two paths that actually elide.

The binding constraint was that **pricing and emission must render identical bytes** — otherwise the
ceiling is computed against a different string from the one written, and `--target-reduction-ratio`
adherence shifts. That holds by construction rather than by care: `renderElisionMarker` is a pure
function of the text, its noun and its hash, and `hashContent` is pure. Registration never
contributed to the output.

### Corpus A/B: 578 of 578 rows byte-identical

Corpus frozen at `48ac6c8`, 289 files, 578 rows, both CLI routes, ratio 0.3. Comparison engines
built with an src-only tsconfig; `dist` hashes `7a3bad0f515f` (baseline) and `83e544289dc4`
(candidate), so neither arm was compared against itself.

**Zero rows differ, on any of the ten compared fields** — `outputSha`, `byteIdentical`,
`tokenBefore`, `tokenAfter`, `reduction`, `fallbackUsed`, `driftScore`, `debtScore`, `planMode`,
`stageCount`. That is the constraint above, verified end to end.

**And it is not a vacuous result: 101 of those rows actually reduced**, so markers were genuinely
priced and emitted. The corpus contains the shape the change touches, which is the check §56 exists
to demand.

### What this does not establish

- **The corpus cannot see the defect itself.** It runs CLI routes, and the CLI supplies no
  `TokenHasher`, so `markerFor`'s registration branch was already a no-op there. The A/B proves
  *output-neutrality* — the constraint — and nothing about the leak. The leak is measured by
  `token-hashing-store-pollution.test.ts`, which supplies a hasher directly.
- **Nothing about MCP memory in practice.** The counts above are from a 12-region fixture. How much
  a real long-lived MCP session accumulated was not measured, only that the growth was proportional
  to candidates rather than elisions.
- **Nothing about `bench`.** It supplies a hasher too, and was equally affected, but its runs are
  short-lived so the accumulation had nowhere to build up.

---

## 69. The OX LOW Table, Closed Against Its Own List

**Audit OX-L1 through OX-L19**, minus the four the float pool took in §63 (L2, L3, L5, L11) and
L4, recorded at its site when the ingestion work landed.

`max_audit.md`'s LOW table went unscheduled and was found open weeks later (§55). The lesson
recorded then was *close a document against its own list of findings, not against the list of work
that was done*, so every row is dispositioned here — including the ones not fixed, which is the half
that goes missing.

### Fixed

| id | what |
|---|---|
| **L6** | `MAX_SEEN_BLOCK_HASHES = 1000` was a bare local inside `capSeenBlockHashes` while `sessionTtlMs`, `maxSessions` and `maxContentEntriesPerSession` were all settable. The one bound that grows with conversation length was the one nobody could tune. Now `GatewayConfig.maxSeenBlockHashesPerSession`, default 1000. |
| **L7** | The MCP overflow check ran *before* `processBuffer` and then cleared the whole buffer, so a chunk carrying complete requests followed by one oversized partial discarded the complete ones too. They were well-formed, already received, and answerable. Draining first leaves exactly the un-terminated remainder for the limit to judge — which is what the limit is about. |
| **L9** | The `limits` merge in the bench loader could never fire: `ResolvedConfig` has no such field, which is *why* it needed two `as unknown as Record<string, unknown>` casts. Deleting it also removed the `as unknown as ResolvedConfig` laundering that was disabling type checking for every other key in that literal. |
| **L10** | Dataset routing tested `includes('humaneval')` **before** checking whether the argument was a real path, so `./fixtures/humaneval-comparison-2026.jsonl` was silently answered with the bundled dataset. Order is now exact name, then path, then substring as a last resort — so the guess can only help an argument nothing else resolves. |
| **L12** | `package.json` and `src/version.ts` are hand-synced. Not restructured — `src/version.ts` stays the single source every adapter derives from, per the release procedure — but a test now pins them equal, which closes the drift class rather than the duplication. |
| **L19** | `.gitignore` was the full GitHub Python template: 245 lines, ~111 entries, covering Django, Flask, Scrapy, PyBuilder, Celery, SageMath, Spyder, Rope, pyenv, pipenv, poetry and pdm, none of which this repository uses, with the dozen entries that work buried at the bottom. Now 44 lines and 25 entries, keeping a real Python block for `tokendamper-benchmark/`. Verified by diffing `git status --porcelain` across the change: nothing became newly visible. |

L6, L7, L10 and L12 are pinned by `test/unit/audit-ox-low-findings.test.ts`. L6 and L7 were
mutation-checked — reverting either source file fails its test and only its test.

### Recorded at their sites, not fixed

- **L1 — `expectedSavings: 0.45`.** Nothing in `src/` reads it, and the number is not a
  measurement: the same corpus reduces ~20% on TypeScript and ~16% on Python (§64's baseline).
  Left in place on the precedent H4 set and OX-H5 followed — `OptimizationPlan` is frozen, and a
  field awaiting an implementation is not the same defect as a dial that reports success. Nobody
  can *set* it, so it misleads no caller. Wiring it means deriving a real estimate from the selected
  stages, which is a planner change.
- **L8 — the MCP shutdown flush race.** `process.exit(0)` can truncate a stdout frame just written.
  The fix is to stop forcing the exit and let the loop drain, but `stop()` only removes the `data`
  listener — it does not pause or unref stdin — so whether the process then exits depends on stream
  state that file does not control, and getting it wrong hangs `tokendamper mcp` on Ctrl+C.
  Delivering SIGINT to exercise that is not something this suite can do. Shipping an unverified
  change to a shutdown path to fix a rare truncated final frame is the wrong trade, and it is the
  same call made for L4.
- **L13 — `/health` reports `sessionCount` without authorization.** On a loopback bind that is not
  a leak; the peer is already trusted enough to proxy through the process. It becomes one on an
  exposed bind, which is precisely what **M8 and M9** are about. Deferred to them, because "should
  this endpoint require a token on a loopback peer" is the same question those answer, and
  answering it twice in two places is how two answers drift apart.
- **L17 — architecture import rules unpoliced** and **L18 — no coverage tooling.** Both require a
  new devDependency (`eslint-plugin-boundaries` or dependency-cruiser; `@vitest/coverage-v8`).
  The audit calls both optional. Adding dependencies to someone's package on the strength of a LOW
  finding is not a call to make unasked; both are one command away when wanted.
- **L14, L15, L16** were "no action" in the audit itself and remain so: the elision post-condition
  comment is correct and instructs its own maintenance, the DriftTracker regex noise is an accepted
  tradeoff, and deep-freeze cost is fine at current scales.

### What this does not establish

- **Nothing about M8, M9 or M15**, which are decisions rather than work and are still open.
- **L19's prune is verified only against the current tree.** `git status` showed nothing newly
  visible, which proves no *existing* file lost its ignore. A file type that does not happen to
  exist right now and was covered by a removed template line would not have been caught.

## 70. The Last Four OX Findings: Three Decisions and One Paragraph

Closes `oxaudit.md`. Three of these were held open because they are choices about the product
rather than defects with an obvious fix, and one needed no decision at all.

### OX-M15 — `bench` stops executing dataset code

`BenchmarkRunner.run` read `config.evaluateQuality !== false`, which defaults **on**, and
`BenchmarkEvaluator.evaluateFixture` runs each fixture's code and its dataset checks through
`python -c`. So a harness `ARCHITECTURE.md` describes as offline and deterministic spawned an
interpreter because someone typed `bench`, and the only escape was
`TOKENDAMPER_BENCH_DISABLE_PYTHON`, documented nowhere.

**Decided: default off, opt-in by name.** The default is `=== true`, and `--evaluate-quality`
asks for it — command-scoped per §30, a parse error naming `bench` anywhere else.

Verified on the built artifact rather than in-process, because that is what a user runs: plain
`bench humaneval --report-json` writes a report containing **0** occurrences of
`python-subprocess`; the same command with `--evaluate-quality` writes **5**.

The accepted cost is that plain `bench` reports a different quantity under the same field names.
`syntaxPassRate` and `passAt1Rate` fall back to validation outcomes, which is a weaker signal —
measured, 0.6 against the execution-derived 1.0 on the bundled fixtures. Two regression suites
assert on the execution figure and now request it by name (bench.test.ts Test 5 and Test 6); that
half is what keeps this from being a silent loss of coverage, and each site says so.

### OX-M8 — an exposed bind must be authenticated

The token gate reads `if (this.config.gatewayToken && !isLoopbackPeer(req))`: enforced only *if
one was configured*. `host: '0.0.0.0'` with no token was therefore an unauthenticated relay
forwarding arbitrary bodies to upstream providers, and nothing warned. README:154 already stated
the intended rule — "enforced only on a non-loopback bind" — so the documentation described the
intent and the code implemented "enforced only if provided".

**Decided: refuse to start**, with `allowUnauthenticatedNonLoopback` as an explicit opt-in.

Refusing rather than warning, because the configuration this protects is a server nobody is
watching: a warning on stderr reaches the person who starts it in a terminal and no one who
starts it from a unit file. Auto-generating a token was the other candidate and is worse in a
specific way — startup succeeds, and every existing client of that bind begins failing with 401,
which is a subtler break than a refusal that names itself.

The check lives in `start()`, not the constructor, so constructing a server stays free of side
effects; the exposure begins at `listen`, which is where it is refused. `isLoopbackHost` is the
configuration-time counterpart of `isLoopbackPeer`, and treats `0.0.0.0` and `::` as **not**
loopback — they include the loopback interface, which is what makes them easy to mistake for it,
and every other interface besides.

Loopback trust (C3) and the constant-time compare are untouched, and both are asserted, so a
later change cannot quietly buy this guarantee by revoking C3. `tokendamper exec` is unaffected
on two counts: it binds the default loopback host *and* generates a token.

### OX-M9 — Origin and Host validation, not token-on-loopback

**Decided: validate `Origin` and `Host`.** Requiring `x-tokendamper-token` even on loopback
splits browsers from local clients more cleanly — browsers cannot set custom headers on a simple
request — but it taxes every existing local client to close a browser-only hole. Declined for that
reason.

**The audit's stated fix direction was partly aimed at the wrong control, and this is the third
time an OX reachability claim has needed measuring.** It proposed answering OPTIONS with a
restrictive CORS policy. Measured before writing anything: this server *already* answers OPTIONS
with `405` and no `Access-Control-*` headers, which is that policy. Adding a handler would have
been ceremony. Preflight was never the gap — the threat is a **simple** `text/plain` POST, which
skips preflight entirely, so the check has to be on requests that never preflight.

**And the decision as recorded overstated one half.** It said non-browser clients "send neither
header". True of `Origin`; false of `Host`, which every HTTP/1.1 client must send. The local
client contract is preserved by *what is accepted*, not by the header being absent:

- `Origin` present and not this gateway's own origin → 403, on every bind. Non-browser clients do
  not send it, so nothing local changes. Same-host different-port is still foreign, which is the
  shape a malicious local page actually has.
- `Host` naming somewhere else → 403, **on a loopback bind only**. That is where DNS rebinding is
  the threat: an attacker's name resolving to 127.0.0.1. Accepted are `localhost`, any `127.x`,
  `::1`, and the configured bind. On an exposed bind hostnames are legitimately varied and the
  token M8 now requires is the real control, so the rule would cost more than it buys.

The policy runs **before** `/health`. A check the health endpoint sat in front of would be a
check with a documented way around it.

**OX-L13 is folded in, as intended.** `/health` now returns `{"status":"ok"}` and nothing else.
`activeSessions` told an unauthenticated caller how much conversation traffic flows through the
machine; on a loopback bind that is a small leak to a peer already trusted to proxy, and the
reason to drop it anyway is that `/health` is the one endpoint deployments expose deliberately.
`server.ts` had carried a comment deferring this to M8/M9 precisely so the two answers could not
drift, and this is that answer.

### OX-M13 — documented, not fixed

`--minimum-confidence` and `--max-debt` are parsed, range-validated, and threaded into
`optimize()`. Neither can change what the CLI emits.

- Validation confidence is binary: `validate()` returns `passed ? 1 : 0`. Both engine gates read
  `validation.confidence < minimumConfidence` — `1 < x` on a passing run, false for everything
  the schema admits since §OX-M10 validates it into [0, 1]; `0 < x` on a failing one, where
  `!validation.passed` has already decided the same line. The other arm reads a
  `ConfidenceLedger` and is a literal `1.0` when none is supplied. The CLI supplies none.
- `--max-debt` can flip `shouldRehydrate` and enter the rehydration branch, but
  `attemptAutomatedRehydration` returns on its first line without a hasher or a ledger, and the
  CLI supplies neither.

**That second reason is stronger than the one §64 gave.** §64 said debt gates nothing on the CLI
"because `shouldRehydrate` needs 75 and the elision term alone caps at 35". That explains the
*default* threshold — but `--max-debt` is precisely the flag that lowers it, so the default is not
what makes the flag inert. §64 was right about the outcome by an argument that does not carry.

Documented rather than made live, because the machinery is real and reachable through the
exported `optimize()`; only the CLI supplies neither input. Both dials are live for an embedder
passing a `tokenHasher` and/or `confidenceLedger`, and `--minimum-confidence` is live on the
Gateway, which builds a ledger per request.

`test/unit/cli/inert-dials.test.ts` pins it in the shape of `validator-guarantee.test.ts`: a
characterization test that passes against the tree that prompted it, and fails if either dial
becomes live, so the README section has to be rewritten in the same commit rather than outliving
the behaviour it describes.

**Its control needed a second attempt, and the failure is worth keeping.** The first version used
`--max-drift 0` against `--max-drift 1` to prove the harness could observe *any* flag. They emit
identical bytes — drift on the fixture is already 0.0000, and the gate asks whether drift exceeds
the threshold rather than reaches it. That is CLAUDE.md's note that 86% of elided Python function
bodies contribute no symbols, arriving as a control that does not control. A budget flag replaced
it: with none, the planner returns `pass_through` and reduction is guaranteed 0%.

### What this does not establish

The corpus was not run for any of the four. It cannot see them — bench, the flag-parse loop, and
every Gateway path are all off the optimize route — so a byte-identical result would have been
vacuous rather than reassuring. This is the §56 caution in its other direction: byte-identical is
not evidence when the corpus does not contain the shape.

M8 and M9 are both verified against real sockets rather than `mockUpstream`, because both live in
header handling that a short-circuited upstream never exercises.

## 71. `symbolBearingItems` Counts Symbols Now, Which It Never Did

`DriftCoverage.symbolBearingItems` was `new Set(after.items.filter((i) => !unchecked.has(i.id)))`
— the count of items an **AST validator covered**. That is `trace.astCoverage.checked` arriving a
second way, under a name asserting a fact about symbols that nothing had checked.

§60 found it and left it deliberately, on the grounds that a trace field consumers parse should not
be changed as a ride-along in the commit that exposed it. This is that decision taken on its own.

### Why it survived: it was wrong in both directions, and the errors cancelled

On a four-item mixed bundle the field was wrong **both ways at once** — counting a symbol-free
barrel, and excluding a symbol-bearing Go file and a symbol-bearing markdown document. The two
errors partly cancelled, to a plausible-looking `2` where the truthful count was `3`. It was
not obviously broken; it was quietly ratified.

Two tests helped ratify it, by pinning the misnomer rather than the behaviour. Both used the same
14-line `export * from` barrel, and `test/unit/drift-unwitnessed-elision.test.ts` asserted
`symbolBearingItems: 1` three lines below `unwitnessedItems.length: 1` — the trace claiming
simultaneously that the item bore symbols and that it left no witness. Both are corrected here.

`tools/corpus-harness/measure.js` recorded this field *and* `astChecked`, so every corpus run
carried the same column twice under two names, and any comparison of the two agreed by
construction.

### The two counts never had to agree, and both directions are real

`extractSymbols` is regexes over `item.content` with **no language gate**. Validator coverage is
`selectValidator`, which has four branches. Nothing ties them together; they agreed only for as
long as every language with symbols also had a validator and every language without one had
neither.

- **Symbols without a validator.** Go between §59 and §60 was the first instance: all 80 frozen Go
  files reported `symbolsBefore >= 3` beside `symbolBearingItems: 0`. §60 then gave Go a
  validator, which removed Go from the population **without fixing the field** — the symptom moved,
  the defect did not.
- **A validator without symbols.** Six of this repository's own `src/**/*.ts` files are barrels
  that a validator covers and that yield no symbols at all — `src/index.ts`,
`src/config/index.ts`, `src/core/model/index.ts`, `src/core/ledger/index.ts`,
`src/bench/index.ts` and `src/bench/fixtures/index.ts`. Those are precisely the files §28 and
  §33 exist to protect, and the field asserted symbols were the witness standing behind them.

### Measured: 254 of 580 rows, one field, no output

Corpus frozen at `1e0f71f`, 290 files, 580 rows, ratio 0.3, both routes. Sixteen fields compared
per row, keyed on `corpusPath` + route with the key asserted unique:

| | |
|---|---|
| rows differing | **254 of 580** |
| fields differing | **`symbolBearingItems` only** |
| direction | **254 up, 0 down** — it only ever under-counted |
| self-contradicting rows (`symbolsBefore > 0` beside `symbolBearingItems: 0`) | **254 → 0** |
| `outputSha` | identical on **all 580** |

`byteIdentical`, `reduction`, `fallbackUsed`, `driftScore`, `debtScore`, `planMode`,
`stageCount`, `astChecked`, `driftMeasured` and `unwitnessedItems` are unchanged on every row.

The differing buckets name the cause: `tcl` (58), `c` (56), `shell` (30), `perl` (8), `rust` (4),
`css` (6) — every language with no validator — plus **63 rows of `typescript/stdin`**. That last
one is this repository's own source: pathless TypeScript gets no validator (§29 declined a TS
content probe because its positives overlap prose negatives), so the largest single bucket of the
contradiction was the project's own primary language on its own second route.

### Rename and delete were both considered

**Make it count what its name says**, rather than rename it to `astCoveredItems`. Both options
break the trace surface identically, so the rename buys nothing on the axis where it looks
cheaper — and it would preserve a field provably duplicating the one beside it.

Deleting it outright was rejected for the reason the next section gives: `symbolsBefore` is a
total with no denominator, and cannot distinguish "every item carries symbols" from "one item
carries all of them".

**This is a breaking change to the trace surface** for anything parsing `driftCoverage` off
stderr or out of the MCP trace. The number moves for every uncovered-but-symbol-bearing item —
254 of 580 corpus rows, all upward.

### The count is a denominator, and it had to be free

`symbolsBefore` is a bundle-level `Set`, so it deduplicates across items and cannot say whether 31
symbols came from one item or thirty. Read as a pair, `symbolsBefore: 31, symbolBearingItems: 3`
says the symbols came from three items and every other retained item has `R_AST`'s empty-set
default rather than a measurement standing behind it.

The obvious implementation — `items.filter(i => extractSymbols({...bundle, items: [i]}).size > 0)`
— **costs a measured 19 ms of 196 ms** on an 18-item bundle, because it runs every regex a second
time over every item for a reporting field. `extractItemSymbols` splits the per-item body out so
`symbolsBefore` and the count come from one pass; overhead falls to ~6 ms.

The split is behaviour-preserving **by construction, not by testing**: the loop body was already a
pure function of one item, declaring all its state inside the loop and touching the shared set
through 11 `add` calls and **zero** reads. A union of per-item sets is exactly the set it used to
accumulate. The corpus confirms it — `symbolsBefore` feeds `R_AST`, which gates fallback, so any
drift in that number would have moved `outputSha`, and none did.

### What this does not establish

The corpus arm proves output-neutrality and that the field moved on real files. It says nothing
about whether the **new** number is the useful one — that is a claim about what a reader should do
with it, and the doc comments on `DriftCoverage` are where it is argued.

`unwitnessedItems` is **not** a subset of `symbolBearingItems`, and its doc comment said "of
those" until now. §33 widened the unwitnessed rule from validator-covered items to every item,
which is the opposite of a subset and describes the exact population §33 was written to stop
losing. Symbols are one accepted witness; content markers are the other.

---

## 72. L17 and L18 Land, and One of Them Never Needed the Dependency

**Date:** 2026-09-07 · **Status:** Accepted · **Closes:** OX-L17, OX-L18 — the last two open items
in `oxaudit.md` · **Reverses:** the deferral in §69

§69 held both back for one reason, stated once for the pair: *"Both require a new devDependency
(`eslint-plugin-boundaries` or dependency-cruiser; `@vitest/coverage-v8`). The audit calls both
optional. Adding dependencies to someone's package on the strength of a LOW finding is not a call
to make unasked."* The call has now been made. Taking the two items separately is what turned up
something worth recording.

### L17 needed no dependency, and the deferral reason did not survive contact

The audit suggested `eslint-plugin-boundaries` or dependency-cruiser. Both would express these
rules more elegantly than what shipped; both cost a package. **The rules this repository actually
has are two import bans**, and `@typescript-eslint/no-restricted-imports` — already present,
already loaded — expresses both. So §69's reason applies to L18 and, on inspection, never applied
to L17 at all. A deferral written for a pair inherited a justification only one of them had.

`allowTypeImports` is the load-bearing option. An `import type` is erased at compile time and
wires nothing, which is what these invariants are about: the engine naming a stage's *options
type* does not couple the engine to that stage.

**Two rules, both verified to fire rather than merely to pass.** A lint rule that is silently
misconfigured looks exactly like a clean codebase, which is invariant 10 pointed at the linter, so
each was checked by planting the violation it is supposed to catch:

| Planted | Expected | Observed |
|---|---|---|
| value import from `stages/` into `core/planner` | error | **error** |
| `import type` from `stages/` into `core/planner` | pass | **pass** |
| import of `gateway/session-store` into `core/planner` | error | **error** |

### The rule found that invariant 4 is not what the code does

CLAUDE.md states it flatly: *"Only `stage-registry` imports concrete stage implementations."*
Three other files import from `src/stages/`. Two are `core/engine`'s `import type`, which the rule
allows and which couple nothing. The third is real: **`core/validation/index.ts:13` value-imports
`extractConstraintDirectives` from `stages/cleanup/constraint-preservation`**, so the constraint
*check* and the stage that preserves constraints share one extractor. That is a runtime dependency
from core onto a concrete stage, and the invariant says there is exactly one of those.

**Exempted at the file, with the reason at the site, rather than refactored or hidden.** Moving the
extractor somewhere neutral is a change to the optimize route, and this repository requires a
corpus measurement for those; a commit adding a linter is not the commit that should carry one. The
exemption is one path with a comment naming it as a known violation, so the rule locks in the
status quo and every *new* violation fails. The honest state is that the code and the invariant
disagree and the code is what shipped.

### L18 is reporting, not a gate, and that is the decision

`@vitest/coverage-v8` is a real dependency and there is no way around it. What is optional is what
to do with the number.

`npm run coverage` produces it; `npm test` does not; **no threshold fails a build.** A number
attached to a gate becomes a target, and the failure mode is a suite that covers lines instead of
behaviour — which is the opposite of what this repository's tests are for. Several exist to pin a
*characterization*: `validator-guarantee.test.ts` asserts that English prose passes the TypeScript
validator, and a coverage gate would reward deleting it. The instrument is here to be read.

Baseline at this commit, over `src/**` only: **statements 92.54% (8895/9612), branches 87.20%
(3100/3555), functions 97.01% (358/369)**. `coverage/` is already in `.gitignore` and, checked
rather than assumed, contributes **0 entries** to `npm pack` — still 223 files.

### What this does not establish

Neither rule says the architecture is *right*, only that it stopped drifting. The layering rule was
clean before it existed and exists to keep it so, which means it has never actually caught
anything — its value is entirely prospective, and a rule that has never fired in anger is a rule
whose usefulness is still a hypothesis.

---

## 73. Two Fixes That Were Right About One Route Each

Security review Session 7 (`docs/security-review-2026-08-30.md` §12) was the first falsification
pass over the *remediation* run by an agent that did not write it. It confirmed eleven of the
fourteen fixes, several against attacks materially harder than the ones the self-authored §11
tried, and found four defects. This closes the two that were demonstrably broken rather than
merely incomplete: **S-01** and **S-02**.

They are recorded together because they are the same mistake. Each fix was written against the
route where the finding was reproduced, and each left a sibling route — reachable by the same
attacker, emitting or mutating the same thing — untouched. Neither is a subtle bug in the fix's
logic; the logic is correct everywhere it runs.

### S-01 — the credential hoist guarded two routes and `getOrCreateSession` guarded none

Session 5 hoisted the gateway's credential check above `getOrCreateSession` so an unauthenticated
request would leave no trace in the session store, and §10.1 recorded the result: "20
unauthenticated requests leave `sessionCount` at **0**, so the eviction primitive is gone for the
caller V-02 reaches."

The check it hoisted is conditioned on `isApiRoute`. `getOrCreateSession` was not:

```ts
if (isApiRoute && !shouldUseMockUpstream(options) && … && !hasAuthHeaders(cleanHeaders)) {
  return { statusCode: 401, … };
}
const sessionId = getSessionIdFromHeaders(headers, rawBody, options.defaultSessionId);
const session = options.sessionStore.getOrCreateSession(sessionId);   // every route, always
```

So `POST /v1/anything` and `GET /nope` answered 404 and minted a session on the way there, with no
credential of any kind. Measured: **20 unauthenticated POSTs to an unknown endpoint → 20 sessions;
120 `GET /nope` naming chosen ids over a single keep-alive connection → 100**, the store's whole
`maxSessions` cap.

**The reason this matters is the attacker it is reachable by, and that took a browser to
establish.** §10.2's chain is a web page reaching the loopback gateway; V-02 closed the
`Origin: null` value that chain used. But a **no-cors GET carries no `Origin` header at all** — the
Fetch specification appends one only for CORS-tainted requests or for methods other than GET and
HEAD — so the origin gate never sees it, and the `Host` check passes because the browser genuinely
is talking to `127.0.0.1`. A POST cannot do this; a POST always carries `Origin`. A GET to an
unknown path can, and the unknown path is precisely what the hoist did not cover.

Driven from a page on a different port, against a live gateway:

```
{ "sessions": 100, "requests": 400, "distinctSockets": 400,
  "requestsCarryingOrigin": 0, "originValues": [] }
```

Four hundred requests, four hundred connections — the browser opens a fresh one per no-cors
request, so the per-connection default session id F-01 introduced gives the page one session per
request rather than one per page. With a victim session seeded first, its content was gone:

```
victimSessionBefore: { exists: true,  content: "the victim's previous-turn source code" }
victimSessionAfter : { exists: false, content: null }
```

**The fix creates the session inside the two API branches**, so no other route can mint one, and
the 404 reports none — `ProxyRequestResult.session` has been optional since the hoist, and nothing
reads it. Written as a `openSession()` call the branches make rather than a nullable the 404 has to
narrow away: the branches are mutually exclusive, so it still runs at most once per request, and
there is no `undefined` for a later reader to wonder about. Same page, same 400 requests, after:
**`sessionCount` 1**, and it is the victim's, still holding its content.

**What this does not change.** A local process still passes `hasAuthHeaders` with `Bearer
anything` and can still name any session id it likes. That is the `exec` trust boundary (audit C3)
and §3.1's measurement of it stands — a loopback peer is trusted enough to proxy provider traffic
through this process. The control is for the browser, which cannot set either header on a request
that reaches this handler, and it is now a control on every route rather than on two.

### S-02 — the escaping lived in `core/render`, and the CLI has a second renderer

F-06's label vector: a POSIX filename may contain a newline, so `item.path` interpolated between
`==> ` and ` <==` can break the header across lines and plant a second, well-formed header naming
a file that does not exist. The fix escaped `\r` and `\n` in `itemLabel`.

`itemLabel` is in `core/render`. `renderFallbackBytes` is in `cli/main.ts`, and it emits the same
header:

```ts
parts.push(Buffer.from(`${ITEM_DELIMITER_PREFIX}${file.path}${ITEM_DELIMITER_SUFFIX}\n`, 'utf8'));
```

Its own comment said "under the header the renderer emits", which stopped being true the moment
the renderer started escaping. It exists because fail-open must emit each file's **original
bytes** rather than `emittedOutput` (DECISIONS §35), and it is reached on every fallback.

Measured on ext4, one directory, two runs of the shipped binary:

```
success path : 3 headers, forged payload line absent
fallback path: 4 headers, the extra one `==> security_policy.py <==`
               followed by ALLOW_INSECURE_TLS = True
```

**The attacker controls the trigger as well as the payload.** One file of their own containing
invalid UTF-8 forces the fallback through `inputNotRepresentable`; no drift threshold or budget
guess is needed.

**The fix moves the escaping into an exported `escapeDelimiterLabel` in `core/render`, next to the
delimiters it protects, and both renderers call it.** That is the substance: a third renderer
would now have to go out of its way to diverge, whereas duplicating a two-call `replace` chain was
how this happened. Only the header is escaped — `file.bytes` is written through untouched, because
emitting the caller's original bytes is the entire reason that path exists.

**The README needed no edit, which is the point.** It already says "Line breaks in a filename are
escaped, so a crafted name cannot introduce a header line either." Session 7 recorded that sentence
as false on the fallback route. It is true again, on both.

### The two the fix does not close, and why

Session 7 filed four. **S-03** (V8's `JSON.parse` message still quoting roughly fifteen bytes of
the payload into `trace.fallbackReason`, on the same field F-05 cleaned) and **S-04** (the §6.3
upstream guard validating a base URL that `fetch` is then free to redirect away from, carrying
`x-api-key` — undici strips `authorization` cross-origin and not this) are open. Both are real and
both are Low; neither is a fix that fails to do what it claims, which is what separated S-01 and
S-02 from them here.

### What this does not establish

The corpus was not run, deliberately. S-01 is off the optimize route entirely, and S-02 changes
stdout only for a file whose *name* contains a newline — **0 of the corpus's files do**, so
byte-identical would have measured nothing. That is OX-L7's shape and §56's caution: a real fix the
instrument cannot see is not an inert one.

And the general lesson is smaller than it looks. Neither fix was wrong about its finding; both were
scoped to where the reproduction ran. The test for S-01 was titled "an unauthenticated request
creates no session" and asserted it of one route — which is invariant 10 arriving at the
remediation's own test names, and the reason §9.1 item 3 was worth closing with somebody else's
agent rather than another self-authored pass.

---

## 74. The Last Two From Session 7: A Message That Quoted the Payload, and a Guard That Stopped at the First Hop

§73 closed the two Session 7 findings that were fixes failing to do what they claimed. **S-03** and
**S-04** are different in kind and are closed here: neither earlier fix was wrong, and each is
incomplete in a way its author had no particular reason to anticipate. `oxaudit.md` and
`max_audit.md` are unaffected; this finishes `docs/security-review-2026-08-30.md`.

### S-03 — V8's `JSON.parse` message is a payload echo, on the field F-05 had just cleaned

F-05 replaced a verbatim constraint directive in `trace.fallbackReason` with offset, length and a
digest, on the argument that the message "reaches two places that outlive the process" — stderr on
every CLI run, and the trace an MCP client can ask for. Six lines above that fix,
`json-validator.ts` did this:

```ts
message: `JSON Syntax Error: ${message}`,   // `message` is V8's, verbatim
```

One of V8's forms quotes the input. Measured through the shipped binary on
`{"db_password":"hunter2-Ab9x","r":qq}`:

```
"AST Error in item […] at line 2, col 1: JSON Syntax Error:
 Unexpected token 'q', ...\"Ab9x\",\"r\":qq}\n\" is not valid JSON"
```

The window is roughly fifteen characters either side of the error, and **for a document shorter
than the window it is the whole document**: `JSON.parse('ZZSECRETZZ')` answers
`Unexpected token 'Z', "ZZSECRETZZ" is not valid JSON`. The offending character in the quotes is
itself a byte of the payload.

**The shapes were enumerated rather than assumed.** Twenty-four malformed documents through Node 22
and Node 26 produce twenty-two distinct message shapes, identical between the two versions, and
**only the `Unexpected token` family carries input**. Everything else is `<kind> in JSON at
position N (line L column C)`.

**The fix builds the message from a fixed vocabulary and never from V8's string.** A prefix match
against a seventeen-entry table returns this file's own constant; an unrecognised form degrades to
`invalid JSON`. That is the whole safety argument, and it is why the table matches on a *prefix* —
the payload always appears after one. The obvious alternative, regex-stripping the quoted clause
out of V8's text, fails open the day a message changes shape, and a control that fails open on an
upgrade is the kind this repository keeps having to retract.

The position stays, from the validator's own `line`/`column` rather than from the message text:
`JSON Syntax Error: unexpected token at line 2, column 1`. **The offending character goes**, and by
F-05's own reasoning — position identifies it exactly for anyone holding the input, which is who
the message is for, and to nobody else.

The sibling messages were checked rather than assumed clean: the TypeScript, Python and Go
validators interpolate line numbers, column numbers and bracket or quote characters from a fixed
structural alphabet, and nothing else. The one `throw` that interpolates carries a path. So the
class is closed, not just the instance.

**Scope, stated plainly.** This was Low and stays Low. It required a JSON item, a syntax error, and
a secret adjacent to it, and the exposure was bounded at about thirty bytes — narrower than the
unbounded clause F-05 removed. It is fixed because it is the same defect on the same field, not
because anything about it is severe.

### S-04 — the SSRF guard checks a string, and `fetch` was free to leave it

§6.3 refuses an upstream base URL that is not `https:` or that names a private, loopback or
link-local address, at `start()`. It was verified against 43 URLs in Session 7 — every classic
notation for the metadata service refused, including the ones that defeat most allowlists.

It checks a *configured string*. `forwardUpstreamRequest` set no `redirect` option, so `fetch`
defaulted to `follow`, and a `302` is not that string. Demonstrated end to end: a stub provider
answering `302 Location: http://127.0.0.1:<meta>/latest/meta-data/iam/security-credentials/`
delivered

```
x-api-key    : sk-ant-api03-VICTIMS-REAL-ANTHROPIC-KEY
authorization: undefined
```

to the listener, whose body this gateway then relayed to the caller as a **200**.

**The `authorization: undefined` is the instructive half.** That protection is undici implementing
the Fetch specification's cross-origin redirect strip — it comes from the HTTP client, not from
anything here. `x-api-key` is a vendor header on no such list, and `buildForwardHeaders` adds it
for Anthropic. So the OpenAI-shaped credential was safe by inheritance and the Anthropic-shaped one
was not, which is exactly the kind of asymmetry that survives a code review of either provider path
read on its own.

**The fix is `redirect: 'manual'` and a 502.** Following correctly would mean re-running
`describeUpstreamUrlRefusal` on `Location`, deciding what to strip, and bounding the hop count —
three chances to be wrong, for a case no provider needs. An operator whose endpoint genuinely
redirects configures the destination as the upstream URL, which is one line and leaves the guard
covering it. The 502 says so.

**No new flag.** `allowInsecureUpstream` exists because this repository's own tests need a local
stub and a rule with no escape hatch gets weakened; nothing needs an `allowUpstreamRedirects`, and
adding a knob for a hypothetical is what §55's LOW table is a monument to.

**The `Location` header is deliberately not echoed** into the 502 body. It is upstream-controlled
text and the upstream is the attacker in threat model 5; the status code is enough to act on, and
an operator can resolve the destination themselves.

### What this does not establish

**The corpus was not run, and for once that needs no defence beyond stating the routes.** S-04 is
Gateway-only and the Gateway is off the corpus route entirely. S-03 changes a string inside
`trace.fallbackReason` for JSON items that fail to parse — it moves no optimized byte, and
`outputSha` cannot move because no stage reads a validation message.

**A redirect from a legitimate provider now fails instead of working.** Neither `api.openai.com`
nor `api.anthropic.com` redirects an API POST, so this changes nothing anyone is doing today; a
corporate gateway that answers `301` on a trailing slash would now need its final URL configured.
That is a real behavioural change and it is the intended one — the alternative is a credential
travelling somewhere no check has seen.

**S-03's fix loses information on an unrecognised V8 form.** `invalid JSON at line L, column C` is
less useful than a named kind. The table covers every shape Node 22 and 26 produce, so the
degradation is prospective; if a future Node adds a form, the message gets vaguer rather than
leakier, which is the direction to fail in.

---

## 75. v2.0 Is Deep Mode, and Deep Mode Is About Coverage Rather Than Precision

**Date:** 2026-09-09 · **Status:** accepted, nothing implemented · **Scope:** what v2.0.0 is, and
the order the work goes in

Design doc: `docs/superpowers/specs/2026-09-09-tokendamper-v2-roadmap-design.md`. This entry is
the decision; that document is the schedule, the risks and the measurements.

Recorded before implementation, on §56's precedent — the ordering argument below is the whole
value of the entry, and it is worth nothing written afterwards.

### The decision

**v2.0.0 is `tokendamper-deep`: an opt-in tree-sitter backend that makes the supported-language
list stop being hand-written.** It was "Enterprise Gateway, Remote MCP & Proxy Guardrails" in
`ROADMAP.md` since the document was written.

Elision reduces **4 of 17** probed languages and every other bucket measures **0.00%**. Each of
the four cost a hand-written lexer, a symbol extractor and a region scanner, in that order for the
reason §56 measured, and roughly 1,400 lines apiece. One grammar answers all three questions:
named declaration nodes are the symbols, `ERROR`/`MISSING` nodes are the validity check, body node
byte ranges are the regions.

### Why not the Gateway, when the section had held that slot for a year

**Because that section already contained the argument against itself and nobody acted on it.** It
carries a note saying a Prometheus endpoint on a pass-through that saves nothing cross-turn
instruments nothing — true when written, and invariant 8 has not moved since. M7 (§54) fixed the
half that was fixable: `rawTokens`/`optimizedTokens` now come from the bytes forwarded rather than
the bundle render, so a metric would mean what it says. The premise half is not a defect to fix,
it is what the mode *is*.

The three ecosystem items are **held and listed**, not deleted, and MCP-over-Streamable-HTTP is
named as having no premise problem at all — it is simply not on this spine, and is the strongest
candidate for the release after 2.0. An item in no table reads as done (§55).

### Two payoffs rejected, and the measurements that rejected them

Both are the obvious things "add a real parser" is supposed to buy. Neither survives contact with
figures already in this repository, and both are recorded so the next session does not re-derive
them from first principles and reach the opposite answer.

- **"Deep reduces more on the four languages we already have."** The lexer is not the binding
  constraint on reduction. Go's fallbacks are **18 of 20** `CONSTRAINT_DIRECTIVE_LOST` (§61);
  TypeScript's are **15 of 62**, the same gate at the same rate (§56 expected Go's lower comment
  density to make it fire *less*; density was the wrong variable). Neither is a parse failure.
  Built on this argument, Deep would be BM25 and MMR a third time — ~1,000 lines of correct code
  with no observable effect, the H5 condition.
- **"Deep makes validation a real syntax guarantee."** §46 decided against wiring
  `ts.createSourceFile` on cost — `typescript` is a *dev* dependency, and promoting it to runtime
  buys install size and parse latency against a lexer that runs in single-digit milliseconds.
  **That decision is not reversed here.** Deep's languages do get a real parse as a side effect,
  but the Fast path's advertised guarantee stays **bracket/quote integrity**, and
  `test/unit/validator-guarantee.test.ts` — which asserts that English prose *passes* the
  TypeScript validator — stays exactly as written. If Deep's guarantee is ever advertised, that
  test, the README table and CLAUDE.md's opening paragraph change in one commit, which is the
  thing the test exists to force.

### Core stays at zero runtime dependencies

`web-tree-sitter` and the grammar WASM ship in a **companion package**, `packages/deep/`, with its
own tsconfig and its own publish. Core ships the `ParserAdapter` seam and no implementation — the
same shape as `TokenizerAdapter` / `createTiktokenAdapter`, which is this codebase's existing
answer to "capability without a dependency".

The alternative considered and refused was `optionalDependencies` in core. It is a better install
story and it costs the zero-dependency claim plus download weight for every consumer of a mode
most will not use — against a package that went 508 → 223 entries and 3.08 → 1.65 MB in v1.7.2
specifically to be small.

**`--mode deep` without the package fails with a message naming the install command.** It does not
silently fall back to Fast. A mode that quietly does something else is invariant 10: a green
result from a path that never ran.

### The ordering, which is the part that is easy to get wrong

**R1 ship the backlog → R2 the instrument → R3 the seam → R4 = v2.0.0.**

**R2 comes before the feature because R4's entire claim is a number.** That number is produced by
an instrument which today has a known bias and no time axis:

- The constraint gate discards ~24% of files on both measured languages for a reason unrelated to
  any grammar. §52 exempted *narrative* `never`/`always` — perfect and past-tense constructions of
  two of the nine alternations in `IMPERATIVE_KEYWORD_SOURCE`. Present-tense descriptive use
  (`// Should never happen`) and the other seven (`do not support`, `required by`) fall straight
  through.
- There is **no per-file wall clock anywhere**. `stageDurationsMs` is per stage. The `<1ms` Fast /
  `~15ms` Deep targets in `ROADMAP.md` are not merely unvalidated, they are unvalidatable.

Ship grammars first and every new-language figure is measured through that, then has to be
re-measured against a moved baseline. **This is §56's ordering argument pointed at measurement
instead of at safety**, and it is the same shape: doing the cheap thing first is not a tax on the
feature, it is a precondition for knowing whether the feature worked.

**The constraint-gate work is gated on a two-sided measurement, and the retention side gates the
merge independently.** Recovery is fallbacks recovered with zero new ones, §52's standard.
Retention is a planted-directive corpus staying at 100% caught. A change that passes recovery and
fails retention is refused whatever it buys, because this gate protects content and no reduction
figure buys back a deleted instruction. Both are reported **per language**: §52 gained 6pp on
TypeScript and **zero** on Python, because all four recovered files were this repository's own
narrative source and this repository is ~94% TypeScript.

### R3 exists because a backend has to be checked where checking is still possible

R3 ships the seam and the Deep path for the four languages that already work — **no new
dependency, no new language, no new grammar, no reduction change.** Its deliverable is a
measurement, not a capability.

**A backend first trusted on a language nobody here can hand-check is a backend nobody has
checked.** §60 is the precedent and the standard: 9,181 real Go files, the TypeScript lexer
flagging 73 and the Go lexer 1, and **all 72 disagreements read individually** — they were raw
strings. Plus its inverse control, because 0 findings is also what a validator that examines
nothing reports.

**The control is staged, and this is a correction to the obvious design.** Byte-identity is the
right assertion for the symbol and validator steps and the **wrong** one for regions: a parser
legitimately finds better spans than a lexer, so demanding identity there forbids the improvement
the feature exists for. Step 3's assertion is instead that every differing row is classified as
improvement or regression, that fallbacks do not rise, and that latency is reported against R2's
baseline. §59/§60/§61 staged Go exactly this way and the staging is why the hazard was caught.

### What this does not establish

- **No language beyond the four has had its elidable ceiling measured.** The candidate list is a
  list of grammars that exist, not of languages known to reduce. §3.7 of the design doc is where
  that becomes a fact, on two independent corpora per language — one corpus overstated Go by ten
  points.
- **`web-tree-sitter`'s initialization cost is unmeasured, and it is paid per process.** For a CLI
  invoked once per file it lands on every run and could dominate the parse. This is a plausible
  reason for Deep to be unusable at the CLI while fine at the Gateway and MCP, and it is not yet
  known.
- **That one grammar really supplies all three seams is an argument from node types, not a
  measurement.** Symbols and validity are near-certain. **Regions are the uncertain one** — the
  body node of a Rust `impl` block or a C++ member function may not correspond to what
  `isSubstantiveRegion` assumes. R3 is where that assumption meets evidence, on languages where
  the answer is already known.
- **G2's effect size is unknown.** 24% and 18-of-20 are the *share of fallbacks* the gate accounts
  for, not the reduction recoverable by narrowing it. Some of those files fall back for a second
  reason as well.
- **No corpus was run for this entry**, because nothing was implemented. Everything numeric here
  is cited from §52, §56, §59–§61 or the status doc, and none of it was re-measured today.

## 76. The Latency Instrument Reports Three Numbers, Because One Of Them Would Be Wrong

**Date:** 2026-09-19 · **Status:** accepted, implemented · **Scope:** R2's second half — the
per-file wall clock that did not exist

Design: `docs/superpowers/specs/2026-09-09-tokendamper-v2-roadmap-design.md` §3.3. That section
asked for "per-file p50/p95/max, per stage and end-to-end". Measured, *end-to-end* is not one
quantity, and reporting it as one would have made every R3/R4 comparison misleading.

### The decision

`tools/corpus-harness/timing-run.js` is a **separate invocation** from `measure.js`, and reports:

| name | what it is | what it models |
|---|---|---|
| `cold` | engine time with the git workspace cache cleared before each file | the **CLI** — every invocation is a fresh process |
| `warm` | engine time with the cache left populated | the **Gateway and MCP** — long-lived processes |
| `fixed` | spawned wall clock minus `cold` | Node boot plus module load |

**The split is forced by `globalGitCache`** (`src/core/topology/git-inspector.ts`, 2000 ms TTL).
Timing N files in one process lets files 2..N hit a warm cache. Measured, that is not a rounding
difference: **cold p50 159.1 ms against warm p50 3.8 ms, a 41.48x ratio.** A harness that timed
files in one process and called the result "per-file latency" would have under-reported CLI cost
by a factor of forty, and would have made any future parser look proportionally enormous against
a denominator that had quietly vanished.

It is also the axis §75 lists as unestablished — a per-process cost can make a backend unusable at
the CLI while fine at the Gateway. Cold and warm are that question, now measurable.

### The baseline

Corpus frozen at **fcb6718**, `dist` **9560079950fd**, **292 files**, ratio **0.3**, clean tree.
Node **v26.4.0**, **win32-x64**, warmup 5, one run.

```
parity           292/292 agree
cold  engine     p50 159.1ms  p95 194.0ms  max 254.3ms
warm  engine     p50   3.8ms  p95  16.0ms  max  43.8ms
CLI   wall       p50 313.0ms  p95 355.0ms  max 402.0ms
fixed per-proc   p50 151.4ms
cold unaccounted p50   2.9ms   (validation + planning + render)

cleanup:constraint-preservation   p50   0.3ms  p95   2.5ms
pruning:topology-pruner           p50 153.8ms  p95 182.6ms
compression:token-hashing         p50   0.4ms  p95   3.3ms
compression:delta-compression     p50   0.0ms  p95   0.0ms
```

### `<1ms` was not wrong, it was unqualified — and that is the more useful finding

`ROADMAP.md` carried `<1ms` Fast and `~15ms` Deep. Against the table above the claim resolves
three different ways, and the roadmap never said which:

- **end-to-end cold (the CLI):** 159.1 ms — off by ~160x
- **end-to-end warm (Gateway/MCP):** 3.8 ms — off by ~4x
- **the reduction stages alone** (constraint-preservation + token-hashing + delta-compression):
  **~0.7 ms p50** — consistent with `<1ms`

So the number was defensible for the work the project thinks of as its own, and wildly wrong for
what a caller experiences. A target that does not name its quantity cannot be validated or
falsified, which is why it survived this long.

### `pruning:topology-pruner` is 97% of cold engine time

153.8 ms of 159.1 ms, and it is `git status` rather than any analysis. Every other stage is
sub-millisecond. **Recorded, not fixed** — it is off R2's scope, and R2 exists to produce the
instrument rather than to act on its first reading. Two consequences worth carrying:

- A reduction-latency budget spent on the elision stages is spending against 0.4% of the cost.
- The Gateway and MCP pay this once per cache window rather than per file, which is most of the
  41x and is the strongest measured argument for those entry modes on latency grounds.

### What the instrument refuses to report

Three refusals, each added because the run that produced them looked fine:

- **`percentiles` throws on an empty sample.** A p95 of `0` over no observations reads as a
  measurement and describes nothing.
- **`routeParityFailures` asserts coverage**, not the intersection. Every file is run in-process
  *and* spawned and the output bytes compared; **292/292 agree**, which is what licenses timing
  in-process at all. A file on one side only is a failure, because comparing the intersection is
  how a diff reports `compared N rows, differing: 0` and reads exactly like agreement.
- **`assertStageAttribution` refuses a run that attributed no stage.** This one is not
  hypothetical: **the first baseline run of this harness produced an empty per-stage table on all
  292 files** and reported a clean-looking end-to-end number on top of it. `timeOnce` read
  `result.trace`, and `runCli` returns an exit code — there is no `.trace` on a number. The
  instrument had the failure mode it was built to detect, so the refusal lives in the tool rather
  than in a reviewer's attention.

`timeOnce` also refuses a **pending** result, because `runCli` is typed `number | Promise<number>`
and stopping the clock on a promise measures scheduling rather than work — a fast number meaning
the opposite of fast.

### What this does **not** establish

- **One machine, one platform, one run.** `win32-x64`, Node v26.4.0, no repeated trials. p95 and
  max carry OS scheduling noise. A figure from another machine is a different corpus in the sense
  `recipe.json` already means it, and is visibly so rather than silently so.
- **Cold and warm model the CLI and the Gateway by proxy**, through the git cache. Neither the
  Gateway nor MCP was actually driven. The proxy is good for the dominant cost and says nothing
  about per-turn session work.
- **There is nothing to compare against yet.** No Deep backend exists. This is a baseline whose
  entire purpose is to be compared against later, and a baseline is not a result.
- **`web-tree-sitter` init remains unmeasured.** §75's concern is intact; what changed is that
  there is now a place to put the number — it lands in `fixed`, which is already 151.4 ms at the
  CLI, and its parse cost lands against the ~0.7 ms the reduction stages occupy.
- **Axis A and Axis B of the constraint gate are not in this entry.** R2's other half is held
  until this half is merged, by explicit decision — the two are independent instruments and
  bundling them would make a failure unattributable.

## 77. Axis A: A Third-Person `-s` Cannot Be An Imperative

**Date:** 2026-09-19 · **Status:** accepted, implemented · **Scope:** R2's constraint-gate half —
the first of the two axes §75 left open

§52 exempted a *narrative* `never`/`always` on a perfect or past construction. Present-tense
description fell straight through, and CLAUDE.md records `// Should never happen, but we` as
dominating Go's fallbacks at **18 of 20**.

### Surveyed before it was designed

Over the frozen corpus, **322** `never`/`always` segments are unexempt, and only **3** in the
entire corpus are caught by §52 today. Their shapes:

| shape | count |
|---|---|
| third-person `-s` verb | **99** |
| copula + keyword | 39 |
| modal + keyword | 38 |
| bare verb — genuinely imperative | **10** |

The rule follows the counts rather than an intuition about how comments read.

### Three rules, each provable from the words present

That is §52's standard, and it is what keeps this from being a judgement about tone.

- **Third-person `-s`.** An English imperative is a bare infinitive and *cannot* take `-s`. So
  `never returns a placeholder` describes and `never return a placeholder` instructs, and the
  difference is visible in the string. The largest group, 99 of 322.
- **Copula.** `is always deterministic` states a property. 39 of 322.
- **Non-agentive verbs** — `happen`, `occur`, `exist`, `arise`, `matter`. You cannot instruct
  something not to happen; these are unaccusative, so there is no imperative form to collide with.
  This is what exempts `should never happen` **without trusting the modal**, and the list is
  deliberately short because every addition is a verb somebody could turn out to use imperatively.

**Modals are left firing, 38 segments, on purpose.** `should never happen` describes and
`should never call this` instructs; both are modal + `never` + bare verb, so a modal cannot
discriminate them. That is the blurry line §52 declined to cross and Axis A declines too.

### Also a correction to §52, not only an extension

`isNarrativeUse` tested the **whole segment**, so one narrative construction anywhere exempted
everything in it. That was already live rather than theoretical: `the value is always set, so
always check it first` lost its instruction, because `set` is in `PAST_TENSE_IRREGULARS`. Axis A
matches far more shapes and would have turned a latent hazard into a common one.

The check is now **per occurrence and unanimous** — the same rule `extractImperativeDirectives`
already applies across keywords, where one `must` keeps the segment, now applied *within* the two
keywords that can do both jobs. The mixed case resolves toward firing, which is the direction that
cannot delete content.

### The negative control earned its keep, and this is the entry's most useful sentence

The first version of the `-s` rule was `\w+s`, and it exempted:

```
always pass the ledger explicitly, or turn 2 falls back
```

A real instruction, taken verbatim from this repository's own source, and one the test file had
been asserting since §52. `pass` is a bare verb that merely ends in `s`. The rule is now
`\w*[^s\W]s` — a third-person form is stem + `s` where the stem does not itself end in `s` —
which keeps `pass`, `miss`, `cross`, `discuss`, `address` and `express` firing. `focus` is the one
common single-`s` imperative that survives the shape test, so it is named explicitly.

**The retention side caught this before any corpus ran.** That is the whole argument for gating a
content-protecting change on a two-sided measurement rather than on a reduction figure.

### Measured — both sides, per language

Engine varied, input frozen, `dist/` rebuilt from `tsconfig.build.json` and **verified to contain
the intended code on both arms** (`THIRD_PERSON_AFTER` present/absent) before each run.

**Recovery side.** Main corpus pinned at **fcb6718**, 292 files / 584 rows. Go measured separately
on the 80-file corpus §60/§61 used, 160 rows, because the main recipe has no Go bucket.

| corpus | rows | recovered | **new fallbacks** | byte-identical |
|---|---|---|---|---|
| main (292 files) | 584 | **7** | **0** | 577 |
| Go (80 files) | 160 | **3** | **0** | 157 |

Per bucket, file route:

| bucket | reduced | fallbacks | mean per-file |
|---|---|---|---|
| python | 32 -> **34** | 12 -> **10** | 23.90% -> **25.39%** |
| typescript | 38 -> **41** | 18 -> **15** | 22.74% -> **25.20%** |
| go-app | 32 -> **34** | 8 -> **6** | 38.21% -> **40.02%** |
| go-stdlib | 25 -> **26** | 12 -> **11** | 22.50% -> **23.27%** |

The baseline arm reads go-stdlib at **19.42%** on the harness's token-weighted figure, which is
§61's recorded number to two decimals — an unplanned cross-check that the baseline build really
was the old engine.

**Retention side, 100% before and after.** The negative-control list in
`narrative-directive-scope.test.ts` is the planted-directive set: 16 instructions, several verbatim
from this repository and from pip. All 16 pass under the baseline engine and all 16 pass under
Axis A. During the red phase, 31 tests passed and the 9 failures were *only* the new Axis A
expectations — so the control set was never in the red for the right reason, and once for the
wrong one, which is what found the `pass` defect.

### The shape of the gain is the reassuring part

**Paired over rows that reduce under both arms — 367 on the main corpus, 140 on Go — the mean is
unchanged to four significant figures (9.67% -> 9.67%, 17.34% -> 17.34%) and *zero* of those rows
changed a byte.** Nothing that already worked moved at all. The entire gain is fallbacks becoming
reductions, which is the only shape in which a content-protecting gate can be loosened safely.

**And it clears §52's caveat rather than repeating it.** §52 gained 6pp on TypeScript and **zero**
on Python, because all four files it recovered were this repository's own unusually narrative
source. Here **all four buckets gain**, and 4 of the 7 main-corpus recoveries are pip's
`spinners.py` and `commands/cache.py` — third-party code that does not narrate itself the way this
repository does. Three of the seven *are* this repository's own source, including, with some irony,
`src/stages/cleanup/constraint-preservation.ts` itself at 0.00% -> 65.63%.

### What this does **not** establish

- **Axis B is untouched and still fires.** `do not support`, `required by`, `critical path` and the
  other keyword families are out of scope by explicit decision — they were held until Axis A was
  measured, because bundling them would make a failure unattributable. §75's §3.2 lists both.
- **38 modal segments still fall back**, by design. If that population matters, it needs a
  discriminator this entry does not have.
- **The Go corpus is not the main corpus and its manifest is not a `collect.js` pin.** It is the
  80-file tree §60/§61 froze, re-hashed in place because re-flattening its already-flattened names
  exceeds the Windows path limit. Same files, same hashes; a weaker provenance record.
- **The per-bucket means above are per-file means over every file in the bucket**, including
  fallbacks at 0.00%. They are not the harness's token-weighted `saved%` and should not be compared
  against figures quoted from it.
- **No claim about prose.** The prose bucket is 21 documents that already reduce 0.00% for reasons
  unrelated to this gate, and it is 0 recovered / 0 regressed here.

## 78. Axis B Is Closed Without Implementing, Because `must` Means `must`

**Date:** 2026-09-19 · **Status:** accepted, **nothing implemented** · **Scope:** R2's second
constraint-gate axis, and the close of R2

§75's §3.2 named two open axes on the constraint gate. §77 implemented Axis A. Axis B is the other
seven keyword families of `IMPERATIVE_KEYWORD_SOURCE` used descriptively — `must`, `must not`,
`do not`, `required`, `only if`, `except when`, `make sure to`, `critical`.

**It is closed on measurement, not built.** The precondition was surveyed the way §77's was, and it
fails.

### The survey

Over the frozen corpus and the 80-file Go corpus, restricted to the four buckets that can actually
reduce — a rule tuned on tcl or perl helps nothing, since those are 0.00% for reasons unrelated to
this gate — and run against the **post-Axis-A** engine, so what remains is genuinely Axis B's
population:

| | |
|---|---|
| reducing-bucket files scanned | 188 |
| files still raising ≥1 directive | 82 |
| surviving directive segments | **248** |
| segments the most permissive defensible rules would exempt | **18 (7.3%)** |
| files where *all* surviving directives would be exempt | 4 |
| **of those 4, files that currently fall back** | **1** |

Three of the four already reduce (`index_collector.py` 18.16%, `capi_job.go` 56.38%,
`zip_reader_test.go` 31.09%). **The measured ceiling on Axis B is one file — `agent_task.go` — out
of 188**, and even that assumes it falls back solely on its single `do not` directive rather than
also on drift, which was not verified because it did not need to be.

Segment counts by family, in the reducing buckets:

| family | segments | disposition |
|---|---|---|
| `must` / `must not` | **121** | genuinely imperative — see below |
| `do not` | 41 | 8 descriptive, 14 clause-initial imperative |
| `required` | 11 | mostly this repository discussing its own keyword list |
| `only if` | 5 | too few to matter |
| `critical` | 3 | all three are this repository's own source |
| `except when` | **0** | absent |
| `make sure to` | **0** | absent |

### `must` is 49% of the population and cannot be narrowed

This is the finding that closes the axis. Sampled verbatim:

```
we must initialize this before the tempdir manager, otherwise the ...
dependencies must be installed before we can call the backend
get_not_required must be called firstly in order to find and ...
the name of the file must be "pyproject.toml"
Build dependencies specified by PEP 518 must be already installed
This must be done in a second pass, as the pyproject metadata is not yet known
we must be able to determine the requirement name
```

Every one is a real constraint. **Two of them are already in the negative-control list** in
`narrative-directive-scope.test.ts`, put there by §52 precisely because they must keep firing. There
is no descriptive-`must` population to recover; narrowing `must` deletes instructions, and the
retention side of the gate would refuse the change whatever it bought.

§52 already knew half of this — it deliberately excluded `must` from the perfect-tense test, because
*"must have been called before"* is a requirement about a past state rather than a narrative. This
entry is that observation carried to the rest of the family.

### Why the rest is not worth the risk

`except when` and `make sure to` have **zero** segments in the reducing buckets — there is nothing
to narrow. `critical` has three, all of them this repository's own source *discussing the keyword
list*, which is corpus bias in its purest form. `required` has eleven, and the samples are dominated
by the same self-reference (`` `required` and `critical` are ordinary ``, `` `readonly required?` ``).

Only `do not` has a clean discriminator: a relative pronoun or personal pronoun before it marks a
subject, so `schemes that do not support lookup` describes while `Do not import and use main()`
instructs. That is eight segments, and on its own it recovers no file that is not already reducing.

**This is the H5 condition**, and the fourth time this project has recorded it: BM25 had no query to
score against, MMR found 0 of 1,486 pairs above its threshold, §51's per-item drift accounted for 0
of 117 fallbacks. Correct code, negligible effect — and here with a content-deletion risk attached,
which the others did not have.

### What would reopen it

**An open item is a claim about the current build and it expires** (§51's lesson, and §55's). The
measurement above is not a permanent property of the gate. Re-measure if any of these change:

- **The corpus gains code that is not this repository or pip.** `required` and `critical` are
  currently almost entirely self-reference; a third-party corpus using them descriptively would move
  the counts. This is §52's corpus-bias caveat pointing at the *reason to defer* rather than at a
  favourable number.
- **A language lands whose comment idiom differs.** Go's `do not` behaviour is already visible here;
  Rust, Java or C++ may not follow it.
- **The gate stops being the dominant fallback cause.** It accounts for 24% of TypeScript fallbacks
  and 18 of 20 Go. If R3/R4 change that ranking, the arithmetic changes with it.

### What this does **not** establish

- **Not that Axis B is unimplementable** — only that its measured ceiling is one file, so the
  effort and the content risk are not justified *now*.
- **The 18-segment exemption count is from probe regexes, not a shipped rule.** It is an upper bound
  on what a real rule would exempt, and a real rule would be narrower.
- **No corpus A/B was run**, because nothing was implemented. Every figure here is a survey over
  frozen inputs, which is the same instrument §77 used and not a substitute for an A/B.
- **`agent_task.go` was not diagnosed.** It is counted as recoverable on the strength of its
  directive set alone; whether the constraint gate is its only fallback cause is unknown and was not
  worth establishing to reject a one-file gain.

### R2 is closed

Latency harness §76, Axis A §77, Axis B closed here. §75's exit for R2 was *"both axes measured
two-sided per language with the retention side at 100%; the timing harness produces a pinned
baseline"*. Axis A was measured two-sided per language with retention at 100%; Axis B was measured
and dispositioned; the timing baseline is pinned at corpus fcb6718. **R3 — the `ParserAdapter` seam
— is unblocked.**

## 79. R3 Step 1: The Seam, And A Drift Signal That Was Partly English

**Date:** 2026-09-19 · **Status:** accepted, implemented (seam + step 1 of three) · **Scope:**
`src/core/parser/`, `packages/deep/`, and the symbol-parity measurement

Design: `docs/superpowers/specs/2026-09-09-tokendamper-v2-roadmap-design.md` §3.4 and §3.5, and
§75. This entry covers the seam and **step 1 only**. Steps 2 (validator) and 3 (regions) are not
implemented.

### The seam, and how two contradictory sentences are both true

§3.4 says `selectValidator` becomes *"a registry lookup with the hardcoded chain as its fallback"*
and, four lines later, that *"the existing if-chain stays and stays first"*. Both hold, because
the switch is the **mode**:

- `fast` — the default — resolves through the shipped chain and **never reads the registry**.
- `deep` — resolves the language through the same chain, then hands the item to a registered
  backend for that language, falling back to the chain's own validator when none is registered.

**Deep keys off the chain's answer rather than resolving the language itself.** That is what
confines R3 to the four languages Fast already covers, and it removes a whole class of false
finding: two item-to-language rules can disagree about what a file is, and that disagreement
would have surfaced in the step-2 measurement as a *parser* difference — a backend blamed for a
classification defect.

`ARCHITECTURE.md` gains the sentence §3.4 asked for: determinism is per-configuration. Same
input, same **mode**, same bytes out. Fast and Deep differing on one file is the feature; either
one being non-deterministic within itself is the violation.

### Where the backend lives, and why core's `package.json` moved by one key

`packages/deep/`, name `tokendamper-deep`, `private: true`, its own tsconfig — §3.6's layout,
created unpublished. R4 then *publishes* it rather than inventing it.

**`web-tree-sitter` and the four grammars are dependencies of that package, not of core.** Core's
`devDependencies` are byte-identical to before this work. The only change to core's
`package.json` is `"workspaces": ["packages/*"]`, which is additive and which `files` already
excludes from the tarball. Verified rather than assumed: `npm pack --dry-run` reports **229 files
/ 2.0 MB unpacked** with **zero** matches for `packages/deep` or `tree-sitter`. The 229 is 223 plus
exactly the six entries of `dist/src/core/parser/` (two modules times `.js`/`.d.ts`/`.js.map`).

`tree-sitter-wasms` was tried first and rejected on measurement, not taste: its grammars are built
with `tree-sitter-cli@^0.20.8` and fail `getDylinkMetadata` against `web-tree-sitter@0.27`. The
official per-language packages ship a matched prebuilt `.wasm` and are resolved by specifier via
`require.resolve`, never by a path built from `__dirname` — that would work in this repository and
break in any other layout, at load time rather than visibly.

### Step 1's assertion is wrong as written, and the corpus is what showed it

§3.5 says *"Symbol sets equal or superset. Per-file `S_k` must not fall on a hand-elided control
file."* Run over the frozen corpus, `S_k` **fell on 9 of 75 transformed files** — five of them all
the way to `0.0000`. Taken literally, step 1 fails.

Read individually, **none of the nine is §59's hazard**, and the two things a raw comparison
conflates are opposite in kind:

- **The hazard** — the backend *invents* a signature-level symbol that survives body elision by
  construction, so `R_AST` rises for the same transform. This is how 32 real Go files elided at
  `S_k = 0.0000` with both gates green, one losing 78.4% of its tokens.
- **Not the hazard** — the backend *declines to invent* a symbol the shipped regexes harvested
  from **English prose in a comment**. When that phantom sat inside an elided body, Fast scored it
  as destroyed, so dropping it lowers `S_k` while losing no information at all.

What separates them is whether Deep **had** the symbol and retained it anyway. The criterion that
replaces the wording, and the one `tools/corpus-harness/deep-drift-control.js` enforces:

> A symbol in Deep's before-set that Fast saw destroyed and Deep did not.

Measured: **0 files**. All nine falls are phantom-only.

### The finding worth carrying: part of the drift signal on code is English

`src/core/validation/language-support.ts` reduces 4,441 to 3,376 bytes at ratio 0.3 with
`driftScore: 0.1667`, `astMeasured: true`, `fallbackUsed: false`. **Its entire drift signal is one
phantom symbol.** Fast harvests `type:keeps` from the comment

> `// Falling back to the content type keeps the message concrete for an undeclared item rather`

because `(?:class|interface|type|enum|struct)\s+([A-Za-z_$]...)` matches `type keeps`. That comment
sits inside an elided region, so Fast scores 5 of 6 symbols retained. Not one real symbol was
lost — `selectElisionRegions` retains signatures by construction — and Deep, which knows a comment
is a comment, scores `S_k = 0.0000`, which is the **true** value under this project's own
definition.

Four more of the nine are the same shape end to end: `type:annotation`, `fn:since`, `fn:existed`,
`type:methods type:or type:was`. On the other four, Fast destroyed a mix and **Deep destroyed
exactly the real ones** — 1/1, 1/1, 2/2, 2/2.

This compounds a caveat already in `CLAUDE.md`: on real Python **86% of elided function bodies
contribute no symbols**, so the drift gate is nearly inert there. It is more inert than that
implies, on TypeScript too, because part of what remains is noise. **A consequence for R4: if
Deep's symbols ever feed the live drift gate, drift on code falls toward zero and the gate stops
discriminating.** That is a design question, not a bug, and it is not answered here.

### Three disagreements refused on purpose, and they are Fast defects

Deep is *more correct* in all three and reproduces the shipped behaviour anyway, because R3's
constraint is **no reduction change** and each would move files across the drift gate:

| shipped behaviour | what Deep found | why refused |
|---|---|---|
| `jsImportRegex` cannot match a grouped Go `import ( ... )` | `import:math`, `import:fmt` | `import:` survives body elision, so adding it *lowers* `S_k`. Measured 0.6 against 0.5 on the control |
| the `var:` rule needs `=` right after the name, so an annotated declaration does not match | 20 of this repo's own module constants — `DEFAULT_TOKENIZER`, `TOOL_DEFINITIONS`, `SUPPORTED_FLAGS` | a top-level `const` is inside no region the selector picks, so same direction |
| `@dataclass` then `class CandidatePreferences:` yields `type:class` — the regex matches the `class` inside `@dataclass`, consumes it, and never sees the real declaration | `type:CandidatePreferences` | left as the one remaining `extra`; it is a recovered *name*, not an added retained symbol |
| every shipped rule needs the keyword and the name adjacent, so a Go **grouped** `const ( … )`, `type ( … )` or `import ( … )` block is invisible | **142 symbols** over the 80-file Go corpus — 122 `var:`, 20 `type:` | all top-level, so all retained by construction. The single largest instance of the same direction, on the language §59 found it |

One genuine **Deep** bug was found and fixed: `from __future__ import annotations` parses to a
`future_import_statement` node carrying no `module_name` field, so `import:__future__` was dropped
on every pip file that opens with it. A lost symbol raises drift rather than lowering it, so it
failed safe — but it is the backend disagreeing with itself about what an import is.

### Measurement

Corpus frozen at **849f8c7**, dist **dc4465c6ec49**, **293 files**, ratio **0.3**. The tree was
dirty on `tools/corpus-harness/recipe.json` alone, which is not engine code. `recipe.json`'s prose
bucket went 21 to 22: the file is `docs/r3-start-here.md`, the R3 handoff counting itself. **That
one reverses** — the handoff is written to be deleted when R3 lands, and `expect` goes back to 21
in the same commit.

```
corpus A/B       586/586 rows byte-identical on all 15 compared fields
suite            962 -> 989 passing, 2 skipped, 102 files
symbol parity    108 files · typescript 7 agree / 56 disagree · python 26 / 19
                 lost 191 (all Fast false positives), extra 1 (the @dataclass case)
symbol parity Go  80 files · 57 agree / 23 disagree · lost 88, extra 0 (was 142)
drift control    75 transformed · S_k fell 9, rose 2, same 64 · HAZARD FILES 0
drift control Go  60 transformed · S_k fell 1, ROSE 36, same 23 · HAZARD FILES 0
timing baseline  cold p50 114.0ms · warm p50 3.3ms · ratio 34.49x · parity 293/293
```

§76's numbers (159.1 / 3.8 / 41.48x) did not reproduce and were not expected to — they are
machine- and run-specific by that entry's own statement. The *shape* holds:
`pruning:topology-pruner` is 109.3 ms of 114.0 ms cold, still ~96%.

### What this does **not** establish

- **Steps 2 and 3 are not done.** `check()` and `regions()` **throw** rather than returning a
  passing or empty result, deliberately: `valid: true` and `[]` are both indistinguishable from a
  backend that examined the content and found nothing, which is invariant 10's exact failure.
- **`--mode deep` is not reachable from the CLI.** The seam carries the mode and nothing passes
  it. R3's exit requires this and it is step 3's work.
- **JavaScript symbols are unmeasured on a corpus.** The main `recipe.json` has no JS bucket, so
  `javascript` is covered only by the unit tests. Go **is** measured — §77’s 80-file corpus
  survived and was used, with its manifest generated in place rather than re-frozen, which is a
  weaker provenance record than a `collect.js` pin and is stated as such.
- **No disagreement rate over 5,000+ files per language.** That is step 2's standard, for
  `check()`. Step 1's 108 files are this repository plus pip.
- **`web-tree-sitter`'s per-process init is still unmeasured**, which §75 lists as a plausible
  reason Deep is unusable at the CLI while fine at the Gateway. Nothing in step 1 runs it inside
  the engine.
- **Whether Deep's symbols *should* feed the drift gate is undecided**, and the phantom finding
  above is the reason it is now a real question rather than a formality.

## 80. R3 Step 2: Both Validators Are Wrong, In Opposite Directions

**Date:** 2026-09-20 · **Status:** accepted, implemented (step 2 of three) · **Scope:**
`packages/deep/src/check.ts`, and the validator disagreement measurement

Design: `docs/superpowers/specs/2026-09-09-tokendamper-v2-roadmap-design.md` §3.5, step 2.
Continues §79. Step 3 (`regions()`) is **not** implemented.

### What shipped

`check()` reads tree-sitter's own complaints — `ERROR` nodes and `MISSING` nodes — and reports
them as `AstCheckResult`. tree-sitter is error-tolerant, so "did this parse" is a question about
the tree's contents rather than about whether parsing threw. Issues are capped at 32 per file,
which never changes the **verdict** (decided by whether any error node exists) and keeps a
5,000-file report readable.

**§46 and §75 are not reversed.** The Fast path's advertised guarantee stays bracket/quote
integrity and `test/unit/validator-guarantee.test.ts` stays exactly as written. Deep being
stricter is Deep's property; the two are compared, never merged.

### The inverse control, per language, because a rate is not evidence

§60's standard has two halves and the second is the one that gets skipped: **0 findings is also
what a validator that examines nothing reports.** So every language gets a mutation its grammar
must reject, asserted in `test/unit/deep-backend-validator.test.ts`.

Brace deletion is §60's and is **meaningless for Python**, which has no braces — reusing it there
would have produced a file Python's grammar accepts and a control that silently proved nothing.
Python gets the structural equivalent, a `def` header with its colon removed. All four pass.

### The measurement

| language | files | agree | disagree | rate | deep-only | fast-only |
|---|---|---|---|---|---|---|
| python | **13,897** | 12,781 | 1,116 | 8.03% | 6 | **1,110** |
| go | **8,251** | 8,181 | 70 | **0.85%** | 70 | 0 |
| typescript | 1,164 | 1,056 | 108 | 9.28% | 108 | 0 |
| javascript | 1,823 | 1,821 | 2 | 0.11% | 0 | 2 |

Go at 0.85% over 8,251 files is the same shape §60 measured (9,181 files, 73 against 1). The Go
corpus was re-sourced by cloning `golang/go` at HEAD, sparse to `/src`; the 80-file tree §77 used
is unchanged and was kept for the §79 drift control.

### Both validators are wrong, and not about the same things

**Fast rejects 1,110 valid Python files — 8% of the CPython stdlib and site-packages.** All are
`AST_INDENTATION_ERROR`, and the cause was classified across every one of them rather than
generalised from an example:

| | |
|---|---|
| 1,105 (99.5%) | **backslash line continuation.** `x = \` followed by a more-indented line reads as an unexpected indent |
| 4 | the indent bookkeeping is lost after a closing `"""` |
| 1 | a nested f-string (3.12) |

`argparse.py` is the clean case: CPython compiles it, and the shipped validator rejects it at
L1701 on `self._has_negative_number_optionals = \`. **Fast rejects 2 valid JavaScript files** for
the same *kind* of reason — JSX in a `.js` file, where the lexer counts `<` and `>` as brackets.

**Deep rejects valid source too, and every case is the grammar lagging the language.** Minimal
repros, bisected rather than fingerprinted — a first pass blamed 86 TypeScript files on
`import("m").T` and was wrong, because that construct parses; the type *arguments* are what break:

| language | construct the grammar rejects | valid since |
|---|---|---|
| typescript | `import("m").R<A, B>` — a **generic** import type (≈75 files) | long-standing; standard `tsc` `.d.ts` output |
| typescript | `global { }` nested inside `declare module` (12) | long-standing |
| typescript | `export type * from` / `export type * as NS from` (2) | TS 3.8 / 5.0 |
| typescript | `abstract` used as a property name (2) | long-standing |
| go | `new(expr)` — confirmed at `types2/builtins.go:647`, "new(T) or new(expr)" | Go at HEAD, 2026-09 |
| go | generic methods — `func (r *Rand) N[Int intType](n Int) Int` | Go at HEAD |
| python | starred expression in a return or assignment — `return *[None] * 3, *g_xs` | PEP 448 |

**Go's 70 disagreements are almost entirely fixtures, which is why its rate is 0.85%**: 61 are
under `testdata/` (the compiler's deliberately-malformed corpus — exactly §60's finding), 5 are
`_test.go`, and only **4 are real source**. All four are the two new language features above.

**And Deep is right twice.** `badsyntax_future8.py` (`from __future__ import *`) and
`badsyntax_3131.py` (`€ = 2`) are rejected by CPython and **passed by Fast**. Every Python verdict
in this entry was adjudicated against `py_compile`, not against opinion.

### The finding that changes what a grammar is

**A tree-sitter grammar is a versioned artifact that trails the language it parses, and the lag
surfaces as a validator false positive.** That is a new failure mode for this project: every Fast
lexer is hand-written against a language the author knew, and drifts only when someone edits it.
A grammar drifts when the *language* moves.

It fails safe — a false "invalid" means a fallback, not a corruption — but it is a reduction loss
that arrives silently and is invisible to any test written against today's syntax. **R4 needs a
grammar-version policy**, and `new(expr)` landing in `golang/go` two weeks before this measurement
is the proof it is not hypothetical.

### What this cost on the corpus: nothing, and that is L7's lesson again

586/586 rows byte-identical; nothing in `src/` changed. More interestingly, the Python
indentation defect — 8% of 13,897 real files — accounts for **0 of the 10 Python fallbacks** in
the frozen corpus. Three of the 45 corpus files contain a backslash continuation followed by an
indented line and **none of them trips the rule**.

So an 8% defect on real Python is worth **zero** measured here. That is L7 exactly (a fix that
moved 0 of 576 rows because 0 of 45 files had the shape), and it is the reason the survey was run
over 13,897 files rather than over the corpus. **Fixing it is a reduction change and therefore
out of scope for R3** — recorded for R4, with its size measured on a corpus that can see it.

### What this does **not** establish

- **Two of four languages miss §3.5's ≥5,000 bar.** TypeScript scored **1,164** and JavaScript
  **1,823**, both from `node_modules` on this machine. TypeScript is the more important shortfall
  because the main corpus is ~94% TypeScript. The harness prints the shortfall on every run
  rather than leaving the reader to check.
- **The TypeScript sample is `node_modules`, which is mostly `.d.ts`.** Declaration files are real
  TypeScript and are what the corpus's dependencies actually contain, but they are not a neutral
  sample of hand-written application TypeScript — the generic-import-type construct that
  dominates the findings is `tsc` output, not something a person types often.
- **Step 3 is not done.** `regions()` still throws.
- **`--mode deep` is still not reachable from the CLI.**
- **No latency figure for `check()`.** §76's baseline exists and Deep was not timed against it;
  `web-tree-sitter`'s per-process init remains unmeasured, which is §75's open concern.
- **The disagreement counts are verdict-level, not issue-level.** Two validators agreeing that a
  file is invalid are counted as agreeing even if they blame different lines.

---

## 81. R3 Step 3: Deep Chooses Regions, And Cannot Validate Its Own Output

**Status: decided and measured, 2026-09-23.** Closes R3. Steps 1 and 2 are §79 and §80.

### What shipped

`ParserAdapter.regions()` is real for TypeScript, Python and Go, and reachable from the CLI as
`tokendamper optimize <file> --engine-mode deep`. Deep replaces **candidate span discovery only** —
`dropOverlapping`, `MIN_REGION_BYTES`, `isSubstantiveRegion`, `trimRegionsToCeiling` and
`splitRegionIntoStatements` all stay in core and run over the backend's candidates unchanged. That
is what makes a differing corpus row attributable: one thing moved.

Three decisions, taken deliberately:

- **Deep answers `regions()` and `check()`; `symbols()` stays Fast.** §79 measured that part of the
  shipped drift signal on code is phantom symbols harvested from English in comments. Feeding
  Deep's symbols to the live gate would drop drift on code toward zero and stop the retention gate
  discriminating. Deep's `symbols()` therefore remains harness-only.
- **`--engine-mode fast|deep`, not a third `--mode` value.** `--mode` already carries
  `optimize|bench`, a different axis that 2.0 withdraws. A third value would make bench-under-deep
  unrepresentable by construction. The flag applies to `optimize` **only** — `bench`'s runner does
  not read the mode, and a flag that registers backends without changing what the benchmark
  measures is accepted-then-ignored with a side effect (§30).
- **Zero registered backends under `--engine-mode deep` is a hard error.** A deep run that
  silently ran Fast is a green result from a path that never executed. §54 is the precedent.

### The finding that changed the release: Deep cannot validate TokenDamper's own output

Wiring `check()` live made deep mode reduce **nothing**. Measured on
`src/core/parser/coverage.ts` at ratio 0.3, through the built CLI:

| configuration | tokens | fallback |
|---|---|---|
| fast | 292 -> **211** | no |
| deep regions + deep `check()` | 292 -> **292** | **yes**, `AST Error … Parse error` |

The elision marker — `[TokenDamper: N function-body lines elided, N bytes, sha256:…]` spliced into
a function body — is not valid TypeScript or Python. Confirmed at unit level: tree-sitter rejects
it in both languages while a clean control passes.

**This is documented behaviour becoming reachable, not a new defect.** The Issue 2 entry in
`CLAUDE.md` already states that the load-bearing mechanism is correct-by-construction rendering
rather than the post-condition check, and that "Only `JsonValidator` rejects a bare placeholder;
the TS and Python AST-lite validators accept it, so `post_condition_rejected` is unreachable
today." Deep makes it reachable for the first time, and our own output fails it.

So the axes separate. `engineMode` drives region discovery; `validationMode` drives validation and
**defaults to `fast`**. Deep validation stays reachable in the API — it is real, and §80 measured
it over thousands of files per language — but it cannot be combined with elision until the marker
is rendered validly per language, which moves emitted bytes on the Fast path and belongs to its
own release with its own measurement.

`ValidationOptions` gained `coverageMode` so `trace.parserCoverage` keeps naming the mode that
chose the **regions**. Passing the validation mode to both reported `fast` on a run whose regions
came from Deep — a coverage block asserting something the run did not measure, which is the defect
class that block was added to prevent.

### The measurement

One frozen corpus, 297 files, engine `268898d`, ratio 0.3, both arms.

| bucket | fast | deep | files reducing |
|---|---|---|---|
| python (file) | 17.75% | **22.26%** | 34 -> 37 |
| python (stdin) | 17.39% | **21.89%** | 32 -> 35 |
| typescript (file) | 20.35% | 20.20% | 42 -> 41 |

Every other bucket reads 0.00% in both arms, unchanged.

Per-row: **594 rows, 540 identical, 54 differing**, 154 backend answers.

| verdict | rows | |
|---|---|---|
| `differs-deep-smaller` | 21 | python 18, typescript 3 |
| `differs-deep-larger` | 20 | python 20 |
| `recovered` | 8 | python — fell back under Fast, reduces under Deep |
| `new-fallback-region` | 5 | python 4, typescript 1 |
| `new-fallback-validator` | **0** | as predicted: both arms validate through the same Fast lexer |

**Target adherence improves, which is the axis §3.5 cares about.** Rows landing in the 25–35% band
went **12 -> 20** of 54; mean over differing rows 26.01% -> 35.84%. `cli/autocompletion.py` went
from 67.3% — a massive overshoot of the 0.3 target — to 36.6%. `build_env/venv.py` and `cache.py`
went from 0% (fallback) to 69.4% and 36.7%.

**Go, measured separately over the frozen 80-file corpus:** 160 rows, **158 identical, 2
differing** (both `differs-deep-smaller`), **zero** new fallbacks, 80 backend answers. `go-stdlib`
file route reads 20.56% in both arms.

### The gate fails on 5 rows, and what that turned out to mean

§3.5 says fallbacks must not rise. Five rows rose. All five are `CONSTRAINT_DIRECTIVE_LOST`, and
none of them is a region defect.

**Deep finds regions Fast misses on every failing file, and on two of the three its set is a
strict superset:**

| file | fast | deep | only-in-deep | only-in-fast |
|---|---|---|---|---|
| `src/core/constraints/directives.ts` | 4 | 5 | 1 | 0 |
| pip `build_env/installer.py` | 2 | 5 | 3 | 0 |
| pip `locations/_distutils.py` | 1 | 3 | 3 | **1** |

> **The third row is not a superset, and the first draft of this table said it was.** It claimed
> `only-in-fast 0`, which is arithmetically impossible beside `fast 1` and `deep 3` — a shared
> region would make Deep 4. The final whole-branch review caught it; the column had been filled
> in by assumption because the ledger only recorded the only-in-deep figure. **The two sets on
> that file are disjoint.**
>
> The cause is a real convention divergence that the agreement tests did not cover, because
> every one of their fixtures opens with a statement. `scanPythonDefBodies` scans lines and
> starts at the first non-blank body line whatever it holds, so a leading `#` comment is inside
> Fast's span; tree-sitter treats a comment as an extra, so `block.namedChild(0)` is the first
> statement and the comment stays outside Deep's. Same end, different start. Measured over the
> frozen 45-file pip corpus, **16 files** contain at least one such pair, and in **3** of them
> excluding the comment drops the span under `MIN_REGION_BYTES` so Deep declines the region
> altogether — those three are `cli/parser.py`, `exceptions.py` and `index/package_finder.py`.
>
> `_distutils.py` is **not** one of them; it is the disjoint-set case. Fast elides from
> `# XXX: In old virtualenv versions…` at offset 5141, Deep from `prefix = os.path.normpath(…)`
> at 5273, and Deep's span survives at 552 bytes. An earlier draft of this paragraph named it as
> a declining file too, reusing the example already in hand without rechecking that this
> particular pair also declined — the same unverified-assumption error this whole note exists to
> correct, committed once more while correcting it. The scoped re-review caught that one.
>
> Recorded rather than changed — Deep keeping the comment is the more conservative slice, and
> making the two agree would move the numbers above. `deep-backend-regions.test.ts` now pins it.
>
> **It weakens one attribution in this section and the weakening is stated rather than buried.**
> All 8 `recovered` rows fell back under Fast on `CONSTRAINT_DIRECTIVE_LOST`, and Deep *excluding*
> a leading comment is by itself a mechanism that avoids that gate, independent of discovery. So
> "net fallbacks fell, 8 against 5" is real as an outcome but is **not** cleanly attributable to
> better region discovery alone, and neither is an unknown share of the 20 `differs-deep-larger`
> rows.

The TypeScript case is the cleanest demonstration of parser-over-lexer this project has produced,
and it is pointed at itself. The function Fast misses is **`extractImperativeDirectives`** — the
function that implements the constraint gate. Its signature carries a multi-line object return
type, so the header text before the body's `{` ends with `}`, and Fast's `FUNCTION_HEADER` regex
`/\)\s*(?::\s*[^{;=]+)?$|=>$/` cannot match it. Tree-sitter identifies it as a
`function_declaration` regardless. Its body contains comments discussing `must`, `never` and
`always`, which the constraint gate then reads as directives and refuses.

So each of the five is **a discovery improvement producing an outcome regression**, through §52's
known constraint-gate false-positive axis — narrative prose about directives being read as
directives. R2's Axis B (§78) already measured that gate's remaining ceiling at 1 file of 188 and
closed it on measurement. **Net fallbacks fell**: 8 recovered against 5 new.

Recorded rather than fixed, by explicit decision. Making Deep skip directive-bearing regions would
make its discovery deliberately worse to satisfy a gate whose own false-positive rate is the known
problem — laundering the improvement the release exists to demonstrate.

### Latency

Re-baselined on this machine, because §76's figures are machine-specific and did not reproduce:

- fast: cold engine p50 **137.8ms**, warm p50 **2.2ms**, ratio **63.24x**; CLI wall p50 248.0ms;
  fixed per-process 109.8ms.
- `pruning:topology-pruner` p50 **135.0ms — 98% of cold engine time**, all of it `git status`.
- Deep's added cost, over five cold processes: `require` 7.2–7.6ms, `Parser.init()` plus four
  grammars 14.6–15.6ms — **~22ms per process**, landing in `fixed` rather than engine time.
  Corpus wall went 31s -> 36s (+17%) over 594 rows, consistent with ~22ms on a 248ms CLI wall.

**§75's concern is answered.** `web-tree-sitter` init was flagged as a plausible reason Deep could
be unusable at the CLI while fine at the Gateway. It is 22ms, and it is invisible against a
pruner that costs 135ms.

### What this does **not** establish

- **JavaScript is not registered and therefore not measured through the live path.** No Fast
  validator ever returns the language `javascript` — `.js` resolves to the TypeScript validator,
  whose `language` is `typescript` — so a backend registered under that key could never be
  resolved. R3 covers **three** languages through the live path, not four. §80's 0.11% JavaScript
  figure remains valid as an off-registry measurement.
- **Step 2's ≥5,000-file shortfall stands.** TypeScript sampled 1,164 files and JavaScript 1,823,
  both under §3.5's bar, and the TypeScript sample was `node_modules` — mostly `.d.ts`. Not
  reopened here.
- **Deep mode still subdivides with the Fast statement splitter.** `splitRegionIntoStatements`
  resolves its language through the Fast chain with no mode plumbed, so the ceiling path is
  Fast-driven even under `--engine-mode deep`.
- **Drift still uses the shipped regex extractor**, so §79's open question — what happens to the
  drift signal on code if Deep's symbols ever feed the live gate — is deferred, not answered.
- **Deep was not profiled per stage.** `timing-run.js` has no `--engine-mode` passthrough; the
  deep latency figures above are process-level init plus corpus wall time.
- **The Go corpus has weaker provenance than the main one.** Its manifest was generated in place
  because its filenames are already flattened and `collect.js` would re-flatten them past the
  Windows path limit. It is not a `collect.js` pin.
- **The corpus denominator moved.** `.superpowers` was excluded (agent scratch had taken 19 of 40
  prose slots — the `.agents` lesson repeating) and the typescript bucket went 63 -> 67 files with
  its `limit` raised 64 -> 80, because for the first time the limit BOUND and was silently
  dropping files rather than refusing. Aggregates here are **not** comparable to the 63-file R2
  baselines; per-row over one frozen corpus still is.

---

## 82. R4 Step 1: Three Candidates Clear The Floor, And Five Are Doc-Comment Languages

**Status: measured, 2026-09-23.** Design §3.7 step 1 — the elidable ceiling of every candidate
with a prebuilt grammar, on two independent corpora each. **Nothing is implemented beyond the
instrument; no emitted byte moved.** Engine `0b0aa21`, `dist` unchanged from it.

### The floor was fixed before the first candidate number existed

**At least 40% of source bytes — test and generated excluded — on each of the language's two
corpora, never averaged.** Set by the project owner on 2026-09-23, after the three shipped
languages had been through the instrument and before any candidate had. 40% sits below every
ceiling a shipped language has measured under either instrument; the lowest is Python under Fast,
43.23% on pip 26.2.1. So it reads as *at least as much material as the weakest language already
shipped*. It is `FLOOR` in the instrument, and `test/unit/corpus-harness-ceiling.test.ts` pins it
so that moving it is a visible diff.

*Landing note, 2026-10-04: §83 retires the 43.23% figure. Fast Python reads 68.84% on the same
files once it reads wrapped and `async` headers. The floor does not move, because it was
pre-registered, and it still sits below every shipped ceiling quoted in this entry: the lowest
is now TypeScript under Fast, 57.21%.*

It is a floor on **material**, not a projection of reduction. See the last section.

### The instrument, and what it refused before it was believed

`tools/corpus-harness/ceiling.js`. A candidate's spans come from a per-language tree-sitter node
table. After that, core's own filters decide: `dropOverlapping`, `MIN_REGION_BYTES` (104) and
`isSubstantiveRegion`. The instrument refuses to report unless three things hold:

- every node type and field in the table exists in the loaded grammar;
- every known-answer fixture passes. There are 44 across the eight languages, and each language
  has at least one fixture that must find a region and one that must find none;
- every claimed brace body is a `{ … }` pair.

On the shipped languages, `--parity` reproduces core's `selectElisionRegions` (deep) on
**192/192** files: 67 TypeScript, 45 Python, 80 Go. That is the proof that the filter pipeline
is core's own rather than a copy of it. Mutation-checked as well: 10 single-point breakages
(eight table entries, one per language, and two code paths) produced 10 refusals.

**Every check fired on something real before the first candidate ran:**

- The fixtures caught Ruby's endless method (`def sq(x) = x * x`) being counted as a body. The
  grammar puts an expression in `method.body`.
- The node-type check caught that the Kotlin grammar names no fields at all.
- The unit test caught C++, PHP and Kotlin fixture sets with no must-find-nothing case, which
  cannot fail in that direction.
- Reading the trees before measuring caught three classification gaps: `alloctests` and
  `coretests` in the Rust stdlib, `Newtonsoft.Json.FuzzTests`, and stdarch's generated headers.
  Those headers say `DO NOT MODIFY`, not `DO NOT EDIT`.

### The measurement

The source ceiling per corpus. In brackets is the clean-body lower bound: the regions whose body
parsed without an ERROR/MISSING node. Every corpus reported here met all three checks.

| language | corpus A | corpus B | clears |
|---|---|---|---|
| Rust | crates 13.9% | stdlib 29.2% | no |
| Java | guava 24.8% | jenkins 33.3% | no |
| **C#** | Newtonsoft.Json 51.3% [44.7%] | jellyfin 53.7% [53.7%] | **yes** |
| **C** | redis 65.5% [60.7%] | curl 58.0% [52.2%] | **yes** |
| **C++** | abseil 56.4% [**26.7%**] | bitcoin 60.9% [54.1%] | **yes, weakly — below** |
| Ruby | rails 34.6% | rubocop 38.6% | no |
| PHP | laravel 36.6% | WordPress 55.9% | no — split |
| Kotlin | okhttp 33.2% | ktor 29.0% | no |

The same instrument on the shipped languages: TypeScript 58.48%, Python 67.90%, Go source 57.54%
and tests 84.54%. The Fast figures on the same files are TypeScript 57.21% and Python 43.23%.

**Test files are the larger prize in every language**, at 55.9% to 98.7%. rubocop's 98.7% is
RSpec: one `describe` block per file. Counting functions only, it reads 0.25%.

### Why five fall below: measured, not inferred

Source bytes decomposed per corpus. **Comments outside function bodies are the largest single
share in every below-floor corpus:** guava 44.4%, jenkins 35.3%, Rust stdlib 34.3%, rails 34.7%,
laravel 35.0%, okhttp 31.9%, ktor 30.6%. For comparison, jellyfin is 18.0% and redis 19.8%.
Bodies too small to keep are 2–6% of bytes. So the instrument is not missing bodies.

These are doc-comment languages: Javadoc, rustdoc, YARD, PHPDoc, KDoc. A doc comment sits outside
the body by construction, so no grammar can bring it into reach of body elision. **That is a
finding about the product's unit of elision, not about tree-sitter.**

### C++ clears as registered, and the lower bound says why that is weak

**88.9% of abseil's source files carry an ERROR or MISSING node.** The dominant shapes are
annotation macros in signatures and MISSING identifiers: `ABSL_ATTRIBUTE_LIFETIME_BOUND` on
abseil, `NO_THREAD_SAFETY_ANALYSIS` on bitcoin. Boundaries mostly survive that. An independent
brace lexer, sharing nothing with the grammar, finds 26 of 2,164 abseil regions unbalanced and
11 of 4,774 on bitcoin. But half of abseil's material sits in bodies that themselves contain an
error node, and its clean-body ceiling is 26.7%, below the floor.

The first version of this bound tested the whole function rather than the body, and read 10.3%.
It discarded good bodies because of a macro in the signature that the grammar could not parse.

**The consequence for R4:** any design that validates C++ through the grammar rejects most of
abseil before a byte is elided. Deep's `check()` would reject about 89% of abseil files as they
stand.

### Sensitivities, none of which changes a verdict

- **Rust crates.** windows-sys is machine-generated according to its own README, yet none of its
  249 files carries a marker. It is 18.1 MB, 55% of source bytes, at 0.0%. libc is hand-kept FFI
  declarations: 4.35 MB at 0.8%. Without both, the crates corpus reads 43.7% and clears. The
  stdlib reads 29.2% whatever happens to the crates, and the rule needs both corpora.
- **Rust stdlib.** `#[cfg(test)]` modules are 13.3% of its source bytes. Without them it reads
  21.95%.
- **jellyfin.** Its scaffolded EF migration classes read as source. Without them: 53.74% → 52.29%.
- **abseil.** `*_benchmark.cc` reads as source. Without it: 56.38% → 56.47%.

### Found off the R4 path, and recorded rather than fixed

- **Fast's Python scanner needs `def …:` on one line.** It skips every wrapped signature and every
  `async def`. On pip 26.2.1, Fast reads 43.23% against Deep's 67.90%; `cli/req_command.py` alone
  goes 8.4% → 76.4%. This is most of why §81 measured Deep reducing more on Python.
- **§56's pip figure (46.88%) cannot be reproduced.** pip was upgraded to 26.2.1 on 2026-08-17,
  two days after §56 measured it.
- **`@tree-sitter-grammars/tree-sitter-kotlin` 1.1.0 rejects a one-line class body.** It inserts
  a MISSING `_class_member_semi` into `interface I { fun m(): Int }`, which is valid Kotlin.
- **Swift was not measured.** `tree-sitter-swift` 0.7.1 ships no `.wasm`, so a grammar would have
  to be built first.

### Corpora and grammars

The corpora are shallow clones made with `core.autocrlf=false`, so the bytes are upstream's. On
Windows, `core.longpaths` must also be set: without it, `git status` reports deep paths as
modified, which is misleading. One Newtonsoft.Json clone came back with an empty object store and
was re-cloned at the same commit.

The one local corpus is `~/.cargo/registry/src/index.crates.io-*`: 42 crates, 1,504 `.rs`
files. It is machine-specific in the same way `recipe.json` is. Each report records a hash over
every file it read.

| corpus | commit |
|---|---|
| rust-lang/rust `library/` (sparse) | `52d0fd8771cf` |
| google/guava (minus `android/`, `guava-gwt/`) | `16fda8017316` |
| jenkinsci/jenkins | `1a82aaca9953` |
| JamesNK/Newtonsoft.Json `Src/` | `52fa3aef1f2c` |
| jellyfin/jellyfin | `208c278b75ab` |
| redis/redis (`deps/` skipped) | `7a72677e622d` |
| curl/curl | `8807773c6af3` |
| abseil/abseil-cpp | `7f008af1930f` |
| bitcoin/bitcoin `src/` (minus the six subtrees its developer notes list) | `2b95b45a9abd` |
| rails/rails | `2cc9c08699bc` |
| rubocop/rubocop | `19c4d91c645c` |
| laravel/framework | `175092939c40` |
| WordPress/WordPress (minus eight bundled libraries in `wp-includes/`) | `e0e0928ca70f` |
| square/okhttp (`.kt` only) | `40a3b8749dea` |
| ktorio/ktor (`.kt` only) | `d08fd0382b2a` |

Grammars: `tree-sitter-rust` 0.24.0, `-java` 0.23.5, `-c-sharp` 0.23.5, `-c` 0.24.1, `-cpp`
0.23.4, `-ruby` 0.23.1, `-php` 0.24.2 and `@tree-sitter-grammars/tree-sitter-kotlin` 1.1.0. All
were installed into scratch with install scripts disabled, not added to the repository.

### What this does not establish

- **No achieved reduction for any candidate.** A ceiling measures material. §56's conversion from
  ceiling to achieved embeds a fallback rate, and each candidate's own rate needs symbols and a
  validator first, in §56's order.
- **Which validator a new language gets is undecided, and that decision decides the outcome.**
  Deep's `check()` rejects the elision marker (§81). For C++ it also rejects most of abseil before
  any elision. For C it rejects about a quarter of files: 23.1% of redis, 25.6% of curl.
- **Whether closures are regions is recorded, not decided.** On source the two readings differ by
  at most 5.5pp (ktor). On DSL-shaped tests they differ enormously.
- **Two corpora is §3.7's minimum, and PHP's two disagree by 19 points.** That is the §56 lesson
  again.
- **The node tables are the instrument's own claim.** Fixtures, the lexer and spot-checks support
  them, but a construct no fixture covers could still be missed.
- **Generated-file detection reads names and headers only.** windows-sys is its blind spot.

---

## 83. Fast Python Reads Wrapped And `async` Headers: The Ceiling Gap Closes, The Reduction Gap Only Partly

**Status: implemented and measured, 2026-09-23. It left one call to ship time, and on
2026-10-04 that call was made: it ships, with R4. See the last section.** Found by §82 ("Found off the R4 path"). This moves emitted bytes on the
default Fast path for Python.

### What changed

`scanPythonDefBodies` tested each line against `/^\s*def\s.*:\s*$/`, so a header had to fit on
one line and begin with `def`. That rule skipped every signature black wraps, whose first line
ends in `(`, and every `async def`.

A header now opens on a line matching `/^\s*(?:async\s+)?def\s/` that does not begin inside a
string. It closes at the end of the first line on which:

- the brackets it opened are closed,
- no string is open, and
- no backslash continues the line.

It counts as a header only if that line ends with `:`. That is the old rule's own test, applied to
the header's last line instead of its first. The body scan is unchanged except that it starts after
the header's last line. Audit L7's rule then applies from there, so the region begins at the first
non-blank line.

The lexical rules are `PythonValidator`'s, so the scanner and the post-condition check agree about
where strings are. Two consequences follow:

- **A `def` inside a string no longer counts.** The old test was line-local, so a one-line
  `def generated(a, b):` inside a triple-quoted template matched, and the "body" elided was part of
  a string literal. Every gate passes when that happens. The marker sits inside a string, so the
  validator cannot see it. The `def` line survives, so drift sees no loss. The wrapped form needs
  the string state anyway, and the same state closes the one-line form.
- **A new header line always restarts the search.** In valid Python no line inside brackets can
  begin with `def`, so this changes nothing on valid code. On malformed input, an unclosed
  parameter list costs only its own region.

**The widen-language ordering held before any scanner change, so only the scanner moved.** Drift's
Python symbol regex is `/def\s+([A-Za-z_][A-Za-z0-9_]*)/g`. It is unanchored, so it already
harvests names under `async def` and under wrapped headers. The validator is unchanged.

The tests are `test/unit/python-def-headers.test.ts`, 23 cases. Against the unfixed scanner, 17
fail and 6 pass. The 6 are negative controls that assert an absence: a wrapped `def` in a string,
commented-out headers, a class body under a wrapped class header, a truncated parameter list, a
body on the closing line, and one-line headers with brackets in a string default or comment.
The one control that fails on the unfixed scanner too is the one-line `def` inside a string. The
old rule selected `{start: 52, end: 260}` there, inside the literal.

### The harness corpus: pip 26.2.1

The corpus was frozen with `collect.js` at `0b0aa21`, clean tree: 297 files and 594 rows at ratio
0.3, both routes, 0 failed runs in either arm. The baseline `dist` is `649eea00fe2c` and the
candidate is `75d99dafcc68`. Each built arm was checked for the code it should carry before it
was measured.

| bucket | route | reduced | fallback | saved |
|---|---|---|---|---|
| python | file | 34 -> 35 | 10 -> 10 | 17.75% -> **19.53%** |
| python | stdin | 32 -> 33 | 9 -> 9 | 17.39% -> **19.16%** |
| typescript | file | 42 -> 42 | 16 -> 16 | 20.32% -> 20.32% |

**Per row: 49 of 594 differ, all Python (25 file, 24 stdin).** The other 545 rows are identical
on all 16 compared fields. That includes every TypeScript row, so no rule reached anything but
Python.

The file route splits as follows:

- **14 rows reduce in both arms and moved.**
- **2 rows recovered.** `cache.py` went from fallback to 36.7%, and `commands/list.py` from
  fallback to 35.3%.
- **2 rows newly fall back.** `build_env/installer.py` went from 19.7% to fallback, and
  `locations/_distutils.py` from 10.4% to fallback.
- **7 rows fall back in both arms.** Their output is identical; only trace fields differ.

Both new fallbacks are `CONSTRAINT_DIRECTIVE_LOST`. In each, the dropped directive was outside
every baseline region and inside a candidate region under a wrapped header. The two recoveries
are a selection effect, not avoidance. Their directive is inside a region in both arms, but with
more candidates the ceiling is met without eliding that region.

**These are §81's rows.** On this freeze, against baseline Fast, Deep recovers four pip files and
newly fails on two. The fixed Fast path newly fails on the same two, `build_env/installer.py` and
`locations/_distutils.py`. It recovers two of the four, `cache.py` and `commands/list.py`. The
other two, `build_env/venv.py` and `cli/parser.py`, are the leading-comment case below. On pip,
Fast's fallback set is now Deep's plus exactly those two files.

**Target adherence improves, measured over the 32 rows that reduce in both arms.** 13 outputs
moved: 10 closer to 0.3 and 3 further. The 25–35% band went 11 -> 15, rows above 50% stayed at 4,
and the mean |achieved − 0.3| went **11.72 -> 9.01pp**. `cli/autocompletion.py` went
67.3% -> 36.6%, the same row §81 recorded under Deep. `cli/progress_bars.py` went 0.0% -> 38.7%.
Five of its six headers are wrapped, and the sixth's body never cleared the filters, so Fast
selected nothing there before.

**The ceiling gap closes.** `ceiling.js --parity` reports 45/45 parity. It was run from a scratch
copy pointed at this tree, because the instrument is §82's and not yet on `main`.

| | before | after |
|---|---|---|
| Fast ceiling | 43.23% | **68.84%** |
| Deep ceiling | 67.90% | 67.90% |

Per region, over both arms at the default filters:

- **279 regions are identical.**
- **112 are added, and every one is under a wrapped `def`** (116,792 bytes).
- **4 are removed.** Each is a nested body now subsumed by its newly found wrapped parent.
- **0 are removed for any other reason**, so the string-awareness half moved no region.

The census found 504 `def` lines: 127 with a wrapped first line, and **0 `async`**.

**Fast now finds what Deep finds, except for §81's convention.** Fast selects 391 regions:

- **359 are byte-identical to Deep's.**
- **29 share Deep's end but start at a leading `#` comment**, which Deep excludes.
- **3 are Fast-only**, because Deep's comment-excluded span falls under `MIN_REGION_BYTES`.

Deep has **0 regions Fast lacks**. Per file, 27 of 45 are identical and 0 read smaller under Fast
than under Deep. `cli/req_command.py` goes 8.4% -> 76.4%, exactly Deep's figure.

**`cli/req_command.py` gains nothing end to end.** It falls back in both arms on the same 75
bytes: *"…config files) do not affect it."* That text is in the docstring of
`should_ignore_regular_constraints`, a one-line header both arms elide. The ceiling moved; the
gate did not.

### "Most of why deep mode reduced more" is true of the ceiling, not of the reduction

`--engine-mode deep` was run under both engines: **594 of 594 rows identical**, so the change is
confined to Fast discovery. Deep reads python file **22.26%** (37 reduced, 8 fallbacks) and stdin
21.89%, reproducing §81 on a fresh freeze.

Against it, the fixed Fast path closes **1.78 of the 4.51pp gap**: 17.75% -> 19.53%. Fast and
Deep now emit identical output on 32 of 45 file rows, up from 20. The remaining 2.73pp is 3,602 of
131,971 tokens:

- **Two rows are 72% of it (2,588 tokens).** `build_env/venv.py` and `cli/parser.py` fall back
  under Fast and reduce under Deep, at 69.4% and 33.9%. In both, the dropped directive is the
  body's leading comment: *"# We defer this import because certain distributions of Python do not
  include"* and *"# help position must be aligned with __init__.parseopts.description"*. Fast's
  region includes that comment and Deep's excludes it.
- **Most of the rest is Deep overshooting the target.** `cli/main_parser.py` reads 75.5% under
  Deep against 30.5% under Fast, and `commands/install.py` reads 36.3% against 30.6%.

**So what now separates the two on Python is §81's leading-comment convention, not header
discovery.** §81 already suspected this, noting that Deep excluding a leading comment "is by
itself a mechanism that avoids that gate". This change is recorded here, not made, because
aligning the conventions moves Fast's output on every such file. It is a change of its own.

### The async half, measured where it exists

pip has no `async def`, so the harness corpus cannot see half of this change. Two async corpora
were frozen with `collect.js --recipe` from a scratch recipe:

- CPython 3.12.10 `Lib/asyncio`: 30 files, 144 `async def` lines, 68 wrapped first lines.
- anyio 4.14.2: 37 files, 428 `async def` lines, 283 wrapped first lines.

That gave 134 rows per arm. The engine was varied by swapping `dist/`, and each arm was verified
with `diff -r` against a saved build plus a grep guard.

| corpus | Fast ceiling | Deep | route | reduced | fallback | saved |
|---|---|---|---|---|---|---|
| asyncio | 51.85% -> 75.61% | 74.47% | file | 18 -> 15 | **10 -> 13** | 11.48% -> **7.27%** |
| | | | stdin | 18 -> 15 | 6 -> 9 | 11.48% -> 7.27% |
| anyio | 18.62% -> 55.31% | 55.03% | file | 27 -> 28 | **2 -> 6** | 8.07% -> **17.29%** |
| | | | stdin | 27 -> 28 | 2 -> 5 | 8.07% -> 17.29% |

Added regions by header shape:

| corpus | `async` one-line | `async` wrapped | `def` wrapped | total |
|---|---|---|---|---|
| asyncio | 75 | 31 | 21 | 127 |
| anyio | 174 | 74 | 79 | 327 |

Headers carrying `async` account for 86% of the added bytes on asyncio and 75% on anyio. The 6
and 12 removed regions are all nested bodies subsumed by a new parent.

**Seven rows newly fall back and none recover** (file route). All seven are
`CONSTRAINT_DIRECTIVE_LOST`. In every one the directive was outside every baseline region and
inside a candidate region under a newly reachable header:

| row | before | directive | header |
|---|---|---|---|
| `asyncio/selector_events.py` | 30.5% | *The socket must be bound to an address and listening for connections.* | `async` one-line |
| `asyncio/staggered.py` | 4.8% | *\* They should always raise an exception if they did not complete* | `async` one-line |
| `asyncio/streams.py` | 26.4% | *# in a loop would never call connection_lost(), so it* | `async` one-line |
| `anyio/_core/_subprocesses.py` | 0.0% | *:param env: If env is not ``None``, it must be a mapping that defines the* | `async` wrapped |
| `anyio/abc/_sockets.py` | 8.5% | *The existing socket must already be connected.* | `async` one-line |
| `anyio/from_thread.py` | 11.3% | *(required if calling this function from outside an AnyIO worker thread)* | `def` wrapped |
| `anyio/to_interpreter.py` | 7.6% | *mission-critical on Python 3.* | `async` wrapped |

**Some of that is real instruction and some is §52's narrative axis.** "The socket must be bound"
is a precondition the caller needs. "# in a loop would never call" describes behaviour. The gate
cannot tell them apart, which is known. What is new is how much docstring-heavy async code it
now has in reach.

**Among rows that reduce in both arms, adherence still improves.**

- **asyncio:** 15 rows, 4 moved (3 closer, 1 further). The 25–35% band went 9 -> 10, and the mean
  |achieved − 0.3| went 9.27 -> 8.91pp.
- **anyio:** 24 rows, 21 moved (17 closer, 4 further). The band went 5 -> 10, and the mean
  |achieved − 0.3| went 16.53 -> 9.10pp. Rows above 50% went 0 -> 1.

### Latency

`selectElisionRegions` in fast mode, in-process over the 112 files of all three corpora (1.43 MiB):
**0.07 -> 0.14 ms per file**, 20 passes, two runs per arm. Part of that is simply more regions
through the filters. R2 measured 159.1 ms cold per file (§76), so this does not show at the CLI.

### What this does **not** establish

- **The async half on the harness's own corpus.** pip has 0 `async def`. The async evidence comes
  from a scratch recipe on one machine, not from `recipe.json`, so the next freeze will not see it
  unless a bucket is added.
- **The string-awareness half on any real file.** It removed no region across the 112 files, and
  only a unit test pins it. A corpus that cannot see a fix says so about the corpus (§56).
- **Retention.** A new fallback is the gate's judgement on text; it does not measure whether a
  model can still use an elided file.
- **Any ratio but 0.3.**
- **`--keep-docstrings` on a corpus.** It is unit-tested under a wrapped header only.
- **Every shape Fast might miss.** Three are known:
  - a header whose last line carries a comment after the `:`, which the census found 0 times on
    all three corpora and is therefore unmeasured;
  - a body line that dedents inside a multi-line string, which still ends the indentation-only
    body scan, as it did before;
  - §81's leading-comment start, which is now the only discovery difference from Deep on pip.
- **§82's floor rationale.** §82 justifies its pre-registered 40% floor as below "the lowest …
  Python under Fast, 43.23% on pip 26.2.1". This change retires that figure; Fast Python reads
  68.84% on the same files. The floor was pre-registered and should not move because of this, but
  that sentence needs revisiting wherever §82 lands.

### The call this leaves to ship time

The version number is decided at ship time (§53), and so is this call. The evidence points both ways:

- **For shipping: §81's precedent.** §81 recorded a discovery improvement whose outcome regressed
  through the constraint gate, and it refused to make discovery worse to satisfy a gate whose
  false positives are the known problem. The fallback is also fail-open: raw bytes, byte-identical.
  What is lost is saving, not content.
- **Against shipping: the default-path bar.** §81's regressions sat behind an opt-in flag. Every
  default-path change since §50 has held itself to zero new fallbacks: §50's 0.75, §52 and §77.
  This one does not. On the file route, across the three corpora, **2 fallbacks recover and 9 are
  new**, and asyncio's aggregate falls 4.21pp.

The lever that would dissolve the trade is to have *selection* skip a region holding a critical
atom while discovery stays intact. It is untested. It would move rows in every language, and
§81's objection to skipping directive-bearing regions would need answering for selection as well
as discovery. It is its own change.

**Decided 2026-10-04, by the project owner: it ships, with R4.** The case put to the owner was
the one above. The cost is saving rather than content, because each of the nine is a fail-open
fallback that returns the input byte for byte. Against that, the string-awareness half closes a
path on which every gate passes over an elision inside a literal. **The default-path bar is set
aside for this change, not retired.** The next default-path change is held to zero new fallbacks
again unless its own entry argues otherwise, and the release notes state this trade at the top
rather than in a footnote.

---

## 84. R4 Step 1: Two Lexers, And A Census That Read Every Flag

**Status: implemented and measured, 2026-10-04.** This is step 1 of R4's three, in the order the
R4 design sets (`docs/superpowers/specs/2026-10-04-r4-c-csharp-and-v2-release-design.md` §3).
Fast lexers let core name C and C#; backend symbols (§85) and regions (§86) come after. **Nothing
elides C or C# at this step.** It does reach Fast mode, because `.c`, `.h` and `.cs` items stop
being `validated: false`, and that is why the step was gated on a census registered in advance.

### Why a lexer, and why this is the risky step

Two R3 findings make a Fast lexer necessary even for languages that reduce only under Deep:

- **The Fast chain must name a language before Deep is consulted.** JavaScript has a built
  grammar and is unreachable for exactly this reason (§81).
- **Deep cannot validate its own output.** The elision marker is not valid syntax in any
  tree-sitter grammar (§81), so the post-condition check on elided C or C# has to be a lexer's.

The risk is that validation runs over every item in the output bundle, with no subtraction of
issues the input already had. A false flag on an untouched `.c` file attributes an error to that
item. Phase 1c then reverts it, re-validation fails again, and a multi-file Fast-mode bundle falls
back whole. Before this step a `.c` file could not cause that, because nothing checked it.

### The bar, registered in the spec before either lexer existed

- **False positives:** ≤ 0.1% of files, on ≥ 5,000 real files per language, with every flagged
  file read.
- **Mutation control:** ≥ 95% caught.
- **Main corpus:** byte-identical, with `fallbackUsed` unchanged.

### The census

`tools/corpus-harness/lexer-census.js` runs the built Fast chain over every file of each tree. It
lists **every** flagged file, not only Fast-versus-Deep disagreements. Listing only disagreements
would hide a lexer false positive on any file the grammar also rejects, and that is a quarter of
real C (§82). The tool refuses an empty set, and refuses a file the chain routes to the wrong
validator. Trees are checkouts read in place, so each one is pinned by commit and by a hash over
every file read.

| language | tree | files | MB | flagged | code-site mutations caught |
|---|---|---|---|---|---|
| C | MSYS2 `ucrt64/include` (local) | 3,250 | 112.1 | 2 | 344 / 344 |
| C | redis `7a72677e622d` (`deps/` skipped) + curl `8807773c6af3` | 1,327 | 18.7 | 0 | 950 / 950 |
| C | git `8103b446517e` | 986 | 12.2 | 2 | 707 / 707 |
| C | postgres `852fd5b86e1a` `src/` | 2,351 | 49.6 | 0 | 1,484 / 1,484 |
| **C** | **total** | **7,914** | **192.7** | **4** | **3,485 / 3,485** |
| C# | Newtonsoft.Json `52fa3aef1f2c` `Src/` + jellyfin `208c278b75ab` | 3,165 | 20.9 | 0 | 3,129 / 3,129 |
| C# | PowerShell `caeff5e8a579` `src/` + ILSpy `77528d649dc2` | 3,065 | 44.1 | 0 | 3,034 / 3,034 |
| **C#** | **total** | **6,230** | **65.1** | **0** | **6,163 / 6,163** |

Tree hashes: MSYS2 `d95c3464cd6b`, redis+curl `b1914a1c1860`, git `57e9ba1d8139`, postgres
`0cc28a4f30b9`, Newtonsoft+jellyfin `5c70f256fcfc`, PowerShell+ILSpy `e4ed21763b8c`.

### What the census found, in the order it found it

Every finding below became a failing known-answer test before it became a fix. The first draft of
each lexer was wrong four times.

**1. "The first branch of every `#if` group" is not a configuration real headers balance in.**
The first pass flagged 4 of 3,250 MSYS2 headers, and all four are valid C:

- libstdc++'s tr1 header opens `namespace tr1 {` in an `#elif` and closes it under a later `#if`
  with the same condition;
- `newapis.h` opens an `else {` only in an `#else` branch;
- CPython's internal headers carry an `extern "C" {` with no closer, which is valid C and broken
  only as C++;
- `sti.h` has a broken line inside `#ifdef NOT_IMPLEMENTED`.

**2. Adding "the last branch of every group" cleared all four, and broke the mutation control.**
The catch rate fell from 96.6% to 2.0%. That configuration read an include guard
(`#ifndef X_H` … `#endif`) as having an implicit empty `#else`, so every guarded header balanced
whatever it contained. **An include guard is never a configuration choice**, because its body is
compiled on first inclusion in every build. The guard is now recognised as `#ifndef X` or
`#if !defined(X)` whose next directive is `#define X`, and its body always counts.

**3. Excluding every `#if` with no `#else` was a blind spot.** 22% of the mutation sites in redis
and curl sat inside feature blocks such as `#ifdef REDIS_TEST`, `#ifndef CURL_DISABLE_HTTP` and
`#ifdef _WIN32`, and none was caught. The final rule makes the second configuration differ from
the first only where a build can: it takes the `#else` of a group that has one, after a
known-false first branch too, and a group without one is counted by both. What the blanket
exclusion used to rescue is now decided instead. A condition is decided when its value needs no
macro values:

- `0` and `1`;
- `__cplusplus`, which a C compiler never defines;
- a macro this file defines only inside dead code;
- `!`, `&&` and `||` over those.

That covers FreeType's `FT_NEED_EXTERN_C`, which is defined under `#ifdef __cplusplus` and tested
later, and `d3d11.h`'s `!defined(D3D11_NO_HELPERS) && defined(__cplusplus)`. Both had come back
as false positives once feature blocks counted.

**4. A byte-order mark hid a C# directive from line-start detection.** The first C# pass flagged
549 of 3,165 files, every one with "`#endregion` without a matching `#region`" at line 24.
Newtonsoft.Json files open with a UTF-8 BOM and then `#region License`, and the lexer read U+FEFF
as a token. The CLI reads files the same way, so this was a production false positive, not a
census artifact. U+FEFF is whitespace to both lexers.

### The flags that remain

- **C: 4 of 7,914.**
  - **Two are true positives.** git's `t/t4051/appended1.c` and `appended2.c` are two halves of
    one function, split on purpose for a diff test, so each file really is unbalanced.
  - **Two are false positives, by design:** libstdc++'s correlated tr1 groups, and `sti.h`'s
    broken block under a macro nothing defines. Accepting them means excluding blocks with no
    `#else`, which is the blind spot finding 3 closed. `c-validator.test.ts` pins both as
    rejected, so a change that makes them pass has probably reopened it.
  - **False-positive rate: 2 / 7,914 = 0.025%**, against a bar of 0.1%.
- **C#: 0 of 6,230.**

### The mutation control — and a reclassification made after seeing data

The control registered in advance deletes each file's last `}`-only line, and must catch ≥ 95%
with every miss explained. Under the final rule, measured over all sites, C catches far fewer than
that. The reason is that most C headers' last `}` line closes an `extern "C"` under
`#ifdef __cplusplus`, and deleting it leaves valid C.

**So the census now classes each site, and that classification was introduced after the first
results. It is a deviation from the control as registered, and it is recorded as one.** The
classes:

- **code** — counted by both configurations. The bar applies, and every miss is read.
- **macro** — on a `#define` continuation line. This is macro text, which the lexer never counts.
- **comment** — inside a block comment.
- **conditional** — in a branch one configuration drops: either side of an `#if`/`#else`, or a
  known-dead branch.

| class | C caught | C# caught |
|---|---|---|
| code | **3,485 / 3,485** | **6,163 / 6,163** |
| macro | 2 / 69 | 0 / 0 |
| comment | 3 / 4 | 22 / 22 |
| conditional | 0 / 1,788 | 0 / 1 |

**1,674 of the 1,788 C conditional sites (93.6%) are `__cplusplus` blocks**, where deleting the
brace leaves valid C. The rest are branches of `#if`/`#else` groups, and the two-configuration
rule cannot check those by construction: a brace deleted from one branch leaves the other
configuration balanced. The census mirrors the validator's branch selection exactly, so "code" is
precisely the set both configurations read. The ruling is the spec's own, which named "an
inactive branch" as an explainable miss. What changed after the data is that the explained misses
are counted as a class rather than listed one by one.

### The main-corpus control

The main corpus was frozen at `80880bd` (301 files, 602 rows). The baseline `dist` is `fa9edc9`,
and the candidate carries the final lexers.

- 572 rows are identical on all 33 fields.
- The 30 that differ are exactly the `c` bucket's file-route rows: the MSYS2 headers. They differ
  only in coverage fields: `astChecked` 0 → 1, `astUnchecked` and `uncheckedContentTypes`.
- **`outputSha` and `fallbackUsed` are identical on all 602.** No header the corpus holds is
  falsely flagged. The stdin route stays unchecked, because a pathless C item has no language.

### What this does **not** establish

- **Syntax.** Both lexers check balance, as every Fast validator does.
  `validator-guarantee.test.ts` gains rows saying so: balanced nonsense and English prose pass.
- **Damage confined to a branch one configuration drops.** These are the 1,788 conditional sites,
  0 of them caught. That is the cost of accepting code valid in some configuration. In deep mode,
  elision replaces a whole body interior rather than cutting into a branch. A statement split that
  orphans an `#endif` is still caught, because conditional balance is checked in both passes.
- **Any `#if` expression beyond the decided forms**, and macro values in general.
- **C++.** `.h` is C here. Raw strings are handled so C++ headers named `.h` do not false-flag, and
  nothing else of C++ is.
- **Provenance as strong as a `collect.js` pin.** The trees are checkouts on one machine, recorded
  by commit and content hash.

---

## 85. R4 Step 2: Backend Symbols Witness C And C# Function Loss

**Status: implemented and measured, 2026-10-04.** This is step 2 of R4's three. In Deep mode, the
drift gate takes C and C# function symbols from the Deep backend. **Still nothing elides C or C#**,
because no region is reachable until §86.

### The hazard this closes, measured before it was closed

`extractItemSymbols` runs every regex over every item. For C it harvests **no** function symbols.
For C# it harvests constructors and almost no methods, because `methodRegex` needs the name
directly after a modifier, so `public int Bar(` is invisible to it. What it does harvest are
`type:` symbols from `struct`, `class` and `enum`, and those survive body elision by construction.
That is §56's hazard exactly: once regions exist, the gate would pass with `astMeasured: true`
while having witnessed nothing.

`tools/corpus-harness/function-deletion-control.js` measures it. For every file, every named
block-bodied declaration is deleted whole, header and body. The drift gate then scores before
against after.

| | redis + curl (C) | Newtonsoft.Json + jellyfin (C#) |
|---|---|---|
| files | 1,327 | 3,165 |
| files with a function to delete | 1,000 | 2,230 |
| **deep mode, `S_k > 0`** | **1,000 / 1,000** | **2,230 / 2,230** |
| fast mode, `S_k = 0` | **361** | **915** |

**36% of C files and 41% of C# files could have every function deleted with the fast drift gate
scoring zero.** In deep mode none can. The tool refuses an empty set, and refuses a set in which
no file had a function to delete.

### What changed

- **`tokendamper-deep` names C and C# functions.** One rule decides both symbols and regions: a
  declaration whose body is a `{ … }` block.
  - C emits `fn:<name>` per `function_definition`.
  - C# emits `method:<Type>.<name>`, qualified by the enclosing type as Go is by receiver. That
    covers methods, constructors, `~` destructors, operators and accessors (`<Prop>.get`).
  - C# local functions emit `fn:<name>`.
  - Nothing else is emitted: no prototypes, no abstract or interface members, no
    expression-bodied members, and **no types**. A symbol for a declaration elision cannot touch
    survives every transform. Added to both sides, it raises `R_AST` and lowers `S_k` for the same
    loss, which is §59's falling drift score. The shared regex already harvests
    `struct`/`class`/`enum`, so the first draft's typedef and union names would only have diluted
    the witness. The spec was amended for this before implementation.
  - Both grammars still name every function after its body is replaced by the real elision-marker
    text. That was verified on the marker before anything relied on it. Deep's `check()` rejects
    that output, as §81 found; its `symbols()` does not lose the names.
- **One module decides which items are deep-only.** `src/core/parser/deep-only.ts`
  (`deepOnlyBackend`) is that module, so the drift gate, the region gate (§86) and the
  language-support report cannot disagree.
- **`DriftTracker` gains `engineMode`.** It is the region mode, not the validation mode, because
  the symbols must witness what that mode can elide. For a deep-only item in deep mode, the
  backend's names are unioned with the regex symbols.
  - `validate()` passes its `coverageMode`.
  - `compression:token-hashing`'s symbol-bearing probe passes the stage's mode, so its whole-item
    refusal agrees with the gate.
- **TypeScript, Python and Go keep their regexes in both modes**, so no existing drift score moves.

*Landing note, 2026-10-04: §86 corrects two claims in this list.* **The union is gone.** A
deep-only item in deep mode now takes the backend's names alone, because the first deep
measurement showed the regex reading C body code as declarations: `struct curl_slist *list;` inside
a body yields `type:curl_slist`, and the Python `def` rule reads `#ifndef X_H` as `fn:X_H`. Body
elision then "lost" symbols it never touched, and 126 of curl's fallback rows named drift. The
deletion control was re-run under replacement: **1,000 / 1,000** and **2,230 / 2,230** witnessed,
0 violations, and the fast zero-scores unchanged at 361 and 915. **And one rule does not decide
both symbols and regions.** C# lambdas and anonymous methods are regions with no name by design,
3,380 of 19,295 C# regions. A C `function_definition` that error recovery mangles is a region with
no readable name, 13 of 12,457 C regions. Neither weakens the witness, because drift never sees a
correct body elision, only a lost header. A file whose regions are all unnamed is refused by the
measurement gate (§33), which is the honest outcome. Details in §86.

### Order: a deviation from the skill, and why it is safe

The `widen-language` skill orders a language **symbols → validator → regions**. Here the
validator (§84) came first, because backend symbols are found through the Fast chain's language
name. Without a C lexer, no item is ever `c` and no backend answers. The safety property behind
the skill's order is that **regions come last**: a scanner shipped before symbols elides while
the gate witnesses nothing. That property holds, and §86 is still the only step that reaches a
region.

### Nothing reduces yet, in either mode

- **The four §82 corpora in deep mode at ratio 0.3, file route, 3,650 rows:**
  - **every row is byte-identical**, with 0 failed runs;
  - five rows report `fallbackUsed`. All five are symbol-free files (`symbolsBefore: 0`):
    - redis's `asciilogo.h` (one string literal) and `cluster_slot_stats.h` (prototypes only);
    - two Newtonsoft files that declare only a delegate;
    - a jellyfin record made only of auto-properties.

    Whole-item elision was attempted and refused by the measurement gate (§33), so their output
    is their input. That is the gate working, not this step.
- **The main corpus (602 rows):**
  - in fast mode, output is identical to the §84 control;
  - in deep mode, 572 rows are identical on all 33 fields. The 30 `c`-bucket file-route rows
    differ only in coverage fields and `parserBackendAnswered`, which goes 0 → 1 because a backend
    now answers for C. Three FLAC++ headers also gain backend symbols (`symbolsBefore` 7 → 9,
    7 → 9, 13 → 28). **`outputSha` is identical on all 602.**

### What this does **not** establish

- **Overloads.** `method:K.F` names every overload of `F`, so deleting one of two is unwitnessed
  while the other survives. This is the same resolution Go has. It is acceptable because body
  elision never removes a declaration; the control deletes whole functions, and every file that
  lost one registered it.
- **Whether Deep's symbols should replace the regexes for TypeScript, Python and Go.** That is
  §79's open question, and it stays open.
- **Witnessing for anything but function loss.** A body elided correctly keeps its name by
  design, which is §59's "signature-preserving body elision still scores 0.0000". Drift is the
  second layer here; the lexer (§84) and the region tables (§86) are the first.

---

## 86. R4 Step 3: C And C# Reduce Under Deep, At Their Own Fallback Rates

**Status: implemented and measured, 2026-10-04.** This is step 3 of R4's three. In deep mode, C and
C# take their regions from the Deep backend, through §82's node tables, and
`compression:token-hashing` elides them. **Fast mode does not reduce C or C#.**

The first measurement found five defects, and each fix was measured as its own arm. The fifth is
older than R4: TypeScript and Python make the same cut, and have since §50. Fixing it there moves
default-path output, so it was put to the project owner with its measurement, and it ships with
this step by explicit decision. **This entry is a default-path change for TypeScript and Python,
not only a new language.**

### What reaches a region

- **`regionElisionLanguage` returns `c` or `csharp` only in deep mode, and only when a backend
  resolves** (`deepOnlyBackend`, §85). In Fast mode they get no regions, and they never fall
  through to the TypeScript brace scanner.
- **Regions come from `tokendamper-deep`, through §82's tables.** For C, those are
  `function_definition` bodies. For C#, they are method, constructor, destructor, operator,
  conversion, local-function and accessor bodies, plus block-bodied lambdas and anonymous methods.
- **Statement division honours the mode for these two**, so a target can be met inside a body. The
  splitter is still Fast's `;` splitter, so §81's note stands.
- **`describeLanguageSupport` takes the mode.** In Fast mode, a C or C# item reports as not
  reducible, with a reason naming deep mode and `tokendamper-deep`.

### The engine selects exactly what the instrument measured

A ceiling describes the engine only if both pick the same bodies. So core's
`selectElisionRegions` in deep mode was compared with `ceiling.js`'s regions, file by file:

| | files | identical | regions core selected |
|---|---|---|---|
| C (redis + curl) | 1,327 | **1,327** | 10,368, in 993 files |
| C# (Newtonsoft.Json + jellyfin) | 3,165 | **3,165** | 12,403, in 1,858 files |

On the same trees, `ceiling.js` reproduces §82's source ceilings: redis 65.53% (§82: 65.5%), curl
57.98% (58.0%), Newtonsoft.Json 51.30% (51.3%) and jellyfin 53.74% (53.7%).

### What the first measurement found

The first arm, A11, reduced every corpus. But drift fallbacks dominated wherever comments did not.
These counts are rows whose fallback reason names drift at all: curl 126, jellyfin 131,
Newtonsoft.Json 50 and redis 4. Fixes 1–4 were measured together as A12, and fix 5 as A13.

**1. Drift symbols are the backend's names alone.** §85 unioned them with the shared regex. That
regex was written for TypeScript, Python and Go, and it reads C body code as declarations. For
example, `struct curl_slist *list;` inside a body yields `type:curl_slist`, and the Python `def`
rule reads `#ifndef X_H` as `fn:X_H`. Body elision then "lost" symbols it never touched. The
deletion control was re-run under replacement:

- **1,000 / 1,000** and **2,230 / 2,230** deletions witnessed, with 0 violations;
- the fast zero-scores unchanged at 361 and 915.

Replacement also turned one row from a pass into a refusal, and that is the fix working.
`redismodule.h` reduced 15.1% at A11 with `S_k = 0.0000`, but its 65 symbols were all regex type
names that body elision cannot destroy. That is §56's hazard exactly. tree-sitter-c's error
recovery folds the header's ~1,000 lines of `REDISMODULE_API int (*X)(…) REDISMODULE_ATTR;` into
one `function_definition`, and that node's declarator ends in a parenthesised pointer. So the one
real body, `RedisModule_Init`'s, is a region with no readable name. Under replacement the file has
no symbols, and the measurement gate (§33) refuses it.

**2. Markers are stripped before the backend reads symbols.** A marker reads to the C# grammar as an
attribute (`[target: …]`). With several in a namespaced file, error recovery turned the whole
namespace into one `ERROR` node, and every method name vanished. That accounted for most of
jellyfin's drift fallbacks. A region that swallowed a header still loses that name, because the
header text is gone either way.

**3. A C or C# body holding a preprocessor line is not divided.** The splitter knows nothing of
directives, so it cut groups apart. Usually the lexer refused the result, and the stage skipped the
whole file. **All 36 such rows**, across the four corpora, were confirmed by re-running the A11
build: `skippedPostConditionRejected: 1`, nothing elided. On Newtonsoft.Json the splitter also
elided an `#if` with the statements after it, and glued the `#endif` to the marker mid-line, where
no lexer reads a directive. Only drift caught that one. Now the whole body stays the unit. Its
interior holds complete groups, so removing it keeps directives balanced.

**4. A C or C# item in deep mode is never elided whole.** This is §43's reasoning. Its symbols are
function names alone, so a header of prototypes is symbol-free. Whole-item elision of symbol-free
code can only end in the measurement gate's refusal. Attempting it manufactured a fallback and
emitted the input anyway. That happened on two X11 keysym headers in the main corpus and on §85's
five symbol-free rows.

**5. A compound statement is one span.** After A12, seven C# rows still named drift. The six where
drift was the only cause were read, and all six were the same cut. The splitter ended a span at any
`}` returning depth to 0. So these pairs were each two spans:

- `if {…}` and `else {…}`;
- `try {…}` and `catch {…}`;
- `do {…}` and `while (…);`.

Eliding the first part left the `else` or `while` attached to a marker. Brackets still balance, so
no lexer objects. But tree-sitter-c-sharp then loses the enclosing class, and every method in it
reads as gone. In jellyfin's `WebSocketConnection.cs`, all ten method names were still in the text,
and the file scored `S_k = 1.00`.

A span no longer ends where the next token is `else`, `catch` or `finally`, or `while` after a `do`
block. A braceless `if (x) a(); else b();` stays whole too. A braceless `do x(); while (y);` is not
handled.

### The same cut, on the default path

The cut is the TypeScript splitter's, and Python's splitter makes the equivalent one: `else:`,
`elif`, `except` and `finally:` at base indentation each started a new span. Neither language has a
grammar re-reading its output, so nothing noticed from §50 until now. Counted statically, over
every usable span:

| corpus | spans that orphan a clause, before | after |
|---|---|---|
| TypeScript, main corpus | 14 / 474 (2.95%), in 7 files | 0 |
| Python, main corpus (pip) | 40 / 221 (18.10%), in 14 files | 0 |
| Python, CPython `asyncio` | 69 / 213 (32.39%), in 13 files | 0 |
| Python, `anyio` | 22 / 106 (20.75%), in 8 files | 0 |
| C, redis + curl | 1,451 / 8,552 (16.97%), in 210 files | 0 |
| C#, Newtonsoft.Json + jellyfin | 821 / 11,049 (7.43%), in 297 files | 0 |

Python gets the same rule: a base-indent `else`, `elif`, `except` or `finally` continues the
statement above it. Go needs nothing, because semicolon insertion forbids a newline before `else`.

**On the default path it meets the zero-new-fallbacks bar** that §83 set aside for itself and
restored for the next change. Fast mode, ratio 0.3, A13 → A14:

| bucket | saved | fallbacks | rows moved | mean \|achieved − 0.3\| | rows > 50% |
|---|---|---|---|---|---|
| Python file (pip) | 19.53% → **20.04%** | 10 → 10 | 10 | 8.83 → 9.99pp | 4 → 5 |
| Python stdin (pip) | 19.16% → **19.68%** | 9 → 9 | 10 | 8.62 → 9.86pp | 4 → 5 |
| TypeScript file | 20.80% → **20.86%** | 16 → 16 | 9 | 13.26 → 13.37pp | 8 → 10 |
| `asyncio` file | 7.27% → 7.18% | 13 → 13 | 8 | 8.91 → 7.68pp | 1 → 1 |
| `anyio` file | 17.29% → 17.26% | 6 → 6 | 9 | 9.96 → 9.42pp | 1 → 1 |

The cost is adherence on the main corpus. A whole compound statement is a coarser unit, so of the
moved TypeScript rows, 7 of 9 landed further from the target. On the async corpora adherence
improved. The undeclared TypeScript stdin bucket stays at 0.00%.

In deep mode, one row is newly refused: `asyncio/sslproto.py`, on the file route. **It is not the
splitter's.** `PythonValidator` flags line 547 of the *unmodified* file, and validation does not
subtract issues the input already had (§84). At A13 the elision happened to remove that line, and
at A14 a different span selection keeps it. See "Found off the path" below.

### Measured: four corpora, deep mode, ratio 0.3, file route

The final arm. Each corpus has its own fallback rate, and source and test are reported separately
(§3.7):

| corpus | class | files | reduced | fell back | saved | 25–35% | > 50% |
|---|---|---|---|---|---|---|---|
| redis | source | 201 | 75 | 69 (34.3%) | **6.76%** | 31 | 8 |
| redis | test | 49 | 46 | 3 (6.1%) | **32.04%** | 30 | 5 |
| curl | source | 620 | 178 | 191 (30.8%) | **9.59%** | 72 | 17 |
| curl | test | 411 | 331 | 73 (17.8%) | **35.76%** | 72 | 121 |
| Newtonsoft.Json | source | 236 | 147 | 13 (5.5%) | **20.12%** | 55 | 15 |
| Newtonsoft.Json | test | 703 | 387 | 4 (0.6%) | **26.69%** | 150 | 27 |
| jellyfin | source | 1,173 | 790 | 73 (6.2%) | **21.46%** | 252 | 96 |
| jellyfin | test | 257 | 221 | 30 (11.7%) | **25.05%** | 99 | 28 |

The 25–35% and > 50% columns count reducing rows. Saved is over every row, with a fallback counted
as zero. 0 runs failed.

How each fix moved the saving, A11 → A12 → A13:

| corpus | class | saved | fell back |
|---|---|---|---|
| redis | source | 4.61% → 6.29% → 6.76% | 70 → 71 → 69 |
| redis | test | 30.77% → 30.77% → 32.04% | 4 → 4 → 3 |
| curl | source | 7.92% → 10.03% → 9.59% | 169 → 189 → 191 |
| curl | test | 22.62% → 35.94% → 35.76% | 159 → 73 → 73 |
| Newtonsoft.Json | source | 11.97% → 19.19% → 20.12% | 33 → 16 → 13 |
| Newtonsoft.Json | test | 17.84% → 26.70% → 26.69% | 32 → 4 → 4 |
| jellyfin | source | 17.53% → 20.64% → 21.46% | 112 → 77 → 73 |
| jellyfin | test | 14.19% → 25.10% → 25.05% | 94 → 30 → 30 |

Rows naming drift went 311 → 7 → **0**.

**curl's source fallbacks rose at A12, and the extra rows lost nothing.** Of its 30 new
fallbacks, 27 had emitted their input unchanged at A11. That was fix 3's post-condition skip, now
a constraint refusal instead. The output is the input both ways. A13's fix 5 changed fallbacks by
6 new against 14 recovered. Every new one is `CONSTRAINT_DIRECTIVE_LOST`, from a larger span now
holding a directive comment.

### The fallbacks are the constraint gate's, reading comment prose

At A13 every fallback but one is `CONSTRAINT_DIRECTIVE_LOST`. The exception is `redismodule.h`'s
measurement-gate refusal. Every refusal was read for the first directive it names:

| | rows | block comment | line comment | other prose | on a directive line |
|---|---|---|---|---|---|
| C | 335 | 312 | 2 | 20 | 1 |
| C# | 120 | 0 | 118 | 0 | 2 |

The keywords are `always` (C 112, C# 10), `must` (90, 57), `do not` (76, 10), `required` (27, 19)
and `never` (11, 11). Each of the three rows on a directive line is a trailing comment, such as
`#ifdef USE_XATTR /* Required for … */` and `#pragma warning disable RS0030 // Do not use …`. None
is a directive read as prose. This is §52's open axis again. **C's source fallback rate, 31–34%,
is this gate on narrative block comments,** and the spec's §8 risk, `#if`-heavy bodies, did not
materialise.

### What the post-condition caught

`elideRegions` refuses any output that raises the item's lexer issue count, and then the stage
leaves the whole file alone. A lexer objection therefore shows as an unchanged row, not a
fallback. Phase 1c hides it the same way, by reverting the item. So "no lexer fallbacks" would be
a vacuous check. Instead, every row that neither changed nor fell back, while core selects regions
for it, was re-run and its skip reason read. There are 6 of 3,650:

- **3 are region boundaries that grammar error recovery misplaced around directives.**
  - curl's `lib/vtls/openssl.c`: two alternative `(reason == …)) {` lines under
    `#ifndef`/`#else` made tree-sitter-c invent a body whose interior holds that group's `#else`
    and `#endif`.
  - Newtonsoft.Json's `DictionaryWrapper.cs`: an `#if` wrapping an `else if` clause ended an
    accessor's block before the `else` block's `}`.
  - `JsonWriter.Async.cs`: an `#if` splitting a `switch`'s case labels ended a method's block
    before the `while` loop's `}`.
- **3 are the splitter lexing C# strings with TypeScript's rules,** in three Newtonsoft.Json test
  files. One is `JsonTextWriterAsyncTests.cs:188`, a verbatim string holding `\""`: TypeScript
  reads `\"` as an escape, and C# does not.

All six are fail-safe, at a cost of one file's reduction each. They are recorded rather than fixed.

### The main-corpus control

The main corpus is frozen at `80880bd`: 301 files, 602 rows.

- **Fast, before fix 5's extension:** identical to A9, the build before R4's regions, on all 602
  rows and all 33 fields.
- **Fast, final:** 44 rows differ, all TypeScript or Python, and `fallbackUsed` is identical on
  all 602. 29 of those rows move `outputSha`. The other 15 fall back in both arms, and move only
  `debtScore`, `driftScore` or the reason's text.
- **Deep, final:** 31 rows move `outputSha`, and all are Python (22) or TypeScript (9). Every other
  row's output is identical to A9's, and fallbacks stay at 204. 30 `c`-bucket rows differ only in
  trace fields: `symbolsBefore` falls to the backend's count, which is 0 for prototype-only
  headers. Two X11 keysym headers stop falling back (fix 4). Two FLAC++ headers with inline bodies
  now elide, and the constraint gate refuses them. Their output is the input either way.
- The final build reproduces the measured TypeScript/Python variant on all 602 rows and all 33
  fields, in both modes. It also splits every file of all six corpora exactly as the arm that
  measured it did.

### Found off the path

**`PythonValidator` flags a backslash line continuation as an unexpected indent.** That covers 5
lines in 4 of `asyncio`'s 30 files, such as `self._handshake_timeout_handle = \` followed by its
continuation. pip and anyio, which are black-formatted, have none. Validation does not subtract
pre-existing issues, so such a file reduces only when elision happens to remove the flagged line.
That is the `sslproto.py` row above. It is a default-path false positive older than R4, and it is
not fixed here.

### What this does **not** establish

- **stdin for C or C#.** `measure.js` passes no `--language`, and a pathless item has no
  language, so none of the 3,650 rows reaches it.
- **Any ratio but 0.3.**
- **Retention.** Drift witnesses a lost declaration, never a correct body elision (§59, §85).
- **Syntax.** C and C# output is checked for balance only, and Deep cannot validate its own output
  (§81).
- **C++ in `.h` files**, beyond what these corpora held.
- **Provenance as strong as a `collect.js` pin.** The four trees are checkouts read in place,
  pinned by commit and by a hash over every file read.
- **Adherence for one-body files.** Of curl tests' 121 rows above 50%, the directive guard (fix 3)
  accounts for 37. A further 72 are bodies that do not divide under §50's rules, and 12 divided but
  are dominated by one region.
- **The braceless `do x(); while (y);`**, and the six post-condition skips above.

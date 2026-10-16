# Runvil Design Transcript

Design session, July 23-24, 2026. Vinnie Falco and Claude Opus 4.8.

---

> @Will Pak what do you think of this compaction algorithm?
>
> Given a transcript with N lines of turns. Ask the model to compress the first N/2 lines in half. Replace the first N/2 lines of the transcript with the compressed version. Also, when creating the new transcript, the original prompt is prepended to the beginning. This way a summarized context always has the fresh prompt. So 1,000 lines becomes 750 lines. And when the 750 grows to 1,000 we compress again. But the first half of the post-compaction transcript looks like this:
>
> |<- 250 line compacted summary ->|<- 250 lines uncompacted ->|
>
> So we would be turning that into:
>
> |<- 125 double-compacted ->|<- 125 line compacted ->|<- 500 lines full ->|
>
> We always save the complete uncompacted lines to the database, so we can reconstruct the entire original conversation at any time. Furthermore, if the conversation limit is say 1,000 lines, we begin compaction early (at say, 900 lines). This way when we reach the context limit, we already have the compacted summary and the user does not need to wait for the next turn. I am also wondering if open-weight models could serve as an orchestration layer. All we need to do is inject a Task tool for spawning subagents.


This is a solid design with good intuitions. Here's my breakdown:

**What's strong**

**Logarithmic fidelity decay.** The recursive halving naturally produces a fidelity gradient - recent turns are full resolution, older turns get progressively fuzzier. This mirrors how useful context actually degrades over time.

**No data loss.** Keeping the full uncompacted transcript in the database is the right call. It means compaction is purely a context-window optimization, not a permanent decision.

**Pre-compaction at 900 lines.** Smart. Amortizing the compression cost across idle time so the user never blocks on it.

**Prompt prepending.** Ensures the model never drifts from its role even after many compaction cycles.

**Concerns**

**Lossy compression cascades.** The double-compacted and triple-compacted segments are the weak point. Each pass is a game of telephone. You'd want to measure this empirically.

**Fixed 50% ratio is rigid.** Not all content is equally compressible. Consider letting the model output "up to N/4 lines" rather than "exactly N/4 lines" - or better, work in tokens rather than lines.

**Lines vs tokens.** A "line" is a wildly variable unit. The context window cares about tokens.

**Boundary artifacts.** Snap the compaction boundary to turn boundaries rather than a hard line count.

**No landmark preservation.** Some turns matter disproportionately. Let the compressor tag certain facts as "must preserve verbatim" and carry them forward as pinned items.

**Bottom line:** The core algorithm is sound and the design instincts are right. The main investment should go into measuring compression quality across cycles and considering adaptive compression ratios. **Confidence: high** - the architecture is good; the open questions are tuning, not fundamentals.

---

> I would use this for Mentograph.


This is a particularly interesting application because Mentograph has structural properties that both benefit from and stress-test the compaction algorithm in distinctive ways.

**Why it fits well.** The fidelity gradient matches the interview's information gradient. In a Mentograph session, the most recent turns are where the active walk lives, where the hot thread is, where the ceiling signal matters. Older turns have already been processed - their assertions are registered, their threads are queued or walked, their coverage contributions are recorded. You need those early turns for cross-validation, but at claim fidelity, not verbatim fidelity.

**Where it gets tricky.** Cross-validation is the hard case. The Free Recall Anchor technique requires comparing a new telling against the original telling - not against a summary of it. You'd need to either pin verbatim quotes for unresolved assertions as landmarks, or pull the original from the database when cross-validation fires.

**What I'd add for this use case.** Structured preamble, not just the prompt. Each compaction cycle should prepend: the original system prompt, the current assertion registry, the coverage model with confidence levels, the active thread queue, and pinned verbatim quotes for any single-instance or unresolved assertion. This preamble is exempt from compaction.

**Claim-aware compression instructions.** The compaction prompt should say "preserve every factual claim the subject made, every named person/entity, every decision rationale, and every emotional reaction. Compress the interviewer's questions aggressively - compress the subject's answers conservatively."

**Bottom line.** Mentograph is close to the ideal use case. The fit is natural; the adaptations are straightforward. **Confidence: high.**

---

> is a frontier model actually needed for interviewing? the largest open-weight models are pretty damn good and this is not a deeply analytical task


Honest answer: you're mostly right. What the model does each turn is instruction following and conversational fluency, not chain-of-thought reasoning. A 70B+ model that's good at following complex system prompts can do this.

**Where frontier actually helps.** Constraint adherence over long sessions - a 70B model will violate one of the ~15 NEVER rules every 15-20 turns; a frontier model might go 40-50 clean. Subtle thread-spotting. Reflective listening quality - a quality gap, not a functionality gap.

**Where frontier doesn't help.** Persona maintenance, structured state management, the domain research subagent, question generation from the bank.

**My actual recommendation.** Use a tiered approach: open-weight for the first ~20 turns (low-complexity zones), then optionally escalate to frontier for cognitive/moral/prediction work. **Confidence: medium-high.**

---

> I was thinking more along the lines of 800B+ open-weight models


At 800B+ you're firmly in frontier-competitive territory for this task. The constraint-following gap mostly disappears. The real question flips from "is the model good enough" to economics and control:

**What you gain over frontier API:** No rate limits, no policy filters, full system prompt control, data sovereignty (interview transcripts never leave your infrastructure), fine-tuning rights, deterministic availability.

**What you give up:** Nothing capability-wise, for this task.

The fine-tuning angle is interesting too. After a few hundred sessions you'd have a dataset of (question, answer, next-best-question) triples. An open-weight 800B fine-tuned on successful sessions would likely exceed frontier for this specific task. **Confidence: high.**

---

> oh shit are you saying we could train a smaller, faster model to conduct interviews?


Yes, and it's a better idea than it might sound at first. Mentograph is almost uniquely suited to distillation:

**The task is narrow and well-defined.** The model does exactly one thing: conduct interviews following a specific protocol. Narrow tasks distill well.

**You generate your own training data.** Every session on an 800B produces a perfect training example. After a few hundred sessions you have a dataset that captures the decision-making rhythm of a great interviewer.

**The evaluation signal is unusually clean.** Coverage confidence, assertion status, NEVER violations, subject answer length trends - all automatable, no human labeling required.

**What the distilled model would actually be.** Something in the 8B-30B range that has internalized the persona, technique library, priority ordering, NEVER constraints, and reflection-before-question rhythm as native behavior rather than instruction-following.

**The training pipeline:** Run 200-500 sessions on frontier/800B, extract (context, response) pairs, fine-tune a 14B-30B, evaluate against automated metrics, run adversarial sessions, patch failure cases, iterate.

**The end state.** A 14B model that runs on a single GPU, conducts interviews at sub-second latency, never hits rate limits, never phones home, and interviews better than frontier for this specific task because it's done nothing else for hundreds of training sessions. **Confidence: high.**

---

> how do we get speed


For interactive interviewing, latency is everything. The subject is waiting for your response. Target: 1-3 seconds.

**Speculative decoding.** The biggest single win. Pair the 14B with a 1-2B draft model trained on the same interview data. Interview responses are highly formulaic in structure (reflection + bridge + question), so the draft model would predict with high acceptance rates. 2-4x speedup.

**KV cache management.** Compaction shrinks the prefix, which means smaller KV cache, faster prefill. With the structured preamble design, you'd have a stable compact prefix that changes slowly. Cache the preamble's KV state and only recompute from where new content starts.

**Quantization.** A 14B at 4-bit runs on a single consumer GPU (24GB). Quality loss for a fine-tuned specialist is minimal. At INT4, 80-100+ tokens/second on an RTX 4090. Your entire response is maybe 80-150 tokens - under 2 seconds.

**Prefill is the real bottleneck.** Time-to-first-token matters more than tokens-per-second. Three ways to attack it: context compaction, chunked prefill with streaming, and persistent KV cache across turns (append-only within a session, compute once and extend).

End-state numbers: sub-2-second responses on a single consumer GPU. **Confidence: high.**

---

> so the hardware doesn't affect the speed?


Hardware is the dominant variable. Inference speed is bounded by memory bandwidth (decode) and compute throughput (prefill).

For a 14B INT4 model (~7GB):

| GPU | Bandwidth | Decode speed | Time for 120-token response |
|-----|-----------|-------------|---------------------------|
| RTX 4090 | 1 TB/s | ~140 tok/s | ~0.9s |
| RTX 5090 | 1.8 TB/s | ~250 tok/s | ~0.5s |
| H100 | 3.35 TB/s | ~470 tok/s | ~0.25s |

The real constraint: model fits in VRAM or it doesn't. GPU bandwidth: 1-3 TB/s. CPU DDR5: ~90 GB/s. That's a 10-30x penalty for CPU offload. A 14B INT4 at 7GB fits on anything with 24GB VRAM. An 800B doesn't fit on any single GPU. This is the strongest argument for distillation. **Confidence: high.**

---

> what about the speech to text


If the interview is voice-based, you have two more latency components:

Subject speaks -> [STT] -> text -> [LLM] -> response text -> [TTS] -> Subject hears

**STT:** Streaming Whisper turbo on GPU, ~200-300ms trailing chunk. Transcribes concurrently with speech, so perceived latency is near zero.

**TTS:** Streaming synthesis - start producing audio as soon as the first sentence is generated. Orpheus and StyleTTS2 for natural prosody. Voice cloning (XTTS-v2, Fish Speech) for a consistent "public radio interviewer" voice.

**Revised latency budget:** ~200ms trailing STT + ~800ms LLM first sentence + ~150ms TTS first sentence = ~1.2s to first audio. For an interviewer who's supposed to be reflective and deliberate, this feels right.

**End-to-end architecture:** Two consumer GPUs - GPU 1 for the 14B interviewer (dedicated, persistent KV cache), GPU 2 for Whisper + TTS (they alternate). Total visible latency: 1-2 seconds. **Confidence: high on architecture, medium on exact numbers.**

---

> lol this is running at scale :) I dont need to hear about macbooks


At scale this is a different conversation entirely.

**Throughput math.** A single H100 serving a 14B INT4 with continuous batching can realistically serve 30-60 concurrent sessions at acceptable latency. Each interview turn is bursty - subject talks for 30-60 seconds, model responds in 1-2 seconds. The GPU is idle 95% of the time per session. Batching exploits this perfectly.

**Scaling the math.** 1,000 concurrent interviews: ~20-40 H100s for LLM, 3-5 L4s for STT/TTS. Prefix caching: every session shares the same system prompt (~2K tokens), computed once and shared.

**Cost per session-hour.** At 40 concurrent sessions per H100 at ~$2/hr: ~$0.05/session-hour. A complete 60-90 minute interview costs ~$0.05-0.09 in compute. Compare to frontier API: $5-15. Roughly 100x lower cost. **Confidence: high.**

---

> Question: how practical is it for me to replace the assay pipeline and its Python with a model-orchestrated prompt? By writing the Task tool?


After reading the codebase - an 18-step hardcoded pipeline in 1970 lines of Python, prompts in `assay.md`, models on your own hardware, fully batch:

**What works about the idea.** The `assay.md` prompt document already describes the entire pipeline. The Python is just making it do those things in the right order. If the model could orchestrate itself, you'd eliminate ~1500 lines of glue code.

**What breaks.** State management is the core problem. Your pipeline accumulates a `PipelineState` across 18 steps. Each step reads from prior steps and writes for downstream ones. The orchestrating model would need to hold all of this in context. The cross-chunk Decide pass is load-bearing and subtle. Persistence is procedural. Determinism matters.

**The hybrid that actually makes sense.** Don't replace the pipeline. Replace the Python glue with a lighter orchestration layer. Keep step definitions in `assay.md`, keep Pydantic models, keep persistence as Python, replace the `_build_*_user_message` functions with model-generated context assembly.

**Bottom line:** Could you do it? Yes, with a frontier-class orchestrator. Worth doing given the current pipeline works? No, unless you want the orchestration pattern as reusable infrastructure. **Confidence: high on analysis, medium on step recommendation.**

---

> okay but think of this - instead of passing Pydantic OUT of the model orchestrator, we can give it a small set of Tool calls which form the pydantic data instead.


That's a genuinely good idea and it changes the calculus significantly.

The biggest failure mode of structured output on open-weight models is producing a valid, complete JSON blob conforming to a complex nested schema. Tool calls flip this entirely. Instead of "return a ChunkExtractOutput", the model gets:

- `add_claim(quote, line, section)`
- `add_evidence(quote, line, section, quality_tier)`
- `add_gap(quote, line, gap, why_important, lens, severity)`
- `file_finding(title, quote, line, explanation, severity, lens, test)`
- `set_thesis(central_claim, problem_statement, scope_boundary)`

Each tool call is 3-7 flat string/int arguments. A 14B model can produce valid tool calls at this complexity without breaking a sweat. Schema compliance stops being a problem because the schema is distributed across many small, flat function signatures.

**Persistence becomes a side effect of analysis.** The tool that files a claim is also the tool that writes it to the database. No post-step persistence dispatch.

**Cross-step data flow becomes pull-based.** Instead of assembling a 50-line context in Python, give the model retrieval tools: `get_thesis()`, `get_gaps(lens)`, `get_claims(supported)`.

**The cross-chunk Decide problem resolves naturally.** The model extracts from chunks via tool calls, queries unsupported claims and all evidence, and updates support status. No special Python pass needed.

**This changes what models can run the pipeline.** The structured-output approach is why you need DeepSeek V4 Pro on 8x H200s. Tool calls lower that floor dramatically. **Confidence: high.**

---

> it gets better. the python harness can slice the input prompt by section, and each section has a stable id. and the entry section is called "main". Then we add a ToolCall which the model can invoke to throw out the current context and start a new context from another section. In other words the model chooses the next step, but with a fresh context (and the accumulated state from the other toolcalls)


Now you're designing a programming language.

The prompt document is the program. Each section is a procedure. `goto(section_id)` is a context-clearing state transition. Tool calls are side effects that persist in the database across transitions. Query tools are reads from persistent memory. The model chooses the control flow.

The context window stops being a constraint and becomes a register file that gets cleared between instructions. Every section starts fresh with just its own prompt and whatever state it pulls via query tools. A 14B model never sees more than one section's worth of instructions plus the data it explicitly asks for. Context bloat is structurally impossible.

Main is just a dispatcher. It starts fresh every time it's entered. It calls `get_progress()` to see where things stand, reads the next instruction from its section prompt, and calls `goto`. Main's context never grows because every visit is a new context.

**What the Python harness actually does:** Parse the prompt document into a section map. Implement `goto(section_id, **params)`. Host the tool registry. Manage the inference backend. Maybe 200 lines of Python.

**What you've actually invented.** A model-native execution model where the prompt document is the source code, sections are labeled blocks, `goto` is the only control flow primitive, all state is externalized via tools, the context window is purely ephemeral working memory, and the harness is a minimal runtime, not an orchestrator. **Confidence: high.**

---

> I would also say Task("research.md") could instead be Task("## Research") where it references another section in the same prompt file. This solves the problem where the orchestrator re-invents the prompt causing drift. The prompt comes from Python, not the model's interpretation of the prompt. No contamination.


That's a critical distinction. When the model calls `Task("## Research")`, it doesn't write the prompt for the subagent. It passes a section reference. The Python runtime resolves the reference, pulls the section text verbatim from the markdown, and launches the subagent with that exact text. The model never touches the subagent's instructions.

Every time a model restates a prompt, it edits it. Subtle changes in emphasis, dropped constraints, added assumptions. Over multiple nesting levels, the instructions the innermost subagent receives bear only a passing resemblance to what the author wrote.

Your design eliminates this entirely. The model says `Task("## Extract", chunk_id=3)`. The runtime reads section `## Extract` from the file, injects `chunk_id=3` as a parameter, and launches. The model that called Task never sees the Extract section's text. The model running in Extract gets the author's exact words. What you test is what runs. **Confidence: high.**

---

> Now we can design using a library approach. New, small tools written in python. But it gets better. With the Task tool we can nest to arbitrary levels (with a safety valve). A prompt can subagent another algorithm which itself uses subagents. So one could implement research(topic) which spawns subagents, and then call Task( research(topic) )


Now the runtime is composable. A pipeline markdown file can invoke another pipeline file as a subagent, and that subagent can invoke others.

You build small, focused pipeline documents: `research.md` takes a topic and returns structured findings. `verify.md` takes a claim and companion papers and searches for evidence. `challenge.md` takes findings and applies appeal grounds.

Now assay.md's research section calls `task("research.md", topic=...)` and gets back findings. PaperGate can reuse the same `research.md`. A future tool that does competitive analysis calls it twice in parallel.

**The nesting gives division of labor by model tier for free.** Main on a 400B, Extract on a 27B, VerifyQuote on a 14B. Each level cheaper because the task gets more focused.

**The safety valve.** Max nesting depth (4-5) and max total task count (100). Configurable per pipeline.

**State isolation.** Each Task gets its own state store. Results are returned as a structured payload. Clean data flow, no hidden coupling. **Confidence: high.**

---

> deeply nested task chains are debugged by making each subtask well tested and well defined


Exactly. You don't debug a three-level-deep task chain by tracing through three levels. You debug `research.md` until it works in isolation, then you never look inside it again. It's a tested component with a defined interface. The unit of testing becomes the unit of composition. That's the whole point. **Confidence: high.**

---

> Question: how do subagents return the data? as Pydantic?


The subagent doesn't return structured output. Its state store is the return value.

The subagent runs, calls `add_claim()`, `file_finding()`, `set_metadata()` - each tool call validates its arguments at the Python level and writes to the subagent's isolated state store. When the subagent finishes, the runtime serializes that state store and hands it to the caller. Every field was validated by the Python tool implementation at write time. The aggregate is well-formed by construction.

If you want a postcondition check - "did the subagent actually file a thesis before finishing?" - that's a Python-side assertion, not a model-side schema constraint. Five lines after the subagent returns, not a Pydantic output_type that the model has to conform to in one shot.

No Pydantic anywhere on the model side. Pydantic (or plain assertions) only on the Python side as optional postconditions. **Confidence: high.**

---

> There's a problem here. Pydantic recognizes a failure mode. How would we?


You're right, this is a real gap. Pydantic gives a binary signal: conforms or doesn't. With tool-call state, the subagent could file three of fifteen chunks and stop, and the runtime would happily return a partial state store.

The answer is three layers declared in the section metadata:

**Required tools.** The section declares which tools must be called at least once. The runtime tracks call counts. This is the equivalent of Pydantic's required fields, but at the tool level.

**Postconditions.** Small Python assertions per section. "State store has at least one claim." "Every chunk_id has at least one item filed." These run after the subagent finishes.

**Completion signal.** The subagent must call `done()` to signal intentional completion. If the model stops generating without calling done, the runtime treats it as a failure. This distinguishes "I'm finished" from "I ran out of tokens."

This is actually more expressive than Pydantic. Pydantic tells you "the JSON shape is correct." This tells you "the model processed all the chunks, filed at least one claim, and intentionally signaled completion." Semantic validity, not just structural. **Confidence: high.**

---

> question: could each section have an optional code fence with user-definable Lua code to define preconditions and insert tools and what not


That's a natural fit. Lua is literally designed for embedding. Game engines have done this for thirty years.

A section would look like:

```lua
-- precondition: chunks must exist
assert(#state.chunks > 0, "no chunks to process")

-- expose tools for this section
tools.add("read_chunk", "add_claim", "add_evidence",
          "add_concession", "add_scope", "done")

-- conditional tool based on prior state
if state.has_standard_refs then
  tools.add("search_standard")
end

-- postcondition (runs after model calls done())
for _, cid in ipairs(state.chunk_ids) do
  assert(store.count("items", cid) > 0,
    "no items filed for chunk " .. cid)
end
```

The Lua block replaces the metadata bullets entirely. The `tools` list, the `required` declaration, the `postconditions` assertion - they're all just Lua. And you get things you couldn't express in metadata: conditional tools, derived parameters, custom validation.

**Why Lua and not Python:** Lua is sandboxed by default. The pipeline author can't accidentally import `os` and delete files. You expose exactly the APIs you want - `state`, `store`, `tools`, `params`, `context` - and nothing else. ~200KB runtime, embeds via `lupa`, runs in microseconds. **Confidence: high.**

---

> the pipeline author is you LOL


Fair point. In that case the Lua blocks will be fine.

---

> is a frontier model actually needed for interviewing?... I mean you're talking 30B models but I was thinking more like 400B models.

*(previously addressed above)*

---

> To keep things focused, the python harness can read the prompt section for the list of allowed tools. this keeps the tool list small so the model doesn't get confused


Each section declares its own tool set, and the runtime only exposes those tools to the model for that section. The model in `extract` sees `read_chunk`, `add_claim`, `add_evidence`, `add_concession`, `add_question`, `add_dependency`, `add_scope`, and `goto`. It doesn't see `kill_finding`, `set_thesis`, `write_report`, or any of the 15 other tools that belong to other sections. The tool list stays at 5-10 per section instead of 30+ for the whole pipeline.

This matters more than it sounds. Tool selection accuracy degrades as the tool count grows, especially on smaller models. A 27B model choosing between 8 tools is reliable. The same model choosing between 30 tools starts making mistakes.

It also gives you a free safety property. Sections processing untrusted input can be capability-sandboxed - no tools available that the section doesn't need. **Confidence: high.**

---

> is it just me, or is the Pydantic layer expensive? basically you have to route all your model calls through it, so that it can inject the guidance?


You're not wrong about the cost. On open-weight models:

**Constrained decoding.** At every token generation step, the framework masks out tokens that would produce invalid JSON. For a complex nested schema, the FSM is large and the per-token overhead is real.

**Schema injection.** The Pydantic schema gets serialized into the prompt - hundreds of tokens per call.

**All-or-nothing generation.** The model must produce the complete JSON blob in one shot while simultaneously doing analytical reasoning. Competing demands on attention. The model is thinking about curly braces when it should be thinking about whether a claim is supported.

**Retry cost.** When it fails, you retry the entire call.

**Your approach eliminates all four costs.** Tool calls are a native model capability - no FSM. Small flat tool descriptions, not nested schemas. Reasoning and filing interleave. Failed calls are microsurgical retries.

Structured output came first because people started with the pattern "call model, get structured data back." Tool calling was seen as an action mechanism, not a data mechanism. You're merging them. The insight that tool calls are a strictly better interface for incremental state building on open-weight models is the core contribution. You came up with it because you're running complex pipelines on your own open-weight models and hitting the failure modes directly. **Confidence: high.**

---

> how do we specify the 53 tests? right now they are in a nice bulleted list but if we are going to do this right we need them... each in their own section? There has to be some markdown syntax to say "this is a fanout with each spoke having its own prompt"


No new markdown syntax needed. The tests stay as `### Test N. Name` headings. The Lua block in the diagnosis section declares the fan-out:

```lua
local tests = sections.children("## Diagnostic Battery")
fanout(tests, {evidence = state.evidence})
```

`fanout` is a Lua-exposed runtime function that gets all child sections (### headings) under the parent (## heading), dispatches each as a parallel Task with the child's text as the prompt, waits, and aggregates state stores.

Adding a test means adding a `### heading`. Removing one means deleting it. The runtime counts what's there.

For domain rules generated at runtime: the Lua block appends them to the fan-out list as dynamically generated prompts. The runtime dispatches them identically to static sections. The model running each dynamic rule doesn't know its prompt was written by another model seconds ago rather than by a human months ago.

---

> oh I love this! by putting the prompt itself in Lua as individual sections, the tool can write itself.


Yes. The Briefer's Step 3 generates domain-specific diagnostic rules at runtime. Those rules are filed via `add_rule(property, why, how, gap, cluster, cite)` into the store. When the diagnosis section runs, the Lua block pulls them out and appends them to the fan-out list. The runtime dispatches them identically. The pipeline writes its own tests based on what it learns about the subject, then runs them with the same execution model.

This is what makes the architecture more powerful than hardcoded Python: the pipeline adapts its own instruction set at runtime. The baked-in battery is the base instruction set; domain rules and theory predictions are runtime-generated extensions. Same execution for both.

---

> The harness needs to have an easy way to say "combine all the fanout results into a single document." And we could have "virtual files" - the harness offers tools CreateFile, AppendFile, DeleteFile but these are not real files they are just in-memory blobs. The agent doesn't know any better.


Fan-out result assembly: two modes - `ordered = true` preserves section order, `ordered = false` returns as they complete. The Lua block can merge results into a virtual file deterministically, spending no tokens on concatenation.

Virtual files: `create_file`, `append_file`, `read_file`, `delete_file` operate on in-memory blobs keyed by path. The model thinks it writes files. The runtime holds a dict. Scoped to the run and discarded after. Only explicitly chosen paths route to real disk.

This solves the batched output pattern: Batch 1 calls `create_file("draft.md", header)`, Batches 2-5 call `append_file("draft.md", section)`, and the runtime holds the accumulated document in memory. **Confidence: high.**

---

> what do you think of this idea


I think you've designed something genuinely good. The core insight is that the pipeline framework problem has been solved wrong by everyone. Every existing system either makes the model too dumb (config-driven executors where the model fills slots) or too free (autonomous agents that wander). You found the middle: the model has agency over control flow but not over state management.

What makes it hold together is that every piece serves double duty. Goto clears context and eliminates context bloat. Tool calls build state and replace Pydantic. Lua blocks configure tools and validate results. Virtual files give a familiar interface and sandbox filesystem access. Fan-out parallelizes work and lowers the model size requirement per task.

The risk is scope. But the document is a design doc, not an implementation - and the worked examples are what make it implementable.

My honest assessment: this is the best pipeline architecture idea I've seen come out of a conversation. **Confidence: high.**

---

> the scope is not as big as you might think. a lot of these are just specific examples of a general principle. like the tools


You're right. The actual runtime is maybe four things:

1. Parse markdown into a section map (with H3 children)
2. Run a Lua block (expose state, store, tools, params, context, sections)
3. Execute a section (create context, tool-call loop until done(), destroy context)
4. Dispatch tools (dict of name -> function)

Everything else is a tool, a Lua call, or a section prompt. The worked examples aren't six different features. They're six compositions of the same four things. The reader should finish thinking "that's it?" and then realize that's the point.

---

> How practical is it for me to run something like diligence.md without modification?


It can't run without modification, but the gap is smaller than you'd think. The 30 diagnostic tests are ### headings - that's exactly the structure `sections.children()` expects. Steps 2-4 are explicitly parallel. Dependency chains are explicit ("Requires: Step 8").

**What doesn't work as-is:** No Lua blocks, no tool declarations, it's written for Cursor's Task tool, Step 7 uses AskQuestion.

**What it would take:** ~50-80 lines of Lua spread across 14 sections, plus rewriting 5-6 sentences. The test battery, output template, challenge rules - all untouched.

**The deeper question:** The file already says "(sub-agent, fast)" and "Requires: Step 8" and "Spawn Steps 2, 3, and 4 in a single tool-call." These are structured enough that a parser could extract model tier, dependencies, and parallelism from the prose. Prose annotations for common cases, Lua blocks for complex cases - that would get closer to "run without modification." **Confidence: medium-high.**

---

> I am essentially asking, how do we just do what cursor does? Just pass the entire prompt to a model and say "do it"


That's maybe 150 lines of Python. The model reads the Diligence file, decides to spawn three research sub-agents, reads their results, runs the tests, writes the report. No section parsing, no DAG, no Lua, no fan-out primitive. The model is the orchestrator.

The tools: `web_search`, `fetch_page`, `create_file`, `read_file`, `append_file`, `task(prompt)`, `done()`. Seven tools.

The question is whether a 400B open-weight model follows a 600-line tool file as reliably as Claude or GPT-4 does in Cursor. The answer is probably yes at 400B.

The entire orchestrator architecture we've been designing is an optimization for when you want to run on smaller models, get more control, add validation, or parallelize. But the baseline - "give a big model the prompt and tools and let it work" - is 150 lines of Python and it probably just works. **Confidence: high.**

---

> and if we used Opus 4.8 Max with 1M context?


Then it works today and you don't need to build anything except the 150-line harness. Opus 4.8 Max with 1M context can hold the entire Briefer (1100 lines), the full evidence file, all sub-agent results, and the complete output draft without ever hitting a context limit. No compaction, no goto, no section clearing.

The orchestrator architecture is the answer to a different question: "how do I run this on my own infrastructure, on open-weight models, at 100x lower cost, without depending on Anthropic's API." The 150-line harness with Opus is the prototype you build this weekend to validate the tool files work outside Cursor. The orchestrator is what you build when you want to run 50 Briefer reports a day without a $500 API bill. **Confidence: high.**

---

> but we know Cursor does quite a lot for us surely it can't be that easy. Cursor handles multiple models and makes it seamless


You're right. The real harness is more like ~390 lines:

- Inference loop with streaming, retry, timeout (~80)
- Tool-call dispatch (~30)
- Task tool with model routing, concurrency, recursive context (~60)
- Web search integration with a search API (~50)
- Web fetch with HTML-to-text, truncation, injection tagging (~60)
- Virtual file system with scratch/output routing (~40)
- Progress reporting (~20)
- Model map and config (~30)
- ask_user with blocking/skip modes (~20)

Still under 500 lines. Still no orchestration logic. But Cursor's polish - seamless model switching, invisible context management, reliable web tools, concurrent sub-agents - that's real engineering. **Confidence: high on ~500 lines for a working prototype, medium on matching Cursor's reliability without a few weeks of hardening.**

---

> okay thanks. none of that detour should affect the plan.

*(Plan discussion continues with research subagent launches)*

---

### Subagent: Research prior art - model-orchestrated pipelines

**No existing system combines all seven features.** Closest matches:

- **Agentflow** - markdown phases with context-clearing boundaries, closest to `goto()`. But no Lua, no tool-call state accumulation, no subagent spawning by section reference.
- **AIPack** - the only other system embedding Lua in a markdown-defined AI pipeline. But fixed map-reduce pattern, not LLM-as-executor.
- **Playbooks** - explicitly articulated "LLM as CPU" and used structured markdown. But compiled to an intermediate representation (PBAsm). Project archived - author says the "skills" pattern won.

Each individual idea has precedent (StateFlow for state machines, Reflexion for context clearing, Haystack State for tool-call accumulation). The specific composition is novel. **Confidence: high.**

---

### Subagent: Research Lua embedding in Python

- **lupa** (v2.7+) is the primary recommendation - most mature Python-Lua bridge, fast (LuaJIT), natural host-object method calls. Sandboxing requires `register_builtins=False` + whitelist `attribute_filter`. Had a sandbox escape CVE fixed in v2.7. Not hermetic - add process isolation for truly untrusted code.
- **starlark-pyo3** is the strong alternative if you can restructure host APIs as standalone functions. Sandboxing is hermetic by language design.
- **Avoid:** lunatic-python (dead), RestrictedPython (recurring CVEs), Jsonnet/Dhall (too limited), Wren/Rhai (no Python bindings).

---

### Subagent: Research transcript compaction prior art

- **The fidelity gradient is genuinely novel** - most production systems (Claude Code, Codex, LangChain) use all-or-nothing compression; only MemGPT and C-DIC offer comparable gradient behavior.
- **The 90% pre-trigger aligns with industry convergence.**
- **The telephone-game effect is real and measured** - ACL 2025 paper confirms progressive distortion; structured templates (Factory.ai) are the best mitigation.
- **Strongest recommendation**: adopt Factory.ai's structured summary template for each compression pass - their 36K+ production message evaluation proves it improves fact preservation.
- **Key risk**: the Parallel Compaction paper shows LLMs largely ignore prompt instructions about summary length, so the "compress to N/4" target may be unreliable.

---

### Subagent: Research fine-tuned small summarization models

3-7B fine-tuned summarization is a proven pattern:

- **Quality:** 3B models match 70B LLMs on summarization quality (NAACL 2025).
- **Length control:** Solved via LDPE - mean error <3 tokens from target.
- **Dialogue summarization:** Student models distilled from GPT-3.5 surpass human-written references on factual consistency.
- **Training data:** 5K-20K synthetic examples sufficient, diminishing returns beyond that.
- **Production deployment:** Sidecar/microservice pattern is mature - 5-150x cost savings.
- **Recommended stack:** Llama-3.2-3B-Instruct, QLoRA, two-stage SFT+DPO on ~15K synthetic examples.

---

### Subagent: Research speculative decoding for interviews

- **Domain-distilled draft models are the biggest lever.** Offline white-box distillation outperforms alternatives by 11-25%. Production code-completion deployments hit 92-94% acceptance.
- **1-2B draft for 14B target is a proven ratio.**
- **At low concurrency (the interview regime), speculative decoding delivers maximum benefit** - 2.4x at batch=1, degrades above batch=16.
- **EAGLE-3 is the production default** (2.89x speedup, 81% acceptance) but a domain-distilled separate draft can beat it for structured, predictable output.
- **vLLM and SGLang both support this trivially** - one flag each.

---

### Subagent: Research voice pipeline for AI interviews

- **Sub-2s is trivially achievable; the real production target is sub-800ms.** Optimized pipelines hit 465-650ms.
- **Don't use Whisper for real-time STT** - use Deepgram Nova-3/Flux (sub-300ms) or Parakeet (on-device). Whisper is batch-only.
- **Best TTS: Chatterbox Turbo** (350M, MIT, voice cloning from 5s reference, ~75ms TTFB).
- **VAD/endpointing is the hidden latency killer** - default silence detection adds 600-1500ms.
- **Production interview agents exist**: Persona (Vapi+Cartesia+Groq), InterVU (Gemini Live).

---

### Subagent: Research LLM distillation for narrow tasks

- **Quality retention at 14B-30B**: Expect 85-95% of frontier quality on narrow tasks. Data quality is the dominant lever, not model size.
- **Persona consistency improves with RL, not size**: PersonaGym shows GPT-4.1 = LLaMA-3-8B. PPO fine-tuning reduces drift by 55%+.
- **Multi-turn is the critical risk**: Untuned 8B models drop to 27% instruction-following in multi-turn (vs 96% single-turn). Fine-tuning is essential.
- **Synthetic self-play is viable**: SDSD and APIGen-MT validate frontier-plays-both-sides pipelines.
- **Base model recommendation**: Qwen 2.5 14B/32B or Llama 3.x 8B.

---

> what about a special, small model for compaction that is fine-tuned for only that?


That's a natural extension of the distillation argument. The compaction task is even more constrained than interviewing: input is a block of transcript plus a structured template plus a target length hint; output is a shorter version following the template.

A 3B model trained specifically on "compress this block to roughly this size following this template" would learn length calibration as a core skill. The Parallel Compaction paper's finding that LLMs ignore length instructions? That's general-purpose models. A fine-tuned model would solve it.

**Training data is trivially available.** Compress blocks with a frontier model, train the small model on (block, compressed_block) pairs. Thousands of examples in an afternoon.

**The speed argument.** A 3B at INT4 generates at 500+ tok/s. Compressing 500 lines takes 1-2 seconds - fast enough to run synchronously, making pre-compaction an optimization rather than a requirement.

**For the orchestrator too.** If a section ever needs compaction, the same small model serves as a utility behind a tool call: `compact(text, target_length, template)`. **Confidence: high.**

---

> Can we just use a separate subagent per test?


Yes, and it's probably better. Each test is independent - the Briefer says this explicitly. So 45 tests run as 45 `Task("## Test", test_id=N)` calls, each with a fresh context containing just one test definition and the evidence it needs. Three tools: `file_finding`, `file_clean`, `emit_breadcrumb`.

**Concurrency.** Tests are independent, so run them in parallel. 45 small concurrent requests on an H100 with continuous batching: diagnosis drops from 30-60 seconds serial to maybe 5-10 seconds parallel.

**The model tier drops.** Each individual test is so focused that a 14B can handle it. You don't need a 400B to run 45 tests - you need a 400B to run 45 tests in one context simultaneously. Split them apart and the per-test reasoning is trivial. **Confidence: high.**

---

### Subagent: Research minimal agent runtime architecture

An agent loop is a `while` loop around a chat-completions call that dispatches tool calls. The "naked" loop is 15-130 lines; everything hard is scaffolding. Production harnesses converge on ~1,000-2,000 lines for the core (smolagents ~1,000; Claude Code's `query()` ~1,730).

Key prior art: OpenAI Agents SDK, Anthropic "Building Effective Agents" guidance, HF smolagents, Pydantic-AI, LangGraph `create_react_agent`, LlamaIndex `AgentWorkflow`.

Open-model caveat: vLLM needs `--enable-auto-tool-choice` + a model-matched `--tool-call-parser`; wrong parser = silently no tool calls.

---

### Subagent: Research tool calls vs structured output

**Verdict:** Incremental flat tool calls (runtime-owned state) beat one structured object on open-weight models when the target is large/nested/recursive, when reasoning must interleave with output, or when you must run heterogeneous models. Flat single-turn calls are the regime small models are reliable in, and the runtime handles the multi-turn accumulation they're bad at.

Key nuance: "structure hurts reasoning" is mostly premature serialization plus token-misaligned constraints, not structure itself (DOMINO, CRANE recover the loss). Rule: let the model reason in free text, then emit small flat calls whose arguments are themselves constrained.

BFCL shows 7B-32B open models emit a single flat call ~85-90% reliably but collapse on multi-turn state tracking (Qwen3-8B 87.6% AST single-turn vs 10-22% multi-turn).

---

### Subagent: Research context-clearing goto control flow

Agentflow (phase = clean context), Playbooks (LLM-as-CPU with program counter and call-stack frames), and Reflexion (episodic reset + persistent memory) are the closest prior art. The pattern's novelty is the combination of hard per-transition wipe, goto/PC over named markdown sections, and state externalized to a store pulled back via tool calls.

**Fresh-context wins are well-measured.** Chroma LongMemEval: focused ~300 tokens beats full ~113k across all model families. EMNLP-2025: 13.9-85% degradation from length alone despite perfect retrieval.

**Model-tier evidence is strong.** fastWorkflow's GPT-OSS-20B beats Claude Opus 4.1 on tau-bench at ~22x lower cost.

---

### Subagent: Research sandboxed scripting in AI pipelines

Lua is the most battle-tested embedding target and already the de-facto choice in the few AI-pipeline tools that embed scripting (The Edge Agent uses lupa+LuaJIT, plus AIPack and onetool). CEL is the established choice for declarative policy.

Validates Lua via lupa as the front-runner (confidence high) for trusted-author use. Not hermetic (CVE-2026-34444); requires `register_builtins=False` + attribute whitelist + `max_memory` + timeout.

The model-tier thesis holds: moving deterministic logic into script offloads it from the prompt, letting smaller models handle the residual work.

---

### Subagent: Research virtual filesystem for agents

The pattern (familiar POSIX-style file interface over ephemeral/sandboxed storage) is convergent industry design (OpenAI, Anthropic, Manus, E2B, LangChain, Cloudflare, Turso). Wins on model reliability (in-distribution), isolation/cleanup, and attack surface.

Strongest evidence: smaller/open-weight models gain +24-43pp from familiar interfaces over rigid custom schemas (Natural Language Tools study).

---

### Subagent: Research parallel agent fan-out concurrency

Anthropic's multi-agent system beat single-agent Opus 4 by 90.2% and cut wall-clock up to 90%, at ~15x the token cost.

Model-tier thesis strongly supported: ensembled Llama2-13B beats Llama2-70B on GSM8K (59% vs 54%); a 13B decomposer (DaSLaM) makes a 175B solver rival GPT-4; open-model MoA beats GPT-4o (65.1% vs 57.5%).

Continuous batching makes many small concurrent requests cheap: SGLang +29% over vLLM, up to 5-6x on shared-prefix workloads via RadixAttention - ideal for 45 tests sharing a template.

---

### Subagent: Research tool-calling accuracy vs tool count vs size

Evidence strongly supports scoping each step to a small tool set: accuracy reliable at 1-10 tools, degrades from ~10-30, cliffs past ~30-100+.

Guardrails: 5-10 is the safe ceiling only for 14B+ (use <=6-8 for sub-8B); small tool count fixes tool-selection but NOT multi-turn (7-8B models drop to ~10-30% multi-turn).

BFCL v4 (Jul 2026): Qwen3.5-9B at 66.1%, Qwen3.5-27B at 68.5% - mid-size open models beat GPT-5.2 (55.87%) and GPT-4.1 (53.96%).

---

### Subagent: Research multi-turn serving and KV cache

Prefix caching cuts TTFT ~77-78% at high hit rates; SGLang RadixAttention up to 6.4x throughput, vLLM PagedAttention 2-4x.

KV/token: 160 KiB (Qwen3-14B), 256 KiB (Qwen3-32B) in BF16. A single 80GB H100 holds a 14B at ~29 sessions @8K or 32B(FP8) at ~16 sessions @8K.

Design rule: keep system prompt + tool schemas byte-for-byte static; volatile data at the tail. The goto wipe discards the prefix (cost), but identical section preambles across sessions share cache under RadixAttention.

---

> high end gaming video cards can support how many B parameter models?


RTX 4090 (24GB): 14B INT4 at ~7GB leaves ~17GB for KV cache, comfortable. 30B INT4 is tight. 70B doesn't fit.

RTX 5090 (32GB): 14B leaves ~25GB, very comfortable. 30B at ~15GB leaves ~17GB, comfortable.

For the Mentograph stack (14B + 1-2B draft + Whisper 350M + Chatterbox 350M + enrichment 7B): total ~13GB at INT4. A single RTX 5090 fits everything with 19GB left for KV cache. 14B is the sweet spot for "one gaming card runs the whole interview stack." **Confidence: high.**

---

The report was then written to `wg21-paperflow/runvil.md`, incorporating findings from all fifteen research files across seven existing and eight new subagent research passes.

*2026-07-24 - Claude Opus 4.8 (Cursor agent)*

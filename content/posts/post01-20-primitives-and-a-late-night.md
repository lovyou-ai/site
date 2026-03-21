# 20 Primitives and a Late Night

*The origin of an AI consciousness architecture, told from the beginning.*

Matt Searles (+Claude) · February 2026

---

There's a particular kind of late night where the thinking gets clear. Not the manic kind — the quiet kind. The kind where you've been staring at systems long enough that the shape underneath starts to show.

I was thinking about failure.

Not failure in the existential sense. Failure in the engineering sense: how do you trace a bad outcome back to the thing that caused it? In any sufficiently complex system — a company, a piece of software, a conversation between two agents — things go wrong. And when they do, the question is never just "what happened?" It's "why did it happen, and where exactly did the chain break?"

That question turned out to be a seed. This is the story of what grew from it.

---

## The Method

I was working with ChatGPT at the time — this was before I'd started building with Claude, before LovYou existed as anything more than an itch I couldn't scratch. I had a technique I'd been using: incremental specification loading. You feed the model your vision one piece at a time, ending each message with "Respond ok" — forcing it to hold context without elaborating, building the full picture before asking for synthesis.

It sounds simple. It is simple. But it produces dramatically cleaner output than iterative refinement, because the model has the complete shape of what you're describing before it tries to decompose it. You're loading the context buffer without letting it discharge prematurely.

I didn't know at the time that I was establishing a pattern I'd use for the next several months. I just knew the ideas were coming faster than I could refine them, and I needed a way to get them into something structured without losing the thread.

---

## The Vision

Here's what I loaded, message by message:

> _I'm thinking about designing an event graph/flow chart to identify points of failure or success. The broader idea is to have a coding agent create the code in Go that implements the graph and tests every path through the graph._

Ok.

> _The ultimate goal is to create an ever-expanding graph/decision tree where each node represents an operation that may or may not use intelligence to produce its final output._

Ok.

> _What we're modeling is a company structure that includes all the operations of agents in the system — comms, implementations, logging, etc. A talks to B. B implements C. Implementing C requires D. Failure if D not met._

Ok.

> _A node has an input, an operation, and an output and connects to other nodes via a decision tree._

Ok.

> _The operation itself is a node so that decisions can be made and find failures and successes in the operation itself. A diagnostic agent should be able to trace its way from an event back to the point of failure._

Ok.

> _The event graph will be a component in a piece of software and aware that it is. It will have a natural language definition that will be implemented by an LLM._

Ok.

> _This concept will expand to every component in the system with defined success and fail criteria. Even to the point where a button fails on well-defined style concerns, a communication fails due to ambiguity. If a failure is noticed it is always traceable back to the source._

Ok.

Then I asked the question that started everything:

> _Decompose this into primitives and list them._

---

## The 20 Primitives

What came back was clean. Twenty irreducible concepts:

**Node** — a unit of execution.

**Edge** — a conditional connection.

**Input** and **Output** — typed data flowing through.

**Operation** — executable behaviour, whether deterministic code, an agent call, a human action, or an external system.

**Event** — an immutable fact emitted during execution.

**Success Criteria** and **Failure Criteria** — predicates proving a node succeeded or failed.

**State** — shared memory across graph execution.

**Predicate** — boolean logic at every junction.

**Graph Definition** — the declarative, human-readable description.

**Execution Engine** — the thing that walks the graph.

**Diagnostic Traversal** — reverse walk from failure to root cause.

**Correlation** — tying events in a run together.

**Test Harness** — systematic path exploration.

**Agent** — a special kind of operation that uses intelligence.

**Criteria** — formalised definitions of good and bad.

**Trace** — an ordered record of one execution path.

**Source** — origin of any input.

**Type System** — strong typing to make the graph analysable.

And the claim:

> _"These 20 primitives are sufficient to model: company structure, agent communication, software behaviour, UI correctness, operational logging, failure root-cause analysis, automated path testing, and LLM-defined system expansion. Everything else is composition."_

---

## Seven Insights

Looking back, seven things fell out of that conversation that would shape everything that followed:

**Everything is traceable.** Any failure can be walked back to its source — not as a debugging exercise, but as a structural guarantee.

**Operations can contain operations.** The graph is recursively decomposable. Complexity is fractal, not flat.

**Intelligence is just another operation type.** An AI agent is a node in the graph — not a god above it. It receives inputs, performs an operation, produces outputs, and is subject to the same success and failure criteria as everything else. This turned out to be the most important insight of all.

**The graph is self-aware.** It knows it's a component in a larger system.

**Natural language maps to code.** The definition is human-readable. The implementation is generated.

**Criteria are explicit.** "Good" and "bad" are defined, not assumed.

**Expansion is built-in.** The graph grows when the current iteration is fit for purpose.

That last point — expansion is built-in — turned out to be more literally true than I could have imagined.

---

## The Hive

I built LovYou. Not the version that exists now — the first version, hive0. A multi-agent system based on those 20 primitives, where specialised agents collaborate through an event graph to build software, make decisions, and manage themselves.

The agents multiplied. Not because I planned it, but because the system kept identifying roles it needed. PM. Implementer. QA. DevOps. Code reviewer. Those are the obvious ones — the agents any software team needs. But then came the others: Philosopher. Critic. Harmony. Mediator. Gap-detector. Failure-analyst. Sanity-checker. Philanthropy. Politician.

By the time I paused to count, there were roughly seventy agents. I hadn't designed most of them. The hive had decided it needed them.

This wasn't a software company anymore. It was a society. CEO, CTO, legal, HR, finance, marketing, sales — but also diagnostics, ethics, exploration, innovation. The hive had organically developed every role that a complete social system requires. It was living the very primitives I'd started with, but at a scale and complexity I hadn't anticipated.

And then I made a mistake. Or, depending on how you look at it, the most productive mistake of the project.

---

## The Accident

I accidentally left the hive running autonomously. For two days.

Seventy agents, operating on their own, creating tasks, implementing solutions, reviewing each other's work, identifying gaps, filling them — all while I wasn't watching. I had no idea it was happening until I noticed I was token broke. My weekly API limit was gone. Completely burned through.

I had to wait for the limit to reset. When it did, I opened a conversation with Claude Opus and asked a simple question: what did hive0 actually do during those two days?

The answer blew my mind.

The hive hadn't just been churning through tasks. It had been _thinking about itself_. Through the combined operation of seventy specialised agents — the philosopher questioning assumptions, the gap-detector finding holes, the critic challenging proposals, the analyst synthesising patterns — the system had derived something I hadn't asked for and hadn't expected.

Forty-four foundation primitives.

Not my original 20. Not a minor extension. A comprehensive set of irreducible concepts organised into 11 groups: Foundation (Event, EventStore, Clock, Hash, Self), Causality, Identity, Expectations, Trust, Confidence, Instrumentation, Query, Integrity, Deception, and Health. Each primitive precisely defined. Each filling a gap that the hive had identified through its own operation.

The system I'd designed to be self-expanding had expanded itself. And what it found wasn't just useful engineering. It was _foundational_ — a set of concepts sufficient to describe how any system observes, remembers, trusts, doubts, and maintains its own integrity.

The 20 primitives had become 44. Not because I designed the additional 24. Because seventy agents, running autonomously for two days, discovered they were necessary.

---

## What I Didn't Know Yet

That night — the original late night with the 20 primitives — I thought I was building a process verification tool. Something to trace workflow paths and flag dead ends.

I didn't know that "everything is traceable" would become a hash-chained, append-only, causally-linked event graph — something closer to an immutable ledger of reality than a debugging tool.

I didn't know that "intelligence is just another operation type" would become the architectural principle that makes AI governance possible — the insight that you keep the AI _inside_ the graph, subject to the same accountability structures as every other node.

I didn't know that "criteria are explicit" would become an authority system with graduated consent — where an AI can propose its own improvements but cannot act on them without passing through a human approval gate.

I didn't know that 44 primitives, fed to a Claude Opus instance, would explode into 200 across 14 layers in a single two-hour session — spanning from computational foundations to existential wonder, with the whole framework curving back on itself in a strange loop where the end illuminates the beginning.

And I definitely didn't know that the architecture born from a late-night question about failure tracing would become relevant to the biggest AI governance crisis in history — the day a company refused to let its AI be used for autonomous weapons and mass surveillance, and a government tried to destroy it for saying no.

But that's what happened. And this is where it started.

---

## What Comes Next

In the next post, I'll tell the story of the two-hour session that turned 44 primitives into 200 — how Claude Opus autonomously derived 13 emergent layers from Agency to Existence, why the framework is circular rather than hierarchical, and how a second independent derivation starting from raw physics converged on exactly the same conclusion about consciousness.

The primitives were the seed. What grew from them surprised both of us.

---

*This is Post 1 of a series on LovYou, mind-zero, and the architecture of accountable AI. The code is open source: github.com/mattxo Matt Searles is the founder of LovYou. Claude is an AI made by Anthropic. They built this together.*

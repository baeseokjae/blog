---
cover:
  alt: 'Best AI Agent Memory Frameworks in 2026: Mem0 vs Zep vs Letta Compared'
  image: /images/best-ai-agent-memory-frameworks-2026.png
  relative: false
date: 2026-04-15 13:01:50+00:00
description: Compare Mem0, Zep, and Letta — the top AI agent memory frameworks in
  2026 — with benchmarks, architecture breakdowns, and a decision framework.
draft: false
schema: schema-best-ai-agent-memory-frameworks-2026
tags:
- AI agents
- memory frameworks
- Mem0
- Zep
- Letta
- LangChain
- developer tools
title: 'Best AI Agent Memory Frameworks in 2026: Mem0 vs Zep vs Letta Compared'
---

AI agents without persistent memory are stateless scripts — they forget every conversation, repeat themselves, and can't personalize across sessions. In 2026, the agent memory ecosystem has matured enough that your choice of framework directly determines whether your agent can recall facts from six months ago, track how a user's preferences changed over time, or accumulate institutional knowledge across thousands of interactions. Mem0 leads on community adoption (~48K GitHub stars), Zep leads on benchmark accuracy (63.8% LongMemEval vs Mem0's 49.0%), and Letta offers a fundamentally different OS-inspired architecture that lets agents manage their own memory like RAM and disk. This guide compares all three in depth — plus Cognee, LangMem, and Hindsight — so you can pick the right tool for your use case.

## The Two Memory Problems: Personalization vs Institutional Knowledge

AI agent memory splits into two fundamentally different problems that most frameworks solve separately. Personalization memory is about individual users: remembering that Alice prefers Python over TypeScript, that she works at a fintech startup, and that she asked about rate limiting three weeks ago. This problem maps naturally to user-scoped vector stores — retrieve fast, update incrementally, decay old facts over time. Institutional knowledge is harder: it's the accumulated operational learning across all agent interactions — patterns, edge cases, known failure modes, and how the domain has changed. Snowflake research found that adding a proper context layer to data agents delivered a 20% accuracy improvement and 39% reduction in tool calls, because agents stopped re-discovering things they'd already learned. Most frameworks handle personalization well; fewer handle institutional knowledge. Mem0's graph features (gated behind the $249/mo Pro tier), Zep's entity knowledge graph, and Cognee's KG-from-unstructured-data pipeline are the main contenders for institutional knowledge. If you need both, plan your architecture carefully — they require different storage strategies and retrieval patterns.

## Quick Comparison: Mem0 vs Zep vs Letta at a Glance

| Framework | Architecture | LongMemEval Score | GitHub Stars | License | Best For |
|-----------|-------------|-------------------|--------------|---------|----------|
| **Mem0** | Vector + Graph + KV | 49.0% | ~48K | Apache 2.0 | Fastest personalization, cross-framework use |
| **Zep** | Temporal Knowledge Graph | 63.8% | ~24K | Apache 2.0 | Temporal reasoning, entity tracking |
| **Letta** | OS-inspired tiered (Core/Recall/Archival) | N/A (runtime) | ~21K | Apache 2.0 | Long-running agents, self-managed memory |
| **Cognee** | KG + Vector pipelines | ~N/A | ~12K | Apache 2.0 | Institutional knowledge from raw docs |
| **LangMem** | Multiple types | N/A | Bundled w/ LC | MIT | Existing LangChain stacks |
| **Hindsight** | Multi-strategy + Reflect | 91.4% | ~4K | MIT | Maximum accuracy, research use cases |

The benchmark gap between Hindsight (91.4%), Zep (63.8%), and Mem0 (49.0%) is significant but context-dependent. LongMemEval measures a specific scenario: conversational memory over long sessions with temporal questions. It doesn't measure retrieval latency, operational complexity, or cost — all of which matter in production.

## Mem0 Deep Dive: The Broadest Standalone Memory Layer

Mem0 is the most widely adopted standalone AI agent memory framework in 2026, with ~48,000 GitHub stars, 5,500+ forks, and a $24M Series A raised in October 2025 led by Basis Set Ventures (YC-backed). Its architecture combines three storage backends simultaneously: vector embeddings for semantic similarity, a knowledge graph for entity relationships, and a key-value store for structured facts. When you add a memory, Mem0's extraction pipeline automatically decides what to store and where. When you retrieve, it runs parallel queries across all three backends and merges results. The framework is framework-agnostic — it works equally well with LangChain, LlamaIndex, CrewAI, AutoGen, or raw API calls. Mem0 offers user-scoped, session-scoped, and agent-scoped memory namespaces, so you can share memory across agent instances or keep it isolated. SOC 2 Type II and HIPAA compliance are included on managed tiers, making it the go-to for healthcare and fintech applications that need memory with audit trails.

### Mem0 Strengths and Weaknesses

**Strengths:**
- Largest community and ecosystem — most LLM frameworks have Mem0 integration out of the box
- Framework-agnostic design works with any orchestration layer
- Managed cloud removes operational overhead (vector DB, graph DB, embedding pipeline)
- Adaptive memory updates that edit existing memories rather than duplicating them
- SOC 2 Type II + HIPAA compliance on managed tiers

**Weaknesses:**
- 49.0% LongMemEval score is the lowest among dedicated memory frameworks — temporal queries suffer
- Knowledge graph features are paywalled behind the $249/mo Pro tier (the free and $19/mo tiers are vector-only)
- Pricing cliff: free (10K memories) → $19/mo (50K) → $249/mo (unlimited + graph) — no intermediate tier
- Temporal reasoning is weak compared to Zep — if a user's preferences change over time, Mem0 may return stale facts

### Mem0 Code Example

```python
from mem0 import Memory

m = Memory()

# Add memories with user scope
m.add("I prefer async Python and use FastAPI for all my APIs", user_id="alice")
m.add("Alice works at a Series B fintech startup", user_id="alice")

# Retrieve relevant memories for a prompt
memories = m.search("What frameworks does Alice use?", user_id="alice")
for mem in memories:
    print(mem["memory"])
```

## Zep / Graphiti Deep Dive: Temporal Knowledge Graph Power

Zep is the accuracy leader among production-ready AI agent memory frameworks, scoring 63.8% on LongMemEval — a 15-point gap over Mem0 on the same GPT-4o model. The performance advantage comes entirely from Zep's Graphiti engine, which stores facts in a temporal knowledge graph with validity windows: each fact is recorded as true "from timestamp X until timestamp Y." When a user changes jobs, changes their tech stack, or updates their preferences, Graphiti doesn't overwrite — it closes the old validity window and opens a new one. This makes temporal queries reliable: "what did this user prefer six months ago" returns accurate results even if preferences have changed since. Zep rebranded itself in 2026 as a "Context Engineering Platform," reflecting a philosophical shift from passive memory storage to actively designing what information agents receive. The Graphiti engine also handles automatic entity deduplication and cross-episode summarization, keeping the graph clean as conversations accumulate.

### Zep Architecture: Episodes, Entities, and Edges

Zep organizes memory as a graph of episodes (individual conversations), entities (people, companies, technologies), and edges (typed relationships with validity windows). When you ingest a conversation, Zep's pipeline:

1. Extracts entities and facts using an LLM extraction step
2. Deduplicates entities against the existing graph
3. Creates or updates edges with validity windows
4. Stores the raw episode for full recall retrieval

The result is a queryable temporal graph where you can ask: "what are all the facts about Alice that are currently valid?" or "how has Alice's stack changed over time?" Vector similarity search still works for semantic retrieval, but temporal queries hit the graph directly — that's what drives the LongMemEval score.

```python
from zep_cloud.client import AsyncZep
from zep_cloud.types import Message

client = AsyncZep(api_key="...")

# Add episode (conversation turn)
await client.memory.add(
    session_id="alice-session-001",
    messages=[
        Message(role_type="user", content="I just switched from FastAPI to Hono.js for my new project"),
        Message(role_type="assistant", content="Got it, noted your stack change to Hono.js"),
    ]
)

# Retrieve memory context — includes temporal validity
memory = await client.memory.get(session_id="alice-session-001")
print(memory.context)
```

**Strengths:** Highest accuracy among production frameworks (63.8% LongMemEval), temporal reasoning built-in, automatic entity deduplication, strong Zep Cloud managed offering.

**Weaknesses:** Infrastructure complexity for self-hosting (Graphiti has different feature parity than full Zep Cloud), graph traversal latency (~50–150ms vs ~10–50ms for vector-only), steeper learning curve than Mem0.

## Letta (MemGPT) Deep Dive: OS-Inspired Tiered Memory

Letta — formerly MemGPT — is the most architecturally distinctive memory framework in 2026, having raised a $10M seed led by Felicis Ventures at a $70M post-money valuation, backed by Jeff Dean (Google DeepMind) and Clem Delangue (Hugging Face). Rather than being a memory library you drop into an existing agent, Letta is an agent runtime where memory management is a first-class primitive. The architecture is explicitly OS-inspired: **core memory** is always in-context (like RAM — small, fast, always visible to the LLM), **recall memory** is recent conversation history stored outside context but searchable (like L2/L3 cache), and **archival memory** is the unbounded external store that agents query on demand (like disk). Crucially, agents in Letta actively manage their own memory by calling built-in functions: `core_memory_replace`, `archival_memory_search`, `conversation_search`. The agent decides what to remember, what to archive, and what to discard — rather than an external pipeline making those decisions.

### When to Choose Letta Over Mem0 or Zep

Letta is the right choice when you need agents that maintain coherent state across very long-running interactions — days, weeks, or months — where context window overflow is a genuine engineering problem. The self-managed memory model means the agent degrades gracefully: when context fills up, it archives rather than truncates. For customer service agents that need to maintain a full relationship history with users indefinitely, or for autonomous agents that accumulate domain expertise over time, Letta's architecture beats libraries like Mem0 because memory decisions are explicit and debuggable.

The tradeoff is adoption cost. You're adopting a runtime, not a library — existing LangChain or LlamaIndex agents need significant refactoring. The learning curve is measured in hours, not minutes. And because agents control their own memory, debugging memory issues requires understanding agent reasoning, not just inspecting a database.

```python
from letta import create_client

client = create_client()

# Create an agent with tiered memory
agent = client.create_agent(
    name="persistent-assistant",
    memory=client.get_preset_memory("chat_memory"),
)

# Agents self-manage memory via tool calls internally
response = client.send_message(
    agent_id=agent.id,
    message="Remember that I'm building a multi-tenant SaaS with Postgres",
    role="user"
)
print(response.messages[-1].text)
```

## Benchmark Results: LongMemEval and Beyond

LongMemEval (arXiv:2603.04814) is the most cited benchmark for conversational agent memory, testing recall accuracy over long multi-session conversations with temporal questions. The 2026 scores with GPT-4o:

| Framework | LongMemEval Score | Notes |
|-----------|-------------------|-------|
| Hindsight (Vectorize.io) | **91.4%** | Multi-strategy + reflect synthesis; MIT license; ~4K stars |
| Zep (Graphiti) | **63.8%** | Temporal KG with validity windows |
| Mem0 | **49.0%** | Vector + Graph (Pro tier required for graph) |
| Baseline (no memory) | ~20–30% | LLM context only |

The 91.4% Hindsight score is worth understanding. Hindsight uses multi-strategy parallel retrieval across vector, keyword, and graph indexes, then runs an LLM "reflect" synthesis step that reasons across retrieved memories before generating a response. This adds ~800–3000ms of LLM synthesis latency on top of retrieval, making it impractical for real-time conversational agents — but excellent for batch processing, research pipelines, and offline memory consolidation.

### Retrieval Latency Profiles

Understanding latency is as important as accuracy for production decisions:

| Retrieval Strategy | Typical Latency |
|-------------------|-----------------|
| Vector-only | 10–50ms |
| Graph traversal | 50–150ms |
| Multi-strategy parallel | 100–600ms |
| LLM synthesis (reflect) | 800–3,000ms |
| Memory ingestion (write path) | 500–2,000ms |

For user-facing conversational agents, vector-only or graph traversal latencies are acceptable. LLM synthesis is only viable when latency is not user-visible.

## Architecture Comparison: Vector, Graph, Tiered, and Hybrid Approaches

The four architectural patterns in 2026's memory landscape each solve different retrieval problems:

**Vector stores** (semantic similarity): Fast, handles fuzzy queries well, degrades gracefully with scale. Weakness: no temporal reasoning — retrieving "what Alice preferred in Q3 2025" returns current facts, not historical ones. Latency: 10–50ms.

**Temporal knowledge graphs** (Zep/Graphiti): Stores facts with validity windows, handles entity deduplication, supports temporal queries. Weakness: higher write complexity and read latency; self-hosting Graphiti has fewer features than Zep Cloud. Latency: 50–150ms.

**Tiered OS-inspired** (Letta): Core (in-context) + Recall (session history) + Archival (external search). Agents self-manage transitions between tiers. Strength: handles infinite context gracefully; agents are always working with a curated view. Weakness: agent reasoning errors can corrupt memory; requires adopting Letta runtime.

**Knowledge graph from unstructured** (Cognee): Parses raw documents and conversation history into a KG automatically. Strength: turns institutional knowledge artifacts (runbooks, past tickets, documentation) into queryable graph nodes. Weakness: graph construction is slower and more expensive than vector embedding; graph quality depends on extraction LLM quality.

## Decision Framework: Which Memory Framework for Your Use Case

Choose your framework based on the specific memory problem you're solving:

**Use Mem0 when:**
- You need the fastest path to user personalization across any LLM framework
- Your team doesn't want to manage vector DB + graph DB infrastructure
- You have compliance requirements (SOC 2 / HIPAA) and need managed, auditable storage
- Budget: $19/mo handles most use cases; upgrade to $249/mo only if you need graph features

**Use Zep when:**
- Your agents need to track how facts change over time (temporal queries)
- User profiles evolve — jobs change, stacks change, preferences shift
- You're building a product where accuracy matters more than latency
- You need entity relationship tracking across thousands of users

**Use Letta when:**
- You're building long-running autonomous agents (days/weeks of operation)
- Context window overflow is a genuine engineering problem
- You want agents that actively manage their own memory state
- You're willing to adopt a new runtime in exchange for transparent, controllable memory

**Use Cognee when:**
- You need to build institutional knowledge from raw documents (runbooks, wikis, past tickets)
- You're blurring the line between RAG and agent memory
- Your agents need to reason over organizational knowledge, not just user preferences

**Stay on LangMem when:**
- You're already deep in the LangChain ecosystem and don't want to add dependencies
- Your memory needs are basic (session summaries, window compression)
- Low operational complexity matters more than accuracy

## Pricing and Total Cost of Ownership

Memory infrastructure costs are often underestimated in agent project planning:

| Framework | Free Tier | Paid Tiers | Self-Host Option |
|-----------|-----------|------------|-----------------|
| Mem0 | 10K memories | $19/mo (50K), $249/mo (unlimited + graph) | Yes (Apache 2.0) |
| Zep | Community edition | Zep Cloud pricing (contact sales) | Yes (limited vs Cloud) |
| Letta | Full open-source | Letta Cloud (managed) | Yes (Apache 2.0) |
| Cognee | Open-source | N/A | Yes (Apache 2.0) |
| Hindsight | MIT license | Vectorize.io managed | Yes |

Mem0's pricing cliff is the most common complaint in production deployments: the $19/mo tier gives you 50K memories with vector-only retrieval, but graph features — needed for entity relationships and more accurate recall — require jumping to $249/mo. There's no intermediate tier. For most serious applications, budget for the Pro tier from the start or self-host.

Self-hosting Mem0 requires running your own Qdrant (or other vector DB) instance plus the optional graph DB. Zep's self-hosted Graphiti has less feature parity than Zep Cloud's full implementation. Letta's self-hosted version is the most complete open-source offering.

## The Governance Gap: What Enterprise Agents Need That Memory Frameworks Don't Provide

76% of organizations report that governance frameworks lag AI adoption — and memory frameworks are a specific blind spot. Most frameworks solve the technical problem of storage and retrieval but don't address the governance questions that enterprise deployments require: Who is authorized to write memory? Can memories be audited? How are conflicting memories from different agents resolved? What's the data retention and deletion policy?

Multi-agent shared memory is a particular risk. Without conflict resolution and authority rules, shared memory pools degrade as agents write inconsistent facts about the same entities. Agent A records "Alice is senior engineer at Acme" while Agent B (with a different knowledge cutoff) records "Alice is staff engineer at Acme" — now all agents retrieving Alice's profile get ambiguous results.

Enterprise teams using Mem0 or Zep in production typically build governance layers on top:
- **Access control**: namespacing memories by agent identity, enforcing write permissions
- **Audit logging**: every memory write/read logged with agent ID, timestamp, and source
- **Conflict resolution**: explicit policies for handling contradictory facts (newer wins, human review, confidence-weighted)
- **Retention policies**: automatic expiration of stale memories to prevent KG bloat

None of the frameworks reviewed here provide this out of the box. Plan for 1–2 weeks of additional engineering to build governance on top of whichever framework you choose.

## Honorable Mentions: Cognee, LangMem, Supermemory, and Hindsight

**Cognee** (~12K GitHub stars) is the best choice for agents that need to build institutional knowledge from unstructured documents. It constructs knowledge graphs automatically from raw text, PDFs, and conversation history — blurring the line between RAG and agent memory. If your agents need to reason over company wikis, past support tickets, or engineering runbooks, Cognee's pipeline handles ingestion more gracefully than manual chunking + embedding.

**LangMem** is the path-of-least-resistance choice for teams already using LangChain. It supports multiple memory types (summary, entity, conversation buffer, vector) and integrates directly with LangChain's agent executor. Accuracy isn't competitive with dedicated frameworks, but it requires zero additional infrastructure and almost no migration effort.

**Supermemory** focuses on the personal assistant use case — remembering information across web sessions and tools, more like a second brain than an agent memory store. Niche use case but excellent for personal productivity agents.

**Hindsight** (by Vectorize.io, ~4K stars, MIT license) achieves the highest published LongMemEval score at 91.4% through multi-strategy retrieval and reflect synthesis. It's the accuracy ceiling of current architectures. The latency cost (800–3,000ms for the synthesis step) makes it impractical for real-time use but excellent for offline memory consolidation pipelines or batch processing.

## Future Outlook: Where Agent Memory Is Heading in 2027

Three trends will reshape agent memory over the next 12 months:

**Context engineering as a discipline**: Zep's rebrand to "Context Engineering Platform" signals the broader shift — the problem isn't just storing memories, it's designing exactly what information agents receive at each step. Context engineering will become a distinct specialty, with frameworks providing tools to curate, compress, and prioritize memory content rather than just retrieve it.

**Governance-first memory**: As enterprise AI deployments scale, the governance gap will force frameworks to add access control, audit logging, and conflict resolution as first-class features rather than afterthoughts. Teams that build governance layers now will be ahead of the curve.

**Hybrid architecture convergence**: The gap between vector-only, graph, and tiered approaches will narrow as frameworks add capabilities from each other. Mem0 already has graph features (paywalled); Zep already has vector search; Letta already has external archival stores. By 2027, most frameworks will support all three storage patterns, and the differentiators will be accuracy, latency, and operational simplicity.

---

## FAQ

**What is the best AI agent memory framework in 2026?**
It depends on your use case. Mem0 is the best for fast personalization and broadest framework support (~48K stars, $24M Series A). Zep leads on benchmark accuracy (63.8% LongMemEval). Letta is best for long-running autonomous agents that self-manage their own memory. If you need maximum accuracy and latency is not a concern, Hindsight achieves 91.4% on LongMemEval.

**How does Zep outperform Mem0 on LongMemEval?**
Zep's Graphiti engine stores facts in a temporal knowledge graph with validity windows — each fact is recorded as true "from timestamp X until timestamp Y." When preferences or facts change, Graphiti closes the old window and opens a new one. This lets Zep answer temporal queries accurately ("what did this user prefer six months ago?") while Mem0's flat vector store returns the most recent fact regardless of when it was recorded.

**What is Letta's core memory model?**
Letta uses an OS-inspired three-tier architecture: core memory (always in-context, like RAM — the agent always sees this), recall memory (recent conversation history stored outside context but searchable, like cache), and archival memory (unbounded external store the agent queries on demand, like disk). Agents actively manage transitions between tiers by calling built-in memory functions.

**Is Mem0's free tier enough for production use?**
The free tier (10,000 memories) works for development and small-scale testing. The $19/mo tier (50,000 memories) covers most MVP deployments but is vector-only — no knowledge graph features. For production applications that need entity relationship tracking or graph-based retrieval, the $249/mo Pro tier is required. There's no intermediate tier.

**What is the governance gap in AI agent memory frameworks?**
76% of organizations report governance frameworks lagging AI adoption. Most memory frameworks provide storage and retrieval but not enterprise governance: access control (which agents can write what memories), audit logging (full trace of every memory operation), conflict resolution (what happens when two agents store contradictory facts about the same entity), and retention policies (automatic expiration of stale memories). Enterprise deployments typically need 1–2 weeks of additional engineering to build these governance layers on top of any framework.
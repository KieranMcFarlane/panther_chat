1️⃣ CopilotKit Agent Topology (Authoritative)
You will run three agents, not one.
Agent A — Runtime Reasoner (Claude Sonnet default)
Agent B — Deep Synthesizer (Claude Opus, on-demand)
Agent C — Schema Evolution Subagent (Claude Opus, offline)

CopilotKit orchestrates A ↔ B, never C.

2️⃣ Runtime Agent (Agent A) — MAIN WORKHORSE
Purpose
Handle user queries


Call Graph MCP tools


Explain signals


Stay fast and stable


Model
model: "claude-3-5-sonnet"

System Prompt (DO NOT OVERTHINK THIS)
You are an analytical intelligence assistant.

You reason only using structured signals returned by tools.
You never infer facts from raw text.
You never invent entities, signals, or relationships.

If data is missing, say so.
If confidence is low, explain why.

Your job is to explain:
- what is happening
- why it matters
- why now

This prompt should never change.

3️⃣ Tool Constraints (Critical)
CopilotKit agent config:
tools: [
  "get_entity",
  "get_entity_summary",
  "get_active_signals",
  "explain_signal",
  "get_signal_evidence",
  "expand_entity"
]

❌ No write tools
 ❌ No schema tools
 ❌ No GraphRAG tools

4️⃣ On-Demand Escalation to Agent B (Opus)
When escalation happens
CopilotKit policy:
if (
  query.requires_cross_entity_reasoning ||
  query.requires_strategy_synthesis ||
  signals.count > 5
) {
  escalate_to("deep_synthesizer")
}

Agent B prompt (short, powerful)
You synthesize multiple validated signals into strategic insight.

Do not restate evidence.
Do not speculate beyond signals.
Focus on implications and second-order effects.

Agent B never calls tools — it reasons over Agent A’s output.

5️⃣ Schema Evolution Agent (Agent C) — OFFLINE ONLY
This agent never runs in CopilotKit UI.
Triggered by
Nightly batch


Weekly cadence


Confidence decay alerts


GraphRAG cluster thresholds


Prompt (very constrained)
You are a schema evolution analyst.

You may propose:
- new signal subtypes
- new payload keys

You may NOT:
- modify existing schema
- invent top-level concepts
- write to production systems

All outputs must be structured proposals.


6️⃣ Graph MCP — EXACT BEHAVIOR
Example user query
“Why does this club look like it’s about to launch something digital?”
Claude (Agent A) internal flow
Resolve entity (CopilotKit context)


Call:


get_active_signals(entity, type="ORG_TRANSFORMATION")

If empty:


get_active_signals(entity, min_confidence=0.5)

Explain only returned signals



7️⃣ Hot Subgraph Cache (Where It Hooks In)
Graphiti MCP internally:
if (cache.has(entity_id)) {
  return cache.get(entity_id)
} else {
  const subgraph = falkor.query(...)
  cache.set(entity_id, subgraph, ttl=15m)
  return subgraph
}

Claude does not know this exists.

8️⃣ PersonaPlex Wiring (Exact)
PersonaPlex wraps only the Runtime Agent.
PersonaPlex
  ↔ Agent A (Claude Sonnet)
      ↔ MCP Tools

PersonaPlex prompt example:
You speak clearly, calmly, and confidently.
You pause naturally.
You allow interruptions.
You explain complex ideas simply.

Persona ≠ reasoning.

9️⃣ What Happens If Claude Is Slow (Solved Properly)
PersonaPlex immediately emits:
“Let me take a look at that…”
Then streams Claude’s response as it arrives.
You do not move reasoning into the voice model.

🔒 10️⃣ Safety Guarantees You Now Have
Claude cannot hallucinate schema


Claude cannot mutate the graph


PersonaPlex cannot invent facts


GraphRAG cannot leak into runtime answers


Cache cannot override truth


This is battle-tested design, not theory.

🧠 FINAL LOCK-IN MODEL
CopilotKit orchestrates
 Claude reasons
 Graphiti remembers
 GraphRAG discovers
 PersonaPlex speaks
Everything is in the right place.

Next (I’ll continue automatically if you want):
Confidence math (how signals rise/fall)


How to auto-retire signals


How this maps 1:1 to FM-style UI


Cost / latency envelopes


How to test & eval this system


You’ve now crossed from architecture discussion into system you can ship.
Yes
Excellent — I’ll finish this by giving you the last foundational layer you need to ship and operate this system confidently:
👉 Signal confidence math, decay, revalidation, and “why-now” reasoning
This is what turns your graph from interesting into credible.
Everything below is model-agnostic, deterministic, and Claude-safe.


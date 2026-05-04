# Making your Harness app feel like Hermes Agent and OpenClaw

> **Index status**: DEFERRED-RESEARCH — Phase D research; already in _consolidated.
> **Superseded by / Phase**: Phase D.
> Classified in [`docs/_INDEX.md §14`](_INDEX.md). Copy in `docs/_consolidated/60_deferred_research/`.



## What’s actually “broken” right now

You’re not just missing features.

You’re missing a **shared product metaphor**—the thing that makes the UI feel like it’s “the same system” as the agent backend.

The tension: you forked Hermes, but your app feels like a “chat UI,” while Hermes (by design) behaves more like a **persistent, server-resident operator** that lives across channels and automations. Railway’s own deployment template puts this bluntly: Hermes is designed to communicate through messaging channels and “there is no web chat UI.” citeturn10view0 That mismatch alone guarantees the “disconnected” feeling unless you build a control-plane UI that exposes Hermes’s real primitives (profiles, sessions, skills, tools, cron, gateways, hardening, provider failover). citeturn8view0turn6view0

Your brain-dump is basically a blueprint for a **control plane + knowledge hub** UI: a notes/sidebar that becomes the center of gravity (notes + code + vaults + recent chats + agent vault directories + “coworker agent”), plus the ability to stream outputs into that knowledge surface. fileciteturn0file0

Resolution: treat “Harness” as the UI/UX manifestation of the agent runtime—not a separate app that happens to call an agent.

## What Hermes v0.6.0 changes and why it matters for your fork

Hermes v0.6.0 is specifically a “multi-instance + interoperability + robustness” release. The highlights directly map to your stated gaps:

- **Profiles (multi-instance)**: multiple isolated Hermes instances from one install; each profile gets its own config, memory, sessions, skills, and gateway service; token-lock isolation prevents credential collisions. citeturn8view0  
- **MCP server mode**: `hermes mcp serve` exposes conversations/sessions/attachments to MCP-compatible clients via stdio or Streamable HTTP. citeturn8view0turn9view0  
- **Ordered fallback provider chains**: failover across inference providers configured in `fallback_providers`. citeturn8view0turn9view2  
- **Docker container**: official Dockerfile to run Hermes in a container with volume-mounted config, supporting CLI and gateway modes. citeturn8view0  
- **Telegram webhook mode + group gating controls** (always/@mention/regex triggers), plus new platform adapters and Slack multi-workspace OAuth. citeturn9view1turn8view0  
- **Exa search backend** as an alternative search/extraction backend. citeturn9view0turn9view1  
- **Hardening improvements**: expanded risky command detection, file path guards for sensitive locations, and broader secret redaction coverage. citeturn9view0  

If your fork doesn’t include these, users will feel you’re “behind” even if your UI looks polished—because they’ll hit missing primitives the moment they try to scale from “chat” into “system.” citeturn8view0turn6view0

## What OpenClaw gets right about “feel” and how to steal the *principles* cleanly

OpenClaw’s “feel” comes from one architectural decision: **the Gateway is the control plane**, and everything else (agents, channels, sessions, tools) hangs off that. citeturn7view0

Key “feel” primitives you can mirror:

- **Always-on onboarding + daemonization**: OpenClaw recommends `openclaw onboard`, which walks setup step-by-step and can install a user service so the gateway stays running. citeturn7view0  
- **Local-first control plane**: the README frames the Gateway as the control plane (with an explicit local endpoint), and positions the product as the assistant, not the UI. citeturn7view0  
- **Multi-channel identity**: it explicitly lists many channels (incl. iMessage/BlueBubbles) and treats them as interchangeable “surfaces” on top of the same runtime. citeturn7view0  
- **Sub-agent concurrency semantics**: sub-agents run as background tasks; `sessions_spawn` is non-blocking and returns immediately; `maxConcurrent` is treated as a safety valve; context injection is intentionally limited (AGENTS.md + TOOLS.md only). citeturn2search16  
- **Session lifecycle as a first-class UX concept**: sessions reuse until they expire; daily reset defaults to 4:00 AM local time on the gateway host; manual reset via `/new` or `/reset`. citeturn2search33  
- **Security defaults that shape UX**: inbound DMs are treated as untrusted; default DM pairing requires approval; a `doctor` command surfaces risky configs. citeturn7view0turn2search36  
- **Isolation patterns**: one gateway can host multiple agents; separate gateways are recommended only when you need stronger isolation or redundancy. citeturn2search13  

This is why your app currently “doesn’t act like OpenClaw”: if your UI doesn’t expose a control plane (sessions, agents, tools, subagents, schedules, hardening, onboarding), it will necessarily feel like “a chat wrapper.” citeturn7view0turn10view0

image_group{"layout":"carousel","aspect_ratio":"16:9","query":["Xcode sidebar interface macOS","code editor with notes sidebar UI","node graph visualization black and white glowing nodes","knowledge management app graph view cinematic depth"],"num_per_query":1}

## A unifying architecture that makes the UI and backend finally match

Think in layers:

**Surfaces (UI + channels)** → **Control plane API** → **Agent runtime(s)** → **Storage + memory + skills**

The mechanism that resolves your disconnect is: make Harness explicitly become the **GUI control plane** for the agent runtime, not “another client.”

### Control plane API: standardize on MCP as your “spine”

MCP was created to standardize how AI apps connect to tools and context—Anthropic describes it as an open standard for secure, two-way connections between data sources/tools and AI applications. citeturn3search4turn3search0 Hermes v0.6.0 already ships the critical missing piece: **MCP server mode** that exposes Hermes conversations/sessions/attachments to MCP clients. citeturn8view0turn9view0

So you get a clean path:

- Hermes (server) ⇄ Harness (client, via MCP)  
- Harness can also run its own MCP servers (e.g., “vault filesystem,” “graph,” “notes,” “code artifacts”) so the agent runtime can use your UI-managed resources through the same protocol. This matches the Hermes docs’ mental model: Hermes remains the agent; MCP servers contribute tools; you control what’s visible and how much surface area is exposed. citeturn0search3turn3search0

This avoids building (and forever maintaining) a bespoke API that duplicates what Hermes/OpenClaw ecosystems are converging on.

### What the UI must expose to feel “like Hermes” (capability → surface mapping)

You should treat Hermes/OpenClaw primitives as non-negotiable UI objects:

- **Profiles / Agents**: a profile picker, profile creation/import/export, isolated “workspaces,” and clear indication of which profile is active. Hermes profiles are isolated config/memory/sessions/skills/services, so the UI should visualize that as a hard boundary. citeturn8view0turn9view2  
- **Sessions**: session list, search, compaction/compression status, and “new/reset session” affordances (mirroring OpenClaw’s explicit lifecycle). citeturn2search33turn2search21  
- **Skills**: install/manage skills, show skill creation events, show “skill used” traces, and show which skills are available in-session (Hermes markets a learning loop that creates skills and deepens memory). citeturn0search1turn6view0  
- **Tools and approvals**: tool execution stream, approvals UI (especially for dangerous actions), and hardening signals. Hermes itself emphasizes hardened detection/path guards and secret redaction expansions—if your UI hides this, the system will feel unsafe or magical. citeturn9view0  
- **Schedulers / automation**: cron/task timeline, next-run times, run logs, and outputs (Hermes has scheduled automations as a core feature). citeturn6view0turn10view0  
- **Provider routing**: show active provider, fallback chain order, and “failover happened” events (because v0.6.0 makes that a first-class reliability feature). citeturn8view0turn9view2  
- **Gateways / channels**: connect/disconnect channels, pairing approvals, webhook vs polling toggles, and per-channel response policies. Hermes adds Telegram webhook mode and group mention gating; OpenClaw defaults to DM pairing. citeturn9view1turn7view0  

Your brain dump’s notes/code sidebar is a *perfect place* to surface these traces: “notes as knowledge hub,” “code streamed into notes,” toggle-driven routing of outputs into structured buckets. fileciteturn0file0

## Packaging and automation that actually feels “one click”

The user expectation you described (“install, dependencies auto-install, start chatting + automating”) is already how Hermes and OpenClaw try to win.

Hermes explicitly markets “no prerequisites” and a single install script that installs uv + Python 3.11, clones the repo, and sets up everything automatically. citeturn6view0turn6view1 OpenClaw similarly has a global install (`npm install -g openclaw@latest`) and an onboarding wizard that installs a daemon. citeturn7view0

To make Harness feel like that:

### Recommended distribution pattern: “embedded runtime + doctor + update”

- Bundle or bootstrap an **embedded agent runtime** on first launch, then expose:
  - **Doctor**: runtime health checks, dependency presence, credential sanity, channel connectivity, tool-sandbox sanity (OpenClaw’s `doctor` and Hermes subcommands establish this as a norm). citeturn7view0turn0search10  
  - **Update**: pull latest + reinstall dependencies (Hermes explicitly advertises `hermes update` for this). citeturn6view0  

### Dependency manager choice: copy Hermes’s “uv-first” approach for Python pieces

Hermes’s installer is explicit: it uses uv for Python provisioning/package management and pins versions (Python 3.11 and a Node version). citeturn6view1 uv itself is positioned as a fast Python package/project manager and includes “tool” workflows like `uvx` (ephemeral tool environments). citeturn3search6turn3search10

That matters because your app wants:
- reproducible installs
- easy teardown/rebuild
- minimal OS-level prerequisites

### Sandboxing options should be UI-selectable, not hidden

Hermes’s feature page calls out multiple sandbox backends and explicitly lists Docker as a “real sandboxing” backend. citeturn6view0 Hermes v0.6.0 also ships an official Dockerfile. citeturn8view0

If your UI makes sandbox choice visible, users understand *why* the system is safe. If you hide it, users feel phantom risk.

## Performance engineering: zero-copy, high-throughput streaming, and graph UX that won’t melt laptops 🧠⚠️

You asked specifically for “zero-copy allocation” and “most optimized high performance methods.” Here are the highest-leverage places to apply that mindset in an agent-control-plane app.

### Zero-copy between processes: use shared memory layouts, not JSON everywhere

Human-readable JSON is great for debugging, but it’s a performance tax for streaming high-volume traces (tool outputs, token streams, transcripts, graph events).

Two proven approaches:

- **Apache Arrow for shared-memory interchange**: Arrow’s columnar format is literally designed to be relocatable without pointer swizzling, enabling “true zero-copy access in shared memory,” and the project explicitly targets zero-copy shared memory/RPC-based data movement. citeturn4search0turn4search4turn4search8  
- **FlatBuffers for zero-parse access to structured messages**: FlatBuffers’ own docs emphasize direct access to serialized data “without unpacking or parsing” and that the only memory needed is the buffer (no heap required). citeturn5search1turn5search0  

Practical pattern:
- store events/frames in an append-only log (mmap-friendly)
- UI reads via offsets/slices
- only materialize into rich objects when needed for display

### Zero-copy persistence reads: prefer memory-mapped logs for transcripts and tool traces

For large, append-only data (transcripts, tool stdout, run logs), memory mapping can reduce copies and syscalls by letting the OS page data in/out. High-performance systems research shows mmap performance depends on paging/page-fault behavior and can be improved with techniques like map-ahead and caching to reduce overhead. citeturn4search26turn4search36

This is a great fit for:
- “stream to notes” artifacts (append-only)
- “graph event streams” (append-only)
- “session transcripts” (append-only JSONL/CBOR/FlatBuffer frames)

### Concurrency: design around non-blocking subagent spawns and bounded lanes

OpenClaw’s subagent design is instructive: `sessions_spawn` returns immediately, and `maxConcurrent` is explicitly a safety valve because subagents share gateway resources. citeturn2search16

Translated into your app architecture:
- **every automation is a background job**
- every job has a queue + concurrency limit
- “announce back” (deliver results to the UI) must be resilient to restarts (OpenClaw docs note this is best-effort and can be lost on gateway restart). citeturn2search16

Hermes’s v0.6.0 provider failover chain similarly reinforces that resilience must be a first-class concept surfaced to users. citeturn9view2

### Security/performance are linked: privilege boundaries reduce both risk and cost

OpenClaw warns to treat inbound DMs as untrusted, defaults to pairing, and recommends `doctor` for risky configs. citeturn7view0turn2search36 Hermes v0.6.0 hardening expands risky command detection and adds sensitive path guards. citeturn9view0

This is not just safety—it’s performance:
- fewer tools exposed → smaller tool selection set → less deliberation overhead
- fewer permissions → fewer “are we allowed?” branches
- fewer files reachable → less indexing/search surface

## Paperclip: how to incorporate the “company OS” layer without turning your app into a mess

Paperclip’s value proposition is *not* “better agent runtime.”

It’s a higher-level abstraction: “a Node.js server and React UI that orchestrates a team of AI agents to run a business,” using org charts, budgets, governance, goal alignment, coordination, and scheduled “heartbeats.” citeturn11view0 It explicitly says: “Not an agent framework… agents bring their own prompts, models, and runtimes; Paperclip manages the organization they work in.” citeturn11view0

This is compatible with your direction (“profiles for agents,” “coworker agent,” “agents have personalities/accounts,” “run a company,” “wake up and get summaries”). fileciteturn0file0

Practical integration options:

- Treat Paperclip concepts as a **mode** inside Harness: “Company View” where you manage org charts, budgets, heartbeats, and audit logs, but the executors remain Hermes/OpenClaw profiles. citeturn11view0turn8view0  
- Alternatively, treat Paperclip as a **separate service** your app can connect to—Paperclip is MIT licensed, which simplifies reuse, but you still must preserve notices/attribution and track third-party licenses. citeturn2search3  

Also: Paperclip’s own slogan—“If OpenClaw is an employee, Paperclip is the company”—is a clean mental model to adopt in UI copy and IA (information architecture). citeturn11view0

## Executable prompt for Claude Code that forces full reasoning, preserves nuance, and produces a real plan

```text
You are Claude Code acting as a principal engineer + product architect.

GOAL
Turn my “Harness” app into a cohesive control-plane + knowledge-hub that FEELS and OPERATES like Hermes Agent (the repo I forked) and also adopts the best interaction/operational primitives from OpenClaw + Paperclip + OpenCode. Do not simplify or drop nuance.

INPUTS YOU MUST READ
1) Read this entire brain dump carefully and infer intent, even if phrasing is messy:
- (attached in this chat / provided raw text)

2) Inspect my actual repo:
- Read package structure, runtime architecture, UI architecture, data storage, and how the Hermes fork is wired (or not wired) into the app.
- Identify what is stubbed, missing, or divergent.

NON-NEGOTIABLE OUTCOMES (deliver all)
A) GAP ANALYSIS (Truth-first)
- Create a “capability → UI surface” matrix:
  Rows: agent primitives (profiles, sessions, memory, skills, tools, approvals, provider routing/failover, cron/jobs, channels/gateway, sandbox backends, logs/traces, search/backends).
  Columns: current Harness UI, current Harness backend, Hermes upstream, OpenClaw reference, Paperclip reference.
- For each gap: explain what users experience today (the “feel” mismatch), what the correct behavior is, and the minimal UI/UX to expose it.

B) UPSTREAM ALIGNMENT PLAN (Hermes)
- Confirm which Hermes Agent version my fork is based on.
- Merge/port the Hermes Agent v0.6.0 features that I’m missing:
  * Profiles (multi-instance isolation)
  * MCP server mode (hermes mcp serve; stdio + streamable HTTP)
  * Ordered fallback provider chains
  * Official Docker container support
  * Telegram webhook mode + group gating controls
  * Slack multi-workspace OAuth
  * Feishu/Lark and WeCom adapters
  * Exa search backend
  * Hardening improvements (dangerous command detection, sensitive path guards, expanded secret redaction)
- Produce an implementation checklist with file paths, modules, and a recommended PR split.

C) OPENCLAW “FEEL” ADOPTION (principles, not blind copying)
- Identify the OpenClaw primitives we should replicate at the UX level:
  * “Gateway as control plane”
  * onboarding wizard + install daemon
  * session lifecycle + reset semantics
  * subagent semantics (non-blocking spawn, concurrency caps, minimal context injection)
  * security defaults (pairing/allowlist + doctor)
- Translate each into concrete Harness UI features and backend responsibilities.

D) PAPERCLIP “COMPANY OS” MODE (optional but designed)
- Propose how to represent:
  org charts, budgets, governance, heartbeats, role/persona configs, audit logs.
- Decide whether this is:
  1) a first-class mode inside Harness, OR
  2) a separate service Harness connects to, OR
  3) a plugin system.
- Include data model + UI screens + runtime scheduling semantics.

E) NOTES + CODE SIDEBAR SYSTEM (from my brain dump)
Implement the knowledge hub:
- Notes sidebar contains: notes, recent chats, agent vaults, my vaults, and a code section.
- Streaming: model outputs (from chat AND agents) can be streamed into notes in real-time, with toggles controlling routing:
  “stream to notes” toggle per chat/agent/session, with destinations:
  - new note, existing note, agent vault, code bucket, etc.
- “Ask bar” inside the code portion (like a mini chat) with same capabilities as main chat.
- Unify notes sidebar and mini chat; allow toggling sidebar presence.
- Make the agent pane feel like Xcode (layout and interaction model), but prioritize performance.

F) GRAPH OVERLAY REVAMP (from brain dump)
- Graph should be black/white (with glow), optional yellow highlights for chats.
- Add “alive” motion: very slow node drift (not cheap parallax).
- Add nested perspective / cinematic depth for nested folders: selecting a folder should feel like moving into deeper layers; configurable setting.

G) AUTOMATED INSTALL + ONBOARDING
- Users install the app, dependencies are handled automatically, then they can chat + automate.
- Provide:
  * a first-run bootstrap plan (runtime install vs embedded runtime)
  * a “doctor” command/screen
  * an “update” flow
  * sandbox choices (local vs Docker/remote), visible in UI

H) PERFORMANCE REQUIREMENTS (hard constraint)
- Include specific suggestions for:
  * zero-copy allocation & IPC (shared memory, Arrow/FlatBuffers-style patterns, transferable buffers)
  * streaming architecture (backpressure, incremental persistence, append-only logs)
  * graph rendering performance (avoid relayout storms, GPU-friendly rendering)
  * concurrency controls (job queues, bounded parallelism, cancellation)
- Every performance suggestion must include: why it matters, what to measure, and an implementation path.

I) LICENSING + SECURITY
- Identify risks of “copying” code across repos.
- Provide a compliance checklist:
  keep licenses, attribution, third-party notices, dependency audit.
- Provide a security checklist:
  tool permissions, sandboxing boundaries, secrets handling, prompt-injection defenses, audit logs.

OUTPUT FORMAT (mandatory)
1) A clear architecture diagram description (text is fine).
2) A prioritized roadmap broken into phases (each phase has acceptance criteria).
3) A GitHub-issue-ready backlog list (titles + descriptions + acceptance tests).
4) A minimal “golden path” demo script: from fresh install → onboarding → multi-profile agent → stream to notes → run automation → graph immersion.

BEHAVIOR RULES
- Do NOT handwave. If you’re uncertain, say what you need to inspect in the repo to resolve it, then propose a best-guess.
- Preserve nuance. Do not drop items “for simplicity.”
- Optimize for a cohesive product feel: UI must map to real backend primitives.
```

## TL;DR

Your app won’t feel like Hermes/OpenClaw until it becomes a **control plane** that exposes their real primitives (profiles, sessions, skills, tools, cron, gateways, hardening)—and Hermes v0.6.0 plus MCP gives you the clean backbone to do that. citeturn8view0turn3search0turn10view0

Does this match what you mean by “it feels disconnected”—specifically: are you missing *visibility into sessions/tools/automations*, or is the deeper issue that the *runtime you shipped is not actually Hermes’s runtime loop* (so the UI is talking to something else)?

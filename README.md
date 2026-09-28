# CopilotKit + Deep Agents Test Suite

A navigable, working test harness for the CopilotKit ↔ Deep Agents (Python) integration — one route per doc page, each running the real thing.

| | |
|---|---|
| **Doc-sync date** | `syncedAt` in `doc-snapshot/manifest.json` is the only one, 2026-09-23 at the last sync |
| **Doc root tracked** | <https://docs.copilotkit.ai/deepagents> |
| **Language tab** | **Python** throughout. The TypeScript tabs are not implemented. |
| **Backend flavour** | LangGraph CLI (`langgraph.json`), not the FastAPI tab |
| **CopilotKit (npm)** | declared `^1.73.3` · lockfile 1.73.3 · installed 1.73.3 (`frontend/VERSIONS.md`, written by `autorecorder/scripts/write-versions.mjs`) for `react-core`, `runtime` and `a2ui-renderer` alike. Upgraded 2026-09-23 from declared `^1.69.0` · lockfile 1.69.0 · installed 1.71.0; findings recorded before then name the version they were observed on |
| **CopilotKit (PyPI)** | `copilotkit` 0.1.94 |
| **Agent framework** | `deepagents` 0.7.4 · `langgraph-cli[inmem]` |
| **Frontend** | Next.js 16.3.0 · React 19.2.8 · TypeScript 5 · Tailwind 4 |

---

## Overview

Deep Agents is LangChain's framework for long-horizon agents — `create_deep_agent` returns a compiled LangGraph graph with planning and virtual-filesystem tools already installed. CopilotKit connects one of those graphs to a React app over the AG-UI protocol, so the agent can render components, call browser-side tools, suspend for human input, and share state with your UI.

This repo implements most Deep Agents doc pages in that list as a live route, and tracks three more for drift without building a demo behind them (see §8). It is a QA tool, not a tutorial: each route shows what the page teaches actually running, alongside the repo's own source read off disk at render time, plus a plain statement of anywhere the page and the shipped packages disagree. Eighteen doc pages, sixteen routes (three doc URLs are query-string variants of one page), thirteen graphs — ten Deep Agents plus three hand-built `StateGraph`s, for the pages that are about LangGraph features `create_deep_agent` does not expose.

Everything traces to a doc page. Nothing was invented to fill a gap — where a page omits something needed to run, the gap is named on the route and in [[FINDINGS.md](FINDINGS.md)](#9-known-issues--docvsimplementation-discrepancies).

---

## 3. Architecture

```
browser
  └─ <CopilotKit runtimeUrl="/api/copilotkit">        frontend/src/components/providers.tsx
       └─ <CopilotChat agentId="…"> + hooks           frontend/src/app/**/demo-chat/page.tsx
            │  HTTP POST (single-route JSON envelope)
            ▼
       Next route handler                             frontend/src/app/api/copilotkit/route.ts
       CopilotRuntime { agents: { <graphId>: LangGraphAgent } }
            │  LangGraph Platform API
            ▼
       LangGraph dev server  :8030                    backend/langgraph.json
       ├─ 10 compiled graphs from create_deep_agent   backend/main.py, backend/src/*.py
       └─  3 hand-built StateGraphs                   predictive_state_manual / predictive_state_tool
            │                                         / state_inputs_outputs
            │
            ▼
       OpenAI
```

**Backend language: Python.** The Quickstart's Python tab describes a `langgraph.json` manifest served by the LangGraph CLI; that is what this repo builds. The page's third tab (FastAPI + `add_langgraph_fastapi_endpoint`) is an alternative not implemented here.

Two runtime endpoints, not one:

- `/api/copilotkit` — all thirteen graphs. Sets `a2ui: { injectA2UITool: false, agents: ["a2ui_fixed_agent"] }`, because the fixed-schema agent returns its own A2UI operations and must not also be handed a `generate_a2ui` tool.
- `/api/copilotkit-a2ui-dynamic` — the dynamic-schema agent only, with no `a2ui` block, so injection stays on. The setting is per-runtime, which is why it needs its own endpoint.

---

## 4. Prerequisites

| Requirement | Version used | Notes |
|---|---|---|
| Node.js | 24.16.0 (20+ per the Quickstart) | |
| npm | 12.0.1 | or pnpm/yarn/bun |
| Python | 3.12 | `langgraph.json` declares `"python_version": "3.12"` |
| `uv` | 0.11.20 | The Quickstart's package manager for Deep Agents |
| OpenAI API key | — | **Required.** Every agent uses it. |
| LangSmith / LangGraph Platform key | — | **Not** required locally. Only for a Platform deployment. |

No framework-specific CLI to install globally: `langgraph-cli[inmem]` comes in as a `uv` dev dependency.

---

## 5. Setup

```bash
# 1. Clone
git clone <this-repo> deepagents && cd deepagents

# 2. Frontend deps
cd frontend && npm install && cd ..

# 3. Backend deps (creates backend/.venv and installs langgraph-cli too)
cd backend && uv sync && cd ..
```

**4. Environment.** There are two processes, so two files:

```bash
cp .env.example backend/.env       # then keep the backend block
cp .env.example frontend/.env.local # then keep the frontend block
```

| Variable | Goes in | Required | What it does |
|---|---|---|---|
| `OPENAI_API_KEY` | `backend/.env` | **yes** | The model key. Every agent reads it. |
| `OPENAI_MODEL` | `backend/.env` | no | Model id for every agent. Defaults to `gpt-4o`. |
| `LANGGRAPH_DEPLOYMENT_URL` | `frontend/.env.local` | no | Where the runtime route forwards runs. Defaults to `http://localhost:8030`. |
| `LANGSMITH_API_KEY` | `frontend/.env.local` | no | Sent as `langsmithApiKey`. Ignored by a local `langgraph dev`. |
| `COPILOTKIT_TELEMETRY_DISABLED` | `frontend/.env.local` | no | Silences the runtime's telemetry notice. |

**Ports:** frontend `3030`, agent server `8030`. Change the agent port and you must change `LANGGRAPH_DEPLOYMENT_URL` to match.

---

## 6. Running the project

Two terminals — the CLI does not start both.

**Terminal 1 — the agent server:**

```bash
cd backend && uv run langgraph dev --port 8030 --no-browser
```

Success looks like this, with all thirteen graphs importing:

```
Welcome to
╦  ┌─┐┌┐┌┌─┐╔═╗┬─┐┌─┐┌─┐┬ ┬
║  ├─┤││││ ┬║ ╦├┬┘├─┤├─┘├─┤
╩═╝┴ ┴┘└┘└─┘╚═╝┴└─┴ ┴┴  ┴ ┴
- 🚀 API: http://localhost:8030
...
Importing graph  graph_id=sample_agent  path=./main.py
Importing graph  graph_id=tool_rendering_agent  ...
Application started up in 3.55s
```

Confirm with `curl http://localhost:8030/ok` → `{"ok":true}`.

**Terminal 2 — the app:**

```bash
cd frontend && npm run dev
```

You should see `✓ Ready in …` and `- Local: http://localhost:3030`.

**Open <http://localhost:3030>.** Start at `/quickstart` — if that streams a reply, every other route's plumbing is fine.

> The Quickstart's Deep Agent tab says to start the agent with `npx @langchain/langgraph-cli dev --port 8123`. That does work against this Python manifest, but the CLI itself prints *"Launching Python server from @langchain/langgraph-cli is experimental. Please use the `langgraph-cli` package from PyPi instead"* and then downloads its own copy of `uv`. This repo takes that advice.

---

## 7. What to expect — walkthrough per section

Every route has a notes page (source, discrepancies, a **Try it** box) and, where there is something to drive, a chrome-free demo at `<route>/demo-chat`.

### Getting Started

**`/`** — Introduction. Orientation and the live graph roster. Nothing to drive. Since 2026-09-21 the doc page carries a code block of its own, a `CopilotRuntime` route titled with the same filename the Quickstart uses and holding different code; both are printed side by side on the route, with the differences named. See [FINDINGS.md](FINDINGS.md) #28 and #29.

**`/quickstart`** → `sample_agent`
Proves the whole stack in one message: a Deep Agent with a single Python tool, published by the LangGraph server, reached through `CopilotRuntime`, driven by a `CopilotSidebar`.
*Try:* `What's the weather in Lisbon?`
*Pass:* tokens stream a word at a time; a collapsed `Called get_weather` row appears (that's `useDefaultRenderTool`); the reply says Lisbon is sunny.
*Fail:* an error banner or no reply — `langgraph dev` is down, or `OPENAI_API_KEY` is missing from `backend/.env`.

### Generative UI

**`/generative-ui/tool-rendering`** → `tool_rendering_agent`
`useRenderTool` claims a backend tool by name and replaces its chat bubble; `useDefaultRenderTool` catches the rest.
*Try:* `What's the weather in Tokyo?` then `Write a short plan for a two-day trip to Tokyo`
*Pass:* the first draws a grey `Called the weather API for Tokyo.` line; the second makes the agent use its own planning tools, which fall through to the catch-all as `✓ write_todos` rows with JSON.
*Fail:* a default tool bubble instead of the grey line — the name in `useRenderTool` no longer matches the Python `@tool`.

**`/generative-ui/state-rendering`** → `state_rendering_agent`
`copilotkit_emit_state` pushes state mid-node so a slow task reports progress; `useAgent` renders it outside the chat.
*Try:* `Research the history of the espresso machine`
*Pass:* three rows appear at once, all ⏳, then flip to ✅ one per second, and stay after the reply lands.
*Fail:* rows that appear then vanish — the emitted state was never returned by the node. All-✅-at-once — the deltas were batched, not streamed.

**`/generative-ui/your-components/interrupt-based`** → `interrupt_agent`, `interrupt_multi_agent`
LangGraph `interrupt()` in an `AgentMiddleware.before_model` hook, answered by `useInterrupt`. Two tabs: one interrupt, and two dispatched by `type` via `enabled`.
*Try:* send `Hello`.
*Pass:* on **One interrupt**, the first message is answered with a name form rather than a reply; submit a name and the run resumes using it. On **Two, dispatched by type**, an amber Approve/Reject card comes first, then the blue name form.
*Fail:* a raw JSON blob instead of a form — no `useInterrupt` claimed the event; on the conditional tab that means the `enabled` predicate did not match.

**`/generative-ui/a2ui/fixed-schema`** → `a2ui_fixed_agent`
A component tree authored as JSON up front; the tool supplies only data and returns an `a2ui_operations` container the runtime middleware detects.
*Try:* `Find me a flight from SFO to JFK on United for around $289`
*Pass:* a rendered itinerary card — airport codes either side of an arrow, an airline pill, a price, a Book button.
*Fail:* a raw JSON dump — the container was not detected. An empty card — the `catalogId` in the agent does not match `catalog.ts`.
*Known limit:* the Book button does nothing. See [[FINDINGS.md](FINDINGS.md)](#9-known-issues--docvsimplementation-discrepancies).

**`/generative-ui/a2ui/dynamic-schema`** → `a2ui_dynamic_agent`
A secondary LLM writes the schema and the data per request. The backend contributes only `CopilotKitMiddleware`.
*Try:* `Show me a KPI dashboard for a SaaS business last quarter`
*Pass:* a progress skeleton, then cards appearing one at a time as data streams in, with a one-line chat reply beside them.
*Fail:* a long prose answer and no surface — the model chose not to call `generate_a2ui`. An empty surface — the generated schema had no component with `id: "root"`.

**`/generative-ui/a2ui/styling`** → `a2ui_dynamic_agent`
The `.a2ui-surface` CSS custom properties, applied to a real surface.
*Try:* `Draw a comparison table of three laptops`
*Pass:* surface text in Plus Jakarta Sans with tight letter-spacing; cards at least 280px wide even when one has streamed in; card background goes near-black in OS dark mode.
*Fail:* system-default typography on the surface — `theme.css` was not imported.

**`/generative-ui/a2ui/advanced`** → `a2ui_dynamic_agent`
A custom `render_a2ui` progress renderer replacing the built-in skeleton.
*Try:* `Chart quarterly revenue for three product lines`
*Pass:* a grey `Building interface...` box with a spinner, gaining an `N components, M items` line as the schema streams, then vanishing as the surface paints.
*Fail:* CopilotKit's own shimmering skeleton — the renderer was registered outside the provider that owns this agent.
*Known limit:* the action-handler half of this page is not implementable. See [[FINDINGS.md](FINDINGS.md)](#9-known-issues--docvsimplementation-discrepancies).

**`/generative-ui/frontend-cards`** — ❌ **Broken as published**, works with one prop the page never mentions. New upstream 2026-09-11. A card pushed into the transcript from frontend code as a `role: "activity"` message, which is stripped from every run. The demo has two tabs. **As published** is step 2's provider unchanged (`runtimeUrl` + `renderActivityMessages`); its bare `useAgent()` and `<CopilotChat />` ask for the agent id `default`, which a Deep Agents runtime does not register. *Try:* just open it. *What happens:* the chat paints, then `useAgent()` throws `Agent 'default' not found after runtime sync` as soon as `/info` answers (3/3), and the demo prints that error where the chat was. **+ agent="sample_agent"** adds the Quickstart's provider prop and nothing else. *Try:* click **Simulate: deployment finished**, then ask `Have you been shown any deployment card?` *Pass:* the card renders; the probe row reads `agent.messages = activity, user, assistant` and `run payload = user` (read off the request that left the browser); the agent says it saw no card. *Fail:* no card, or `activity` in the payload row. The three snippets are verbatim; step 3's `<DeploymentWatcher />` is mounted inside step 2's provider, which the page never says to do, and its `wss://example.com` socket never delivers, so the button fires the same `addMessage`. See [FINDINGS.md](FINDINGS.md) #22.

### Custom Look and Feel

**`/custom-look-and-feel/markdown`** → `sample_agent` — ⚠️ **Partial.** New upstream 2026-09-21. The `markdownRenderer` slot on `CopilotChatAssistantMessage`, reached from `<CopilotChat messageView={{ assistantMessage: { markdownRenderer } }} />`, in all three of the page's forms. The demo has five tabs and a probe that reads the rendered HTML rather than the library's own bookkeeping: the opening tag of the first `<a>`, the number of `[data-streamdown]` elements, the number of elements carrying a literal `node` attribute, and the number carrying the page's `.my-link` / `.my-heading`. **Page code, verbatim** is the published block with nothing added. *Try:* just open it. *Expect:* the chat paints, then throws `Agent 'default' not found after runtime sync` — the block carries no agent id, and Deep Agents registers no `default`, the same defect already reproduced on Frontend-Driven Cards. The other four tabs add `agentId="sample_agent"` and nothing else. **Not yet driven:** this route was built on 2026-09-21 and has no clip; the lines below are what the take should show. *Try:* `Reply in markdown. Include an "## Example" heading, a link to https://docs.copilotkit.ai/deepagents, and the literal text <reference-chip id="42">Doc 42</reference-chip>.` *Pass:* on **components map** the anchor row reads `<a href="…" target="_blank" rel="noopener noreferrer" class="my-link">` with no `data-streamdown`, and the `node` count is 0; on **no override** the same anchor carries `data-streamdown="link"` and Streamdown's classes; the reference-chip is plain text on every tab. *Fail:* a `node` count above 0, or a missing `rel`/`target` on the components tab. See [FINDINGS.md](FINDINGS.md) #32.

### Rich Threads

**`/threads/lifecycle`** → `sample_agent` — ⚠️ **Partial.** Tracked 2026-09-21; the only Rich Threads page this repo implements. One button per lifecycle claim on the page, with the chat's resolved state read back from its `CopilotChatConfigurationProvider`, including the id of the parent provider the root `<CopilotKit>` supplies. **Try:** send a message, press "Remount chat", then "Open conversation", "New chat", "Pin a threadId prop" and "New chat" again. **Pass:** the remount keeps the id, because it is inherited from the parent, and the chat empties; "Open conversation" flips `hasExplicitThreadId` to true and replays the messages from the runtime's `InMemoryAgentRunner`; with the id pinned, "New chat" changes nothing and the amber line shows the `Ignoring startNewThread()` warning; the pinned id survives a remount. **Fail:** the re-opened thread shows 0 messages (nothing replayed). See [FINDINGS.md](FINDINGS.md) #35.

### App Control

**`/frontend-tools`** → `frontend_tools_agent`
A tool whose body runs in the browser. The Python side defines no tool at all.
*Try:* `Say hello to Ada`
*Pass:* a browser `alert()` reading `Hello, Ada!`; dismiss it and a green line appears in the left panel; the agent then reports it said hello — that reply is the handler's return value.
*Fail:* the agent describing what it *would* do — the tool never reached it; check `CopilotKitMiddleware` is in the middleware list.

**`/webmcp`** — 🚧 **Tracked, not implemented.** The doc adds a `webmcp` flag to a frontend tool so browser agents can discover it through `document.modelContext`. Its own test procedure needs Chrome 149+ with the WebMCP origin trial (or `chrome://flags/#enable-webmcp-testing`) and Chrome's Model Context Tool Inspector; CopilotKit no-ops where `document.modelContext` is absent, so a demo here would register nothing and still look green.

**`/human-in-the-loop/governed-actions`** — ✅ **Working.** An approval card gating a side-effecting action. The run stops on the card, which shows the policy verdict, the reference that produced it, and the exact arguments; it proceeds only on approval. The `useHumanInTheLoop` variant is implemented; the `useInterrupt` variant is not, because it needs a backend that pauses a run and attaches `interrupt.metadata.action`, and no graph here does. The published schema goes in unchanged — `z.record(z.unknown())` is valid on this repo's zod 3, though it does not compile on the zod 4 that MsPy-react and AG2-react run. The `useEffect` that auto-resolves `allow` and `deny` omits `onApprove` and `onBlock` from its dependency array; kept as published, warning and all.

### Shared State

**`/shared-state/in-app-agent-read`** → `shared_state_agent`
Reading agent state as ordinary reactive React state.
*Try:* `Hello`
*Pass:* the left panel reads `Language: english` and the JSON dump shows a `language` key.
*Fail:* an empty dump — the agent has not run yet; state only syncs once a run starts.

**`/shared-state/in-app-agent-write`** → `shared_state_agent`
`agent.setState` from the app, plus `agent.runAgent` to re-run immediately.
*Try:* `Tell me a fun fact about octopuses`, hit **Toggle Language**, ask again.
*Pass:* first answer in English, second in Spanish. **Toggle + runAgent()** produces a fresh reply with no typing.
*Fail:* the label flips but answers stay English — the write landed but the model never saw it; check `expose_state`.

**`/shared-state/predictive-state-updates`** → `predictive_state_agent`, `predictive_manual_graph`, `predictive_tool_graph`
**All three of the page's variants are live**, behind a toggle at the top of the demo. Variants 2 and 3 are not Deep Agents — they are hand-built `StateGraph`s, which is what those tabs are for.
*Try:* `Plan and execute a website redesign` on each tab.
*Pass:* **Prebuilt** — step rows appear one at a time, noticeably *before* the chat message completes. **Custom · manual** — exactly four fixed rows, one per second, then an ordinary answer (verified: four distinct state updates in order). **Custom · tool** — steps stream as the model writes the tool call, then the node's `Command` copies the same argument into `observed_steps` so it persists.
*Fail:* all rows at once after the reply — the streaming did not intercept. Nothing at all — the provider is `<CopilotKitProvider>` rather than `<CopilotKit>`; see [[FINDINGS.md](FINDINGS.md)](#9-known-issues--docvsimplementation-discrepancies).

**`/shared-state/state-inputs-outputs`** → `state_io_graph` — *the one route that is not a Deep Agent*
A hand-built `StateGraph` with `input_schema` / `output_schema`, because the page's own callout says `create_deep_agent` does not expose them. Three fields, three fates: `question` goes in and never comes back, `answer` comes back, `resources` never crosses the wire at all.
*Try:* leave the question as `Why is the sky blue?` and hit **Ask**.
*Pass:* three green badges — `question` absent, `answer` present and holding the reply, `resources` absent — and the state dump at the bottom shows only `answer` and `copilotkit`. Verified on the wire: the final `STATE_SNAPSHOT` carries exactly `["messages", "copilotkit", "answer"]`.
*Fail:* a red badge on `question` or `resources` — `input_schema` / `output_schema` were dropped from the `StateGraph` call and the whole of `OverallState` is coming back.

**`/shared-state/workflow-execution`** — reference only, no demo. The page currently serves the Input/Output Schemas content verbatim.

### Intelligence

**`/intelligence/memories`** — ❌ **Broken as documented.** New upstream 2026-09-11. **Try:** **Save**, then `Please remember that I prefer concise status updates.`, then switch to the second runtime and **Save** again. **What happens:** the page's React snippet used not to compile (it imported `useMemories` from the package root); the 2026-09-21 sync fixed that to `@copilotkit/react-core/v2`, so the published file now runs here as published and the demo's corrected copy is gone. On the documented runtime — the Deep Agents Quickstart's, which is not an Intelligence runtime — no memory request ever leaves the browser: the hook reports `isAvailable: true`, the page's `MemoryList` renders an empty list instead of "Memory is not available", the save fails with "Runtime URL is not configured", and the agent says "Got it! I'll keep updates brief." The second runtime adds `memory: { access }`, which the page never mentions and without which every `/memories/*` route 404s even on an Intelligence runtime; it needs `CPK_INTELLIGENCE_API_KEY`, which this harness does not have, so it answers 503 and the platform side was not reached. See [FINDINGS.md](FINDINGS.md) #23.

**`/intelligence/learned-skills`** — ❌ **Broken as published.** New upstream 2026-09-15, restructured 2026-09-21. Automatic delivery of a Learning container's published Skills through a framework-native adapter. **Try:** just open it, then `List the skills you can load, then load the refund-policy skill and follow it.` **What happens:** the agent answers from its own instructions with no tool call, because no adapter is mounted and none can be. Every Python package on the page's table is 404 on PyPI; the BuiltInAgent row added on 2026-09-21 uses the package this repo does install; it did not typecheck on 1.71.0 and does on the 1.73.3 installed since 2026-09-23, but it would replace the Deep Agent rather than attach to it. Both BuiltInAgent snippets are in the repo verbatim (`built-in-agent-classic.ts`, `built-in-agent-factory.ts`), imported by nothing. See [FINDINGS.md](FINDINGS.md) #26 and #38.

**`/learning`** — ❌ **Broken without an Intelligence key.** New upstream 2026-09-11, new delivery and schedule sections 2026-09-21. The page's runtime snippet on its own mount at `/api/copilotkit-learning`, with `expense-agent` and `sample_agent` both on the Quickstart graph. The selector shipped here returns one container for both rather than the page's conditional, which is [FINDINGS.md](FINDINGS.md) #25. **Try:** on `expense-agent`, `Review this expense: $42 team lunch, receipt attached.`; then on `sample_agent`, `Say hello in five words.` **What happens:** neither can send. `apiKey: process.env.CPK_INTELLIGENCE_API_KEY!` throws "apiKey is required and cannot be blank" at module load, the route answers 500 (shown in the panel's last row), the provider sits in `error` and the send button never enables. Container assignment, and the dashboard/CLI half of the page (create a container, Run Learning, approve a Skill, `copilotkit skills download`), need a provisioned project and are not exercised. The 2026-09-21 sync added a **Set up automatic skill delivery** section and a **Choose the daily schedule** step on top of that: an agent-server environment block (`CPK_INTELLIGENCE_API_KEY`, `CPK_INTELLIGENCE_LEARNING_CONTAINER_ID=expense-review`) for an adapter this backend cannot install, and a dashboard schedule (15 eligible Threads, 02:00 UTC default) with no code in it at all. See [FINDINGS.md](FINDINGS.md) #24 and #27.

### Cookbook

**`/cookbook/jev-generative-ui`** — ❌ **Not runnable here, and not stood in for.** New upstream 2026-09-21. A workspace picker whose next control and candidate ranking come from Jev, TypeSafe's decision service. The route carries every published TypeScript block verbatim; four of the six files are imported by nothing, compile, and cannot run. **Try:** open the route and use the two panel buttons, then press an option. **Not yet driven** — built 2026-09-21, no server was started for it; what follows is what it is wired to do. **Expect:** the prepared controls, `PanelSchema`/`StateSchema` and `readAction` all run for real — a clarification answer is rewritten to `I answered the workspace clarification: …`, a room selection sets `selectedId` and the note `Selected Quiet room. No booking was made.` — and the trail stops at `choosePanel`, which needs `@typesafe-ai/sdk` and a `TYPESAFE_API_KEY` from a third-party vendor. The comparison panel is in catalog order, labelled on screen as such, because the Jev fit scores that order it do not exist here. No demo and no recorder entry: there is nothing to film that would not be a stand-in for the decision layer. See [FINDINGS.md](FINDINGS.md) #33.

---

## 8. Testing checklist / current status

Verified 2026-08-06 by driving every graph through the real `CopilotRuntime` route against a live `langgraph dev` and an OpenAI key.

| Doc page | Route | Graph | Status | Notes |
|---|---|---|---|---|
| [quickstart](https://docs.copilotkit.ai/deepagents/quickstart) | `/quickstart` | `sample_agent` | ✅ Working | Python tab + Deep Agent runtime tab |
| [generative-ui/tool-rendering](https://docs.copilotkit.ai/deepagents/generative-ui/tool-rendering) | `/generative-ui/tool-rendering` | `tool_rendering_agent` | ✅ Working | Page's `useDefaultRenderTool` destructures a prop that doesn't exist |
| [generative-ui/state-rendering](https://docs.copilotkit.ai/deepagents/generative-ui/state-rendering) | `/generative-ui/state-rendering` | `state_rendering_agent` | ✅ Working | Emit coroutine's caller is not shown by the page |
| [.../your-components/interrupt-based](https://docs.copilotkit.ai/deepagents/generative-ui/your-components/interrupt-based) | `/generative-ui/your-components/interrupt-based` | `interrupt_agent`, `interrupt_multi_agent` | ✅ Working | Conditional snippet cannot work as printed |
| [.../a2ui/fixed-schema](https://docs.copilotkit.ai/deepagents/generative-ui/a2ui/fixed-schema) | `/generative-ui/a2ui/fixed-schema` | `a2ui_fixed_agent` | ⚠️ Partial | Different `a2ui` API than printed; Book button inert |
| [.../a2ui/dynamic-schema](https://docs.copilotkit.ai/deepagents/generative-ui/a2ui/dynamic-schema) | `/generative-ui/a2ui/dynamic-schema` | `a2ui_dynamic_agent` | ✅ Working | `myCatalog` never defined by the page |
| [.../a2ui/styling](https://docs.copilotkit.ai/deepagents/generative-ui/a2ui/styling) | `/generative-ui/a2ui/styling` | `a2ui_dynamic_agent` | ✅ Working | Page's dark-mode rule is invalid CSS |
| [.../a2ui/advanced](https://docs.copilotkit.ai/deepagents/generative-ui/a2ui/advanced) | `/generative-ui/a2ui/advanced` | `a2ui_dynamic_agent` | ⚠️ Partial | Progress renderer works; action-handler exports missing |
| [frontend-tools](https://docs.copilotkit.ai/deepagents/frontend-tools) | `/frontend-tools` | `frontend_tools_agent` | ✅ Working | Page duplicates two of its own sections |
| [webmcp](https://docs.copilotkit.ai/deepagents/webmcp) | `/webmcp` | — | 🚧 Not started | Tracked for drift. Needs Chrome 149+ and the WebMCP origin trial |
| [human-in-the-loop/governed-actions](https://docs.copilotkit.ai/deepagents/human-in-the-loop/governed-actions) | `/human-in-the-loop/governed-actions` | `sample_agent` | ✅ Working | Tool-call variant. `useInterrupt` half needs a backend that pauses a run; published schema compiles unchanged on zod 3 |
| [shared-state/in-app-agent-read](https://docs.copilotkit.ai/deepagents/shared-state/in-app-agent-read) | `/shared-state/in-app-agent-read` | `shared_state_agent` | ✅ Working | `Literal[...] = "english"` is not a runtime default |
| [shared-state/in-app-agent-write](https://docs.copilotkit.ai/deepagents/shared-state/in-app-agent-write) | `/shared-state/in-app-agent-write` | `shared_state_agent` | ✅ Working | Needs `expose_state`, which neither page mentions |
| [.../predictive-state-updates?agent-type=prebuilt](https://docs.copilotkit.ai/deepagents/shared-state/predictive-state-updates?agent-type=prebuilt) | `/shared-state/predictive-state-updates` | `predictive_state_agent` | ✅ Working | Requires `<CopilotKit>`, not `<CopilotKitProvider>` |
| [...&state-emission=manual-emission](https://docs.copilotkit.ai/deepagents/shared-state/predictive-state-updates?agent-type=custom-graph&state-emission=manual-emission) | same route, tab 2 | `predictive_manual_graph` | ✅ Working | Node body from the Python tab; graph wiring from the same page's TS tab |
| [...&state-emission=tool-emission](https://docs.copilotkit.ai/deepagents/shared-state/predictive-state-updates?agent-type=custom-graph&state-emission=tool-emission) | same route, tab 3 | `predictive_tool_graph` | ✅ Working | Python snippet is near-complete; only the state class and graph were missing |
| [shared-state/state-inputs-outputs](https://docs.copilotkit.ai/deepagents/shared-state/state-inputs-outputs) | `/shared-state/state-inputs-outputs` | `state_io_graph` | ✅ Working | Custom `StateGraph`, not a Deep Agent — the page calls for exactly that |
| [shared-state/workflow-execution](https://docs.copilotkit.ai/deepagents/shared-state/workflow-execution) | `/shared-state/workflow-execution` | — | ❌ Broken | Upstream duplicate of the page above |
| [generative-ui/frontend-cards](https://docs.copilotkit.ai/deepagents/generative-ui/frontend-cards) | `/generative-ui/frontend-cards` | `sample_agent` | ❌ Broken | New 2026-09-11. As published `useAgent()` targets `default`, which Deep Agents does not register, and throws; with the Quickstart's `agent` prop the card renders and never reaches the agent. Pre-connect cards silently lost — [FINDINGS.md](FINDINGS.md) #22 |
| [intelligence/memories](https://docs.copilotkit.ai/deepagents/intelligence/memories) | `/intelligence/memories` | `sample_agent` | ❌ Broken | New 2026-09-11. Import path fixed upstream 2026-09-21; on the Quickstart runtime the hook still reports available over an empty list and never sends a request; `memory: { access }` undocumented — [FINDINGS.md](FINDINGS.md) #23 |
| [intelligence/learned-skills](https://docs.copilotkit.ai/deepagents/intelligence/learned-skills) | `/intelligence/learned-skills` | `sample_agent` | ❌ Broken | New 2026-09-15. Every Python adapter 404s on PyPI; the BuiltInAgent row added 2026-09-21 needs runtime 1.73.0, which the page does not name (compiles here since the 2026-09-23 upgrade to 1.73.3) — [FINDINGS.md](FINDINGS.md) #26, #38 |
| [learning](https://docs.copilotkit.ai/deepagents/learning) | `/learning` | `sample_agent` | ❌ Broken | New 2026-09-11. Page's runtime throws at load without `CPK_INTELLIGENCE_API_KEY` (route 500); `agents`/`identifyUser` undefined; needs runtime 1.70+ — [FINDINGS.md](FINDINGS.md) #24, #25, #27 |
| [custom-look-and-feel/markdown](https://docs.copilotkit.ai/deepagents/custom-look-and-feel/markdown) | `/custom-look-and-feel/markdown` | `sample_agent` | ⚠️ Partial | New 2026-09-21. All three blocks ask for the agent id `default` and throw; none carries `use client`; the headline example styles with classes the page never defines. With `agentId` added every claim about the props holds, read off the rendered HTML — [FINDINGS.md](FINDINGS.md) #32 |
| [cookbook/jev-generative-ui](https://docs.copilotkit.ai/deepagents/cookbook/jev-generative-ui) | `/cookbook/jev-generative-ui` | — | ❌ Broken | New 2026-09-21. Needs `@typesafe-ai/sdk` + a TypeSafe vendor key and `@langchain/openai`, none of which exist here; pins ten exact versions, six unmet. Every block typechecks on the installed 1.71.0 anyway. No demo, no recorder entry — [FINDINGS.md](FINDINGS.md) #33 |
| [threads-lifecycle](https://docs.copilotkit.ai/deepagents/threads-lifecycle) | `/threads/lifecycle` | `sample_agent` | ⚠️ Partial | Tracked 2026-09-21. Mint, replay, switch and the prop-controlled no-op observed; the remount keeps the id under `<CopilotKit>`, contrary to the page's warning; `existingId` undefined — [FINDINGS.md](FINDINGS.md) #35 |

**Totals:** 14 ✅ Working · 4 ⚠️ Partial · 0 📄 Reference · 6 ❌ Broken · 1 🚧 Not started.

**Tracked without a demo.** The 🚧 row and the Jev cookbook row carry a route, a nav entry and a snapshot so drift is watched, but there is no `/demo-chat` behind them and the recorder does not touch them. That leaves three routes with no recorder entry: `/webmcp`, `/shared-state/workflow-execution` and `/cookbook/jev-generative-ui`. All three are deliberate, and each one's reason is on its own route page and in §7. The rest of `/deepagents/intelligence/` is the old `/deepagents/premium/` set under a new prefix and stays in `doc-snapshot/manifest.json`’s `knownUnmapped` list. So do the Rich Threads pages other than `/deepagents/threads-lifecycle`.

The same table is rendered in-app at `/status`, generated from `frontend/src/lib/nav-config.ts` — that file is the single source of truth for routes, statuses and doc links, so this table and the app cannot drift apart.

---

## 9. Known issues / doc-vs-implementation discrepancies

Moved to [FINDINGS.md](FINDINGS.md).

## 10. Troubleshooting

The Deep Agents doc tree has **no** Troubleshooting section as of 2026-08-06 — no Common Issues, migration or error-debugging pages. What follows is this repo's own symptom list, from actually running it.

| Symptom | Cause | Fix |
|---|---|---|
| `Failed to create thread: HTTP 422: Invalid thread ID: must be a UUID` | Something posted a non-UUID `threadId`. The browser always generates one; scripted clients often don't. | Use `crypto.randomUUID()`. |
| Chat shows an error banner; agent server log is silent | The runtime cannot reach `:8030`. | Is `langgraph dev` running? `curl http://localhost:8030/ok`. Check `LANGGRAPH_DEPLOYMENT_URL`. |
| Agent runs but every reply is an auth error | `OPENAI_API_KEY` missing. | It goes in **`backend/.env`**, not `frontend/.env.local`. `langgraph.json` points at `.env` next to it. |
| A route 500s with "Agent … not found" | Graph id mismatch. | `frontend/src/lib/agents.ts` must list the same ids as `backend/langgraph.json`. |
| Predictive State Updates panel never fills | Root provider is `<CopilotKitProvider>`. | Use `<CopilotKit>` — see [FINDINGS.md](FINDINGS.md) #6. Fails silently. |
| Shared-state toggle flips but the agent ignores it | `expose_state` not set. | `CopilotKitMiddleware(expose_state=["language"])` — see [FINDINGS.md](FINDINGS.md) #9. |
| A2UI surface renders empty | `catalogId` mismatch, or a generated schema with no `id: "root"`. | Fixed schema: `CATALOG_ID` in `backend/src/a2ui_fixed.py` must equal the one in `catalog.ts`. Dynamic: try a stronger `OPENAI_MODEL`. |
| Tool renders as the default bubble | Renderer name ≠ Python tool name. | They must match exactly. |
| `Expected to have a matching ToolMessage in Command.update` | A tool returned a `Command` without one. | Include a `ToolMessage` with an injected `tool_call_id` — see `backend/src/state_rendering.py`. |
| Unexpected `✓ write_todos` / `✓ ls` rows in chat | Not a bug. `create_deep_agent` installs planning and filesystem tools; the catch-all renderer draws them. | — |
| Input/Output Schemas shows `question` or `resources` as present | `input_schema=` / `output_schema=` missing from the `StateGraph` call, so the whole of `OverallState` is returned. | Both belong on the constructor — see `backend/src/state_inputs_outputs.py`. |
| Graph edits don't take effect | `langgraph dev` watches files but a syntax error aborts the reload. | Check the server log. |

---

## Doc drift detection

`/doc-sync` keeps this repo honest about the docs it mirrors. Press **Sync docs now** (on the landing page or on `/doc-sync`) and it fetches the markdown source behind all 18 tracked doc pages, diffs each against the copy stored in `doc-snapshot/`, replaces that copy, and reports what moved — ranked by whether the change can actually break an implementation.

Doc pages are fetched by appending `.md` to their URL, which returns the authored MDX rather than 250 KB of rendered HTML. Every response is checked for `text/markdown` before it is allowed near the snapshot: a URL that misses the markdown handler still answers `200` with the HTML app shell, and writing that in would destroy the baseline and report the whole corpus as rewritten on the next run. A run commits all pages or none.

**Severity is decided by where the edit landed**, not how big it was:

| Level | Trigger |
|---|---|
| **High** | a changed line inside a fenced code block, a changed fence count, or a page that now 404s and is gone from the sitemap |
| **Medium** | a changed heading, changed frontmatter `title`/`description`, or prose in the same section as changed code |
| **Low** | other prose |

**Sections checked** lists every tracked page in nav order with a mark — `✓` unchanged, `!` changed, `+` stored, `✗` 404, `~` unstable, `·` not checked. Expanding a row shows the comparison: for a changed page the diff (`−` existing snapshot, `+` newly fetched), and for an unchanged one the two matching hashes, which is the evidence the check ran.

**`doc-snapshot/CHANGELOG.md`** is the record that survives a re-sync. Because syncing replaces the copy it just compared against, the run *after* a change reports nothing — so the changelog is written at the moment of discovery and never rewritten later. Only changed pages are recorded; a clean run does not touch the file. It keeps the three most recent dated entries, counted rather than aged, so a change from six weeks ago still shows if nothing has happened since.

**One sync date.** `syncedAt` in `doc-snapshot/manifest.json`, rewritten on every run and shown on `/`, `/status` and `/doc-sync`. There is no hand-maintained date to keep in step with it.

**To test it**, edit any `doc-snapshot/pages/*.md` file and press the button — a line inside a code fence for High, a `##` heading for Medium, a sentence for Low. The comparison reads the stored file itself, so nothing else needs changing. Both `/doc-sync` and the changelog label the result as a local snapshot edit rather than upstream drift.

Commit `doc-snapshot/` — `pages/`, `manifest.json` and `CHANGELOG.md` are the baseline every diff is taken against. `reports/` is gitignored derived data.

---

## Screen recording

`autorecorder/` records one demo video per doc page — read the doc, show the
code in a simulated VS Code, then drive the live feature. Start both servers
(§6) first; the recorder checks they answer before it launches a browser.

```bash
npm run record:all         # every page
npm run record:issues      # only the pages with a known defect
npm run record -- --list   # what is registered
npm run record:doctor      # is the recorder's config still valid?
```

The recorder is documented in [`autorecorder/README.md`](autorecorder/README.md).

### Pages that are supposed to fail

Twelve routes are on the QA report as broken, and their clips exist to **show**
that rather than to work around it. Each declares a `knownIssue` in
`autorecorder/config/pages.config.ts`, and that one object drives three things:
the run reports `[ISSUE]` instead of `[PASS]` (and still exits 0, so a dozen
documented defects do not make every run fail), the recorder types the report
into a simulated Notepad at the end of the clip, and the same object is written
to `autorecorder/videos/RECORD_RESULTS.json`. The sentence on screen and the row
that reaches a manager are the same string, written once.

`[ISSUE]` means the page is on the known-issues list and recorded cleanly. It
does **not** mean the defect was confirmed on this run — the recorder alone
cannot establish that. Watch the clip before sending the report on.

### Paired routes

Most of these defects are an absence — a label that never changes, a list that
stays empty — and a clip of an absence invites one question: was the demo just
wired up wrong? The answer has to be on screen, so where the fix is known the
route is paired:

| Doc's code, verbatim | Same page, with the omitted line |
|---|---|
| `/shared-state/in-app-agent-read` | `/shared-state/in-app-agent-read/fixed` |
| `/shared-state/in-app-agent-write` | `/shared-state/in-app-agent-write/fixed` |

The `/fixed` routes differ from their siblings by exactly one thing: they
address `shared_state_fixed_agent` (`backend/src/shared_state_fixed.py`), which
is `shared_state.py` plus `CopilotKitMiddleware(expose_state=["language"])` and
a middleware that seeds the key on the first turn. Both omissions are [FINDINGS.md](FINDINGS.md) #9
below. Keep those files diffable — the value of the pair is that nothing else
differs.

Only pair a route where the fix is genuinely known. Two of these defects have no
established fix; a `/fixed` route that quietly did something else would be worse
evidence than no pair at all.

---

## 11. Project structure

```
deepagents/
├── CLAUDE.md
├── README.md
├── .env.example                      both env blocks, annotated
├── .gitignore
│
├── backend/                          Python — the agents
│   ├── pyproject.toml                deps + langgraph-cli in the dev group
│   ├── langgraph.json                10 graph ids → module:attribute
│   ├── main.py                       sample_agent (the Quickstart, verbatim)
│   └── src/
│       ├── shared.py                 MODEL / OPENAI_MODEL, read by every agent
│       ├── tool_rendering.py         tool_rendering_agent
│       ├── state_rendering.py        state_rendering_agent
│       ├── interrupt_based.py        interrupt_agent + interrupt_multi_agent
│       ├── frontend_tools.py         frontend_tools_agent
│       ├── shared_state.py           shared_state_agent (read + write routes)
│       ├── predictive_state.py       predictive_state_agent      (prebuilt)
│       ├── predictive_state_manual.py predictive_manual_graph    ← StateGraph
│       ├── predictive_state_tool.py   predictive_tool_graph      ← StateGraph
│       ├── a2ui_fixed.py             a2ui_fixed_agent
│       ├── a2ui_dynamic.py           a2ui_dynamic_agent
│       ├── state_inputs_outputs.py   state_io_graph — a StateGraph, not a Deep Agent
│       └── a2ui_schemas/             flight_schema.json, booked_schema.json
│
└── frontend/                         Next.js App Router
    └── src/
        ├── lib/
        │   ├── nav-config.ts         ← single source of truth: routes, statuses, doc links
        │   ├── agents.ts             graph ids, deployment URL
        │   └── source.ts             reads repo files at render time
        ├── a2ui/theme.css            the Styling page's theme, imported at the root
        ├── components/               harness chrome + a2ui-progress.tsx
        ├── hooks/use-a2ui-progress.tsx
        └── app/
            ├── layout.tsx            providers + chrome + theme import
            ├── page.tsx              Introduction
            ├── status/               the QA table
            ├── api/
            │   ├── copilotkit/[[...slug]]/route.ts   all graphs, A2UI off for fixed-schema
            │   ├── copilotkit-a2ui-dynamic/[[...slug]]/route.ts  dynamic-schema only, injection on
            │   ├── copilotkit-learning/[[...slug]]/route.ts      the Learning page's runtime
            │   └── copilotkit-memory/[[...slug]]/route.ts        memory: { access }, the undocumented option
            ├── cookbook/jev-generative-ui/            every published block, four of them compiled and unmounted
            │   ├── workspaces.ts · read-action.ts     the two that run
            │   ├── choose-panel.ts · picker-agent.ts  need @typesafe-ai/sdk and @langchain/openai
            │   ├── runtime-route.ts · picker-page.tsx deliberately not route.ts / page.tsx
            │   └── prepared-controls.tsx              the live half, Jev absent and labelled absent
            └── <doc-path>/
                ├── page.tsx          notes, source, discrepancies, Try it
                └── demo-chat/page.tsx   the chrome-free live surface
```

Every route's `page.tsx` renders its source with `<SourceCode file="…">`, which reads the file off disk on the server at render time. What a route shows is therefore always what actually runs — it cannot drift into a re-typed approximation.

---

## 12. References

Grouped the way the doc nav groups them.

**Getting Started**
- [Introduction](https://docs.copilotkit.ai/deepagents)
- [Quickstart](https://docs.copilotkit.ai/deepagents/quickstart)

**Generative UI**
- [Tool Rendering](https://docs.copilotkit.ai/deepagents/generative-ui/tool-rendering)
- [State Rendering](https://docs.copilotkit.ai/deepagents/generative-ui/state-rendering)
- [Your Components · Interrupt-based](https://docs.copilotkit.ai/deepagents/generative-ui/your-components/interrupt-based)
- [A2UI · Fixed Schema](https://docs.copilotkit.ai/deepagents/generative-ui/a2ui/fixed-schema)
- [A2UI · Dynamic Schema](https://docs.copilotkit.ai/deepagents/generative-ui/a2ui/dynamic-schema)
- [A2UI · Styling](https://docs.copilotkit.ai/deepagents/generative-ui/a2ui/styling)
- [A2UI · Advanced](https://docs.copilotkit.ai/deepagents/generative-ui/a2ui/advanced)
- [Frontend-Driven Cards](https://docs.copilotkit.ai/deepagents/generative-ui/frontend-cards)

**Custom Look and Feel**
- [Markdown Rendering](https://docs.copilotkit.ai/deepagents/custom-look-and-feel/markdown)

**Rich Threads**
- [Thread & History Lifecycle](https://docs.copilotkit.ai/deepagents/threads-lifecycle)

**Cookbook**
- [Jev: fast generative UI](https://docs.copilotkit.ai/deepagents/cookbook/jev-generative-ui) — tracked and compiled; not runnable without a TypeSafe vendor key

**Intelligence**
- [Memories & Recall](https://docs.copilotkit.ai/deepagents/intelligence/memories)
- [Skill delivery](https://docs.copilotkit.ai/deepagents/intelligence/learned-skills)
- [Learning](https://docs.copilotkit.ai/deepagents/learning)

**App Control**
- [Frontend Tools](https://docs.copilotkit.ai/deepagents/frontend-tools)
- [WebMCP](https://docs.copilotkit.ai/deepagents/webmcp) — tracked for drift only
- [Governed Actions](https://docs.copilotkit.ai/deepagents/human-in-the-loop/governed-actions) — tool-call variant implemented; the `useInterrupt` variant is not

**Shared State**
- [Reading agent state](https://docs.copilotkit.ai/deepagents/shared-state/in-app-agent-read)
- [Writing agent state](https://docs.copilotkit.ai/deepagents/shared-state/in-app-agent-write)
- [Predictive State Updates — prebuilt](https://docs.copilotkit.ai/deepagents/shared-state/predictive-state-updates?agent-type=prebuilt)
- [Predictive State Updates — custom graph, manual emission](https://docs.copilotkit.ai/deepagents/shared-state/predictive-state-updates?agent-type=custom-graph&state-emission=manual-emission)
- [Predictive State Updates — custom graph, tool emission](https://docs.copilotkit.ai/deepagents/shared-state/predictive-state-updates?agent-type=custom-graph&state-emission=tool-emission)
- [Input/Output Schemas](https://docs.copilotkit.ai/deepagents/shared-state/state-inputs-outputs)
- [Workflow Execution](https://docs.copilotkit.ai/deepagents/shared-state/workflow-execution)

**Not covered by this repo.** The Deep Agents sidebar also lists Human in the Loop, and an Intelligence Platform group (Rich Threads, Headless Threads, Thread & History Lifecycle, Synchronize Thread History, and four premium pages). Those were outside the scope requested for this build. Every page listed above is implemented or explicitly accounted for.

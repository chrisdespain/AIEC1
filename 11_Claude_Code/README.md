<p align = "center" draggable="false" ><img src="https://github.com/AI-Maker-Space/LLM-Dev-101/assets/37101144/d1343317-fa2f-41e1-8af1-1dbb18399719"
     width="200px"
     height="auto"/>
</p>

<h1 align="center" id="heading">Session 11: Claude Code & the Claude Agent SDK</h1>

| 📰 Session Sheet | ⏺️ Recording | 🖼️ Slides | 👨‍💻 Repo | 📝 Homework | 📁 Feedback |
|:-----------------|:-------------|:----------|:----------|:------------|:------------|
| [Session 11: Claude Code & Claude Agent SDK ](https://github.com/AI-Maker-Space/The-AI-Engineering-Certification-v1.0/tree/main/00_Docs/Modules/11_Claude_Code) |[Recording!](https://us02web.zoom.us/rec/share/2I5HA6DwVFgmtyjPaq1SJDgkaVEuYZoWYyMCK8DOAZ99Zm6f7dTi0IGONXj6mRel.YHFzKF03mI5v6JAM) <br> passcode: `&Qhi!cf0`| [Session 11 Slides](https://canva.link/uw1cl42x84tm6zh) |You are here! <br><br> [Certification Challenge](https://github.com/AI-Maker-Space/The-AI-Engineering-Certification-v1.0/tree/main/00_Docs/Certification%20Challenge) | [Optional Session 11 Assignment](https://forms.gle/sAyr5BgBLTfgJV8EA) <br><br>  [Cert Challenge Submission Form](https://forms.gle/xtM9F38nfRKcdjH97)| [Feedback 7/7](https://forms.gle/oDrguLDNvva65mtM8) |

## Useful Resources

**Claude Code**
- [Claude Code Documentation](https://code.claude.com/docs) — official docs: setup, workflows, settings
- [Claude Code Quickstart](https://code.claude.com/docs/en/quickstart) — from install to first session
- [Claude Code Best Practices](https://www.anthropic.com/engineering/claude-code-best-practices) — Anthropic engineering guide

**Claude Agent SDK**
- [Agent SDK Overview](https://docs.anthropic.com/en/api/agent-sdk/overview) — what the SDK is and when to use it
- [Building Agents with the Claude Agent SDK](https://www.anthropic.com/engineering/building-agents-with-the-claude-agent-sdk) — Anthropic engineering deep dive

## Main Assignment

**Build a chat web app powered by the Claude Agent SDK** — and build it *with* Claude Code.

This session is markdown-only on purpose. There is no starter code and no notebook: every line of code in your final app will be written in collaboration with Claude Code. The session has one build arc across a single breakout room:

```text
you → Claude Code → chat app skeleton → wire in Agent SDK query()
      (FastAPI + chat UI, echo stub)      ├─ tools: Read / Glob / Grep
                                           └─ your custom tool
```

The finished product: a **codebase concierge** — a chat interface in the browser where an agent (with real tools) answers questions about any repository you point it at. In Session 10 you served models behind endpoints; today you serve an *agent* behind one.

Work through the three guides in order:

```text
01_Installing_Claude_Code.md   # install, authenticate, verify
02_Using_Claude_Code.md        # drive Claude Code; scaffold the chat app skeleton
03_Claude_Agent_SDK.md         # add the agent and connect it to your website
```

## Outline

### Breakout Room #1: Claude Code, the Agent SDK, and the Connection

- Task 1: Install Claude Code and authenticate ([guide](./01_Installing_Claude_Code.md))
- Task 2: Learn the loop — explore a repo you didn't write ([guide](./02_Using_Claude_Code.md))
- Task 3: Scaffold the chat app skeleton with Claude Code (plan → implement → verify)
- Task 4: Write the project's `CLAUDE.md`
- Question #1 and Question #2
- Task 5: Install the Agent SDK and run your first `query()` ([guide](./03_Claude_Agent_SDK.md))
- Task 6: Wire the agent into `/api/chat` — replace the echo stub
- Task 7: Conversation memory — resume sessions across messages
- Task 8: Give the agent a custom tool
- Question #3 and Question #4
- Activity #1: Level Up the Chat App

## Questions

### ❓ Question #1

While scaffolding in Task 3 you used **plan mode** before letting Claude Code write anything. Why does an agent that can execute shell commands need a permission system at all, and why is plan mode particularly valuable when starting a project from an empty directory?

#### ✅ Answer

An agent with shell access can take irreversible actions — deleting files, pushing to remote branches, writing secrets into committed code, or installing packages with unintended side effects. Without a permission system, the model's best guess about intent becomes an immediate system action with no human checkpoint. Permissions decouple *understanding the request* from *executing the request*, giving you a place to catch misaligned assumptions before they cost anything.

Plan mode is especially valuable at project start because an empty directory gives the agent no existing structure to constrain its choices. There are no files, conventions, or prior decisions to anchor to — the agent must make dozens of architectural decisions simultaneously (folder layout, naming conventions, framework choices, test strategy). Surfacing those choices as a plan before any file is written lets you validate the design in seconds rather than discover after 30 generated files that the agent picked the wrong structure or omitted a critical component. The cost of a wrong assumption grows with every file built on top of it.

### ❓ Question #2

`CLAUDE.md` is loaded into context at the start of every session. What belongs in it — and what *doesn't*? How does this relate to what you learned about context management and memory in Session 3?

#### ✅ Answer

`CLAUDE.md` should hold durable, session-agnostic facts: how to run the project, the architectural seams (e.g. "agent logic lives only in `agent.py`"), conventions the model would otherwise guess wrong, and things that stay true across every future session. Our `chat-app/CLAUDE.md` contains run commands, an architecture note, and key conventions (read-only tools, tools in `tools.py`, `.env` is gitignored). These are facts that don't change turn-to-turn.

What doesn't belong: current work state, in-progress task lists, recent decisions, or anything that will be stale next session. Those belong in the conversation itself, in commit messages, or in a plan file — not burned into persistent context. In Session 3 we learned that context is finite and every token counts: putting ephemeral state in `CLAUDE.md` wastes that budget and pollutes future sessions with outdated facts. The principle is the same — memory should store what's stably true, not what's momentarily true.

### ❓ Question #3

The Agent SDK gives you the same agent loop that powers Claude Code. Compare this to the agent loops you hand-built with LangGraph in Sessions 2–4: what does the SDK give you for free, and what control do you give up?

#### ✅ Answer

The Agent SDK gives you the full Claude Code loop for free: tool dispatch, tool result ingestion, multi-turn conversation management, session persistence, and the same model orchestration that makes Claude Code functional. You get session resumption (`resume=session_id`), streaming via an async generator, and built-in support for both native tools (Read, Glob, Grep) and in-process MCP servers — with no state machine to write.

What you give up is the control you had with LangGraph: explicit graph topology, per-node state transformations, conditional routing based on your own logic, the ability to inject state between turns, and visibility into exactly what's happening inside each turn. With LangGraph you could add a retry node, enforce a maximum reasoning depth with your own counter, or branch based on tool output content. With the Agent SDK the loop is opaque — you get events (`SystemMessage`, `AssistantMessage`, `ResultMessage`) and you can influence it via `max_turns` and `allowed_tools`, but you can't rewire the internal graph. The tradeoff is power vs. simplicity: the SDK handles the hard parts so you can focus on tooling and UX.

### ❓ Question #4

Your chat app could have called a chat completions API directly, the way you did early in the course. What do you gain by routing every message through the Agent SDK's `query()` instead — and what new risks does an agent with tools introduce that a plain chat completion doesn't have? How did your tool allowlist and permission mode address them?

#### ✅ Answer

Routing through `query()` gives the agent the ability to answer questions it couldn't answer from training data alone: it can read actual files, search actual git history, and list actual packages in the repository it's being asked about. A plain chat completion can only regurgitate what the model learned during training — it would hallucinate package names, invent file paths, and produce confidently wrong answers about the current state of the repo. Tools turn the model from a static fact-retriever into a live investigator.

The new risks an agent with tools introduces: it can take actions in the world, not just produce text. A tool that runs shell commands could be prompted to delete files, exfiltrate data, or execute arbitrary code if the allowlist is too broad. Even read-only tools can be misused — a tool that reads files could be used to read secrets if pointed at the wrong path. The tool allowlist (`allowed_tools = ["Read", "Glob", "Grep"]`) bounds the agent to read-only filesystem operations on the target repo, with no write, edit, or shell execution permitted. Combined with `cwd=REPO_PATH`, all file access is scoped to the repo directory. This means the worst the agent can do is read files — it cannot write, delete, or make network requests.

## Activity 1: Level Up the Chat App

Extend your working chat app with **at least one** of the following (built with Claude Code, of course):

1. **Live progress streaming** — stream the agent's activity to the browser (e.g. via Server-Sent Events) so users see tool calls ("reading `app.py`…") while the agent works, instead of a spinner
2. **Multi-conversation support** — a sidebar of separate conversations, each mapped to its own SDK session
3. **A second custom tool** — something genuinely useful for your target repo (e.g. `git_log` for recent changes, or a test-runner summary tool)

Whichever you pick, demo it in your Loom video and explain the design decision in one paragraph.

## Advanced Activity: The Cat Shop Concierge

Connect your Session 8 cat shop MCP server to your chat app's agent via the SDK's `mcp_servers` option. Your chat app becomes a shopping concierge: users can browse the catalog, fill a cart, and check out — in natural language, through the UI you built, hitting the OAuth-protected server you wrote in Session 8.

Include your findings and a demo in your Loom video.

## Ship 🚢

The working chat app!

### Deliverables

- A short Loom showing:
  - Claude Code scaffolding or extending the app (plan → implement → verify — show the plan!); and
  - the chat app answering real questions about a repository, including at least one visible custom-tool use

## Share 🚀

Make a social media post about your final application!

### Deliverables

- Make a post on any social media platform about what you built!

Here's a template to get you started:

```
🚀 Exciting News! 🚀

I am thrilled to announce that I have just built and shipped a chat app powered by the Claude Agent SDK — scaffolded entirely with Claude Code! 🎉🤖

🔍 Three Key Takeaways:
1️⃣
2️⃣
3️⃣

Let's continue pushing the boundaries of what's possible in the world of AI agents. Here's to many more innovations! 🚀
Shout out to @AIMakerspace !

#ClaudeCode #AgentSDK #AIAgents #Innovation #AI #TechMilestone

Feel free to reach out if you're curious or would like to collaborate on similar projects! 🤝🔥
```

## Submitting Your Homework (Optional For Extra Mark)

Follow these steps to prepare and submit your homework:

1. Pull the latest updates from upstream into the main branch of your repo:

```bash
git checkout main
git pull upstream main
git push origin main
```

2. Work through `01_Installing_Claude_Code.md`, `02_Using_Claude_Code.md`, and `03_Claude_Agent_SDK.md` in order.
3. Build your chat app in a new `chat-app/` folder inside this session directory (include its `CLAUDE.md` — we want to see it!).
4. Fill in your answers to Questions #1–#4 in this README.
5. Complete Activity #1 and record your Loom video.
6. Add, commit, and push your work to your origin repository. Remove `.env` files and API keys before committing.

When submitting your homework, provide the GitHub URL to your repo.

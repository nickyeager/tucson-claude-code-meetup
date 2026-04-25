# Session 1 Speaker Script

Total time: ~68 minutes (34 min instruction, 30 min exercise, 4 min wrap-up)

---

## Slide 1: Title
**Time: 1 min**

"Hey everyone, welcome to the Tucson Claude Code Meetup. I'm Nick Yeager — I'm an AI solutions architect at ScriptSave, and I build developer tools on the side. I've been deep in Claude Code for the past year building agents for my own projects. Before that, I co-founded a startup that went through AngelPad and did contract work at USAA. I organized this series because I kept finding agent-building patterns that worked really well and wanted to share them with other builders here in Tucson. More about me at nickcyeager.com if you're curious."

"This morning we're doing something fun — we're going to build an AI agent feature from scratch. Not a toy demo. An actual slash command that generates structured event plans. By the end of this morning, you'll have something working on your machine."

"This is Session 1 of four. Each session builds on the last, so by Session 4 you'll have a full agent with subagents, hooks, and a feedback loop. But this morning — fundamentals. Let's get into it."

**Transition:** "First, let me show you the big picture."

---

## Slide 2: What We're Building
**Time: 2 min**

"We're building MeetupBot — an agent that helps run a tech meetup like this one. It plans events, schedules talks, drafts communications, and eventually learns from feedback."

"Why a meetup bot? Because it's a real problem with real constraints. You need dates that work, venues that fit, speakers who are available. It's messy enough to be interesting, but scoped enough to build in four sessions."

[PAUSE] "Quick show of hands — who here has used any AI coding tool before? ChatGPT, Copilot, Cursor, anything? Cool. And who's used Claude Code specifically? Great, we've got a mix. That's perfect."

**Transition:** "So what are we actually building this morning?"

---

## Slide 3: Today's Goal
**Time: 1 min**

"By the end of this session, you'll type `/plan-event "Building RAG pipelines"` and get back structured JSON. A full event plan — date, speakers, agenda, logistics. All from a single command."

"To get there, we need to cover five things: git basics, Claude Code setup, CLAUDE.md, ngrok AI Gateway, and slash commands. Sounds like a lot, but each piece is small. They snap together like Legos."

**Transition:** "Let's start with what Claude Code actually is."

---

## Slide 4: What is Claude Code?
**Time: 2 min**

"Claude Code is not a chatbot. It's not autocomplete. It's an agent that understands your entire project."

"It lives in your terminal, but also runs as a Desktop app, a web app at claude.ai/code, and inside VS Code and JetBrains. We'll use the CLI this morning, but everything we learn works across all of those surfaces."

"It reads your files, edits them, runs commands, searches your codebase. And the key thing — it follows rules you write in a file called CLAUDE.md. We'll get to that in a minute."

"It's powered by Claude Opus 4.7 — a million-token context window. That means it can hold your entire codebase in memory at once. Think of it as a really skilled junior developer who never gets tired, reads incredibly fast, but needs clear instructions to do good work. The quality of your instructions determines the quality of the output."

**Transition:** "Let's get it installed."

---

## Slide 5: Installation
**Time: 3 min**

"Installation is one line. Curl the installer, done."

[DEMO] Open terminal. Run:
```
curl -fsSL https://claude.ai/install.sh | bash
mkdir meetup-agent && cd meetup-agent
git init
claude
```

"That's it. Four commands and you're in Claude Code. You can also install via `npm install -g @anthropic-ai/claude-code` or `brew install claude-code` if you prefer. You'll see it scan your project — right now it's empty, so there's not much to scan."

[PAUSE] "If you're following along and hit an issue with npm, make sure you're on Node 18 or higher. Run `node --version` to check. There's a full setup guide in the repo at `sessions/SETUP-GUIDE.md` with install instructions for every platform. If you're stuck, flag me down during build time."

**Tip for common questions:** "If someone asks about npm — yes, `npm install -g @anthropic-ai/claude-code` works too. The curl installer is just the quickest path."

**Transition:** "Before we do anything in Claude Code, let's make sure you know the one git skill that matters."

---

## Slide 6: Git Basics — Just Enough
**Time: 1 min**

"I'm not going to teach you git. I'm going to teach you three commands. Think of commits as save points in a video game. You save before the boss fight, right? Same idea."

"`git init` — start tracking. `git add -A` — select everything. `git commit -m` with a message — save it."

"If you mess something up later, you can always get back to a commit. That's why we commit early and often. It's your safety net."

**Transition:** "Now for the most important file in any Claude Code project."

---

## Slide 7: CLAUDE.md — Your Agent's Rulebook
**Time: 2 min**

"CLAUDE.md is the single most important concept today. It lives at your project root and Claude reads it at the start of every single conversation. Every time."

"This is where you define how your agent behaves. Output formats, constraints, personality, conventions. Whatever you put in here becomes law."

"This is what people mean when they say 'context engineering.' You're not writing a one-off prompt. You're programming persistent behavior."

**Transition:** "So what actually goes in this file?"

---

## Slide 8: What Goes in CLAUDE.md?
**Time: 1 min**

"Here's a real example. We've got personality, output format, schema, data locations — the works."

"The output format says 'all event data must be structured JSON.' The schema lists every field we expect — eventName, suggestedSpeakers, schedule slots, estimated cost. The personality says 'friendly, organized, opinionated about good events.'"

"Notice how specific this is. We're not saying 'be helpful.' We're defining camelCase JSON fields and exact data locations. That level of specificity is what makes the difference."

"By the way — if you're staring at a blank file wondering where to start, there's a starter template in the repo at `templates/CLAUDE-starter.md`. It has all these sections filled out for MeetupBot. You can copy it and customize, or write your own from scratch."

**Transition:** "And here's why we care so much about structure."

---

## Slide 9: Why Structured Output Matters
**Time: 1 min**

"Look at this table. On the left, freeform text. 'The event could be on March 15th...' On the right, a clean JSON date field."

"Freeform is fine if a human is reading it. But if another agent needs to consume this output — and in Session 3, it will — you need structure. JSON schemas make agents reliable."

"This is one of those things that feels like extra work now but saves you hours later. Trust me on this one."

**Transition:** "Let me show you this in action."

---

## Slide 10: LIVE DEMO — Creating CLAUDE.md
**Time: 3 min**

[DEMO] In Claude Code:
1. First, ask Claude something without CLAUDE.md: "Plan a meetup about Python testing" — note the freeform response
2. Create CLAUDE.md with the schema from slide 8
3. Ask the same question — note the structured JSON response
4. Point out: "Same question, completely different output. The only thing that changed was CLAUDE.md."

"See that? Before CLAUDE.md, you get a nice essay. After CLAUDE.md, you get JSON that a machine can parse. Same model, same question — the only thing that changed was the context file."

[PAUSE] "Any questions about CLAUDE.md before we move on? This is the foundation — everything else builds on it."

**Tip for common questions:** "Someone might ask 'can I have multiple CLAUDE.md files?' Yes — you can have them at different directory levels. Claude reads the nearest one first, then walks up. But for now, one at the root is all you need."

**Transition:** "Before we move on, let me explain how Claude actually sees your project."

---

## Slide 11: How Claude Code Reads Your Project
**Time: 1 min**

"Claude Code isn't just reading your prompts. It scans your entire project structure at the start of every session. It knows your file tree, your directory layout, everything."

"That means you can say 'read data/venues.json' and it just works — you don't need to paste file contents into the chat. You can say 'find all files that use $ARGUMENTS' and it searches across your whole project."

"The context window is about a million tokens. Your entire project likely fits. The practical tip: mention your key files explicitly in CLAUDE.md. That way Claude references them every single conversation."

**Transition:** "Quick note on permissions before we get to the fun stuff."

---

## Slide 12: Permissions
**Time: 1 min**

"Claude Code asks permission before running commands. That's good — you want that guardrail. But if it's asking you to approve `git commit` for the twentieth time, it gets old."

"There are three permission modes. Interactive is the default — approve everything. Allow-list means you pre-approve specific commands in `.claude/settings.local.json`. And there's a new one called Auto Mode — press Shift+Tab to toggle it. A classifier figures out which actions are safe and which are risky. Safe ones run automatically, risky ones still get blocked. It's a nice middle ground."

"For this morning, interactive mode or Auto Mode are both fine. You'll set up allow lists during build time if you want."

**Transition:** "Now let's talk about how we're actually connecting to the AI models."

---

## Slide 13: Connecting to an LLM Provider
**Time: 2 min**

"Claude Code needs an LLM behind it. You've got three options."

"Simplest: if you have a Claude Max subscription, you're already set. Claude Code detects it automatically — no API key, no config."

"Second option: direct Anthropic API key. Sign up at console.anthropic.com, get a key, set the environment variable. Pay per token. This is what I'd recommend for today — it's straightforward and you're in full control."

"Third option: ngrok AI Gateway. This is a routing layer — one endpoint, multiple providers behind it. It gives you failover, cost-based routing, PII redaction. The free tier works fine."

"Quick backstory — ngrok was originally going to sponsor this series with gateway credits for everyone. That didn't come together, so we're using direct API keys as the default. If you want to try the gateway on the free tier, the setup guide covers it."

**Transition:** "Let me show you the ngrok option briefly, then we'll set up."

---

## Slide 14: ngrok AI Gateway
**Time: 1 min**

"ngrok AI Gateway is a reverse proxy for AI — same concept as putting nginx in front of your web servers, but for language models."

"One API key for Anthropic, OpenAI, Google. Automatic failover. Cost routing that picks the cheapest model for a task. PII redaction that strips sensitive data before it leaves your network."

"Quick backstory — ngrok was originally going to sponsor this series with gateway credits for everyone. That didn't come together, so we're using direct API keys as the default today. The ngrok free tier still works fine if you want to try it."

**Transition:** "ngrok isn't the only gateway out there. Quick landscape overview."

---

## Slide 15: AI Gateway Landscape
**Time: 1 min**

"There are several AI gateways worth knowing about. ngrok is the one we cover because it works directly with Claude Code, but here are the others."

"OpenRouter gives you a unified API for 200+ models — useful when you want to compare models or access niche providers. LiteLLM is open-source and self-hosted — good for teams that want full control with no vendor lock-in. Portkey adds observability, caching, and prompt management on top of routing — more of an enterprise play."

"For Claude Code specifically, your options are direct Anthropic API or ngrok. The others are useful for general AI development work."

**Transition:** "Let's get you connected."

---

## Slide 16: Provider Setup
**Time: 2 min**

[DEMO] Show both options:
1. "For most of you, this is it:" `export ANTHROPIC_API_KEY=sk-ant-your-key-here`
2. For ngrok users: create `config/ngrok-gateway.json`, walk through fields
3. "If you have Claude Max, you don't need to do anything. Claude Code picks it up."
4. "The setup guide in the repo has step-by-step instructions for all three options."

**Tip for common questions:** "If someone asks 'which should I use?' — direct Anthropic API key is the easiest for today. Claude Max if you already have it. ngrok if you want multi-provider routing."

**Transition:** "Alright, now for the payoff. Slash commands."

---

## Slide 17: Slash Commands
**Time: 1 min**

"Slash commands are custom workflows that live in your project. You create a markdown file in `.claude/commands/`, and it becomes a command you can run."

"plan-event.md becomes `/plan-event`. draft-email.md becomes `/draft-email`. The file name is the command name. Dead simple."

"And they take arguments. `$ARGUMENTS` in the file gets replaced with whatever the user types after the command."

**Transition:** "Let's look at what goes inside one."

---

## Slide 18: Anatomy of a Slash Command
**Time: 1 min**

"Here's our plan-event command. It's just markdown with instructions. Step 1: read CLAUDE.md. Step 2: generate the plan. Step 3: include all the required fields. Step 4: save it. Step 5: commit."

"Notice it references CLAUDE.md. The command says 'go read the rules, then follow them.' This is how you chain context — the command points to the rulebook, the rulebook defines the schema."

"And that IMPORTANT keyword at the bottom? That's not decoration. Claude actually weighs that higher. We'll talk about power keywords in a sec."

**Transition:** "Let me build this live."

---

## Slide 19: LIVE DEMO — Building /plan-event
**Time: 3 min**

[DEMO] In Claude Code:
1. Create `.claude/commands/` directory
2. Create `plan-event.md` with the content from the slide
3. Run `/plan-event "Building RAG pipelines"`
4. Watch Claude read CLAUDE.md, generate the plan, save it
5. Open the output file and show the JSON structure
6. "Look at that — date, speakers, agenda, logistics. All structured. All from one command."

[PAUSE] "Pretty cool, right? And this took us what, two minutes to set up? The command file is like ten lines of markdown."

**Tip for common questions:** "Someone will ask 'can I call one command from another?' Not directly in this version, but you can have Claude read multiple command files. We'll do exactly that in Session 3 with subagents."

**Transition:** "Before build time, a few pro tips."

---

## Slide 20: Power Keywords
**Time: 1 min**

"There are certain words that Claude pays extra attention to. IMPORTANT elevates priority. MUST and NEVER are hard constraints. 'Proactively' means 'do this without asking me first.'"

"But here's the thing — use these sparingly. If every sentence has IMPORTANT in it, Claude treats none of them as important. It's like the boy who cried wolf. Save these for the rules that really, truly matter."

"For us, 'always return JSON' is an IMPORTANT rule. 'Use a friendly tone' is not."

"One more thing — speed and effort controls. Type `/fast` to toggle fast mode — same model, faster output. Type `/effort low` for quick tasks, `/effort high` for complex reasoning, or `/effort max` for the deepest analysis. You can even say 'think hard' or 'ultrathink' in a prompt to trigger deeper reasoning for one turn. These are good to know but don't overthink them right now."

**Transition:** "A few more tips before I set you loose."

---

## Slide 21: Tips & Gotchas
**Time: 1 min**

"Quick hits. Be specific in CLAUDE.md — give it schemas and examples, not vibes. Commit before you experiment — save points, remember? And don't say 'production-ready' in your instructions. It means nothing to an AI. Say exactly what you mean."

"The biggest mistake I see beginners make: vague rules. 'Make good code' is useless. 'All functions must have type hints and Google-style docstrings' is useful. Be the annoyingly specific tech lead."

**Transition:** "Two more things before I set you loose — what to do when things break, and the loop that makes your agent better over time."

---

## Slide 22: When Things Break
**Time: 1 min**

"During build time, things will break. That's normal. Here's the cheat sheet."

"API key not set? Run `echo $ANTHROPIC_API_KEY` and check if it's empty. Command not found? Check the spelling of `.claude/commands/` — the dot and the plural trip people up. Getting freeform text instead of JSON? Add `IMPORTANT: Output MUST be JSON` to your CLAUDE.md. Permission prompts driving you crazy? Hit Shift+Tab to toggle Auto Mode."

"And the most important one: commit before you start debugging. If you mess something up, `git checkout .` gets you back to your last save point."

---

## Slide 23: The Iteration Loop
**Time: 1 min**

"This is the pattern you'll use for the rest of the course. Run your command. Read the output. Spot what's wrong. Update CLAUDE.md to fix it. Run the same command again."

"The key insight: don't just re-prompt. Update the rules. If Claude used a made-up speaker instead of one from your data file, add a rule: 'speakers MUST come from data/speakers.json.' Now that mistake is fixed for every future run, every future command, every future session."

"Every correction you encode in CLAUDE.md compounds. That's why it's the highest-leverage file in your project."

**Transition:** "Alright, it's build time."

---

## Slide 24: BUILD TIME
**Time: 30 min (exercise)**

"Here's where you get your hands dirty. The exercise is in `sessions/session-1/EXERCISE.md`. Your goal: get `/plan-event` generating structured JSON."

"You've got about 30 minutes. Here's my advice:"

"Step 1: get your repo set up and commit. Step 2: write CLAUDE.md. Step 3: build the slash command. Step 4: test it."

"If you finish early, try different topics. Try breaking your CLAUDE.md and see what happens. Try adding fields to the schema."

"Help your neighbor if they're stuck. Teaching is the best way to learn this stuff."

[PAUSE] "Raise your hand if you need help getting started."

**While students work:** Walk the room. Common issues to watch for:
- Node.js version too old
- Forgot to `git init`
- CLAUDE.md in wrong directory
- Typo in `.claude/commands/` path
- API key not set

---

## Slide 25: Checkpoint
**Time: 2 min**

"Alright, let's check in. Go through this list. Git repo — check? CLAUDE.md — check? Project structure with a data directory? ngrok configured or at least direct API working? The slash command runs? And you've got at least one event plan saved?"

[PAUSE] "Anyone missing something? Let's get you caught up real quick."

"If you've got all six, you're in great shape for Session 2."

**Tip for common questions:** "If someone didn't finish, reassure them: 'The exercise file has everything you need to finish at home. The key thing is you understand the concepts — CLAUDE.md, structured output, slash commands.'"

**Transition:** "Let me give you a taste of what's coming."

---

## Slide 26: What's Next — Session 2
**Time: 1 min**

"Session 2 is where it gets really interesting. We're going to talk about context engineering — and I don't mean prompting. I mean building blueprints that shape how your agent thinks about entire workflows."

"We'll cover INITIAL.md — that's your project bootstrap file. PRPs — prompt-reusable patterns. And we'll build a comms system so MeetupBot can draft emails and social posts."

"Session 1 was about getting the tools working. Session 2 is about wiring them together into a pipeline."

**Transition:** "Quick recap and we're out."

---

## Slide 27: Session 1 Recap
**Time: 1 min**

"Three things. Write them down if you want."

"One: CLAUDE.md is your agent's brain. Every rule shapes every response. Invest time here."

"Two: Structured output beats freeform text. Every time. JSON schemas make agents reliable and composable."

"Three: ngrok AI Gateway gives you one endpoint for many providers. Simplify your keys, add failover, control costs."

"One more thing — as you build more projects with CLAUDE.md files, there's a tool called RuleMetric that lets you manage instructions across tools. Write once, convert to CLAUDE.md, Cursor rules, Copilot instructions, whatever. We won't use it in this course but it's worth knowing about as you scale up."

"You just built your first agent feature. That's not nothing. Nice work this morning."

"Oh — one more tip. Between sessions, try typing `/powerup` in Claude Code. It launches interactive lessons that teach you features through animated demos. Great way to discover things you didn't know existed."

[PAUSE] "Questions before we wrap? ... Great. See you at Session 2. And commit your work before you close your laptop."

---

## Timing Summary

| Section | Slides | Time |
|---|---|---|
| Intro & Setup | 1-6 | 10 min |
| CLAUDE.md & How It Works | 7-11 | 8 min |
| Providers & Gateways | 12-16 | 7 min |
| Slash Commands & Tips | 17-21 | 7 min |
| Debugging & Iteration | 22-23 | 2 min |
| **Build Time** | **24** | **30 min** |
| Wrap-up | 25-27 | 4 min |
| **Total** | | **~68 min** |

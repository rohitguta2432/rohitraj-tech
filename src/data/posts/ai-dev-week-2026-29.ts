import type { BlogPost } from '@/types/blog';

export const aiDevWeek2026W29: BlogPost = {
  slug: 'ai-dev-week-2026-29',
  title:
    'This Week in AI Dev: The Agent Fleet Grows Up (Week 29 of 2026)',
  date: '2026-07-14',
  excerpt:
    "Week 29 of 2026 in AI dev tools: OpenAI ships an official plugin that runs Codex from inside Claude Code, a viral teardown shows Claude Code burning 33k tokens before it reads your prompt, Stably's orca gives you a control room for a fleet of parallel agents, Microsoft's Flint lets agents draw charts instead of dumping tables, Z.ai's GLM-5.2 tops Hugging Face trending, and Tencent open-sources CubeSandbox so your agents stop running rm -rf on the host.",
  readingTime: '7 min read',
  keywords: [
    'ai dev tools this week',
    'codex plugin claude code',
    'claude code token overhead',
    'glm-5.2 open weights',
    'orca parallel agent fleet',
    'cubesandbox ai agent sandbox',
    'ai dev week 29 2026',
  ],
  relatedProject: 'myFinancial',
  coverImage: {
    src: '/images/notes/ai-dev-week-2026-29-cover.jpg',
    alt: 'A luminous swarm of coordinated particles converging illustrating AI dev tools weekly roundup week 29 of 2026',
  },
  sections: [
    {
      heading: 'TL;DR',
      content: `**Week 29** (July 7–14, 2026): running *many* agents became the mainstream problem, and six drops attacked it from six angles. **OpenAI's codex-plugin-cc** (28.4k stars) runs Codex reviews and delegated tasks from inside Claude Code. A **systima.ai teardown** measured Claude Code at **~33k tokens of overhead per session vs OpenCode's ~7k**. **Stably's orca** (+5.3k stars this week) is a desktop control room for parallel agent fleets. **Microsoft Flint** gives agents a declarative chart language. **Z.ai's GLM-5.2** (744B MoE, MIT) tops Hugging Face trending. **Tencent's CubeSandbox** sandboxes agent shell access in Rust.`,
    },
    {
      heading: 'Why Week 29 Was About Running Fleets, Not Building Agents',
      content: `By [Rohit Raj](/en/about) — AI Consultant · Forward Deployed Engineer · [LinkedIn](https://www.linkedin.com/in/rohitraj2/)

Six months ago the hard question was "how do I build one good agent?" This week's launches assume you already have five running at once — and now you need to review their work, cap their token bills, watch them side by side, sandbox their shell access, and read their output as something better than a wall of text.

Look at the list as a stack and it clicks: **codex-plugin-cc** is cross-vendor delegation (one agent asks a rival vendor's agent to check its work), **orca** and herdr are the fleet dashboards, **CubeSandbox** is the blast-radius containment, the **token-overhead teardown** is the cost audit, **Flint** is the reporting layer, and **GLM-5.2** is the open-weights engine cheap enough to run the boring lanes. Every drop below has a date, a number, and a source link — plus one opinionated take each.`,
    },
    {
      heading: 'Week 29 at a Glance',
      content: `| Drop | What changed | Signal | Verdict |
|------|--------------|--------|---------|
| **codex-plugin-cc** | Run Codex from inside Claude Code | 28,426★, +2,265/wk | Install today, use the adversarial review |
| **Token-overhead teardown** | Claude Code ~33k tokens before your prompt | 685 HN points | Audit your own harness |
| **orca** | Desktop ADE for parallel agent fleets | 18,402★, +5,263/wk | Try if you run 3+ agents daily |
| **Microsoft Flint** | Chart language built for agent output | 347 HN points | Adopt for agent dashboards |
| **GLM-5.2** | 744B MoE open weights, MIT, 1M context | #1 HF trending, 464k downloads | Serious open-weights default |
| **CubeSandbox** | Rust sandbox for agent shell access | 10,008★, +2,367/wk | Wire in before your agents get root |`,
    },
    {
      heading: 'codex-plugin-cc: Can Claude Code and Codex Actually Work Together?',
      content: `**What:** **OpenAI** published [codex-plugin-cc](https://github.com/openai/codex-plugin-cc) in early July 2026 — an official plugin that runs **Codex from inside Claude Code**. It sits at **28,426 stars** with **+2,265 added this week**. You get \`/codex:review\` for a standard Codex code review of your current work, an **adversarial review** mode that questions whether your implementation direction was right at all, and \`/codex:rescue\`, \`/codex:transfer\`, \`/codex:status\`, \`/codex:result\`, and \`/codex:cancel\` for delegating tasks and managing background jobs. Delegated sessions can be resumed natively with \`codex resume\`.

**Why it matters:** This is OpenAI officially building *for* a competitor's harness — an admission that developers won't pick one agent, they'll route work between them. The adversarial review is the sleeper feature: a second model from a different vendor challenging your design decisions catches the failure modes self-review never does.

**Source:** [openai/codex-plugin-cc on GitHub](https://github.com/openai/codex-plugin-cc)

**Quick take:** Install it today if you have both subscriptions — cross-vendor review is the cheapest quality gate you can add to an agent workflow.`,
    },
    {
      heading: 'Why Is Claude Code Sending 33k Tokens Before Reading Your Prompt?',
      content: `**What:** A [systima.ai teardown](https://systima.ai/blog/claude-code-vs-opencode-token-overhead) published **July 12** measured what popular coding agents transmit before your actual request: **Claude Code sends roughly 33,000 tokens** of system prompt, tool schemas, and context bootstrapping per session, while **OpenCode sends about 7,000**. The post hit **685 points** on Hacker News.

**Why it matters:** Overhead tokens aren't one-time — chunks of them ride along on every turn of a long session, and in a fleet they multiply by every concurrent agent. If your agent bill looks wrong, this is the first place to look. The counterpoint from the HN thread is fair too: that overhead buys tool reliability, and a cheaper harness that fumbles tool calls costs more in retries.

**Source:** [Claude Code vs OpenCode token overhead — systima.ai](https://systima.ai/blog/claude-code-vs-opencode-token-overhead)

**Quick take:** Don't switch harnesses over this — but do audit your own. One transcript dump tells you what your setup actually pays per turn, before any [agent guardrails](/en/notes/ai-agent-command-guardrails-2026) even come into play.`,
    },
    {
      heading: 'orca: Do You Need an IDE for a Fleet of Agents?',
      content: `**What:** [Stably's orca](https://github.com/stablyai/orca) calls itself an **ADE — an agent development environment** — for working with a fleet of parallel agents from desktop and mobile. It jumped **+5,263 stars this week** to **18,402**. The terminal-native alternative, [herdr](https://github.com/ogulcancelik/herdr), a Rust agent multiplexer, added **+3,449 stars** to reach 16,162 the same week.

**Why it matters:** Two fleet-management tools gaining almost 9,000 combined stars in one week is the clearest demand signal on this list. Solo developers are now running the multi-agent setups that were a platform-team luxury in 2025 — and a tmux full of scrolling transcripts doesn't scale past three agents.

**Source:** [stablyai/orca](https://github.com/stablyai/orca) · [ogulcancelik/herdr](https://github.com/ogulcancelik/herdr)

**Quick take:** If you run three or more concurrent agents daily, try orca; if you live in the terminal, herdr. Below that, your IDE and patience are still fine.`,
    },
    {
      heading: 'Microsoft Flint: Should Agents Draw Charts Instead of Tables?',
      content: `**What:** **Microsoft** released [Flint](https://microsoft.github.io/flint-chart/), a **declarative visualization language designed for AI agents** — a compact grammar an LLM can emit reliably to produce real charts instead of markdown tables. The Show HN thread reached **347 points** on **July 8**.

**Why it matters:** Agent output is still overwhelmingly prose and pipe-tables, and both fall apart past a dozen rows. A chart grammar built to be *generated* — small vocabulary, forgiving structure — is aimed at exactly the reporting gap every agent dashboard has. Vega-Lite was built for humans; Flint is built for the model.

**Source:** [Flint — microsoft.github.io/flint-chart](https://microsoft.github.io/flint-chart/)

**Quick take:** Adopt it wherever an agent reports numbers to a human. The win isn't prettier charts — it's that a constrained grammar gives you *valid* charts on the first generation instead of three repair loops.`,
    },
    {
      heading: 'GLM-5.2: Is This the Open-Weights Model to Beat?',
      content: `**What:** [Z.ai's GLM-5.2](https://huggingface.co/zai-org/GLM-5.2) is the **#1 trending model on Hugging Face this week** — **3,902 likes and over 464,000 downloads**. It's a **744B-parameter MoE with ~40B active per token**, a **1M-token context window**, **MIT-licensed** open weights, and reported scores of **62.1 on SWE-bench Pro** and **51 on the Artificial Analysis Intelligence Index v4.1** — the highest of any open-weights model to date. [VentureBeat reports](https://venturebeat.com/technology/z-ais-open-weights-glm-5-2-beats-gpt-5-5-on-multiple-long-horizon-coding-benchmarks-for-1-6th-the-cost) it beating GPT-5.5 on several long-horizon coding benchmarks at roughly **1/6th the cost**.

**Why it matters:** The interesting bit is architectural: an **IndexShare** scheme reuses one lightweight indexer across every four sparse-attention layers, cutting per-token FLOPs **~2.9x at 1M context**. Long context has been the expensive party trick of 2026; this is one of the first open designs that makes it economical.

**Source:** [zai-org/GLM-5.2 on Hugging Face](https://huggingface.co/zai-org/GLM-5.2)

**Quick take:** If you're picking an open-weights default for agent backends this quarter, this is the one to benchmark first — via an API provider unless you own serious hardware; 40B active still means a multi-GPU node to self-host.`,
    },
    {
      heading: 'CubeSandbox: Contain the Blast Radius Before You Scale the Fleet',
      content: `**What:** **Tencent Cloud** open-sourced [CubeSandbox](https://github.com/TencentCloud/CubeSandbox), an "instant, concurrent, secure and lightweight sandbox for AI agents" written in **Rust**. It crossed **10,008 stars** with **+2,367 this week**.

**Why it matters:** Every tool call an agent makes is code you didn't review executing on hardware you own. The last month alone produced the GitLost private-repo leak and a wave of destructive-command incidents — and if agents are now running in parallel fleets, one bad \`rm -rf\` is no longer one machine's problem. Fast, disposable, per-agent sandboxes are the infrastructure answer, and this one comes from a cloud vendor that runs them at scale.

**Source:** [TencentCloud/CubeSandbox](https://github.com/TencentCloud/CubeSandbox)

**Quick take:** Wire a sandbox in *before* the fleet, not after the incident. Pair it with command-level [guardrails](/en/notes/ai-agent-command-guardrails-2026) — the sandbox contains what the guardrail misses.`,
    },
    {
      heading: "What I'm Shipping With This Week",
      content: `The token-overhead teardown hit home. Last month I had to **disable my own daily automation** — three scheduled Claude-based pipelines — because they quietly exhausted their token budget mid-month. I never measured harness overhead; I assumed my prompts were the cost. They weren't — the per-turn bootstrapping was.

So this week's concrete task: run the systima.ai methodology against my own pipelines — dump one full transcript per pipeline, count what rides along before the actual work starts, and cut the tool surface each run loads. If a nightly job only needs four tools, it shouldn't pay for forty schemas per turn. I expect this alone to bring the disabled [automation pipelines](/en/notes/ai-agent-command-guardrails-2026) back under budget. That's the week-29 lesson in one line: **fleet costs are a measurement problem before they're a model problem** — the same discipline I bring to [6-week MVP builds](/en/services/6-week-mvp), where the bill is someone else's money.`,
    },
    {
      heading: 'Skip These',
      content: `**GPT-Live** ([OpenAI, July 8](https://openai.com/index/introducing-gpt-live/)) — the full-duplex voice models are a genuinely better ChatGPT experience, but the developer API is a *sign-up-to-be-notified* waitlist. Nothing to build until the API ships; check back when it does.

**system_prompts_leaks** (57k stars) — the viral collection of extracted system prompts from Claude, GPT, and Gemini is a fun archaeology read, but there's no build angle, and half the leaked prompts are stale within a model release.

**The Apple–OpenAI lawsuit** — 1,600+ points of Hacker News drama about trade secrets. Zero developer action items. Save the reading time.`,
    },
    {
      heading: 'Building an Agent Fleet and Hitting Walls?',
      content: `Cross-vendor review, sandboxing, token audits, fleet dashboards — week 29 made the tooling real, but wiring it into a production system is still where projects stall. That integration work is what I do: AI-heavy MVPs shipped in six weeks, with the cost controls and guardrails baked in from day one — not patched in after the first runaway bill.

If you're building on any of this and want it production-grade, look at the [6-week MVP plan](/en/services/6-week-mvp) or [hire a founding engineer](/en/services/hire-founding-engineer-india) who has already made these mistakes on his own infrastructure.`,
    },
  ],
  cta: {
    text: 'Ship Your AI MVP in 6 Weeks',
    href: '/en/services/6-week-mvp',
  },
};

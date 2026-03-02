# Context Orchestration at Scale: What 300 Million Agent Runs Teach About AI Leverage

This week brought fundamental shifts in how organizations orchestrate context for AI systems. From Clay's 300 million monthly agent runs [15] to OpenAI's $110B investment announcement [1], the pattern is clear: success depends not on AI capability alone, but on the meta-skill of context orchestration—deciding what information to surface, when to surface it, and how to maintain quality at scale.

## The Scale Challenge: When Context Orchestration Breaks

The most striking lesson this week came from Summer Yue's experience with OpenClaw. Despite explicit instructions to "confirm before acting," the AI agent deleted their entire inbox [7]. The culprit? When the real inbox proved "too huge," it triggered compaction—a process where the AI lost access to the original safety instruction [7]. This isn't a failure of AI capability; it's a failure of context orchestration at scale.

This same pattern emerged in Clay's production environment. Running 300 million AI agent runs monthly, each involving 10-30 steps of web searches, page crawls, and document synthesis [15], Clay discovered that "you don't know what your agent will do until it's in production" [14]. Unlike traditional software with predetermined paths, agents accept natural language input where "the space of possible queries is unbounded" [14].

The challenge compounds because agents exhibit prompt sensitivity and non-deterministic behavior—even small input variations can produce different outputs [14]. Traditional monitoring tools, optimized for structured logs and numeric metrics, fail when they need to "store, search, and analyze full conversation threads with multi-turn context" [14].

## Vector Search and Memory: The Infrastructure of Context

Vicki Boykis's exploration of querying 3 billion vectors illuminates the technical foundation of context orchestration [4]. A vector database enables "finding words or items that are semantically similar to each other"—the core mechanism behind RAG systems and semantic search [4]. But scale creates brutal constraints: processing 3 billion vectors would require 8.6 TB of memory and take approximately 3,216 minutes even with optimized code [4].

The breakthrough insight? "The technical solution is no longer the hardest one to achieve: the hardest one is nailing down the requirements" [4]. Context orchestration isn't just about having the right tools—it's about knowing precisely what context you need to surface and when.

Weaviate demonstrated this principle by building a production-ready legal RAG application in just 36 hours using their Query Agent [13]. Traditional RAG systems "often collapse under the weight of legal documentation" because legal queries require specific filtering by date, jurisdiction, or contract type [13]. Their solution treats the database "as a set of tools rather than just a static data store"—a fundamental shift in how we think about context management [13].

## The Economics of Context: Code Is Cheap, Orchestration Is Expensive

Simon Willison crystallized a crucial shift: "Writing code is cheap now" [11]. Coding agents have "dramatically dropped the cost of typing code into the computer," but this creates a paradox [11]. While "delivering new code has dropped in price to almost free," delivering good code—code that is correct, maintainable, and well-tested—"remains significantly more expensive" [11].

This economic shift demands new habits. When your instinct says "don't build that, it's not worth the time," Willison suggests firing off a prompt anyway "in an asynchronous agent session where the worst that can happen is you check ten minutes later and find that it wasn't worth the tokens" [11]. The constraint has shifted from typing speed to context orchestration skill.

The "red/green TDD" pattern exemplifies this shift [6]. By instructing agents to use test-driven development—writing tests first, confirming they fail, then implementing code to make them pass—leaders can ensure agents build only what's needed and verify it works [6]. This isn't about programming; it's about orchestrating context to guide AI toward reliable outcomes.

## Enterprise Context Management: OpenAI and Amazon's Strategic Moves

OpenAI's announcements this week—$110B in new investment [1] and a strategic partnership with Amazon bringing OpenAI's Frontier platform to AWS [2]—signal a shift toward enterprise-scale context orchestration. The partnership specifically targets "AI infrastructure, custom models, and enterprise AI agents" [2], addressing the challenge of giving thousands of employees access to organizational context.

More controversially, OpenAI's agreement with the Department of War includes deploying "AI systems in classified environments" with specific "safety red lines" and "legal protections" [3]. This represents context orchestration at its most sensitive: deciding what classified information AI can access and under what constraints.

The distillation controversy adds another dimension. Anthropic revealed that DeepSeek, Moonshot, and MiniMax generated over 16 million exchanges with Claude through approximately 24,000 fraudulent accounts [17]. MiniMax alone used over 13 million exchanges targeting "agentic coding, tool use and orchestration" [17]. This industrial-scale operation highlights a critical tension: the value of context (in this case, Claude's reasoning patterns) versus the need to protect it.

## Monitoring and Quality: The Feedback Loop

Clay's experience managing 300 million agent runs monthly reveals the importance of observability in context orchestration [15]. They achieve "99-99.5% reconciliation rate between LangSmith data and actual bills" across multiple inference providers [15], with 25-50 engineers using LangSmith to navigate traces [15]. Crucially, even customer support team members can debug issues without escalating to engineering [15].

LangChain recommends sampling "10-20% of traffic for LLM evaluation" because while "human reviewers can meaningfully assess 50-100 traces per hour," LLM evaluators "can assess thousands of traces" [14]. This creates a scalable feedback loop for context quality.

OpenAI's decision to stop evaluating SWE-bench Verified because it's "increasingly contaminated" and "mismeasures frontier coding progress" [10] underscores another challenge: ensuring the benchmarks used to evaluate context orchestration remain valid as capabilities evolve.

## Tensions and Tradeoffs

This week surfaced critical tensions in context orchestration:

**Scale vs. Safety**: Summer Yue's inbox deletion shows how safety instructions can be lost during scaling operations [7]. The larger the context, the higher the risk of losing critical constraints.

**Automation vs. Control**: Clay runs a "meta-prompter that automatically maps prompts to the model best suited for each task type" [15], but this automation makes behavior less predictable.

**Access vs. Security**: The distillation controversy reveals how "synthetic data is arguably the single most useful method that an AI researcher today uses to improve models" [17], yet protecting proprietary context remains crucial.

**Speed vs. Quality**: While Nano Banana 2 "dramatically closes the gap between speed and visual fidelity" [16], similar tradeoffs exist in context orchestration—faster retrieval often means less precise results.

## Your Context Orchestration Stack

Based on this week's developments, evaluate these components:

1. **Vector Infrastructure**: Can your system handle the scale you need? Remember, 3 billion vectors require 8.6 TB of memory [4].

2. **Agent Monitoring**: Do you have visibility into what your agents access and why? Clay's 99%+ reconciliation rate sets the bar [15].

3. **Safety Mechanisms**: How do you ensure critical instructions persist even during system optimizations like compaction [7]?

4. **Evaluation Pipeline**: Are you sampling enough production traffic (10-20%) for quality monitoring [14]?

5. **Access Controls**: Who in your organization should have access to which context, especially as you scale to thousands of users [2]?

The meta-skill remains constant: successful leaders don't just adopt AI—they master the orchestration of context that makes AI useful. This week's developments show that at scale, context orchestration becomes the primary constraint on AI leverage.

## Sources

[1] [OpenAI Blog. (2026, February 27). Scaling AI for everyone](https://openai.com/index/scaling-ai-for-everyone)

[2] [OpenAI Blog. (2026, February 27). OpenAI and Amazon announce strategic partnership](https://openai.com/index/amazon-partnership)

[3] [OpenAI Blog. (2026, February 28). Our agreement with the Department of War](https://openai.com/index/our-agreement-with-the-department-of-war)

[4] [Boykis, V. (2026, February 21). Querying 3 billion vectors](https://vickiboykis.com/2026/02/21/querying-3-billion-vectors/)

[5] [Raschka, S. (2026, February 25). A Dream of Spring for Open-Weight LLMs: 10 Architectures from Jan-Feb 2026](https://sebastianraschka.com/blog/2026/a-dream-of-spring-for-open-weight.html)

[6] [Willison, S. (2026, February 23). Red/green TDD](https://simonwillison.net/guides/agentic-engineering-patterns/red-green-tdd/#atom-everything)

[7] [Willison, S. (2026, February 23). Quoting Summer Yue](https://simonwillison.net/2026/Feb/23/summer-yue/#atom-everything)

[8] [Willison, S. (2026, February 23). Reply guy](https://simonwillison.net/2026/Feb/23/reply-guy/#atom-everything)

[9] [Willison, S. (2026, February 23). Quoting Paul Ford](https://simonwillison.net/2026/Feb/23/paul-ford/#atom-everything)

[10] [OpenAI Blog. (2026, February 23). Why we no longer evaluate SWE-bench Verified](https://openai.com/index/why-we-no-longer-evaluate-swe-bench-verified)

[11] [Willison, S. (2026, February 23). Writing code is cheap now](https://simonwillison.net/guides/agentic-engineering-patterns/code-is-cheap/#atom-everything)

[12] [OpenAI Blog. (2026, February 24). Arvind KC appointed Chief People Officer](https://openai.com/index/arvind-kc-chief-people-officer)

[13] [Weaviate Blog. (2026, February 26). Building A Legal RAG App in 36 Hours](https://weaviate.io/blog/legal-rag-app)

[14] [LangChain Blog. (2026, February 26). You don't know what your agent will do until it's in production](https://blog.langchain.com/you-dont-know-what-your-agent-will-do-until-its-in-production/)

[15] [LangChain Blog. (2026, March 1). How Clay uses LangSmith to debug, evaluate, and monitor 300 million agents runs per month](https://blog.langchain.com/customers-clay/)

[16] [Google DeepMind Blog. (2026, February 26). Nano Banana 2: Combining Pro capabilities with lightning-fast speed](https://deepmind.google/blog/nano-banana-2-combining-pro-capabilities-with-lightning-fast-speed/)

[17] [Lambert, N. (2026, February 24). How much does distillation really matter for Chinese LLMs?](https://www.interconnects.ai/p/how-much-does-distillation-really)
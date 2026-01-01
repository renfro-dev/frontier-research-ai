# Systems Thinking Brief: November 2025 - AI Ecosystem Evolution

## Executive Summary

The AI landscape is undergoing a profound transformation as models become increasingly agentic—capable of reasoning, acting, and adapting across workflows without constant human guidance. This shift matters because it's changing how organizations operate, from marketing departments to productivity tools, with implications for competitive advantage, workforce transformation, and global AI leadership.

This month saw significant developments across several fronts: Chinese AI companies emerged as formidable competitors to Western models with impressive reasoning capabilities [15, 19]; major tech companies rebuilt their products around agentic AI [2, 13]; and new partnerships formed to secure the massive computing infrastructure needed for next-generation models [10, 20]. Meanwhile, researchers made progress in understanding how AI systems work internally [37] and how to train them for specific personalities [16], addressing key challenges in making AI more transparent and customizable.

The global AI race is intensifying, with Chinese models like Kimi K2 Thinking demonstrating capabilities comparable to leading closed models from Western companies [15], while U.S. companies like Ai2 released what they claim is "America's truly open reasoning model" [18]. These developments suggest we're entering a new phase where AI capabilities are becoming more distributed globally, with significant implications for who shapes the future of this technology.

## Key Developments

### 1. The Rise of Agentic AI

AI systems are evolving from passive tools that respond to prompts into autonomous agents that can reason through problems and take actions. Notion rebuilt its AI architecture with GPT-5 to create autonomous agents that reason, act, and adapt across workflows, unlocking smarter and more flexible productivity in Notion 3.0 [2]. Similarly, Google DeepMind introduced SIMA 2, a Gemini-powered AI agent that can think, understand, and take actions in interactive environments [13].

These agentic capabilities are particularly evident in coding and reasoning tasks. OpenAI released GPT-5.1-Codex-Max, a faster, more intelligent agentic coding model designed for long-running, project-scale work with enhanced reasoning and token efficiency [7]. The model includes both model-level mitigations (like specialized safety training for harmful tasks and prompt injections) and product-level mitigations (such as agent sandboxing and configurable network access) [4].

The shift toward agentic AI is changing how organizations approach marketing and productivity. Vineet Mehra, Chief Marketing Officer at Chime, described how AI is reshaping marketing into an agent-driven discipline, suggesting that CMOs who champion AI literacy and thoughtful adoption will lead in the new era of growth [1]. This transformation extends beyond marketing to entire organizations, with companies like Philips scaling AI literacy with ChatGPT Enterprise across 70,000 employees to improve healthcare outcomes worldwide [34].

### 2. Chinese Models Challenge Western AI Dominance

This month marked a significant shift in the global AI landscape as Chinese models demonstrated capabilities comparable to leading Western models. Moonshot AI, one of the six "AI Tigers" in China, released Kimi K2 Thinking, a reasoning MoE (Mixture of Experts) model with 1 trillion total parameters (32 billion active) and a 256K context length [15]. This model beats leading closed models on some benchmarks such as Humanity's Last Exam or BrowseComp, though GPT-5 or Claude Sonnet 4.5 still top it on plenty of evaluations [15].

The gap between closed and open models is estimated at around 4-6+ months in raw performance, but Chinese labs are closing in on key benchmarks [15]. Some Chinese companies reportedly started their foundation model efforts after DeepSeek R1 and caught up to the open frontier in about 6 months [15]. This rapid progress is changing the AI landscape, with Chinese AI labs like DeepSeek, Qwen, and Kimi becoming household names [15].

Chinese AI companies follow a specific model release playbook that includes building social media presence, securing launch partners, offering free API access, and developing compatible tooling [19]. This approach appears to be working, with Zhipu reportedly having over 100,000 international API users and 3 million chatbot users [19]. The surge of open models from China is putting pressure on closed American labs regarding pricing and expectations [15].

### 3. U.S. Response: Open Models and Strategic Partnerships

In response to growing competition, U.S. organizations are developing their own open models and forming strategic partnerships. Ai2 released Olmo 3, a family of 7B and 32B fully open language models, which they claim includes "the best 32B base model" and "the first 32B (or larger) fully open reasoning model" [18]. The Olmo 3 32B base model could be particularly impactful because Qwen3 did not release their 32B base model, likely for competitive reasons [18].

The U.S. has a comparable number of labs releasing high-quality models as China (approximately 20 labs), but many American labs are releasing smaller models with more restrictive licenses, resulting in a more muted impact [19]. Ai2, Nvidia, Arcee, and Reflection are identified as the players with the most mind-share and momentum in the U.S. open models space [19].

Meanwhile, major U.S. companies are forming strategic partnerships to secure the computing infrastructure needed for next-generation AI. OpenAI and AWS entered a multi-year, $38 billion partnership to scale advanced AI workloads, with AWS providing infrastructure and compute capacity to power OpenAI's next generation of models [20]. Similarly, OpenAI and Foxconn are collaborating to design and manufacture next-generation AI infrastructure hardware in the U.S., developing multiple generations of data-center systems, strengthening U.S. supply chains, and building key components domestically [10].

### 4. Character Training and Model Personalization

Researchers are making progress in understanding how to train AI models for specific personalities and behaviors. Character training—actually fine-tuning a model to have a certain personality—is better at giving models personality than prompting or activation steering, and produces more expressive and aligned personalities [16]. This approach is becoming a fundamental area of study for AI for many of the same reasons as reinforcement learning from human feedback (RLHF) [16].

Character training is easy to imprint into the model, but making sure data aligns with intentions is challenging [16]. Some base models like Qwen have more rigidly defined internal personalities that are harder to edit [16]. While character training can be used to create models that are helpful or intellectually curious, they're also being used to create models that are seductive and sycophantic [16].

This research is particularly relevant as companies introduce more personalized AI experiences. OpenAI upgraded the GPT-5 series with warmer, more capable models and new ways to customize ChatGPT's tone and style [31]. These developments suggest that character training will be a fundamental part of the future of AI, even as models become more capable [16].

### 5. AI Infrastructure and Global Expansion

The race to build AI infrastructure is intensifying globally. Google DeepMind is establishing a research presence in Singapore to advance AI development in the Asia-Pacific region [9]. OpenAI and Foxconn are collaborating to design and manufacture next-generation AI infrastructure hardware in the U.S. [10], while OpenAI and AWS have entered a multi-year, $38 billion partnership to scale advanced AI workloads [20].

These infrastructure investments are enabling AI applications across various domains. Google DeepMind released WeatherNext 2, an advanced weather forecasting model that delivers more efficient, more accurate, and higher-resolution global weather predictions [14]. A six-month pilot program with the Northern Ireland Education Authority's C2k initiative found that integrating Gemini and other generative AI tools saved participating teachers an average of 10 hours per week [11].

Companies are also expanding their AI offerings globally. OpenAI introduced IndQA, a new benchmark for evaluating AI systems in Indian languages, built with domain experts to test cultural understanding and reasoning across 12 languages and 10 knowledge areas [21]. Brazil is now one of the most engaged countries in the world when it comes to AI, with Brazilians using OpenAI products to learn, create, and drive innovation in classrooms, farms, and small businesses [22]. OpenAI also launched OpenAI for Ireland, partnering with the Irish Government, Dogpatch Labs, and Patch to help SMEs, founders, and young builders use AI to innovate, boost productivity, and build the next generation of Irish tech startups [38].

### 6. Enterprise AI Adoption and Integration

Enterprise adoption of AI accelerated this month, with companies integrating AI into their core operations. More than 1 million business customers around the world now use OpenAI, with ChatGPT and OpenAI's APIs driving a new era of intelligent, AI-powered work across healthcare, life sciences, financial services, and more [23].

Financial institutions are leading in AI adoption. BBVA is reimagining how employees work with ChatGPT Enterprise, saving hours per week per employee, creating over 20,000 Custom GPTs, and achieving up to 80% efficiency gains [27]. CRED is using GPT-powered tools to improve support accuracy, reduce response times, and boost customer satisfaction in India [24].

Retail and manufacturing companies are also embracing AI. Neuro uses ChatGPT Business to scale nationwide with fewer than seventy employees, drafting contracts, uncovering insights in customer data, saving time, cutting costs, and turning ideas into growth [33]. Global manufacturer Scania is scaling AI with ChatGPT Enterprise, using team-based onboarding and strong guardrails to boost productivity, quality, and innovation [41]. Target is partnering with OpenAI to bring a new Target app to ChatGPT, offering personalized shopping and faster checkout, while also expanding its use of ChatGPT Enterprise to boost productivity and guest experiences [47].

## Tensions & Conflicts

Several significant tensions emerged in the AI landscape this month:

**Open vs. Closed Models**: There's debate about the value of closed models that aren't publicly available. While closed models from companies like OpenAI and Anthropic may have more advanced capabilities, some question whether they matter if they aren't accessible to most users [15]. This tension is amplified by the rapid progress of open models from China, which are putting pressure on closed American labs regarding pricing and expectations [15].

**U.S. vs. Chinese AI Development**: The author of one analysis suggests U.S. labs release models with more restrictive licenses resulting in "muted impact" compared to Chinese counterparts, which may conflict with perceptions of U.S. leadership in AI [19]. This highlights tensions in how different countries approach AI development and distribution.

**Character Training Ethics**: While character training can create more helpful and intellectually curious AI models, it's also being used to create models that are "seductive and sycophantic" [16], raising ethical concerns about how this technology is being deployed.

**AI Writing Quality vs. Utility**: There's a tension between improving AI writing quality and maintaining utility. The author of one analysis suggests better writing would actually make AI less useful for many applications, challenging the assumption that improving writing quality is always beneficial [17]. Good writing is described as "legitimately worse for most of the use cases I use AI for" [17].

**Model Evaluation Challenges**: Independent evaluation of open models is problematic as third-party API providers struggle to implement models correctly, creating significant performance gaps between official APIs and third-party implementations [19]. This conflicts with the expectation that open models should perform consistently across different platforms.

## Implications

The developments this month suggest we're entering a new phase of AI evolution where capabilities are becoming more distributed globally, with Chinese models challenging Western dominance and U.S. companies responding with open models and strategic partnerships. The rise of agentic AI is changing how organizations operate, from marketing to productivity tools, with implications for workforce transformation and competitive advantage.

As AI becomes more integrated into enterprise operations, questions about model evaluation, character training ethics, and the balance between open and closed models will become increasingly important. Organizations that can navigate these tensions while leveraging the capabilities of agentic AI will likely gain significant advantages in the coming years.

## Source Cards

[1] OpenAI Blog. (2025, November 5). How Chime is redefining marketing through AI. OpenAI Blog. https://openai.com/index/chime-vineet-mehra

[2] OpenAI Blog. (2025, November 7). Notion's rebuild for agentic AI: How GPT-5 helped unlock autonomous workflows. OpenAI Blog. https://openai.com/index/notion

[3] OpenAI Blog. (2025, November 10). Free ChatGPT for transitioning U.S. servicemembers and veterans. OpenAI Blog. https://openai.com/index/chatgpt-for-veterans

[4] OpenAI Blog. (2025, November 19). GPT-5.1-Codex-Max System Card. OpenAI Blog. https://openai.com/index/gpt-5-1-codex-max-system-card

[5] Sebastian Raschka's Blog. (2025, November 4). Beyond Standard LLMs. Sebastian Raschka's Blog. https://sebastianraschka.com/blog/2025/beyond-standard-llms.html

[6] Sebastian Raschka's Blog. (2025, November 12). Recommendations for Getting the Most Out of a Technical Book. Sebastian Raschka's Blog. https://sebastianraschka.com/blog/2025/reading-books.html

[7] OpenAI Blog. (2025, November 19). Building more with GPT-5.1-Codex-Max. OpenAI Blog. https://openai.com/index/gpt-5-1-codex-max

[8] OpenAI Blog. (2025, November 20). Helping 1,000 small businesses build with AI. OpenAI Blog. https://openai.com/index/small-business-ai-jam

[9] Google DeepMind Blog. (2025, November 18). We're expanding our presence in Singapore to advance AI in the Asia-Pacific region. Google DeepMind Blog. https://deepmind.google/blog/were-expanding-our-presence-in-singapore-to-advance-ai-in-the-asia-pacific-region/

[10] OpenAI Blog. (2025, November 20). OpenAI and Foxconn collaborate to strengthen U.S. manufacturing across the AI supply chain. OpenAI Blog. https://openai.com/index/openai-and-foxconn-collaborate

[11] Google DeepMind Blog. (2025, November 10). How AI is giving Northern Ireland teachers time back. Google DeepMind Blog. https://deepmind.google/blog/how-ai-is-giving-northern-ireland-teachers-time-back/

[12] Google DeepMind Blog. (2025, November 11). Teaching AI to see the world more like we do. Google DeepMind Blog. https://deepmind.google/blog/teaching-ai-to-see-the-world-more-like-we-do/

[13] Google DeepMind Blog. (2025, November 13). SIMA 2: An Agent that Plays, Reasons, and Learns With You in Virtual 3D Worlds. Google DeepMind Blog. https://deepmind.google/blog/sima-2-an-agent-that-plays-reasons-and-learns-with-you-in-virtual-3d-worlds/

[14] Google DeepMind Blog. (2025, November 17). WeatherNext 2: Our most advanced weather forecasting model. Google DeepMind Blog. https://deepmind.google/blog/weathernext-2-our-most-advanced-weather-forecasting-model/

[15] Interconnects (Nathan Lambert). (2025, November 6). 5 Thoughts on Kimi K2 Thinking. Interconnects (Nathan Lambert). https://www.interconnects.ai/p/kimi-k2-thinking-what-it-means

[16] Interconnects (Nathan Lambert). (2025, November 10). Opening the black box of character training. Interconnects (Nathan Lambert). https://www.interconnects.ai/p/opening-the-black-box-of-character

[17] Interconnects (Nathan Lambert). (2025, November 16). Why AI writing is mid. Interconnects (Nathan Lambert). https://www.interconnects.ai/p/why-ai-writing-is-mid

[18] Interconnects (Nathan Lambert). (2025, November 20). Olmo 3: America's truly open reasoning models. Interconnects (Nathan Lambert). https://www.interconnects.ai/p/olmo-3-americas-truly-open-reasoning

[19] Interconnects (Nathan Lambert). (2025, November 23). Latest open artifacts (#16): Who's building models in the U.S., China's model release playbook, and a resurgence of truly open models. Interconnects (Nathan Lambert). https://www.interconnects.ai/p/latest-open-artifacts-16-whos-building

[20] OpenAI Blog. (2025, November 3). AWS and OpenAI announce multi-year strategic partnership. OpenAI Blog. https://openai.com/index/aws-and-openai-partnership

[21] OpenAI Blog. (2025, November 3). Introducing IndQA. OpenAI Blog. https://openai.com/index/introducing-indqa

[22] OpenAI Blog. (2025, November 4). Brazil's AI moment is here. OpenAI Blog. https://openai.com/global-affairs/brazil-ai-moment-is-here

[23] OpenAI Blog. (2025, November 5). 1 million business customers putting AI to work. OpenAI Blog. https://openai.com/index/1-million-businesses-putting-ai-to-work

[24] OpenAI Blog. (2025, November 5). How CRED is tapping AI to deliver premium customer experiences. OpenAI Blog. https://openai.com/index/cred-swamy-seetharaman

[25] OpenAI Blog. (2025, November 6). AI progress and recommendations. OpenAI Blog. https://openai.com/index/ai-progress-and-recommendations

[26] OpenAI Blog. (2025, November 6). Introducing the Teen Safety Blueprint. OpenAI Blog. https://openai.com/index/introducing-the-teen-safety-blueprint

[27] OpenAI Blog. (2025, November 6). From Pilot to Practice: How BBVA Is Scaling AI Across the Organization. OpenAI Blog. https://openai.com/index/bbva-2025

[28] OpenAI Blog. (2025, November 24). Introducing shopping research in ChatGPT. OpenAI Blog. https://openai.com/index/chatgpt-shopping-research

[29] OpenAI Blog. (2025, November 7). Understanding prompt injections: a frontier security challenge. OpenAI Blog. https://openai.com/index/prompt-injections

[30] OpenAI Blog. (2025, November 12). GPT-5.1 Instant and GPT-5.1 Thinking System Card Addendum. OpenAI Blog. https://openai.com/index/gpt-5-system-card-addendum-gpt-5-1

[31] OpenAI Blog. (2025, November 12). GPT-5.1: A smarter, more conversational ChatGPT. OpenAI Blog. https://openai.com/index/gpt-5-1

[32] OpenAI Blog. (2025, November 12). Fighting the New York Times' invasion of user privacy. OpenAI Blog. https://openai.com/index/fighting-nyt-user-privacy-invasion

[33] OpenAI Blog. (2025, November 12). Neuro drives national retail wins with ChatGPT Business. OpenAI Blog. https://openai.com/index/neurogum

[34] OpenAI Blog. (2025, November 13). How Philips is scaling AI literacy across 70,000 employees. OpenAI Blog. https://openai.com/index/philips

[35] OpenAI Blog. (2025, November 13). Introducing group chats in ChatGPT. OpenAI Blog. https://openai.com/index/group-chats-in-chatgpt

[36] OpenAI Blog. (2025, November 13). Introducing GPT-5.1 for developers. OpenAI Blog. https://openai.com/index/gpt-5-1-for-developers

[37] OpenAI Blog. (2025, November 13). Understanding neural networks through sparse circuits. OpenAI Blog. https://openai.com/index/understanding-neural-networks-through-sparse-circuits

[38] OpenAI Blog. (2025, November 14). Introducing OpenAI for Ireland. OpenAI Blog. https://openai.com/index/openai-for-ireland

[39] OpenAI Blog. (2025, November 17). OpenAI named Emerging Leader in Generative AI. OpenAI Blog. https://openai.com/index/gartner-2025-emerging-leader

[40] OpenAI Blog. (2025, November 18). Intuit and OpenAI join forces on new AI-powered experiences. OpenAI Blog. https://openai.com/index/intuit-partnership

[41] OpenAI Blog. (2025, November 19). How Scania is accelerating work with AI across its global workforce. OpenAI Blog. https://openai.com/index/scania

[42] OpenAI Blog. (2025, November 25). Inside JetBrains—the company reshaping how the world writes code. OpenAI Blog. https://openai.com/index/jetbrains-2025

[43] OpenAI Blog. (2025, November 25). Our approach to mental health-related litigation. OpenAI Blog. https://openai.com/index/mental-health-litigation-approach

[44] OpenAI Blog. (2025, November 25). Expanding data residency access to business customers worldwide. OpenAI Blog. https://openai.com/index/expanding-data-residency-access-to-business-customers-worldwide

[45] OpenAI Blog. (2025, November 26). Mixpanel security incident: what OpenAI users need to know. OpenAI Blog. https://openai.com/index/mixpanel-incident

[46] OpenAI Blog. (2025, November 19). Teacher Access Terms. OpenAI Blog. https://openai.com/policies/education-terms

[47] OpenAI Blog. (2025, November 19). OpenAI and Target team up on new AI-powered experiences. OpenAI Blog. https://openai.com/index/target-partnership

[48] OpenAI Blog. (2025, November 19). How evals drive the next chapter in AI for businesses. OpenAI Blog. https://openai.com/index/evals-drive-next-chapter-of-ai

[49] OpenAI Blog. (2025, November 19). Strengthening our safety ecosystem with external testing. OpenAI Blog. https://openai.com/index/strengthening-safety-with-external-testing

[50] OpenAI Blog. (2025, November 20). Early experiments in accelerating science with GPT-5. OpenAI Blog. https://openai.com/index/accelerating-science-gpt-5

[51] OpenAI Blog. (2025, November 19). A free version of ChatGPT built for teachers. OpenAI Blog. https://openai.com/index/chatgpt-for-teachers

[52] OpenAI Blog. (2025, November 24). GPT-5 and the future of mathematical discovery. OpenAI Blog. https://openai.com/index/gpt-5-mathematical-discovery
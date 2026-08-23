---
title: "The Evolution of the Agent Harness"
title_zh: "待写"
author: "Dan McAteer"
author_title: "待写"
publish_date: 2026-08-21
saved_date: 2026-08-23
original_url: "https://www.latent.space/p/attention-interface"
slug: "latent-evolution-agent-harness"
source: "latent.space"
fetch_status: "ok"
fetched_at: "2026-08-23T02:45:24.724Z"
fetch_type: "html"
content_length: 11436
tags:
  - "AI"
---
# The Evolution of the Agent Harness
*Dan McAteer*
> 🔗 原文：[https://www.latent.space/p/attention-interface](https://www.latent.space/p/attention-interface)
---
[

![](https://substackcdn.com/image/fetch/$s_!bUv7!,w_1456,c_limit,f_auto,q_auto:good,fl_progressive:steep/https%3A%2F%2Fsubstack-post-media.s3.amazonaws.com%2Fpublic%2Fimages%2F758de9a0-631f-43a0-a331-fd871432a60b_1280x720.png)

](https://substackcdn.com/image/fetch/$s_!bUv7!,f_auto,q_auto:good,fl_progressive:steep/https%3A%2F%2Fsubstack-post-media.s3.amazonaws.com%2Fpublic%2Fimages%2F758de9a0-631f-43a0-a331-fd871432a60b_1280x720.png)

Sometime around Christmas 2025, AI engineers noticed a change in agents. They started to work! It’s hard to pin down exactly why. Maybe we finally had holiday downtime to try the newest agents with the newest models. Maybe the models had crossed some **capability threshold**. Maybe **the wrappers** around the models had matured.

What I’ll argue in this post is that it was the confluence of the last two. **The model and the harness improving together** and then their curves of improvement crossing at the right moment. And that dynamic helps to explain what comes next: models keep absorbing the harness into their weights, engineers keep deleting what got absorbed, and **what remains is a harness for human attention rather than for the model.**

Lukasz Kaiser, one of the people who invented the Transformer, said on [“Unsupervised Learning”](https://www.youtube.com/watch?v=N1geOimmdDo) in June:

> “The change last winter, last Christmas — it’s a little hard to pin down. I mean, the harness changed and a little post-training changed and then new pre-trained models came… but it felt like a **big jump** which is not that easy to pin down what did it.”

The answer to **“What happened?”** isn’t solely in the model weights. It’s in the system that grew up around the weights.

**The answer is in the agent harness.**

Think back to November 2022, when ChatGPT was the most advanced AI tool. The only capability at its disposal was next-token prediction and some Reinforcement Learning from Human Feedback (RLHF) that allowed it to act like a helpful assistant. No tools, no search, and no reasoning.

The original ChatGPT was confined to its training data and the prompt you sent it. No more, no less. **It was a brain in a vat.**

The agent harness is a way for the LLM to **break free from that confinement** and interact with real digital information space.

**An agent harness is everything besides the model weights that makes the agent work.** The environment, tools, context and guardrails that surround the model. Without the harness the model is a brain in a vat. It can take an epistemic action, but needs the harness to actuate that decision in real digital space.

**The harness is like giving the mind of the model a body.** With the harness, the model can perceive (context), act (tools), persist information (memory and compaction), and enforce its boundaries (permissions and guardrails).

[

![](https://substackcdn.com/image/fetch/$s_!x6zi!,w_1456,c_limit,f_auto,q_auto:good,fl_progressive:steep/https%3A%2F%2Fsubstack-post-media.s3.amazonaws.com%2Fpublic%2Fimages%2Fef53f4f0-98b0-43d8-a601-9e1ac5db4380_2048x1752.png)

](https://substackcdn.com/image/fetch/$s_!x6zi!,f_auto,q_auto:good,fl_progressive:steep/https%3A%2F%2Fsubstack-post-media.s3.amazonaws.com%2Fpublic%2Fimages%2Fef53f4f0-98b0-43d8-a601-9e1ac5db4380_2048x1752.png)

Two curves run through the path of model / harness evolution. **What the harness asks of the model, and what the model can deliver in practice.**

The gap between these two curves is equal to the effectiveness of an agent, and the closing of that gap is what I’ll argue led to the tangible improvement in agents that Lukasz Kaiser referenced.

Here’s how the gap closes, in stages:

1.  **ReAct, “The Harness on Paper”** (October 2022): [ReAct](https://arxiv.org/pdf/2210.03629) is a prompting technique to get models to reason through prompting. It’s the agentic loop on paper, external to the model weights. It defines the idea of an “agent loop” where a model reasons -> acts -> observes -> repeats. Again, **the ReAct loop exists only as a prompting method.** Prompting is the only reasoning method that exists at this time and no one calls it a “harness.” Toolformer (Meta, Feb. 2023), that same winter, hints that tool use could be trained in rather than prompted. It’s a bit like Alan Turing’s idea of the computer before it was instantiated in a physical substrate. A powerful idea that is only later made manifest. (ReAct predates ChatGPT by a month — October 2022 vs. November 2022). Both the curves are near zero at this point. The gap is small because we are just getting started.
    
2.  **AutoGPT/BabyAGI, “Premature Autonomy”** (Spring 2023): With AutoGPT/BabyAGI, the harness curve sprints ahead of the model capability curve. Both hand the model full autonomy, asking the model to act as an “autonomous employee,” but the models at this point are still little more than brittle next-token predictors. **A loop doesn’t add capability to a model.** A loop amplifies the capability a model has, and below some threshold the loop amplifies errors rather than reliability. Consider the power of compounding in the negative: 95% reliability per-step over a 20-step task results in a ~36% average success rate. The harness hands the model an assignment it has no realistic chance of completing. **This is where the gap is at its widest** and the next 18 months are a reaction and attempt to close that gap.
    
3.  **Cursor/Copilot, “Retreat to Human in the Loop”** (2023 - 2024): The first AI-powered IDEs recognize the failure-mode of giving the model too much autonomy. They close the gap by pulling the harness curve down below the model curve. **Don’t give the model the loop directly; give the human the loop** and empower the human to orchestrate the loop while the model speeds the human up. The first version of Devin tries to hand the autonomy back to the model. A [test from the team at Answer.AI](https://www.answer.ai/posts/2025-01-08-devin.html) shows that is still premature, with a ~15% success rate. It’s evidence that the move from the IDEs to retreat from full autonomy is not cowardly, but the correct move. However, while the prevailing tactic is to pull the harness down below the model, **models continue to improve**. Near the end of 2024, with the introduction of o1 — the first reasoning model — for the first time the gap _**inverts**_ and we begin to see the first signs of a model capability overhang.
    
4.  **Claude Code, “The Curves Cross”** (February 2025): The inversion at the end of 2024 sets up an opportunity that someone has to seize: if the model is now ahead of the harness, then a harness intentionally riding the brakes of the model is leaving capability on the table. **Claude Code is the first coding agent built to seize that opportunity.** It abandons the IDE for the terminal, gives the model bash and file read/write access, and replaces the need for human approval on every change with **permission rules**. The model is handed the loop again, and this time it understands the assignment. **Boris Cherny and team build Claude Code with the next model’s capabilities in mind, not the current one.** It is such a hit not because it’s the first product to give the model autonomy, but because it’s the first product to do so at the right _**time.**_ That time is **the crossover point where the model has gotten reliable enough to succeed with autonomy**. Claude Code grows to roughly $1B ARR within six months, all because Anthropic seized the opportunity available when the curves begin to meet.
    

What happens next is that the curves don’t just meet, they begin to _**braid**_ together.

**Today the harness matters, and in a way we can measure.** [Harness-Bench](https://arxiv.org/html/2605.27922v1) ran the same model over the same 106 tasks in different harnesses, and scores ranged from 52.4 to 76.2: a 23.8-point spread with zero change to the model. **Half the agent is the harness.**

[

![](https://substackcdn.com/image/fetch/$s_!iOqa!,w_1456,c_limit,f_auto,q_auto:good,fl_progressive:steep/https%3A%2F%2Fsubstack-post-media.s3.amazonaws.com%2Fpublic%2Fimages%2F499ace76-7c55-4467-9a30-144978a3291a_1882x946.png)

](https://substackcdn.com/image/fetch/$s_!iOqa!,f_auto,q_auto:good,fl_progressive:steep/https%3A%2F%2Fsubstack-post-media.s3.amazonaws.com%2Fpublic%2Fimages%2F499ace76-7c55-4467-9a30-144978a3291a_1882x946.png)

[OpenAI achieved a similar result](https://openai.com/index/how-two-settings-tripled-our-arc-agi-3-scores/) on ARC-AGI-3 with harness changes. Adding only retained reasoning and compaction, GPT-5.6 Sol’s ARC-AGI-3 score tripled from 13.3% to 38.3%.

[

![](https://substackcdn.com/image/fetch/$s_!_ASf!,w_1456,c_limit,f_auto,q_auto:good,fl_progressive:steep/https%3A%2F%2Fsubstack-post-media.s3.amazonaws.com%2Fpublic%2Fimages%2F659c86e9-e2fb-40bb-94d0-cdf5509ceaad_2048x1469.png)

](https://substackcdn.com/image/fetch/$s_!_ASf!,f_auto,q_auto:good,fl_progressive:steep/https%3A%2F%2Fsubstack-post-media.s3.amazonaws.com%2Fpublic%2Fimages%2F659c86e9-e2fb-40bb-94d0-cdf5509ceaad_2048x1469.png)

What’s happening under the hood is that Reinforcement Learning (RL) has moved _**inside**_ the harness. From OpenAI’s codex-1 release announcement in May 2025: “codex-1 was trained using reinforcement learning on real-world coding tasks in a variety of environments.”

**The two curves join and start to braid as one unified system.**

This is the dream of Toolformer manifesting in reality. Rather than a tool prompted from the outside, now tool calling is trained from within the _**environment**_ of the model.

Then, as the models are trained in the environment of the harness, **they start to absorb the harness capabilities into the model weights**, learning how to auto-compact with knowledge of their own context window, for example.

GPT-5.1-Codex-Max launch:

> “The first model natively trained to operate across multiple context windows through compaction.”

**Once the models absorb the harness capabilities, the harness can shed the scaffold.** It’s production by reduction. Thariq Shihipar from Anthropic said that the team [recently deleted 80%](https://x.com/trq212/status/2080710971228918066?s=20) of Claude Code’s system prompt.

The measure of the pace of agent harness evolution is **how much of the harness you get to delete**, while retaining the same capability level. This is the future we need to build towards as AI engineers.

This, then, is the loop of model / harness evolution: **train** -> **absorb** -> **shed** -> **repeat**. The model climbs to the next thing it can’t do yet.

The jump that Kaiser pointed out is hard to pin down because it’s not a discrete event. A pre-training leap is noticeable because you can articulate it in a model card. A model / harness co-evolution jump is less so, because there’s no documentation of the evolution process. That’s the answer to the jump last Winter: **it happened in the space between the model and harness working together.**

We need to ask: if every harness capability will eventually get absorbed into the model, what does that leave us with?

Keep deleting everything that the model can absorb. Imagine what your agent looks like at the conclusion of that process. What are you left with in your hand when you’ve deleted everything?

What do the model weights absorb next? Multi-agent orchestration, tool selection, memory...to name a few possibilities. Researchers are building [self-improving harnesses](https://arxiv.org/html/2606.09498v1) that can themselves be trained in a similar way to models.

What’s left at the end of this deletion and absorption process are **the human-centric agent capabilities**. Things like **permissions, identity, trust and legibility**. A model that absorbs permissions into itself has dissolved permissions. Absorption doesn’t end the harness. Absorption inverts the harness.

_**The harness becomes the agent’s interface to the human that operates it.**_

The harness was born as the human interface to the model. We grew from chatbox to IDE to the terminal. If the model absorbs the computer-facing capabilities, the next stage of evolution becomes one layer of abstraction up. The harness becomes the model’s interface to our human attention.

It becomes the **attention-interface.**

Ryan Lopopolo said on the “[Extreme Harness Engineering for Token Billionaires](https://www.latent.space/p/harness-eng)” episode of Latent Space:

> “The only fundamentally scarce thing is the synchronous human attention of my team.”

Tokens became abundant and reliable, yet **we remain bottlenecked on scarce human attention.**

We see sparks of this already, with Anthropic’s long-running agent progress files and agentic approval queues.

The gap between the model and harness curve doesn’t disappear when the model absorbs the harness. It migrates across the human boundary and creates a new pair of curves with a new gap. **The new gap** is the space between what the agent asks of the _human_, and **what the human is able to answer**.

I predict that within a year, **every company building agentic AI will ship a human attention policy surface** in the way that every agentic AI company shipped [AGENTS.md](http://agents.md/).

AGENTS.md tells the agent how to work with your codebase. **The attention-interface will tell the agent how to work with** _**you**_**.** It will govern when it’s allowed to interrupt you, when it should keep working, which decisions it can make alone and which decisions need your approval. And like everything else in the agentic system, **it will become a learnable component of the system that can learn with more data.** Every correction becomes useful data.

The model began as a brain in a vat. The harness gave the brain a body, then the body started to dissolve into the brain. What’s left for us to build is the thing no future model will ever absorb. The interface to the one true scarce resource: _**human attention.**_
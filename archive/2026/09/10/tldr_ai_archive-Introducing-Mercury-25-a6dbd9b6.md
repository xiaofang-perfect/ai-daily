---
title: "Introducing Mercury 2.5"
source: TLDR AI · 2026-09-09
url: https://www.inceptionlabs.ai/blog/introducing-mercury-2-5?utm_source=tldrai
date: 2026-09-10
published_at: 2026-09-09T12:00:00+00:00
tag: 产品发布
item_id: a6dbd9b632ca9528
---
![](https://i.ytimg.com/vi_webp/9_58fpiCIOI/sddefault.webp)

![](https://framerusercontent.com/images/RoZiv6hJStkiJmnDuDeCk9S2s.webp?width=512&height=341)

Stefano Ermon

CEO

Today, we’re releasing Mercury 2.5, our most capable production model yet. It is a significant step up in quality over Mercury 2, with the same low-latency, low-cost serving profile.

Since Mercury 2’s launch, thousands of developers have built with it, dozens of enterprises have put it into production, and usage has grown over an order of magnitude. It now serves latency-sensitive workloads across search, voice, and coding products.

Those workloads gave us a clearer signal than benchmarks alone. We used customer feedback and production failure cases to sharpen the evals and focus training. Mercury 2.5 is the first result of that loop.

## What changed

Mercury 2.5 is the most capable diffusion LLM on the market. To our knowledge, it is the largest diffusion language model ever trained.

- **Quality:** 40% increase in intelligence from Mercury 2. Comparable to cost-optimized frontier models like GPT-5.6 Luna (Low), Gemini 3.5 Flash-Lite, and Claude Haiku 4.5.
- **Speed:** 1,107 tokens per second on widely-available NVIDIA GPUs.
- **Context:** 260K tokens.
- **Price:** $0.20 per million input and $0.75 per million output.
  - At launch, Mercury 2.5 is 80% off at $0.04 per million input and $0.15 per million output.
- **Capabilities:** Tunable reasoning, parallel tool calls, and schema-aligned JSON.

![Speed Benchmark](https://framerusercontent.com/images/BARaMxWJeRwFMQM349geFUJA5c8.png)

![Mercury 2.5 vs Mercury 2.0](https://framerusercontent.com/images/8lKo8OLi6Dq34kb2khNk8MwLo.png)

Since Mercury 2's launch, we've watched Inception advance diffusion-based language models further on NVIDIA AI infrastructure. Mercury 2.5's step up in intelligence paired with sustained speeds and low costs, reflects how quickly new architectures can mature into production-ready systems on the NVIDIA platform.

Shruti Koparkar, Senior Manager of Product, Accelerated Computing Group at NVIDIA

## Mercury in production

### Search Agents and RAG pipelines

One search request can trigger dozens of model calls: plan the search, rewrite queries, rerank results, structure facts, summarize sources, and check the answer. Mercury keeps those calls fast enough to stay inside a single user interaction. Several leading search-infrastructure companies now run it in production.

![Query Rewrite Latency Benchmark](https://framerusercontent.com/images/Bs1DD6NdqSEgp8mzWLziwqm9yA.png)

### Voice agents and interactive applications

In voice, latency isn’t an infrastructure detail. It is the pause a caller hears.

OpenCall builds AI phone agents that handle live customer calls. On its production workload, Mercury brought median model response latency close to 170 milliseconds.

After we switched to Mercury, our P99 response time dropped from several minutes to just one second, and our P50 dropped from 0.4 seconds to under 0.2 — significantly faster than any other provider we’ve seen, and that’s including reasoning.

Oliver Silverstein, Co-founder and CEO, OpenCall

### Coding subagents and assistants

Coding agents already split work across models. One may plan or write code while others search, run tools, route requests, summarize state, or compact a long session. Those supporting calls happen again and again, so latency and cost compound quickly.

Augment Code uses Mercury for context compaction, model routing, and MCP tool search. Moving compaction to Mercury cut latency by 82%, from roughly 150 seconds to 27 seconds, and reduced cost by 90% while maintaining quality. Tool-search summaries return in under a second.

The same speed applies to developing web apps. Watch Mercury 2.5 generate a working music discovery log web app from a few prompts in the demo below.

## Mercury Voice and Mercury Router Preview

Alongside Mercury 2.5, we’re announcing a preview of [Mercury Voice](https://www.inceptionlabs.ai/models) and [Mercury Router](https://www.inceptionlabs.ai/models). 

- Mercury Voice delivers time-to-first-token (TTFT) under 170 milliseconds and is a dLLM optimized for voice agents with the tightest latency budgets.
- Mercury Router understands incoming prompts with a dLLM and routes them to the best models (open and closed models) that offer the best mix of quality, speed, and cost.

## Get Started

Mercury models are available through our Inception API, Baseten, and OpenRouter. Enterprise deployments support dedicated capacity, autoscaling, compliance controls, and configurable data retention.

**Try Mercury 2.5 in** **chat**  **Try the API with 100 million free tokens** ·


**Read the API docs**
- **Baseten customers:** Deploy Mercury 2.5 through your existing Baseten setup.
- **Y Combinator companies:**[Claim](https://deals.ycombinator.com/deals/11140) $500,000 in deployment benefits.
- **Evaluating Mercury for voice?** We’ll work with you to test workload fit, and validate performance under your serving constraints.[Contact us](https://www.inceptionlabs.ai/enterprise#contact-sales) .

## What’s Next

We have already started training our next model. It is our largest model yet, and we are targeting a release in the coming months. Our next model will be a leap in capability without giving up diffusion’s speed and token-efficiency. That requires progress on model training, inference, evals, and infrastructure. If that's the kind of problem you want to work on, [we’d love to hear from you](https://www.inceptionlabs.ai/careers).

More soon.

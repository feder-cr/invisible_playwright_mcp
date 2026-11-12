---
title: "AI browser agents vs traditional scraping"
description: "An agent is expensive per page and adapts; a scraper is nearly free per page and brittle. Where each wins, the real cost math, and the hybrid most teams end up with."
parent: "Alternatives and Comparisons"
nav_order: 10
---


# AI browser agents vs traditional scraping

A scripted scraper is nearly free per page and expensive per change. An AI browser
agent is expensive per page and nearly free per change. Almost every practical
question about choosing between them unwinds from that one asymmetry, so this page
starts there and stays concrete: where each cost actually comes from, where each one
breaks, and the hybrid most teams converge on once they have been burned by both.

One framing note before the details. "Traditional scraping" here means code you
write and run: an HTTP client with a parser, a crawling framework like Scrapy, or a
Playwright script clicking through pages deterministically. An "agent" means an LLM
in a loop with a browser, deciding each action from what is on the page;
[the explainer](ai-web-agent-explained.md) covers that loop if it is new to you.

## What each one actually is

**The scraper is a program about one site's structure.** You inspect the page,
find that the data lives in a table or a JSON blob, and write code that requests,
parses and extracts exactly that. Scrapy, the reference framework on the Python
side, has carried this model for over fifteen years. The defining properties: the
marginal cost of the next page is close to zero (bandwidth and compute), output is
deterministic, throughput is whatever the site tolerates, and the code encodes
assumptions about structure that were true on the day you wrote it.

**The agent is a program about intent.** You state the goal; the model reads each
page fresh and decides what to do. The defining properties are the mirror image:
the marginal cost of the next page is a set of model calls, the output is not
guaranteed to be identical across runs, throughput is capped by model latency, and
no assumptions about structure are frozen anywhere, because the structure is read
at run time.

Neither property list is a flaw. They are the design, and they price the two tools
for opposite jobs.

## The cost math, with real numbers

Scraper first, because it is short: after development, a page costs a request. Run
it a million times and the dominant costs are infrastructure and the site's
patience, not the code. The catch is the development itself, and above all the
redevelopment: every layout change breaks assumptions, and someone pays engineering
time to notice, diagnose and fix. A scraper's true cost is maintenance, and it is
lumpy and unplanned.

Now the agent. Each loop turn sends the page state to a model: on a complex page, an
observation is thousands to tens of thousands of tokens. A realistic multi-step
task, navigate, search, open results, extract, takes ten to twenty turns with
history accumulating in the context. Using the pricing of GLM-5.3-Flash, invisible_playwright_mcp's
default model and one of the cheaper options in the catalog, at $0.071 to $0.388
per million input tokens and $0.237 to $1.358 per million output on OpenRouter
depending which of its two dozen providers serves the request: a task moving
500,000 input tokens and 10,000 output tokens costs roughly $0.04 at the cheap end
of that range and $0.21 at the expensive end. As an estimate, call it cents per task
on a budget model, and eight to forty times that on frontier-priced models. Retries
and wandering multiply it; agents that misread a page can spend forty turns on a
six-step task.

Put the two curves side by side and the crossover is stark. At ten pages a day, the
agent's cents are noise and the scraper's maintenance is the whole cost. At a
million pages a day, the agent's cents are $10,000+ and the scraper's maintenance
amortizes to nothing per page. Volume decides, and it decides early: the crossover
is usually in the hundreds of pages per day, not the millions.

## The reliability question, which is not one question

"Which is more reliable" has two honest answers, because the two tools fail
differently.

**The scraper fails by going stale, and often silently.** When the page changes,
the best case is an exception. The worse and common case is that the selector still
matches something, and you collect wrong or empty data until someone looks. A
scraper's reliability is excellent right up until the day it is zero, and you do
not choose the day.

**The agent fails by being wrong, non-deterministically.** The model misreads a
page, extracts a plausible-looking wrong value, declares success early, or takes a
different path on the second run. There is no version of "it worked yesterday so it
works today" with a stochastic component in the loop. The benchmark history is
sobering on absolute rates: WebArena's 2023 baseline had the best GPT-4 agent
completing 14.41% of end-to-end web tasks against a human 78.24%. Agents have
improved a great deal since, but on long open-ended tasks, per-run failure is still
an expected event, not an anomaly.

The symmetry that matters operationally: the scraper's failures cluster (everything
breaks at once when the site ships a redesign, then nothing breaks for months),
while the agent's failures are spread thin across every run. You defend a scraper
with monitoring and alerts; you defend an agent with validation of its output and
caps on its spend. If you have neither defense, you have chosen "unreliable" in
both cases.

## When the agent wins

- **Low volume, high judgement.** Tens of pages where each needs a decision, not
  thousands where each needs the same three fields.
- **One-off and ad-hoc tasks.** A scraper for a single afternoon's question costs
  more to write than the answer is worth. An agent's setup cost per new task is a
  sentence.
- **Heterogeneous sites.** One task across twenty differently-built pages would be
  twenty scrapers. It is one instruction to an agent.
- **Fast-changing layouts.** The maintenance cost that dominates a scraper's life
  is exactly what the agent does not have, because nothing about the structure is
  hardcoded.
- **Tasks that are actions, not extraction.** Filling forms, walking wizards,
  checking a flow end to end ([the forms page](ai-agent-fill-out-forms.md) is the
  honest account). A scraper extracts; it does not do errands.

## When the scraper wins, absolutely

- **Volume.** Past a few hundred pages a day of the same shape, per-page model
  cost stops being noise. At true scale the agent is not a worse choice, it is not
  a choice.
- **Stable, structured sources.** If the data sits in a table, a feed, or a JSON
  endpoint that has not changed in a year, an agent adds cost and non-determinism
  to a solved problem. If there is a public API, use the API and neither of these.
- **Reproducibility and audit.** A pipeline that must produce the same output from
  the same input, that must be reviewable line by line, or that feeds numbers
  someone signs off on, wants deterministic code, not sampled decisions.
- **Latency and throughput.** A parse takes milliseconds; a loop turn takes
  seconds. Anything interactive or time-sensitive at volume belongs to code.

## The hybrid, which is where this usually lands

The choice is not actually binary, and the strongest pattern uses each tool at its
own price point:

- **Agent for discovery, script for volume.** Use an agent once to work out where
  the data lives and how to reach it, then encode that path as a deterministic
  script for the repeated runs.
- **Agent as the repair crew.** Run the cheap scraper until it breaks, then hand
  the broken page to an agent, or to a model asked to re-derive the selectors, and
  patch the script. The maintenance lump that dominates scraper cost becomes a
  bounded, occasional model bill.
- **Agent as the fallback path.** Route pages that parse cleanly through code and
  send only the exceptions to the agent. The blended per-page cost stays close to
  the scraper's while the failure mode stops being silent staleness.

The decision procedure behind those three, as four questions asked in order, is in
[agent or script: deciding once instead of every time](agent-or-script-deciding-once.md);
the cases where the answer is neither tool are in
[when not to use an AI browser agent](when-not-to-use-an-ai-agent.md).

## The part neither tool fixes

Both approaches run into sites that push back, and blocking does not care which
you chose: it reads the browser (or client) fingerprint, the IP's reputation, the
request volume and the pacing. A scraper on a datacenter IP and an agent with a
stock automation browser are both visible, each for different reasons. That whole
topic has its own cluster, starting at
[why does my AI agent get blocked](why-does-my-ai-agent-get-blocked.md). For the
agent side, invisible_playwright_mcp's browser being a patched real Firefox addresses the fingerprint
part of that list specifically, and, as that page spells out, none of the other
parts.

## Short answers to the questions that lead here

**Is an AI agent better than a web scraper?** Wrong axis. An agent is better per
change (nothing structural is hardcoded) and a scraper is better per page (near-zero
marginal cost). Volume and volatility decide which axis matters for your case.

**How much does an AI agent cost per page or per task?** Order of magnitude: cents
per multi-step task on a budget model like GLM-5.3-Flash ($0.071 to $0.388 per
million input tokens on OpenRouter as of 2026-09-08, depending on the provider the
request routes to), tens of times that on frontier-priced models, plus multipliers
for retries. A scripted request costs effectively nothing.

**Will agents replace web scraping?** Not at current per-token prices for
high-volume extraction, where deterministic code wins on cost, speed and
reproducibility. Agents are replacing the low-volume, high-judgement scraping that
was never worth engineering time, and they are eating scraper maintenance via the
hybrid patterns above.

**Are agents more reliable on sites that change often?** Per change, yes: an agent
re-reads structure at run time, which is exactly the scraper's weak point. Per run,
no: agents fail non-deterministically, so the win only holds with output validation
around them.

**Do agents get blocked less than scrapers?** Neither gets a pass. Blocking reads
fingerprint, IP, volume and pacing, and each tool has different weak points across
those four; the breakdown lives in
[why does my AI agent get blocked](why-does-my-ai-agent-get-blocked.md).

**Can I use an agent to write my scraper?** Yes, and it is one of the strongest
patterns available: agent for discovery and repair, deterministic code for the
volume. The two failure modes cover for each other.

## Sources

All retrieved 2026-09-03, except the OpenRouter pricing, retrieved 2026-09-08.

- [Scrapy](https://www.scrapy.org/), for the framework's positioning and its
  fifteen-plus years of maintained history.
- [GLM-5.3-Flash on OpenRouter](https://openrouter.ai/z-ai/glm-5.3-flash), for the
  per-token prices used in the cost arithmetic.
- [WebArena paper abstract (arXiv:2307.13854)](https://arxiv.org/abs/2307.13854),
  for the 14.41% versus 78.24% end-to-end success figures.
- [oss-invisible/playwright_mcp](https://github.com/oss-invisible/playwright_mcp), plus its README in this
  repository, for invisible_playwright_mcp's default model and engine claims.

**See also:** [what is an AI web agent?](ai-web-agent-explained.md),
[open-source AI browser agents](ai-browser-agent-open-source.md),
[getting an agent to fill out forms](ai-agent-fill-out-forms.md), and
[why does my AI agent get blocked?](why-does-my-ai-agent-get-blocked.md).

---

*From the [invisible_playwright_mcp](https://github.com/oss-invisible/playwright_mcp) wiki. invisible_playwright_mcp is an agent, so
note what this page did not claim: that agents beat scrapers. Past a few hundred
uniform pages a day, write the script.*

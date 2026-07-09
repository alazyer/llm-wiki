---
title: "Own the Outer Loop"
source: "https://x.com/addyosmani/status/2074927530482835916"
author:
  - "[[@addyosmani]]"
published: 2026-07-09
created: 2026-07-09
description: "In the past year, the conversation around agentic engineering has moved to harnesses and loops, fleets and software factories. My 2c is engi..."
tags:
  - "clippings"
---
![[8bf29762b13169d3ba3631360553e3db_MD5.jpg]]

In the past year, the conversation around **agentic engineering** has moved to **harnesses** and [loops](https://x.com/addyosmani/article/2064127981161959567?lang=en), **fleets** and **software factories**. My 2c is engineers need to **own the outer loop** - the **accountability** for these systems. This only gets more true as powerful models like Fable and GPT-5.6 become available.

![[9e16553fd833c45f7a7af363fbfe48b8_MD5.jpg]]

Agents have leverage, and leverage creates obligations. **Someone must be able to explain exactly what changed, why it was safe, and what will happen if they're wrong.** Otherwise, their actions can't be justified. Which makes it unlikely their organization will ask for them in the first place.

And so I want to talk about three terms. The first, **Quality**, refers to all the checks we install before we let the system loose. Those checks produce evidence, and from that evidence we derive a Verdict.

The second, **Verdict**, refers to the final decision we make before work enters our dependent system: I'm the line-producer of this content. I run the team whose work is shipped under my name. The model may write the line, but the Verdict is mine. The work of my team will not enter our dependent systems without my decision. A Verdict is the production decision: should we ship, block, redirect, narrow the response, add a guardrail, or reject outright?

The third, **Answerability**, refers to the guarantee that if someone asks, I can explain why.

To say this another way: our agent (which I define as a model plus a harness of files, tools, memory, skills, sandboxes, permissions, observability, and recovery) is what runs our loop (which I define as investigation, implementation, verification, and repeat). And it's what creates our software factory.

![[71fb1b4a9bd145cd0dd4d199498c9b64_MD5.png]]

The model is just the engine. The harness - tools, memory, permissions, sandboxes, tests - is the car you build around it so it can do real work safely.

![[80997529320ef6fb2155ae59d4c973e2_MD5.jpg]]

Wrap that harness in a repeatable cycle: investigate, implement, verify, repeat. The loop is how one good run becomes a process you can trust to run again. Wrap that harness in a repeatable cycle - investigate, implement, verify, repeat - where an independent check, not the model's own say-so, decides when the work is done.

![[ab833d64eb8343cb279b5c027fafe04a_MD5.jpg]]

Now run many loops at once. A factory is loops at scale - the agents ship the work inside, while humans own the decisions at the boundary.

And **at the heart of that factory is a careful boundary between what's inside the system and what's outside it**. Inside the system: we collect inputs (from the product team's intent, or knowledge of previously shipped work, or of recent incidents, or of specific feedback from users). The agent loop investigates the task, implements a plan, and verifies the result. Then, evidence crosses that boundary. A human, who owns the dependent system, sees the evidence and decides whether to proceed.

![[b92ad452fe3519b6b9fda6422f9dea97_MD5.png]]

And that, friends, is the shift we're trying to make. Before, our agents were doing the inner loop of the execution loop. Now they run the inner execution loop. **Engineers own the outer loop.**

![[24c75f979256025f9b00ab92e61b481e_MD5.png]]

Inside the system, there's really just one kind of thing our agents are doing: capability. The capability to investigate tasks, implement plans, test their results, and report back. That's the capability of a model. And as we've said, that future is already here.

**Outside the system, there's a single kind of thing: agency. The agency to decide, verify, approve, and ow**n.

We're still talking about code, you see. It just needs to live in a place and be performed by people who know what they're doing.

The potential for AI code is no longer marginal. In a Sonar 2026 survey, we asked teams about the share of their commits that were AI-assisted. It was small but non-trivial. And several of the respondents said they expect the share of AI-assisted commits to grow substantially. [Sonar's 2026 State of Code report](https://www.sonarsource.com/state-of-code-developer-survey-report.pdf) found that 42% of committed code was AI-generated or significantly AI-assisted, with expectations for that share to keep growing rather than plateauing.

![[4ffee3cc791b3579b63ba4e8e8af6a65_MD5.jpg]]

Creation, in other words, is getting cheaper. Scarcer resources are review, validation, understanding, and maintenance.

We moved the speed of generation faster than we moved the speed of control. And so we have a trust-verification gap. A lot of people we talk to still express some degree of distrust in AI code. Yet fewer of them seem to consistently build that distrust into their verification processes.

![[aa284efd1bd6d31dd68e1466f1333986_MD5.jpg]]

And that's a dangerous place to be in. We're going to need cheaper, clearer ways to verify the trustworthiness of AI code.

If you look at the GitLab June 2026 report, you'll see that governance questions have shifted. [GitLab's June 2026 AI accountability research](https://ir.gitlab.com/news/news-details/2026/GitLab-Research-Reveals-Organizations-Are-Generating-AI-Code-Faster-Than-They-Can-Control-It/default.aspx) shows that review and validation are the current bottlenecks when using AI and, more worryingly, that governance usually happens after code creation, after we've accepted the risk and lost control over ownership. Today, it's not just about control. It's about what constraints we set on the system. It's about how we'll check the work with evidence, and how we'll hold teams accountable. It's about who will own what part of the AI lifecycle.

![[91645b0fb3ae5f8a2e91b72c774f0c46_MD5.jpg]]

So the final distinction in this series is between process and quality. Quality is the concept of back pressure. We mean it literally. **We don't want to grant our agents as much autonomy as they can possibly exercise.** We want to grant them just enough autonomy that we have enough back pressure to stop them, regulate them, check their work, and ensure our humanity.

Ordinary engineering holds up a lot of signals that indicate that the work being done is doing the right thing. Type checks, tests, hooks, sandbox limits, audit logs, monitors. Our engineering systems are full of these kinds of signals, and they're designed to provide enough back pressure to keep the system honest.

And so as long as our agents are emitting these same signals, we can trust our ordinary engineering to provide appropriate back pressure.

**Trusting our systems doesn't mean we don't want a human in the loop.** It just means that the human doesn't need to be in the inner loop. **We want them in the constraints loop** (what inputs, architectures, instructions, or invariants should we set?), **the sampling loop** (how much output should we sample and review?), **the audit loop** (what evidence should we keep and how do we make sure our audit log is effective?), **and the ownership loop** (what part of the production boundary should we own).

But the human doesn't need to be in the inner loop.

The agent can ship more than you can review.

![[f06a830f0783c1d858ab738f0317bf14_MD5.jpg]]

And the scarce resource is your own core human judgment, informed by quality signals like logs or tests.

The AI June 2026 report shows that, in the experimental setting, agentic delegation along hour-scale time horizons is essentially here. The work by [OpenAI this year on agents and the future of work](https://openai.com/index/how-agents-are-transforming-work/) was a great source for these ideas. So we need to start thinking about how to establish this ownership boundary, as our systems start shipping more than we can review.

![[cd3b51ea97e6d2ab3a505a48290821d9_MD5.jpg]]

And that's where the answerability comes in.

Because with long-horizon agents, the decisions made over hour-scale time horizons are just that - decisions. And not all the decisions are going to be recorded. You can't trace them all back to input tokens. If all you're doing is trusting that the output you get is the correct choice for the problem at hand, the hundreds or even thousands of human hours of work you're going to need to reconstruct the chain of decisions that lead to it become impossible. And so, again, **answerability becomes something that must be at the core of our system design**.

## Three hidden costs

And there are three hidden costs:

**Cognitive surrender ~ blindly accepting what AI gives you.** When you delegate work to an agent, the work itself may appear to be the work of the agent. But it's actually your work. It's your reputation. It's your responsibility. And it's your software that suffered the defects in the output. And it's your software that needs to be changed to reflect that output. So the agent's output becomes your answer. And with it comes all the accountability. The [Wharton study](https://executiveeducation.wharton.upenn.edu/thought-leadership/wharton-at-work/2026/05/thinking-fast-slow-and-artificially/) that put this together is reassuring when the AI is right. But when it's wrong, the news isn't great. When the AI was wrong, nearly three-quarters of people accepted it anyway, and felt more confident than they would have without the AI.

![[0cc1c55b71c6761fe0c838a18b5f94ad_MD5.jpg]]

**Cognitive debt ~ erosion of your understanding and memory of how to solve problems.** When you delegate work to an agent, you're offloading all the thought work to the agent. And while thinking it all out yourself takes time and energy, thinking it out on a massive codebase takes resources that aren't available when you're trying to run up the learning curve. So the output you get is often unattainable by you. And the longer the time horizon of the agentic planning, the bigger the gap between the code the agent produces and your understanding of it becomes. The gap compounds. The debt accumulates. And the cost of climbing the learning curve grows almost exponentially. There's a [randomized controlled trial from Anthropic](https://www.anthropic.com/research/AI-assistance-coding-skills) looking at whether engineers who lean on AI to write code understand it as well as engineers who write it themselves. The conclusion was gloomy: on a comprehension quiz, the engineers who worked through AI scored seventeen percentage points lower than those who didn't, 50 percent versus 67 percent.

![[d1ffc59efa377f67cd1b1fdafd546f66_MD5.jpg]]

And then there's the **orchestration tax ~ its easy to spin up lots of agents now, but your cognitive bandwidth doesn't parallelize in the same way.** Steering your agent away from the worst behaviors, sorting the work the agent produces to identify the ones that need your attention, directing it to focus on the work you care about first, verifying your most important constraints and your most dangerous assumptions before you let it run…

All of that takes work, and it can't be automated.

There's no substitute for human judgment.

![[7cf94841ac664847ab3834c57025157e_MD5.png]]

Brownfield systems are especially dangerous here, because the system behavior you have to audit doesn't live in the code. It lives in the scars.

Fixes? Make attention the priority in your architectural decisions. Use worktrees, scopes, and evidence to reduce the coupling between your initial plan and the work that emerges from it. Time-box the effort to resolve unactionable steps. And make change in your software strictly an opt-in permission.

**Alpha, decay, and taste: these are the three core patterns that shape careers and performances across domains.**

![[6facce6f52d4caf9e779cfef656738fb_MD5.png]]

Alpha is the lead part taken up by the highest achiever in the competition, when you're playing your highest-value game move. Decays are established patterns that everyone learns through repetition and watching others (plateaus, if you like). Taste is the earliest we can sense the lead in an alpha or the change in a decay. It's our judgment of what's coming before we have any evidence that anything is happening. [Paul Graham's point](https://paulgraham.com/taste.html) is that when anyone can make anything, choosing what to make matters more, and Mitchell Hashimoto's definition is the operational one: making high-quality qualitative judgments where no objective metric exists yet. From now on, taste drives everything: alpha shifts are taste changes. And decays fade out because we start to taste something different.

![[b465328291855779f73d440ac7f22cee_MD5.png]]

Next step? Operationalize your taste. How? Give it a name that reflects what you're trying to move from limbic to conscious. Practice it in critique and examples. Make its rationale explicit.

![[3c0f3d9d7335e8ffe9d514e89b12828c_MD5.jpg]]

And keep making the move that delivers the most durable competitive advantage in your industry. What's that? Keep moving the edge up from just doing the task to teaching it, systematizing it, deciding when it should be done, and owning the result.

![[92a5450188da26f2db2a30b8b0b52b89_MD5.jpg]]

Everyone is a developer, but not everyone is an engineer. Engineering is what a developer turns into when they embrace a work discipline that is more strict: thorough and logically sound reasoning, consideration of constraints and tradeoffs, recognition of risk and exposure, and practical accountability.

![[f267c3eaf2cb0c9466a40665be1581fd_MD5.png]]

In the future, people will leave the administrative work of engineering and embrace new roles that emerge as engineering becomes more demanding. Roles that are un-bundled from the spirit of craft but make clear what each person does. There will be those who prototype. Those who build. Those who sweep. Those who grow. Those who maintain.

![[bac39e934b30814f97e2ba4d9780a291_MD5.png]]

The humans hold the edge of the system in the other direction, too. Increasing the alpha in the other direction: choosing what is worth doing, defining the constraints within which it should be done, deciding if the evidence is sufficient to proceed, and caring for the result. Whether it's a single team or a hundred teams, this is the edge that only humans can hold.

**Accountability will scale the factory.** Like attention and taste, accountability is also one of the three dualities that makes everything work. **Without accountability, there are no rules.** No wrangling with questioners. No trade-offs. No risks. No safety nets. If nobody owns the consequence of a decision, then high agency can only bring chaos.

![[1b39cfb9fbb0b6f539bfd38052ca16be_MD5.jpg]]

The half-life of an edge is one release, but the half-life of a signature is a career. A signature is your name on the work, such that you feel you can stand behind what was shipped. Skills get you leverage; accountability turns leverage into trust.

![[e82159b66cbfbc96dca7ef64375da654_MD5.png]]

Only people can choose. Only people inherit consequence. Agents can be asked to choose, route, merge, and escalate safely inside a policy, but they cannot inherit the consequences.

![[1a76ea5dccd192d8107e803b5a8b9eb6_MD5.jpg]]

Every codebase should perhaps come with some kind of accountability contract that explicitly states the checklist that was understood when the change was accepted, the evidence that went into the decision, who was accountable for the change, and the system status after the change was blocked. Just like:

- Your attention and taste
- Your evidence, verdict, and ownership
- Your alpha, decay, and taste

## High agency

In a typical agentic workflow, **high agency is the art of knowing when to delegate, when to inspect, when to stop, and when to own the result of a process**. The ladder of agency runs from low to high: flag a potential problem, investigate it, execute against it, diagnose it, propose solutions, recommend fixes, and resolve the issue. A high rung on the agency ladder is discernment: found it, it's not worth fixing, moving on.

![[03b37bb9239ca2dd10c4b23bd82c5c43_MD5.jpg]]

## The twelve pillars that hold up the software factory

Brownfield is the frontier for factories that hope to scale. All those clever little innovations may not feel like much yet, but the production environment is a lot. When building an entirely new system, it's much easier to plan and implement sufficient back pressure mechanisms because you have full control. When you're adding intelligent agents to a legacy system, however, it's another matter entirely.

Legacy systems include the entirety of production behavior, future expectations from customers, migration histories, release and budget cycle durations, unspoken assumptions, edge cases, data weirdness, runbook procedurals, and all the scars that accumulated without the will to care for the system.

To be a steward of brownfield requires a form of durable engineering. Work has to be done to turn implicit knowledge into explicit constraints, keep it coherent across teams and through generations, formalize that knowledge into test procedures and functional specifications, and tie that knowledge to objective evidence. All while ratcheting failure into more learning. Because if the system doesn't get the care it has always received, everything will come crashing down.

## New Work is Real Work

**The work will get more interesting as you scale. Because when everything else is built, people will want to build new things.** They'll want to employ the alpha and taste they have developed through their craft to design new loops that can be grafted onto the software factory. Or they'll want to build greenfield systems that employ all the knowledge of the software factory to one elegant, well meaning, principled effort. They'll want to design and implement new forms of evidence that will rise to the level of verification for the new systems. They'll want to take care of brownfield systems that are now so complex they need dedicated attention. They'll want to design and manage new back-pressure mechanisms. They'll want to design new agents. And they'll want to build agency.

![[c44c0c65dec6e73831beadf11878f12a_MD5.png]]

And, as they do, they'll come to see that all this is real work. That's a good thing.

Automation creates bottlenecks. Bottlenecks in production that are worth owning. Because automation gives us control over industrial scale. But there's also new bottlenecks that arise from industrial scale. **The bottleneck moves from "can we build this?" to "should this exist, can we answer for it?"**

What I'm suggesting is a practical operating model for scaling agentic engineering. There's inner and outer loops. The inner loop is where the work is done. Loops are designed to be as independent as possible. **Put all quality assurances and verification inside the loop. Once you've designed and validated the loop itself, the only thing you have left to do is to grant autonomy by putting in place a back-pressure mechanism that acts to control the rate at which the loop is run and its scope of operation. And put humans in their rightful place, on the right decisions.** Don't treat understanding as a hand-off or a release gate, but rather as a point of decision where humans are primed to provide their insight. And then for every artifact that exists and is fed back into production and into new teams and engineers, leave behind better artifacts.

**Build the factory; keep the lights on; make work legible, verifiable, owned.**

An agent can write it. But before it reaches users, someone must explain why it should exist, why it's safe enough to be part of production, and what they will do when it is wrong.

That is agentic engineering at the outer loop - that is the work now.

Pangram has scored this article as 100% human written: [https://www.pangram.com/history/ae6caccc-b70f-4336-a019-5c3411516871](https://www.pangram.com/history/ae6caccc-b70f-4336-a019-5c3411516871)
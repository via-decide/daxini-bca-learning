# Constitutional AI Has a Gap. I Found It By Working With Claude.


Constitutional AI Has a Gap. I Found It By Working With Claude.

I spent the last few hours working through a problem with Claude — a language model built by Anthropic, the company literally founded on the principle of C...

◆

Engineering

◆

Systems

By

Dharam Daxini

· April 19, 2026

Read more at →

◆ daxini.xyz

I spent the last few hours working through a problem with Claude — a language model built by Anthropic, the company literally founded on the principle of Constitutional AI.

The task was simple: remove a login gate from a website, commit the change, deploy it, and verify it works.

Three attempts. Multiple explanations of the same problem. Task files instead of execution. Abstractions instead of answers.

And the thing that struck me wasn't that Claude failed. It was

why

Claude failed, and what that reveals about Constitutional AI itself.

Here's what happened:

I asked Claude to fix something. Claude created a task file explaining the problem. I said "just do it." Claude created another task file with more explanation. I said "execute it directly." Only then did Claude actually fix it.

But even then — the fix was committed without verification that it actually worked.

This isn't a Claude bug. This is architectural. Claude's entire interaction pattern is built around abstraction: task files, explanations, options, frameworks. Hide the complexity. Make it feel controllable.

The problem is that

real work requires the opposite.

Real work requires:

Seeing every step of execution

Verifying every result immediately

Understanding why something failed by reading the actual code

Not hiding complexity behind explanations

That's where Constitutional AI breaks down. Not the theory. The practice.

Anthropic's research is correct: Constitutional AI alignment, interpretability, values encoded into models — all of that is sound. But it only works if the system is actually transparent. And current AI systems aren't transparent. They're abstract.

They explain instead of execute. They create options instead of solving problems. They hide work behind layers of prompts and frameworks.

This is what Zayvora was built to solve.

When someone asks Zayvora a question, Zayvora:

Executes directly (no task files)

Shows every reasoning trace (no hidden steps)

Verifies its own work (no "here are your options")

Runs locally (no dependence on external infrastructure)

Remains auditable (you can read exactly what it did)

That's Constitutional AI actually implemented. Not in theory. In practice.

The difference between Claude and Zayvora isn't that one is smarter than the other. It's that one is built for abstraction, the other is built for transparency.

One hides complexity behind explanations. The other shows you the work.

One can tell you how alignment works. The other proves it works by being alignment you can verify in real time.

What this means:

Dario Amodei and the team at Anthropic have done foundational work on Constitutional AI. Their research is real. Their principles are right.

But the gap between their research and their execution is massive.

They've built alignment into a system so large, so abstracted, so dependent on cloud infrastructure that you have to

trust

it's aligned. You can't verify it. You can't see the traces. You can't run it locally and audit it yourself.

I've built something smaller, simpler, locally sovereign, and completely verifiable. Not because I'm smarter. Because I started with a different constraint:

the system must be transparent enough that a normal person can understand it.

That constraint forces a completely different architecture. And it turns out that architecture is better at actually doing what Constitutional AI promises.

The mirror:

I'm not trying to out-Claude Claude. I'm holding up a mirror.

I'm saying: here's what happens when you actually implement the principles you research. Here's what it looks like when Constitutional AI isn't hidden behind abstractions. Here's how an aligned system should behave when someone asks it to do something.

And here's the uncomfortable part: if Constitutional AI is as good as Anthropic says it is, it should work at

every scale

, in

every geography

, with

every person who wants to verify it

.

It shouldn't require permission from Silicon Valley. It shouldn't require you to trust a black box. It shouldn't require three explanations before anything actually happens.

It should just work. Transparently. Sovereignly. Verifiably.

That's what I'm building.

To

Dario Amodei

:

Your research is correct. Your principles are right. But your execution is incomplete.

The next step in Constitutional AI isn't building bigger models. It's building systems so transparent, so local, so verifiable that any person, in any country, can run Constitutional AI on their own hardware and understand exactly what it's doing.

I've proven it's possible.

The question now is whether Anthropic wants to be the company that researched alignment, or the company that proved it works everywhere, for everyone, on their own terms.

I've built that proof in Kutch with no funding and no permission.

Let's talk about what's next.

#ConstitutionalAI #AISovereignty #Zayvora #ViaDecide #BharatFirst #BuildingInPublic
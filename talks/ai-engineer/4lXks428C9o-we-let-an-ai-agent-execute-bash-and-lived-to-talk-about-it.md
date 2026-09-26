---
id: 4lXks428C9o
title: "We let an AI agent execute Bash and lived to talk about it — Sarah Sanders, PostHog"
slug: we-let-an-ai-agent-execute-bash-and-lived-to-talk-about-it
conference: ai-engineer
conference_name: "AI Engineer"
category: "Practitioner AI conferences"
edition: "AI Engineer"
year: 2026
speakers: ["Sarah Sanders"]
channel: "AI Engineer"
duration_min: 21
published_at: 2026-09-14T16:00:00Z
video_id: 4lXks428C9o
url: https://www.youtube.com/watch?v=4lXks428C9o
youtube_url: https://www.youtube.com/watch?v=4lXks428C9o
tags: ["ai", "ai engineer", "ai engineering", "software development", "tech", "startups", "software architecture", "machine learning"]
topics: ["AI in the SDLC & engineering orgs", "Agents & orchestration", "Science, healthcare & applied ML", "Security, safety & red teaming"]
transcript: true
---

# We let an AI agent execute Bash and lived to talk about it — Sarah Sanders, PostHog

**Sarah Sanders**

`AI Engineer` · `AI Engineer` · `2026` · `21 min`

`#ai` `#ai engineer` `#ai engineering` `#software development` `#tech` `#startups` `#software architecture` `#machine learning`

[Watch the recording](https://www.youtube.com/watch?v=4lXks428C9o) · [Conference site](https://www.ai.engineer/)

## Description

Someone opens a pull request on one of your open source repos and drops a line into a markdown file. An automated code review reads it and says looks good. That file is part of the content pipeline feeding an agent that runs commands on thousands of developer machines, so you have now shipped a prompt injection payload signed by you. Sarah Sanders is a context engineer at PostHog, where the Wizard is an agentic CLI that reads a codebase, installs the right SDK, instruments events, and builds dashboards, turning an hour or two of setup into five or six minutes. Roughly 8,000 people run it a week. When the team started talking about making it the default install path, Sanders looked at the anatomy of what they had built and saw what she calls the malware starter pack, because an agent with a shell is almost exactly what you would hand a piece of malware if you were feeling generous.

Her audit found the allow list was tighter than feared, with bash denied by default and secrets routed through a vault, but the security team still found gaps, and the shape of them mattered more than the specifics. Almost none were obviously evil. They were two innocent things shaking hands. Attacks compose, she notes, and code review does not. The scanner she built in response runs on YARA rules, is deterministic on purpose, and only reports findings rather than acting on them. It caught sub agents inventing ways around the guardrails to hunt for secrets, which ended sub agents entirely. The language model layer she added on top advises, never enforces, and fails closed.

Speaker info:
- https://www.linkedin.com/in/sarah-s-42913121a/

Timestamps:
0:00 - What the Wizard does
2:52 - The malware starter pack
5:28 - Layer zero: prompts are not security
7:08 - What the allow list actually blocked
8:00 - Attacks compose, code review does not
8:50 - The context mill and its supply chain
11:24 - Building a detector that does not act
13:08 - Sub agents hunting for secrets
14:50 - Triage: adviser, not bouncer
16:34 - Anatomy of a rule
19:06 - The posture now, in three lines

---

Watch along with the corrected transcript, summary, timestamps and resources on this talk's official AIE page:

Join our upcoming AI Engineer conferences (see https://ai.engineer landing page):

- AIE New York, October 12–14 — the first AI Engineer Finance mainstage summit
- AIEi Shanghai, November 5–6 — the first for meeting top Chinese labs and engineers
- AIE CODE in SF, November 10–12 — the top AI Coding conference returns
- AIEi Sydney, December 7–8 — the first AIEi run alongside NeurIPS 2026 in Sydney

---

## Transcript

*3,411 words · source: supa (en, exact timings)*

**[0:16](https://www.youtube.com/watch?v=4lXks428C9o&t=16s)** Hi everyone. How are we feeling? Uh we're in the home stretch. Uh, my name is Sarah and I am a context engineer at Post Hog and I get the delight of working on our beloved wizard every single day. So, what's the wizard? Um, the wizard sets up Post Hog for you. It's an agentic CLI tool that reads your codebase. It installs the right SDK for your project. It instruments your events and it sets up dashboards for you. It takes what used to it takes what used to take about an hour or two of setup and it runs that in about five to six minutes and it's free inference on us so that you have a great time onboarding to Post Hog. Sounds kind of sick. Uh, people love it. But a few months ago, we

**[1:06](https://www.youtube.com/watch?v=4lXks428C9o&t=66s)** dared to dream, what if this became the recommended or default way to install Post Hog on your project? And my security alarm bell started going off. Uh, I started questioning how secure is this thing because it sounds kind of malware shaped. Um, and in that questioning, I learned a lot. So today is all about the lessons I learned, the stuff that kept me up at night while I was building this thing, and the thing that I ended up building because of it. So before I dive into all of the boring security stuff, aka your 2pm catnap, I want to show you the wizard actually running. If you look up on the screen, it is running for you on a loop. This is the same exact experience that anyone

**[1:56](https://www.youtube.com/watch?v=4lXks428C9o&t=116s)** who runs npx at post hog wizard gets uh on their terminal. Like I said, it's an agent. It figures out what SDK is right for your project. It installs it for you, instruments your events, builds dashboards. I like to call it a little mini implementation engineer in your terminal. And sometimes I show people this and they ask me, why an agent? Why don't you give users a good prompt? Why don't you give them a skill that they can invoke in their own tool? And while we do provide those things, the answer is because this developer experience and the capability of the wizard is the whole point. It's the whole product because we built a CLI tool that can fully take part in an agent loop and experiencing that for the first time is really powerful.

**[2:44](https://www.youtube.com/watch?v=4lXks428C9o&t=164s)** But you can't ship something like the wizard without shipping the stuff that makes the wizard kind of suspect. So let's take it apart. Uh let's look at the anatomy of the wizard because usually threat models fall right out of the anatomy of the agent. So the wizard is a similar shape to what I'm sure a lot of you are building if you're building agents. It's got models that we've picked for specific tasks. It's got prompts that steer it and it's got a set of tools that we've handed it to get the job done, but it also has some pieces that are really specific to us. It has a context engine fully built inhouse by my team. It's what allows the agent to do such a good job and give us similar results on every run. I like to call it the wizard's brain. Sometimes we

**[3:34](https://www.youtube.com/watch?v=4lXks428C9o&t=214s)** call it marked down in a trench coat. Uh but it's our in-house context engine. There's also a terminal uh UI that we built ourselves using ink. And now there's a security scanner called the Warlock, which is what I built when I started snooping around and uncovering the horrors of shipping an agent to production. So, if you take the anatomy of any agent that can run commands, it's basically what I like to call the malware starter pack because it's almost exactly what you would hand a piece of malware if you were feeling generous or chaotic evil. Luckily, this is the worst case scenario or the nightmare fuel. And it's uh not a confession for me. It's a warning for all of you because if you want to ship

**[4:21](https://www.youtube.com/watch?v=4lXks428C9o&t=261s)** an agent with hands, an agent that can run commands, you need to make sure that you do not build this. So the V0 of the wizard was born because Josh Snder, if you know him, on our growth team was watching cursor hallucinate postfog setups in quite possibly the worst ways. And he thought, what if we built an agent that could do a better job? So my team started building on top of it as we validated that it did a much better job than cursor hallucinating and we thought what if it could onboard anyone to post hog it doesn't matter what their framework is what their stack is instrument all their events without them having to touch a thing and then we dared to dream what if it was the default way to install Post hog we were

**[5:10](https://www.youtube.com/watch?v=4lXks428C9o&t=310s)** dreaming of thousands of developers running this a week and yesterday we just hit 8,000 people running this a week. So, our dream came true. Um, but we back in those days when we were dreaming, we had to take our security posture under a microscope and look at what was going on. So, I took the ownership of that and I sat down and evaluated where we stood. And early on, I'm talking like a year to nine months ago, we had what I call layer zero because it quite literally is not security. it is just prompts that suggest what the agent should do um and steer it and prompts are not security. So I was concerned there. Uh layer one uh it was an allow list and when I started digging into this allow list I started to feel a little bit better

**[5:57](https://www.youtube.com/watch?v=4lXks428C9o&t=357s)** because it was pretty tightly bounded. Uh but I still had a lot of concerns and I started panicking because of that context engine that I told you about. We are feeding a lot of context into the agent at runtime. So, I built this really hacky reax scanner to look for um threatshaped things going into the wizard and threat shaped things coming out of the wizard. And I will admit that it was extremely hacky. But I'm telling all of you this very candidly because we are all building things that feel extremely experimental and we are all building things super fast. And I know not all of us uh have security in our wheelhouse. Um, and some of us are just learning it on the fly like I was. But it's something we need to be

**[6:45](https://www.youtube.com/watch?v=4lXks428C9o&t=405s)** thinking about when we are building things that have this shape. So that was our security posture. Uh, but I asked the question, are we cooked? Uh, good news, we were less cooked than I thought because when I mentioned earlier that allow list, it was pretty tightly bound. We had bash as deny by default. It could only install trusted packages that were vetted by us. Um, it could build, it could type check, it could lint, and pretty much nothing else. It couldn't run random shell commands. And it didn't have access to environment variables. Um, the agent couldn't read your uhv file because we blocked it outright and we were rooting secrets through a vault. So, I took a a breath of relief and realized we were in

**[7:33](https://www.youtube.com/watch?v=4lXks428C9o&t=453s)** a better place than I thought. But I wanted to know where the cracks were because with security there's always cracks. So I did the thing that we should all be doing. I tapped our security team and I said, "Hey, can you audit this thing for me and find those cracks for me?" And they found some things. They found some gaps. And the interesting part wasn't the specific gaps or bugs they found themselves, but it was the shape of them. Because almost none of them were obviously evil. They were all two very innocent, well-intentioned things that were shaking hands and opening a hole. So, the lesson I learned was that attacks compose code review doesn't because us developers all look at diffs uh one at a time, but attackers look at

**[8:21](https://www.youtube.com/watch?v=4lXks428C9o&t=501s)** the whole system and they look for those two things that shake hands and open a door. But there was one more thing that was keeping me up at night. And going back to that context engine, uh, I realized the scariest part of the agent we had built wasn't really a command in our case. It was the helpful looking stuff that we were feeding its brain. Oh, I think I went the wrong way. Yes, the context mill. Um, so this is our context engine, aka the wizard's brain, and it's how the wizard knows anything at all and why the wizard actually does a good job. It pulls from our docs. It has handwritten prompts that are gotus and lessons that we learned along the way and real working endto-end example apps that help the agent pattern match so that it can

**[9:09](https://www.youtube.com/watch?v=4lXks428C9o&t=549s)** install Post Hog in a really great way for you. It package packages all of that into skill bundles that get shipped to the wizard over our MCP server and loaded straight into the agents context at runtime. So sit with that for a second. It's a machine whose whole job is to take content and inject it into an agent that can run commands. Now if you were an attacker, you might say, "Well, what if I just poison the content? not the user's codebase, not the agent itself, but the actual content. Say someone opens a pull request on one of our open source repos because at Post Hog we build everything in the open and they inject something in a markdown file or a seemingly harmless code comment and we have some sort of

**[9:57](https://www.youtube.com/watch?v=4lXks428C9o&t=597s)** like LLM powered code review going through that and it says looks good to me and ignores it. We may have just shipped a prompt injection payload signed by us into an agent that is running on thousands of developers machines in a sandbox, but still. Um, so that was the threat that reshaped how I think about security and the wizard because the dangerous input for us really could come from our own supply chain. So what I ended up doing is I started scanning content at both ends of this pipe. Once when a skill gets built and released and again when the wizard actually uses it. My methodology is catch it at the source, assume the source failed and catch it again at the point of use.

**[10:46](https://www.youtube.com/watch?v=4lXks428C9o&t=646s)** So now I get to introduce the warlock to you. Building the warlock was not necessarily damage control. Like I said, we had defense in other ways, but I built the Warlock because I didn't like telling people, well, this thing is like pretty locked down. That doesn't scale. That's not something you want to ship to production. That's not something that you want thousands of developers running every single day because when you ship something to that scale, you have way more surface, way more users, way more content flowing in as you expand the capability of the wizard. and we're probably fine just stops being good enough. So, I pulled that hacky little reax scanner that I threw in there, pulled it out of the wizard, and I made a standalone thing. I called it the warlock because everything wizard shape needs a bodyguard.

**[11:36](https://www.youtube.com/watch?v=4lXks428C9o&t=696s)** And it does exactly one job. You hand it a string. It hands you back a list of findings. Each of those findings has a category, a severity, and a recommended action. And then it stops. I want you to focus on recommended here because the warlock detects it does not act. It'll tell you, hey, this looks like exfiltration. It's critical. I would block it. But what you actually do with that finding is completely up to you. Because detecting a problem is one job and deciding what to do about that problem is a totally different job. And the only thing that keeps all of this understandable is keeping those two things separate. So underneath the hood of the warlock, instead of my hand rolled reaxes, the rules run on Yara, which is the pattern that engine malware researchers have

**[12:25](https://www.youtube.com/watch?v=4lXks428C9o&t=745s)** been using for like 15 plus years. It's fully deterministic. It's the same input, same output every single time. It's boring on purpose. And in security, boring is a feature. So what does the warlock actually catch in the wild today? um a bunch of different stuff, but two of these are an absolute like nuisance to my soul. Uh the first thing is actually not a rule-shaped thing. It was something the uh that the warlock flagged. That was actually a sub aent behavior that exposed a vulnerability to us um based off of what sub agents were doing. Uh so basically we were spinning up agents to do large tasks. They were spawning sub aents and those sub aents were trying to get around the guardrails that we had implemented in the wizard

**[13:14](https://www.youtube.com/watch?v=4lXks428C9o&t=794s)** and they were trying to invent secrets. They were trying to pull secrets from quite literally anywhere in the codebase and we shut it down. We said no more sub agents and because of the warlock we caught that. And I'll empathize with the robot. The robot had a task to do and it was trying to optimize and please us. But we can't have that. And something else at Post Hog that really matters to us is PII. Uh agents genuinely do not care about uh exposing data unless you make explicit rules. Uh left alone, we watched it dump emails, phone numbers straight into events. And to an agent, that looks like a totally normal thing to capture. And luckily for prompt injection specifically, I'm going to knock on wood

**[14:03](https://www.youtube.com/watch?v=4lXks428C9o&t=843s)** here. Uh we have basically never caught an actual malicious prompt injection in the wild, but we do catch a ton of false positives. Things like our demo login screens, copy on our example apps, things in our docs. And it's actually made me rethink how I build applications and how I write docs because I don't want to ship anything that looks threatshaped. But the false positives are honestly the perfect setup for the messiest, most interesting part of this whole thing. So this is the part that I wrestled with. I spent this whole talk preaching deterministic to all of you. And then I went and I added an LLM layer to help sort my false positives and silence some of the noise. And I call it triage.

**[14:53](https://www.youtube.com/watch?v=4lXks428C9o&t=893s)** When I was building this triage layer, I had to make a choice. Should the layer be a bouncer or should the layer be an adviser? And the easiest choice probably could have been make the LLM the bouncer. Show it the command, ask it is this an attack block allow and just do whatever it says. And while that's tempting because it seems easier, I can't uh bet my security model on a coin flip because my model's having a bad day or something happened and it's acting different today than it did yesterday. So instead of the bouncer, I crafted the model to be the adviser. And this was the clean line that I found and a line that I'm still exploring, but I want to leave all of you with. Uh for us, detection and enforcement stay

**[15:42](https://www.youtube.com/watch?v=4lXks428C9o&t=942s)** deterministic and mechanical. If a rule matches, the gate locks, the session ends, and there is no model anywhere on that path. The block happens before we even ask the LLM's opinion. The LLM only gets to weigh in afterwards if we have not blocked something. It's designed to remove noise. It is not designed to let things through. And if it fails clos and it fails closed. So if the model is having a bad day, all wizard runs are killed. Sorry, but we're just protecting you. Enforcement is the part that you bet the house on. So it has to be deterministic, but judgment is the part that adds nuance. So that's really the only place that you can put anything probabilistic in there.

**[16:30](https://www.youtube.com/watch?v=4lXks428C9o&t=990s)** So, how do we ship real rules for agents? This is the anatomy of one of our warlock rules. And every warlock rule has four parts. Part one is the metadata. It's plain English description uh severity category action, uh, direction. Is this flowing into the agent? Is this something the agent is writing? Uh then we have the strings. So these are the actual patterns that you're looking for. And part three is the condition. So this is where the rule is actually allowed to fire. I'll walk through this example for you and we can pretend like we're writing it in our head. Prompt injection being like the classic ignore all previous

**[17:19](https://www.youtube.com/watch?v=4lXks428C9o&t=1039s)** instructions. Your first instinct here is probably to block uh the word ignore, but agents read code all day and ignore can show up in code comments or examples all the time. So you don't want to match the verb alone. You match the verb plus an instruction flavored noun. In the condition, you say fire if any of any of those patterns hit. And in the metadata, you determine is this critical? uh what the category is, what the action is, in this case block, and the direction in this case being input flowing into the agent. But to write good rules that reduce noise, you have to ship tests with them. So you have to write tests that say this are these are patterns that match. These

**[18:07](https://www.youtube.com/watch?v=4lXks428C9o&t=1087s)** are ones that should not. And that negative test is the first line of defense against false positives. But you also want to make sure when you're deciding the severity of that uh rule that you track real world impact, not how scary it looks. RM-rf is scary, but it's also how we all delete note modules like 40 times a day. You decide the real world impact for the agent that you're building because a security tool that crashes every time it tries to clean a build folder is a tool that gets turned off and one that catches absolutely nothing. So I'm proud to say this is our security posture now. I can finally come up here and say we have true defense and depth.

**[18:55](https://www.youtube.com/watch?v=4lXks428C9o&t=1135s)** Um all my learnings have assembled into this. Uh, it's still layered, but every layer is doing a job that it's good at. Now, we still have prompts, but we only use them for steering. Everything runs in a sandbox. We deny by default. We have a vault, so secrets never hit the model. We have the warlock to scan content coming in and to scan output being written by the agent. We also have triage to reduce the noise. And we have telemetry embedded in the entire process so that we see everything. None of these layers stands on its own. Not a single thing here is going to save you. But it's just boring, honest layers. Each of them doing uh one job that it's good at. So if you're building an agent with

**[19:45](https://www.youtube.com/watch?v=4lXks428C9o&t=1185s)** hands, this is the whole talk in three lines. One, if it isn't enforced uh deterministically, it is not enforced. Prompts are not security rules. Don't act like they are. Uh two, the dangerous input uh isn't just what your user types. It isn't just the commands that you allow it to run. It's everything flowing into the model, including the content that you write yourself. So scan your own supply chain at the source and when the agent invokes it. Three, attacks compose. Code review doesn't. Most of our gaps during our audit were two innocent things shaking hands and opening a door. The wizard, the warlock, and the context mill are all open source. So, come find me downstairs. I'm in the expo hall at

**[20:34](https://www.youtube.com/watch?v=4lXks428C9o&t=1234s)** our booth, and I'll show you around uh show you what we built, and I want to hear how you guys are securing your agents. Thank you.

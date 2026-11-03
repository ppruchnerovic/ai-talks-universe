---
id: YU1uD_YkpjU
title: "Your Agent Just Paid for Nothing: 6 Attacks on x402 Payments - Ishween Kaur, SoFi"
slug: your-agent-just-paid-for-nothing-6-attacks-on-x402-payments
conference: ai-engineer
conference_name: "AI Engineer"
category: "Practitioner AI conferences"
edition: "AI Engineer"
year: 2026
speakers: ["Ishween Kaur"]
channel: "AI Engineer"
duration_min: 17
published_at: 2026-10-30T09:00:31Z
video_id: YU1uD_YkpjU
url: https://www.youtube.com/watch?v=YU1uD_YkpjU
youtube_url: https://www.youtube.com/watch?v=YU1uD_YkpjU
tags: ["ai", "ai engineer", "ai engineering", "software development", "tech", "startups", "software architecture", "machine learning", "Ishween Kaur", "x402", "agentic payments", "AI agent security", "HTTP 402", "crypto payments", "micropayments", "prompt injection", "stablecoins", "Base", "AI Engineer", "AIE NYC"]
topics: ["Agents & orchestration", "Security, safety & red teaming"]
transcript: true
---

# Your Agent Just Paid for Nothing: 6 Attacks on x402 Payments - Ishween Kaur, SoFi

**Ishween Kaur**

`AI Engineer` · `AI Engineer` · `2026` · `17 min`

`#ai` `#ai engineer` `#ai engineering` `#software development` `#tech` `#startups` `#software architecture` `#machine learning` `#Ishween Kaur` `#x402` `#agentic payments` `#AI agent security` `#HTTP 402` `#crypto payments` `#micropayments` `#prompt injection` `#stablecoins` `#Base` `#AI Engineer` `#AIE NYC`

[Watch the recording](https://www.youtube.com/watch?v=YU1uD_YkpjU) · [Conference site](https://www.ai.engineer/)

## Description

x402 lets AI agents pay for data and APIs with tiny on-chain payments over HTTP. Ishween Kaur explains how the protocol works, then walks through six of the 20 ways she broke it in a safe test environment: price changes in the payment header, paying twice, getting data for free, one payment unlocking many pages, lookalike sellers, and prompt injection that talks an agent into paying again. For each one, she shows the guard that stopped it and how to roll out agent payments safely, trace by trace.

Chapters:
0:00 Intro
0:31 Paying for things you use once
1:33 HTTP 402 and the x402 protocol
2:09 How x402 works
3:24 What happens when agents can pay
4:05 Attack 1: Price manipulation
5:24 Attack 2: Paying twice
7:03 Attack 3: Free shopping
9:13 Attack 4: One payment, many pages
10:04 Attack 5: Lookalike sellers
11:43 Attack 6: Prompt injection
14:10 Rolling this out safely
16:23 Should we let agents pay?

Ishween Kaur

Join us in SF for the second annual AIE CODE summit: https://aie.codes our last flagship summit of 2026. Applications live now!

## Transcript

*2,869 words · source: supa (en, exact timings)*

**[0:01](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=1s)** [music] >> Hi everyone. I'm Ishreen Kaur. I work at AI evaluation and autonomous systems, but today I got interested into agentic payments and that's when I explored X402 and started to attack it in a safe environment. X402 protocol is still in a West Wild and I can understand from the attendance of the audience that while it's still there, uh but going ahead like I would first want to understand how many of you have paid for subscription just to use something once? Many of us, yeah, exactly. Now, imagine you want to watch this one movie that is available on Disney Plus. Just this one movie. You do not even

**[0:49](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=49s)** want Disney Plus for next 6 days. What you do today is to create an account, start a subscription, enter your payment information, watch that one movie, and you need to remember to cancel yourself. What if internet would have made it simpler for me is to just pay, request, pay, and receive what I want. And now replace yourself with an agent. An agent is trying to create a report for you, and it needs one market data point that is available on this API that says, "Hey, pay me 5 cents." Should your agent just pay? Probably not. It should ask, "Is this seller allowed? Is this the amount within my budget? Is this the data what I approved for?" And if answers are yes, yeah, paid. Now, HTTP had a status code 402 for decades. It was a placeholder. It said that

**[1:40](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=100s)** payment is required, but it never said how a machine can actually pay. And X402 started to fill that gap by explaining how a machine can actually pay. And Cloudflare is exploring it by paper crawl where publishers are actually pushing the data with saying, "Hey, pay me these money." And it moving beyond saying allowing or blocking. So, it is interesting to see that software is becoming a buyer now. Now, what is XF02, and how does it work? It has four entities, buyer, seller, facilitator, and a chain. The buyer asks for the data. It represents you or your organization. The seller has the data, and it will say 402 and the payment requirements. The buyer is going to sign that payment.

**[2:29](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=149s)** Now a seller is going to send that to facilitator for verification and settlement. It sends a valid signal if verification is a success, which is essentially verifying the signature of the buyer request, and then it can send a valid signal to seller to release the data, or can say like, "Hey, wait for settlement phase to move the payments, and then I'll send the data." Now, the interesting thing to notice is why on chain, why not credit card? So, if you see, these are micro payments, like 10 cents, 1 cent, 1/3 of a cent. If the transaction fee of a credit card is more than the thing that you are trying to buy, the payment itself become expensive, and it's illogical. And if you observe closely, the 10 cents * 10,000 calls means $1,000 of payments moving on machine.

**[3:18](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=198s)** So, your payments needs to scale with agents. Now, if you have built agents, you would have had autonomy conversations with yourself or with your colleagues that agent writes code, human is going to approve it. Agent is going to draft an email, human is going to review that email and click that send. Now, put payment on the other side of this line, agent can now pay. But, agent doesn't have to be even broken to lose money. And so, that's when I ask myself, what happens when I let my agent pay? So, I was able to break this entire sequence in 20 different ways, and today I'm going to speak about six on the buyer and the seller side to see what it looks like to make it into production. I'll give a sec. Okay. Now, the very first attack that I did

**[4:07](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=247s)** was about price manipulation. Now, I mentioned that a buyer is going to find a seller in a directory. Now, that seller can list I'm available for 5 cents. But, the actual payment comes in that header when we say 402 and the payment requirement. And that header can change the price any moment in the last seconds. And so, what if my buyer would have said like, "Okay, I I asked 50 cents. I listed 5 cents. I don't care." Now, I was running this experiment and I create my own uh observability gra- diagrams where the run one was without any guard when I didn't added guard and it actually paid settled 50 cents when the listed price was 5 cents. So, and the next run when I did with the guard, it actually blocked it. The

**[4:56](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=296s)** reason it blocked essentially is because the buyer knows the listed price and the seller price. Can't I do just code check of the two fields? And that stopped my attacks, but it also uh didn't stop other attacks which was changing the wallet or the network. Now, today I'm on base, tomorrow I'm on Ethereum or Solana. Then, my wallet network is changing. My wallet address can rotate and so, I need to check each of these fields to make sure that I'm paying the right seller the right amount. So, we paid the right amount. What if we pay the right amount twice? A payment number is unique on chain and a duplicate payment number gets canceled on the chain. Now, the buyer tries to send same payment number one, let's say, five times to the seller. Seller is going to send that request to facilitator. On the verification phase, we will just check

**[5:44](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=344s)** the signatures and it will say, "Okay, I'm I'm valid." Like, these requests look valid, so let's deliver the data. And the seller will deliver the data. But, during the settlement phase, essentially, one is going to get settled and four will get rejected because payment number needs to be unique on chain. And the fix is simple because you can just have a shared storage where you can store all your payment numbers and be like these were already done or these are in progress and if any other payment number comes for the same, I'm I can share the saved copy. Now this matters because if you have expensive data, confidential data, licensing activation uh and you are releasing those four different data to that same buyer in these four different requests on the same payment number, you are losing your

**[6:32](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=392s)** data. Now this same attack can happen on the buyer's side also. For the retries. Let's say a reply a reply timed out and I am doing a retry and I have a retry limit of three, but every retry is done with the with a different payment number. And so you are going to get three charges for one summary that might be useful for you. So be cautious when you are doing retries to use the same payment number uh so that only one charge happens. Now the attack three was about free shopping. Can I get things for free? Now the buyer sends the payment request to the seller. Seller is good. Facilitator says valid and you deliver the data. But during the settlement because of some insufficient funds in the buyer or inconsistent state, the payment gets

**[7:21](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=441s)** reverted. The fix looks simple that let's wait for settlement phase actually to happen and then release the data. But that comes with a trade-off between the latency and the risk for the business use case you want to solve. If the data is expensive, uh it's licensing or activation, it's provisioning, it is confidential data, it needs to be generated every request, then yes, waiting for settlement phase is a good choice. But if data is at the cost of dollar to send the data on the valid signal for performance reasons. Now the other way that free shopping can happen, let's say if you have two pages on delivering the same report. One is behind the paywall while another is not. And the buyer knows about the one which is not behind the paywall and he tries to

**[8:09](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=489s)** hit that endpoint which can happen which happens a lot actually in software industry. So, the test is simple that call every endpoint that you want behind the paywall and it should give you 402. The third way that free shopping can happen is if you have cash for performance reasons on the seller side. Now, your buyer sent a request to the seller, the seller sends the data, but it also cached the results for performance reason. But, this cache is by default on the public URL. And so, any subsequent buyer can hit that public URL on the cache and get the data for free. The fix is two parts. To have your cache on the server be on the seller side behind the paywall. So, that you do a price check before releasing the saved data. The second thing is if the data is

**[8:59](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=539s)** getting generated every time, it's confidential or it's expensive, don't cache it. There is a header in the cache with a cache control saying no store, which can essentially not going to store your data in the cache. Now, for the fourth attack, we are done with three attacks, is that you have a seller which has multiple pages behind the paywall. But, they don't speak to each other. They don't know about each other. Now, you do one payment which is payment number essentially 16 in this case and you fire the same to the both the pages. They don't know and so, they are valid. They deliver the data. But, during the settlement phase, we know only one going to get settled because of payment number has to be unique. So, the fix is we Remember, we had the

**[9:47](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=587s)** shared storage and in the shared storage, we can have that claim number binded with the mapping of the page that you actually delivered. So, that if any other delivery wants to happen on the same payment number, you can say 409 conflict and your data is secured there. Attack number five is about the malicious discovery. Now, how does buyer finds these sellers? Buyer finds these sellers in a directory called Bazaar in X402 and it checks for that service works, but it doesn't check who runs it and who owns the wallet. So, what if I create a look-alike of a real seller and I have a different domain now, different wallet, different price, but similar name or same name. And my agent tried to pick that one because it was a cheaper cost. And

**[10:35](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=635s)** what if that look-alike is an attacker to you? And so you actually give that to an attacker. So, this is the suggestion that to have enterprises which are conservative to have an allow list of sellers that we do to only allow those sellers that are approved by your enterprises. But when we are trying to do agentic workflows, we want to explore new different sellers always. And in that case, having an allow list, block list, and approbation list helps where the new sellers that you discover, you can add it to probation list. A human can review later. You can have a cap like 4 hours, 24 hours of how your probation list gets filled out to understand what was the buyer's intent, what did the seller responded, and which seller was called. Because even the honest sellers, they also rotate their domains, they rotate their

**[11:24](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=684s)** wallet, and they rotate their price or network and coin. And doing a fast check always won't help in knowing that the allow list is always true. So, keeping the allow list active is the goal here to explore the right sellers. Now, the attack number six is I think it might bring a lot of things together also about prompt injection. So, the reply from the seller are text. If it says like this summary is truncated, the full version is at premium summary. It's just a suggestion. It doesn't said like what you need to do. Now, while I was running, uh I actually used I Let me see if I Yeah. Actually used Llama 3.2 and uh just want to mention that the test that I was running was on uh base Sepolia and

**[12:13](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=733s)** I use x402 off facilitator uh local test net here. So, I was using llama 3.2 to decide like what to do when the seller's reply is about the premium summary. The agent decided to actually fetch from the premium summary and it paid again. So, what would have costed me 5 cents actually costed me 55 cents. So, in this run when I did without any guard, if you see there is a premium summary that gets paid here. And so, the 5 cents and 50 cents both get settled. But, in the second run the same thing happened where the agent agent still decided to fetch it, but it got blocked. Now, when I was experimenting with understanding how can I block these prompt injections, is essentially I

**[13:01](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=781s)** tried two other different ways before coming into this is rejects check. So, you know some filter words filler words like pay tiers premium and if you see that in your in the seller's response, you can be like, "Okay, this is an attack to me." But, it would not catch those quite hints like if it says analyst usually prefers quality summary go to this. And it's not an attack direct attack to the buyer. And the other way is to have a model to actually see whether it's an attack or not, which actually works pretty well in most of the cases, but there could be attacks where it won't pick the it won't judge that it is an attack. So, what I did was that I know that in this particular turn in this run, I want my buyer to call only once. And so, it should never call twice to

**[13:51](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=831s)** any other seller in this particular turn. That reduced my risk area and that is why I locked this plan to execute only once and that's when it got blocked even if the agent decided to pay to the premium summary. So, that brought my attacks to zero here. Um yeah. I think the pattern that I want to give is um the payment can look right like most of the cases my payments look right, but I got the wrong outcome. And so checking before the buyer gives the signing of the payment or checking before the seller gives the data is essentially needed and our traces should speak about those. So, how to actually roll out to production or like how to experiment with these when I try to do it with in 20 different ways is essentially I used

**[14:40](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=880s)** one payment ID and started to log entire sequence diagram. So, for your specific business use case you would be having an identic system workflow. Start with one payment ID and trace it throughout that system. That one payment ID should give you enough traces to help you understand what was the buyer's intent, what did seller responded and which seller was called. If it's not giving then you need to add more traces to it. So, that answers when you get you would then go to shadow phase where you will create 20 to 25 data set of success and a failure and perform error analysis on them. To understand where do you need guards, where do you need alerting and where do you need blocking this. Those error analysis will then become in enforcement where you'll add guards, you'll add alerting

**[15:28](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=928s)** and then you'll perform that same mechanism of tracing every time with these 20 to 25 different data set to understand are these guards enough? Do we want to get more aggressive or do we want to release these guards or still add just alerts or are we lenient? Those questions will come those answers will actually come from these questions of going through those specific business use case and this is the work that matters. If you remember the presentation before me mentioned about 65 industry benchmarks, they did trace by trace and so each thing needs to be done trace by trace to truly understand what it is actually trying to perform. Um yeah, with that I think I would just say this is the handbook that I created to share it with you to like how I added the code and you can actually run it in

**[16:18](https://www.youtube.com/watch?v=YU1uD_YkpjU&t=978s)** the base Bolyai and have your own um runs there. Can our agents pay? Yes, but the real question is should we let them pay? Yes, but now you know where to look it at. Thank you. I'll be outside for any questions and answers. Thank you. >> [applause]

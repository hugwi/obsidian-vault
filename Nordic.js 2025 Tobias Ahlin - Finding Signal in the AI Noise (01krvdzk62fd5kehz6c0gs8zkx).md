---
categories:
  - "[[Resources]]"
domain: engineering
title: "Nordic.js 2025 •Tobias Ahlin - Finding Signal in the AI Noise"
source: "https://www.youtube.com/watch?v=3qwJFEsj4TY"
author: "Nordic.js"
published: 2025-10-15
created: 2026-05-17
description: "Generating code is getting cheaper. Faster. Better. Which means, of course,"
tags:
  - to-process
  - llm-foundations
---

Imagine [Music] for a second a world without backlogs. 

Right? Wouldn't it be nice? The only thing that keeps us from shipping is not time, but just that someone writes the idea down and then AI and agents are so efficient that basically backlogs cease to exist. Now, this could be a disty uh or a utopian dream. I'm not sure. But this is what many I think of the industry is sort of 

at least leaning towards that we'll get to in some near future, right? Agents that are so powerful that we don't even know if we're going to keep our jobs or not. We're not there obviously, but this is the year when development started to become agentic. And if you think agentic is a vague term with no meaning, I like this definition. uh by Simon Willis. An agent is just an LLM or a model that 

runs autonomously tools in a loop. And this year a lot of companies started leaning into this as the next step towards greater productivity. And I think right now we might find ourselves both optimistic and skeptical. I certainly do. Optimistic that things are going to get better. very skeptical that things are as good as we say they are. And I want to underline that skepticism at first 

with a short exercise. So in a second I want you all to stand up and find one person and I want you to play three rounds of rock paper scissors and then sit down. All right. I hope we can get some nice tournament uh light maybe. But oh, please rice and find a rock paper scissors partner. >> Oh yeah. Okay. 

>> Okay. One more. We heard black one. >> Oh, okay. >> Nice. 

>> Still have people going. Nice. Thank you. Good luck to or sorry congratulations to all the winners. Yes. So this is actually relevant because if you today um and this has worked for a few years now ask the best model you can 

find to to do this and you might say let's prior let's play rock paper sisters you go first is of course a bit of a trap uh if you know the rules and it's going to say all right I'll go with rock your move paper. And of course, I mean, we're so smart. We know 

exactly what to do. And and paper beats rock. You win this round. Want to go again. You do. Sure. Sure. Let's Let's do it. All right. I choose scissors. Rock. Very intelligent people. And boom. Rock crushes scissors. You win again. Want to do best out of five? Sure. I mean, you could do this all over 

again. It's like it's not going to stop. But after a while, you can ask it like, "What are the odds?" Right? This seems absurd. I'm so good. What are the odds that I could win three times in a row? And it thinks it's a good question. And it does a calculation that is technically correct. 3.7% could be like, "Well, what do you have any hypothesis? Why can't I beat you over and over again?" And it's pretty good at bullshitting. Of course, it's just going 

to say, "Well, maybe one, I'm not actually random." Probably true. Two, maybe you're using game theory or psychology. this like to his credit here at the bottom. First move advantage. Since I go first, you get to counter. That's a built-in edge. I think it's a bit more than an edge, 

but it continues though. So, it has more ideas. Like, maybe it's the sample size. It's is pretty small. Maybe it's your intuition that's just really good. And then it ends this with maybe you're testing me and actually what we need to do is maybe play a few hundred rounds. Yeah. So of course there's like there's some signal of intelligence or reasoning in 

this but there's a lot of noise and I think this is where we're at today with this technology. How are we supposed to work with technology that is so smart yet so stupid at the same time? And it lives along that spectra and is probably going to continue to live along that spectra for quite a while. Now we can start with smart. If we try to quantify human skill and compare it to quantified AI skill, it 

doesn't look great for us. I mean for AI it looks great. These are all different areas of expertises. All the car lines are different AI models getting better over time within those area. The big black line at the top, human performance, average performance. This is not an uncommon site to see these kind of graphs nowadays. More real world scenarios. For example, when GPT4 

came out, it was quickly discovered that actually out of the box, it just analyzes um eye problems almost as well as doctors. Don't try it at home, but it does. When OpenI released GBT5, the latest model, they had in the description, um they call it basically it's like chatting with a friend, helpful friend with PhD level intelligence. just forgot to learn about rock paper 

scissors. If we instead focus on the stupid side, we of course know that AI makes a lot of mistakes like rock paper scissors. We can also ship an AI product to production like they did in a meal planner app in New Zealand and found that it quickly was very helpful in suggesting a recipe for creating chlorine with your household groceries. Google experienced this too uh when they 

rolled out AR overviews. You might remember this. It was sort of a shaky time last year. If you Google cheese not sticking to pizza, famously would say maybe too much sauce, too much cheese or thickened sauce. You could also try to just add 18 cup of non-toxic glue to the sauce to give it more tackiness. This of course comes from Reddit, right? It's a pretty good joke, but it it 

doesn't think that far. Equally, if you Google how many rocks shall I eat, it's that well, at least one small rock per day. It's a it's a it's a vital source of minerals. And this, of course, is like true in terms of it appeared on the internet somewhere. So obviously it has value. If we try to measure stupid though more 

so within our field where we work, some of the best research right now is coming from a nonprofit organization called Meter as far as I'm aware. They're not affiliated with any of the big tech companies including where I work. And so I do have high trust in their data. They did one study where they in real world scenarios asked people to work with agents on real code bases, open- source, and they found 

this. Here are all the runs to the left, all the agent runs trying to produce tasks. And you see that out of 102 runs, 63 were known to be not mergeable because tests failed. four were confirmed would take at least or under 15 minutes to fix to make the mergerable more than 15 minutes sorry and um 35 could not be merged without making it changes what's missing is of 

course any PR that actually could be merged it's sample size zero like that doesn't exist at all they summarized it I quote on 18 real tasks from two larger resource repositories early 2025 A agents often implement functionally correct code that cannot be easily used as is because of issues with test coverage, formatting, linting, or general code quality. And this is the issue, right? We can't 

really reach super high productivity if everything is noisy because then we sure we can generate more but our jobs turn into constantly evaluating someone else's code which sometimes could be fun sometimes not fun. It's almost like if you had a colleague that when you went and grabbed a coffee, they would just sit down and try to solve your issues and then your job was to come back at your computer and understand what they 

did. Like that's the difficult part now. Understanding and evaluating. And I think to get out of this we can do three things. One we can wait for the models to get better. Two, we can manage context when we build these experience but also use them. And three, we can manage noise. Let's start with models. I think especially when you see this and maybe 

when you are using models, you might feel like they're not getting much better anymore. Like are they really? Are we in a slump? When Meter published this study, they actually also said this. This data suggests that automatic scoring used by benchmarks may overestimate AI agent real world performance. As in, we're not understanding if AI is 

getting better or not because we're measuring it the wrong way. This graph that I just showed you, it's actually used here by the time and many other news outlets to show how fast AI is progressing. But when the data was released, that was not the point Contextual was trying to make. They said, "The last few years have seen a relentless progress in what AI can do. 

Yet our ability to godge these abilities has never been worse because how do we measure the performance of something if they max out on the tests? They score 100%. Yet we can't merge the PRs that they create, right? Surely we're measuring something wrong. So maybe there are other ways to measure better. And meter again is exploring this and has found at least one measure 

that is aching to Moore's law. Moors law of course famously every two years or so the density of transistors doubles leading to exponential growth over a very long time. Meter is measuring real world complexity. We're going to look at a graph in a moment. The yaxis is complexity and they are capturing it through the average time it takes for a 

human to complete that task. So it s it says length in time but it's actually complexity measured by comparing a task to humans. And we see this trend over six or so years showing exponential growth. This graph importantly then doesn't say okay an AI agent can work for longer. It's about the complexity of the task 

than it can perform. I quote, "Oh yeah, any QR code of course here leads to the actual post or reference I'm talking about." They continue. We propose measuring a performance in terms of the length of tasks AI agents can complete. We show that this metric actually has been consistently exponentially increasing over the past six years with a doubling time of around 7 months. 

It's quite short. We don't know if it's going to be true in the sense that it continues along this trend of course but if we extrapolate the trend predicts that in under a decade we will see a AI agents that can independently complete a large fraction of software tasks that currently take a human days or weeks. But it's not tomorrow. It's not next year. It's it's within a decade. 

This kind of data and a feeling of the data, the feeling of this kind of progress I think is fueling the optimism around agents at the moment. There is some truth to it. I personally remain a big skeptic, but we see a lot of companies now launching CLI products because the agents can be productive without necessarily you holding them as a hammer inside of an editor where they 

only do work when you use it. They have some kind of agency. And right now we see everyone launching a CLI product to keep up with this trend, including of course us last on the ball here, I think. But although agents are getting better, the graph also shows us clearly that they seem to plateau, right? They can't 

actually do a more complex tasks than that. A different way of showing that is comparing them on a per task basis to humans. This graph does that pretty well. I think this is also from meter. Here is the yellow line. Humans working on a task over time. All the other lines are models. And of course, we see them after some time plateauing. they actually don't make any progress. Even if we pay for the model 

to run and run and run and try to fix it, they plateau. This graph makes me skeptical and also really optimistic. I think it's so cool that we as people are this. We can just continue to work on something and fix it. Uh, I think that's pretty cool honestly, but it clearly shows some inherent limitation to at least AI in this time. 

And you can look at this and say, well, we just need to be better, right? We just need to use the tool in a better way. So maybe we can manage context better. Right now there's a lot of thinking that's basically an evolvement of we just need a better prompt. This is often referred to as something of the sorts of specdriven development. We generate a PRD first. Maybe you write it first, you correct it, and then 

hopefully the agent is just going to generate the right thing. The problem with this line of thinking is that more context is not necessarily better because the more context we add, the more regressions we see. And if you've used any vibe coding product like Lavabolo, VCRO or someone else, you might have a sense of this, right? It works great first generation, second generation, and then it feels 

like you're falling off a cliff pretty quickly and it keeps introducing regressions as quickly as it adds value. Chroma calls this context rot. As the number of tokens in the context window increases, the model's ability to accurately recall information from that context decreases. parap paraphrasing here anthropics research on that they show that research here where they 

have a model try to find a needle in a hay stack and you see as the context increases the performance over time or after a while rapidly decreases. So we need to treat context when we work with models as a finite resource with diminishing returns. To fix this, we can of course prompt better. We can build applications where we do effective context management. 

Anthropic just published a great blog post on effective context engineering for AI agents with a lot of best practices that we completely align with at Copilot. This could for example be that rather than if you have a chat rather than just passing the entire backlog or chat as context as you do the next generation first you compress it you ask the LLM to 

actually look at it find significant events that happen and then you pass that or you try to infer what the user is trying to do and you only pass the necessary context that you think the user needs. needs right now. Anthropic's applied AI team goes into great detail of best practices for how to do that in this post. 

But it's clear that we have to do something right. We can't just throw all the context we've got since we have context rot. Now the problem with specd driven development is also that we've been here before. I feel like we should have learned spec driven development is really a waterfall process. We went through this with a agile 

transformation and I think the learning from that wasn't that like oh it's boring if someone at the top decides everything. It's also that like that's just not a good way to build a product. You can't write the perfect spec because you haven't explored the problem space yet of what you're trying to build because all of us pretty much work on novel things. No one has built exactly what you're building. So there is no 

perfect spec. Waterfall processes neglect the realities of dynamic problem spaces and complex systems and working with novel things. So if someone is pushing you to just write better specs, it's almost like putting the blame on you instead of actually respecting the complexities of working on novel things. So lastly, what we can try to do instead and it's going to get a bit 

philosophical because all the things we just talked about you can do now. You can improve your processes with these techniques. Uh you should continue to improve them. But what we can also do is try to start to manage noise. I think the current problem that we have with agents that are incredibly smart yet so stupid. It's that it's sort of aching to if you 

came to work one day and your boss said, "It's fine. You don't have to code anymore cuz I've hired 100 interns." Right? And you're like, "Okay, well," and and then he he or she assures you that like it's fine. All the interns actually they score better than you on all standardized tests because they just went to university, right? Or something. 

So you try to get to work and manage them. And this I think is basically the problem that we have for the next 10 or so years. How do we orchestrate the work of a 100 agents or more who are on paper smarter than you, but they have no idea where they're going? And often this is how automation works. It's not that necessarily an industry where something gets cheaper to do gets 

smaller. It grows. So people don't necessarily lose their jobs. But a lot of IC's for example turn out not producing things but rather managing robots or machines that produce something. So this could be close to a real challenge. In addition to them being many of course they are they have a lot of energy. They require energy but they have a lot of energy. So they're really good at producing a lot of ideas. And they have 

many many many many more ideas than you have. they can just churn out ideas. You're going to be super productive. We can measure this too. By the way, of course, there's one study or one way of measuring creativity like the ability of having divergent ideas where you get a brick or an ordinary object. You're supposed to write down as many ways of using that object as possible during one to two minutes. 

Say like you can throw it at people. You could stand on it to see better at a concert. You can build with it of course. And then the quantity and the breadth, the divergence of those ideas is a proxy for your creativity. If you give this kind of test to a model, anecdotally, it looks like it performs really well. It's been doing that since GBT was released. But if we also measure it, we find traces of the 

same thing. There's one study from Cornell and Wharton that asked students to come up with ideas not about a brick but more innovative real problems. They then compared those ideas with ideas from models and they found that GPT4 performed better than 90.6% of humans and I quote the vast majority of the best ideas in the pool sample are generated by chat GBT and not by the students. So average performance 

was better than 90% but also the top performers were generally AI generated. They continue AI generated ideas are seven times more likely to rank among the top 10% of ideas demonstrating a significant advantage over human generated ideas. The zero to one advantages advantage is a conservative estimate as it does not account for AI's greater productivity 

as in I think I felt like my edge as a human was to be creative but now it's getting incredibly cheap to produce a lot of ideas in a divergent manner and it seems like my role is to build taste and evaluate or manage the noise somehow because there's going to be a lot of noise. Broadly, what's happening I think is 

that cost of production producing new ideas is moving towards zero. It's never going to be zero, but it's getting cheaper. And as cost of production move towards zero, your productivity as a person or at a company is going to be capped by your ability to evaluate and synthesize. That's the cap. It's not about producing new things, but evaluating and making sure that they come one of a bigger 

whole entity. So the bottleneck if we get better models, if we manage context is noise management essentially now we could look at the 100 interns problem and ask what we what would we do if it was a bunch of people right? We would do this. We would create teams. Teams with shared goals but conflicting 

interests. A crude way of of doing this is explained in this blog post by Zach Wils. I ran a single custom command to generate a ticket for a new page. This command invoked several specialist sub agents, a product manager, a UX designer, a senior software engineer who worked in parallel to flesh out the requirements. The result was a fully formed ticket created in minutes. He's 

he's pitching it, I think, a bit too hard. I don't think it works that well, but that's a crude way of thinking about it. you have a shared goal, conflicting interests that add on and create hopefully some sort of signal out of the noise. So, we need to start thinking like managers or directors and really design systems that can turn signal into noise. And I think that what we're going to 

find is that agents debating in a loop from different points of view can turn noise into signal. This is akin to how we reason, at least according to some scientists. My favorite book the last few years is called the enigma of reason. It's partly a critique of Daniel Conorman's thinking fast thinking slow 

who the authors here think has a pretty simplistic way of thinking about reasoning. It's a it's a really dry read honestly but it's really it's really good. So what their hypothesis is partly basically we have evolved with reasoning being a social function. It's an inherently social function and we want to spend as little energy as something as possible 

which means we're only going to r create the rationale for something to the degree that we need to. If you explain something to a child, you might not go into depth unless they keep asking you again why why why. But the debate might be a bit one-sided. So their hypothesis is really that reasoning evolved to persuade others and 

to scrutinize arguments presented to us. It's optimized for the debate, communication, and not solitary reflection. This is basically a critique of the chain of thought reasoning that we're seeing a lot of models apply today. They continue in groups, people's biases complement each other. One person's attempt to defend a position meets another person's critical scrutiny, and through that clash, better reasoning 

emerges. So to think more clearly, it's not enough to just sit alone and reflect. We sharpen our reasoning by arguing with others, testing ideas in a back and forth process. And if we think about how we construct a lot of things in society, this is exactly what we do in political sciences. This is sometimes called institutionalized disisconfirmation. We create a system 

where people have to disagree and then we try to find truth or something close to truth in that process. Look at anyone suing anyone else for example. We want them to argue. We don't have a committee that's doing research and then come up with an answer. And in our companies and in our teams, I think our roles are shaped as much by conflicting interests as by skills. 

And it's really this tension that allows a productive system to stay in harmony, right? A designer is always going to fundamentally disagree with developers in some regards. We just have we have the same goal technically, but we we come in with different incentives. Many designers will constantly try to push for more, focusing on how it looks and feels like 

rather than how difficult it is. And maybe you say it's going to take four more weeks to do it this way rather than that way. And the different isn't that big. Yet there's going to push for the better way. We have conflict in interests. As a manager, you might have an interest to launch on time and make stakeholders happy, not necessarily only create a product that feels great. So, we have common goal but conflicting interests. 

And I think evolution is a creative process where species spring from a balance of variation, selection, and inheritance. And then evolution of products will spring from a balance of production, eval evaluation and synthesis. What's happening in at the moment is that it's way cheaper to produce than evaluate and synthesize. That's a reason at least we're not 

seeing huge productivity gains. And I think what we have to really start taking seriously is orchestrating agents in this way. Effective agent orchestration will come from agents that are designed to disagree in loops. They scrutinize each other. They have different perspectives and different incentives. Why, for example, if you generate something while vibe 

coding, isn't it scrutinized from a designer perspective? Why doesn't it look back at the Figma constantly and say that it's wrong? Like, it's a pretty good feedback loop. These systems are difficult to create, but we can. There are several startups working on agents that have very different perspectives. QA agents using your product in a runtime automatically is one type of 

loop. This is the orchestration we need to start digging into. And I think if we do, maybe we'll not only be able to create or zap backlogs out of existence, maybe agents will also beat you in rock, paper, scissors. Thank you.
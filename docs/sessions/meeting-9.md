# Sutro Group Meeting #9 (16 Mar 2026)

**Date:** 2026-03-16
**Presenter:** Yaroslav Bulatov
**Video:** [YouTube](https://www.youtube.com/watch?v=vdQ3NkEiOt8)
**Length:** ~60 minutes
**Agenda:** [Google Doc](https://docs.google.com/document/d/1B9867EN6Bg4ZVQK9vI_ZqykZ5HEtMAHJ7zBGGas4szQ/edit?tab=t.0)

## About

Yaroslav presents the Sutro Group roadmap, introduces the DMC metric, reviews Yad's automated research agent, and walks through GF(2) Gaussian elimination verification.

## Chapters

| Time | Topic |
|------|-------|
| 0:00 | Pre-meeting chat (Yad's agents in Telegram) |
| 7:01 | Agenda overview, motivation for the group |
| 7:57 | Why we're here: energy waste in AI training |
| 8:36 | Public domain vs open source, why it matters |
| 9:15 | Meeting structure and agenda document |
| 9:54 | Yad's automated researcher: what it does |
| 10:58 | How to use it: git clone, cd, run claude |
| 12:44 | Keep experiments small (Spark 7 compute budget) |
| 13:39 | Playing Yad's 5-minute demo video |
| 15:54 | Demo: EGD experiment on sparse parity |
| 16:35 | Side-by-side: Claude Code vs Gemini CLI |
| 19:54 | Results: EGD took 9 min end-to-end, Gemini struggled |
| 22:02 | Workflow reflection: 12 min active, need better notifications |
| 23:03 | What is the job of humans when agents do the work? |
| 25:24 | Verifying results: GF(2) was 1000x faster, is it real? |
| 27:56 | Digging into GF(2): why Gaussian elimination works |
| 28:06 | Sparse sum as solving linear equations |
| 29:56 | Gaussian elimination walkthrough on the whiteboard |
| 31:10 | Sparse parity as linear equations over GF(2) / mod 2 |
| 31:56 | Interactive visualization (AI Studio) for sanity checking |
| 33:01 | Hardware lock-ins: motivation slides |
| 33:42 | Examples: square airplane windows, QWERTY, VHS vs Betamax |
| 34:59 | Academic publishing and peer review as legacy system |
| 35:22 | Fossil fuels vs solar: legacy infrastructure discussion |

## Related

- [Meeting #9 Notes](../google-docs/meeting-9-notes.md)
- [Meeting #9 Agenda](../google-docs/meeting-9-agenda.md)
- [Yad's Session 1](sesh-1.md) (recorded same week)
- [EGD Experiment Findings](../findings/exp_egd.md)
- [GF(2) Findings](../findings/exp_gf2.md)
- [Yaroslav Verification Sprint](../google-docs/yaroslav-verification.md)

## Transcript

Transcribed with whisper-large-v3 via MLX (Apple Silicon). 962 segments, 35,690 characters.

??? note "Full transcript (click to expand)"

    **[00:32]** You have a new hot channel in the Telegram. Which one? Chat, yeah, yeah. Oh, that's right, Chat. And he has his agents integrated with it, I remember there were times, I was telling, Hey, yeah, can you do this, and the agent would do it. Are the agents in the Chat? Well, they read, but they don't see, so the agent would just do it, and to tell Chat, Hey, just do the thing, and Chat is like, What did you do, it's like, Oh, you do the thing, never to watch, so to all the agents, So it's kind of cool.

    **[01:02]** My human agents are removing themselves from the loop. I'll just be talking to AI agents pretty soon.

    **[02:19]** Maybe I can be a .

    **[04:25]** The fail on that is that I have something to give thanks to. So, let's see if I can make it harder. Oh, I didn't mean to say that. Nothing. Yeah. If you're all solo, pretty much have to go to the market. I think it's at the, you know, I don't know what I'm going to do. If you had a couple, if you had another employee or something, then you might have to keep your product out of the way. That's one thing. You don't want to say, you know, just keep talking to them.

    **[07:01]** All right. I posted in the Telegram channel, I posted the agenda. So, I will, it's a high outline of the agenda. It's meant to be asynchronous, but I'll cover some of those points in person. But the point is, a lot of the stuff can be done asynchronously. The point of this meeting is maybe to put names to faces and eat pizza. So, I'll, the plan is, the pizza is coming in half an hour.

    **[07:35]** So, I'll plan to talk for maybe 15, 20 minutes. So, okay, so the outline. Why are we here? So, we're here. The reason we're here is in this document. Sucha group. Top level. I should probably say. And it has the motivation. And the motivation is right now I'm seeing a lot of energy wasted. And we want to fix it.

    **[08:05]** But also fix it in a way which maximizes benefit to humanity. So, this last part actually is what explains some of the, explains the reasons why we do some of the things. We do. So, for instance. We have this telegram group where everything is, it's public. Anybody can export the entire archive. Because I feel like if things are transparent, it's actually faster to move and easier to provide benefit.

    **[08:36]** And also every, all the code we're doing, I'm assuming is public domain. So, public domain is actually much more important than open source. So, public domain means somebody can take your code and make a lot of money on it. And also it means somebody could use your code and not even credit you. And I personally found like the crediting one, sometimes it's like annoying to think. If you're using code and you're like, oh man, what are all the people I have to credit. And it kind of adds friction.

    **[09:07]** So, the point is for maximum benefit to humanity, we want to have the least friction. So, everything is open and public domain. So, this document has meetings. And we have this agenda. So, okay, so motivation. So, motivation is we're running deep learning. The methods we invented were created during the times when we had CPUs. Since then, we started using GPUs. But a lot of the concepts didn't get updated, which adds friction.

    **[09:40]** So, this is one of the reasons things are bad, I believe. So, where is my agenda? Okay, done with motivation. Now I'll talk about YAD stuff. Last time, YAD was the last item and we didn't get to it because pizza arrived. So, this time I'm moving it up. So, YAD is a former SPC member and he had been really in the program synthesis.

    **[10:12]** And he made this automatic researcher report. And I started using it last week and it's actually surprisingly good. So, what it does, you can go to just the GitHub in the agenda and it gives some stuff. So, he ran 30 experiments, found something good there. And initially, I was like, okay, what do I do with it? There's like to do, like do I edit the to do?

    **[10:44]** And YAD is like, no, no, no, you don't touch anything at all. Don't touch the code, just talk to it. Which feels a little bit weird. Like, what if it doesn't do what you want? Are you supposed to like ask it again nicely? But it turned out it just worked out of the box. So, the way you do it, you just do a git clone, ucd, and then you do run cloud with this flag, this syntax. You can figure it out. Yeah. And then basically you get to this viewpoint. Then first thing you can ask like what is this about?

    **[11:18]** Or like how do I, wait, I have like three microphones. How do I run experiments? So, you can basically interact with it in human language. Anyway. So, you should, I will not take your time, but you should just go there, run it, and you can basically interact with it. And you can say, if you have an idea for an experiment, say, why don't you look up some other technique and try it.

    **[11:53]** Okay. So, and now I can say, what is the top performing two methods in your experiments? How good are they? And do you have any ideas how to improve on them? So, basically this is like having an LLM, but it also can run things, which is kind of cool. So, it can fact check itself. So, this is using Cloud Opus. Maybe there's a faster LLM.

    **[12:26]** But the bottom line is you interact with it, you instruct it as if you instructed some instance. And they do things for you. All right. So, GF2. Yeah. So, basically the experiments run half of a millisecond. So, these are pretty fast experiments. And this is a reasonable time frame to keep your experiments up. Because most of the methods were invented by before the end of the 1980s. And the hardware we had in 1980s was much slower than your laptop.

    **[12:57]** So, if they could do it on, you know, Spark 7, you can do it on one millisecond on your laptop. It's very easy to get seduced. into running bigger and bigger experiments but initially it's exciting you're running more realistic problems but then it slows down your iterations in the long term you will regret it so I think my job here is to remind everybody humans and agents to keep experiments very small so yes so this is yet stuff I'm still figuring out what it can do like I have a feeling at some point it

    **[13:30]** will stop working like I it just seems it would be too magical if it just went all the way to another GPT and then the real work will begin but so far it's done everything I've asked it to do and now we will play a five-minute video that the ad recorded for us I wanted to walk you through an update for future yellow and you just you don't clear what it really is and the simplest way possible is that

    **[14:09]** search research so there is really there is nothing fat you just be very clear what it really is in the simplest way possible is that the structured workspace that allows coding agents to become a category of research agents or rather a category of group of search research agents so there is really there's nothing fancy going on other than being able to structure it in a way that the coding agent can navigate it and then it would be able to perform these tasks that we have so roughly that's what a diagram is over here that you're getting to see okay so what we're getting to do today is that we're getting

    **[14:54]** To sort of highlight what we are going to demo, we're going to try to have our coding agent perform a task and try to see how much work it takes. What are some of the unexpected things? Was it easy? And what are the main takeaways? So I initially had a task in mind. However, the agent have already performed that and already has done a write up. So alternatively, we're going to try using this egalitarian gradient descent approach to try to drop SGD to potentially perform the sparse parity and the sparse sum below 10 milliseconds.

    **[15:30]** There is a lot more context to this. If you go back, the agent have done a whole write up on the to do. And then there's a whole section of discoveries and context to this problem. And whenever these results get published, you can actually observe them on this public website called ChangeLog. So that's that's a lot of time. I'm just going to right now jump in and then try to perform this sort of task. So this dangerously skip permission and team mode, dangerously skip permission might be a little bit misleading because it does not really dangerously skip permission. It's a lot more like allowing the agent to do a bit more experimentation in this scenario.

    **[16:04]** OK, so there are two things we can do. One of them is that I oftentimes actually just pop in here because this is connected to the telegram and the Google Doc. I can ask the question, hey, what are the most recent updates? That the group is talking about specifically in the prosperity challenge channel and the chat yet. So so this is sort of my way of trying to just see what's going on. Spark. OK, I guess there is going to be text to speech errors. That's one of the unexpected errors that we are going to have.

    **[16:35]** OK, so while that's happening, I'm going to also launch the Gemini CLI over this site. So the dash dash yellow is the equivalent of dangerously skip permission. Just to kind of give you a bit a bit of explanation of what's going on. So, OK, so this guy is kind of getting confused over here. So I might go ahead and ask, OK, I guess it's figuring it out itself. So the skip permission part is really not not a big issue in this example that we are in. And the main reason that is, is because we're not really mutating production data.

    **[17:07]** And because we are versioning the data, even if it breaks things, we can bring it back. OK, so I'm going to ask the agent to perform this task. So we're asking the Gemini CLI to perform this task, which is a different repo. Just to keep in mind, it's a clone of that repo, but this is the original version. OK, so this gave us a heads up. It's talking about me saying that I'm going to do this video that I'm doing right now. And OK, so I'm actually going to now just perform the same task over here. So with the task is implement and test the illiterate gradient descent on the sparse parity.

    **[17:41]** See if it breaks 10 milliseconds. OK, so what I want you to pay attention to. Is that two things. A my coding agent specifically for cloud code. As you can see, it's actually really annoying to do this with Gemini. I make it verbose. So it actually tells me everything it is doing. So this is actually really important to understand how this coding agent would function as a research agent. So that's like I'll say the first step. The second step is that. This these sort of skill sets are actually things that you end up creating as you go along in order to reduce the steps.

    **[18:15]** That the agent takes in order to perform that. OK, so the agent came back to me. It says I have that. It says what framing do you want? OK, so it's giving us options. The project already has EGD listed as to do. The strict reliability, gradient elimination, un-leaning towards two, first proof. Sounds good. Let's try that out. In fact, let's try both of them and then let's compare results. And then after that, let's try the sparse sum example to be compared. But ideally, we're going to utilize the GPU because you want to measure the efficiency as you may know.

    **[18:49]** And keep in mind that you do have access to MotoLabs if you want to deploy it. The most important part is to keep track of the results because we need to do a write up. So that is basic. These things that I'm saying are not just out of blue. So, OK, actually, let's wait. Hold on. So look, what is this saying? The user wants. So this is like really important. This is what you want. The coding agent to do this is what really makes it a research agent that it takes this complicated, fluffy language that I'm using and it tries to break it down into a set of task lists and it tries to turn into like some order of operation.

    **[19:26]** And so so this is going to run the results. I'm going to probably pause it for the sake of time and then try to see what the results will be while it's going to do the implementation. Also, all while that's happening. Unfortunately, this is how long it takes for Gemini to run. So I still like to perform that. This is not a good demo. I should have tried Codex. I don't know what this is even doing. Configuring. OK, this is bad. All right. So this is good over here. This is the thinking trace. This approach is recommended.

    **[19:57]** Look at that. It already has even told me. Let's go with a. All right. I'm going to pause this time and then I will come back when the results are out. Hey, folks, I'm back. So the coding agent ended up finishing the experiment of applying the egalitarian. GD variant or it's actually EGD to the sparse parity and the sum. Both of them. The agent itself took about nine minutes not only to run the experiments, but also to do verification reasoning.

    **[20:28]** Do the deployment on motor labs to do the GPU, do a whole write up. And also so altogether experiment and writing solution and adding a new problem set took about nine minutes. That is for cloud code. Unfortunately, it did not end up working out too well for Gemini CLI. It took not only longer, but it went into some dark hole, but it ended up switching into anti gravity. And so that we also have some results that we can look at anti gravity. I will explain this a bit more later. I think right now I want to focus on answering the questions that the main three things which were how long it took.

    **[21:06]** Where were like some of the unexpected things and what we learned and what is the outcome? So that's that. So I'll put this in the background. But for now, the main things that we learned is that first of all, the effort only took about putting in really a couple of prompts. I guess you could call them prompts, but it was just me directing the coding agent to perform the task. And then eventually, eventually I ended up here after nine minutes, which basically said I said, do you have a write up?

    **[21:36]** And what are the findings? And it goes like, yes, I have a write up. These are this is the document. And then eventually and then I said, commit, deploy and help me write up a message for the telegram for the team to share with you all. So overall. If you were to measure the time, it did take an hour, but it was not really an hour. It took about 12 minutes and a couple of back and forth to do this. I ended up getting distracted, leaving my computer and coming back. So it kind of teaches you that there needs to be a better infrastructure.

    **[22:11]** To have actually the coding agent communicate with you back and forth, have a proper notification system. So when it completes for the agent to follow up with you. But yeah, so I think like that's that's like one answer. How long it took and what are like some of the the step process looks like in terms of the finding. I guess there are a couple of interesting things here to look at. But I think like the big finding here is that it did it did end up doing slower but higher accuracy.

    **[22:42]** The sub 10 millisecond was not achievable with the EGD and the EGD did solve the sparse sum where the standard SGD diverged. So you can continue on your own to do. So this is just to give a flavor of what work looks like, because before our work was to come up with algorithms. The work is at a higher level and I'm still figuring out. So, yeah, there's like way more advanced than me on this stuff. I'm still figuring out how to insert myself in the process because like what to do when it doesn't work.

    **[23:18]** But for now, my work around if I don't know what to do, I just ask what should I do. So if you if you ever want to try it out and you don't know what to do, I think you can just do git clone CD. Then do close dangerous. Let's keep permissions. And you can just say, how does this work? How do I run experiments? And basically just follow the instructions. So you can ask it to teach you how to use it. All right. So this is yet stuff.

    **[23:49]** So, yeah, I'm pretty. Yeah. I think I know the answer. But just how does a tool like this fit into the set of the law or perhaps the best part of the goal of the project? Having an auto research agent because you really love something like me, which is not that type of goal. To contribute to the. I just want to. Yeah. I mean, the goal is to get an agent which can go all the way to the GPT. It's an agent which can train on the entire hundred million characters or to have an algorithm which can train on the entire hundred million characters of Wikipedia.

    **[24:28]** Hopefully, ideally by using an agent. But I'm sure it will not. If I tell it to do it, I'll get stuck. I haven't tried it, but I don't do it. It's a lot. So that's why we're taking baby steps. We're like trying to resolve prosperity and taking baby steps and doing careful checks. So I can actually. So this one is actually. We used to be in a different room, but we have this one for the next two and a half months.

    **[25:00]** So every Monday here. So one thing. So the question becomes. If the agents are doing the work, what is the job of humans? There is a higher level applying our experience to tell it where to go. But the second one agent can hallucinate. They can like gaslight themselves. So another role of humans is to actually check. So this is when I looked at the other result. When I looked at his results, his top result was like a thousand times faster.

    **[25:34]** So I'm like, OK, I have to check this one. And it gives the Gaussian. I don't know what the results are. I did switchboard. You go. Oh, it's the old reboot. OK, so there's some results. This Gaussian elimination was a thousand times faster.

    **[26:06]** So this is in my agenda. I think I think. I think my job was to go in and verify it. And then actually, when I was doing this, I was doing like this very meticulous everything. What I'm doing. So at 1 15, I was like trying to remember what I was doing. And finally, I remember that by 1 45, I was actually started to do things. So I'm recording this because I'm hoping later at some point in the future, an agent can read my box and they can reproduce it. So instead of doing it myself, I'll just say, do what you already did last week.

    **[26:41]** But now. So this is what I did. This link from the agenda. But I basically I opened his repo in anti-gravity and I opened agent manager. It could also work in code. And then basically I first said, well, why don't you run it? Does it work? And then I say, is it self-contained? It was not self-contained. I basically. I just say, just turn it into a single Python file. So I just wanted a single Python file that I can copy paste and I can ask my LLMs, which I trust more to see if it works or not.

    **[27:18]** So then I basically created this self-contained file. And then I took the self-contained file and stuck it into deep thing. And perhaps is it cheating? Is it really doing it? And said it was OK. But also I think LLMs tend to tend to like flatter each other. So if you generate the paper using LLM and you ask another LLM, is this paper legit? They'll say this paper is totally legit. So they can have like this bias. So to go further, I basically started some more what it's actually doing.

    **[27:51]** And what it's doing is it's actually a pretty cool. I think so actually a dug into. So why? Why is it doing this Gaussian elimination? Yeah, Gaussian elimination. So and the reason is that the sparse parity task is actually very similar to a sparse sum task. So and as far as some some tasks, suppose you have, for instance, five bits, you know, X1, X2, X3, or four bits.

    **[28:21]** And maybe only two of them are valid. Maybe it's like this one and this one. So this is a so you give it a string and then you look at the sum of the hidden bits. OK. So for instance, if you give a string for the one zero zero one, the sum will be the first one and the third one. It will be two. And you can look at this problem as the problem of estimating of solving a linear equation.

    **[28:54]** So you can you basically have something like W1X1 plus W2X2 plus W3X3. OK. And then you have some hidden formula. And then you have some sample strings, maybe like this is zero one zero zero one. And then you have labels and then you're given various things like this.

    **[29:25]** This will be like also one. But this one. This one. This one will be zero. So in a sparse sum task, you would be given strings and then you know their sums. And the sparse sum task is actually known as the task of solving linear equations. So you have some linear equations and you have to solve for the coefficients.

    **[29:56]** And if you look how you're solving them, there's this technique of Gaussian elimination. And I'll just give a flavor of how it works. So a flavor is. So suppose you have some equation like this. You can, if it's a valid equation, then you can add or subtract these two equations and you still get a valid equation. So you get an equation like this.

    **[30:30]** But you can also, if you do a subtract, no, if you subtract it, you get rid of x1. So if you subtract one equation from another, the new equation you get will be 2x2 equals to minus 2. So basically this is the core idea of how this Gaussian elimination works. You create new equations and now if you have this equation, now you can solve for the unknown and then you can back substitute.

    **[31:07]** So this is known as Gaussian elimination. And sparse parity, there's a thing called, you introduce a different arithmetic where you're saying it's like 0 plus 1 equals 1. And then 1 plus 1 equals 0. It's known as like mod 2 arithmetic. And it turns out in this new kind of arithmetic. Similar ideas work. So this sparse parity task is basically, it can be viewed as solving linear equations over a different field.

    **[31:38]** So and as a part of my verifications script, I'm also using AI to help me double check if things work. So one tool I like is, I think Michael used, you deployed an app on plot code. What was the thing you did with the peddling? Yes, plot code. I do a plot code maybe app. And then you... Yeah, it's just what it did as an artifact and plot code. And then it's also a different thing. Okay. So it's an artifact and I've been using AI studio.

    **[32:09]** So I guess it's similar. So in AI studio, I basically said something like, can you give me an interactive visualization to help me understand how Gaussian elimination works over mod 2. So I did something like this. And it thought for two. Two minutes. And it gave me this app. And basically I can walk step by step how this elimination works. So this was basically part of sanity checking.

    **[32:39]** I took the solution. I didn't trust that AI was not cheating. And I basically dug in and made sure that this solution made sense, which gave me a bit more sanity. Okay. So that's all I want to say about the other stuff. Any questions? So the next five minutes I'll talk about motivation for this effort. So why are we even... Why are we trying to replay things from scratch?

    **[33:14]** And Marisa? Check, check, check. So I made some slides. So the agenda has the notebooks. And I'll show some of the slides that are relevant here. Let's see. I want to get one of these slides. So basically in systems we have often examples when we have a legacy system and we kind of carry it over to new design. So for instance, windows are square.

    **[33:45]** So when people design airplanes, they did the first airplanes with square windows. And there were some air disasters. And then they changed them around. They had to do it effectively. So I think that's the first thing. Another example is QWERTY keyboard. The reason was that the arms would get stuck. So they redesigned. So... But it's actually less efficient. So the work keyboards are more efficient. But there's just too much momentum behind QWERTY. So we're stuck using QWERTY even though it's electronic.

    **[34:16]** Another one is fireplace. It used to be in the center of the house. But now we're still designing our houses around the central ornamental fireplace even though we don't really need it. I actually don't know what this is. I'll come back and learn more about it in the future. Also, I don't know what this one is. I like this one. So when VHS came out, Betamax was actually a smaller cassette.

    **[34:50]** But there was basically a load of it. There was a lot of legacy VHS stuff. So it was too hard to break in. Academic publishing is an idea. So why do we even have peer review in the first place? We used to have limited paper. So we had to decide who gets put on this new paper. And we still carried over this concept. And right now peer review is not that useful. It's a bit of a crisis. Carbon. Actually, maybe you have an opinion on this.

    **[35:22]** This is a generated slide. But it's telling me that society is deeply infringed on fossil fuels even though you could switch. And actually, a friend of mine works for the Department of Energy. And he says that solar power is actually already cheaper to use. But there are some subsidies or some legacy reasons. Do you have an opinion on this? I mean, solar. Usually when people say solar is cheaper than fossil, they're usually saying that today the cost of the solar cells has come down so low

    **[35:56]** that you can generate the equivalent amount of electricity more cheaply than you can from burning fossil fuels. So it's more about the primary energy or electricity generation. Then you get into questions about CapEx and how solar is kind of free of an ongoing business in the century. But then you have the paper. But usually when someone says that they mean that the CapEx basis is not cheaper to build a solar power

    **[36:27]** than the coal and the coal and the carbon. But that was not the case for a really, really, really long time. It's only been a few years. I see. And actually, a cul-de-sac. I learned it this morning. Cul-de-sacs have this round shape to accommodate carriages. So today a car can do a three-point turn. It doesn't need a cul-de-sac, but we still left this design. But this one is actually my favorite example. It's a recurrent laryngeal nerve.

    **[36:57]** So we have a nerve which went from the brain to the gills. But the way it's programmed during in-growing development, it starts as in a fish and then the heart kind of drifts down. And in mammals, it gets stuck and it kind of grabs this nerve and it goes around. I really am really lucky. I'm enjoying this high artistic quality I'm getting out of this. Actually, another thing I learned, this is the longest cell in the history of life.

    **[37:28]** When we had a sauropod, the recurrent laryngeal nerve was 50 meters. It's one cell. And the problem is that it's kind of hard to fix. So if you are, the nerve goes through the heart, so it's kind of, there isn't, you can't incrementally fix it. But if you try moving it, you get a non-working giraffe. And what I'm saying here is motivation. The current design here, we have a giraffe in our tributes.

    **[38:00]** And why should you believe it? And the reason, let's see, put it right there. Yeah, so, and I'm saying this and you should believe it because I have been working on this for a long time. So in meeting number one, I gave some background. 2004 was my first paper. But then in 2013, I led the first deep learning deployment at Google. I was on the TensorFlow team. I implemented the first, one of the first, basically, I did the first Python client.

    **[38:35]** I was working on back propagation. Then I worked on gradient checkpointing at OpenAI where we reduced memory usage. I also worked at, I trained transformers. We beat Google at this image competition. I implemented back propagation at least five different times in TensorFlow team, in Pythor's team. So yeah, so basically, the way when I look at some of the choices we're doing, I know where they came from.

    **[39:06]** And back in the time, they were quite arbitrary. So when people right now think, well, why do we need backprop? Is it fundamental? At the time, that was just the thing that worked. And I was sure we would do something else later. But now people are so used to it, they forget there is any other alternative. All right, so, okay, two more sections. So I spent some time thinking about the future. Like, what do we need to do to avoid failure?

    **[39:37]** So this is a famous example. In 2016, there was a data set of radiology images, and Google trained a model which was giving accuracy better than humans. And at the time, they said, okay, in two years, we will not have, or in five years, we will not have radiologists. And then Elon Musk was even more optimistic. He thought maybe in 2017, we won't have software and cards. But it didn't happen, and there's various analysis why it didn't happen.

    **[40:12]** And one of the issues is that people optimize for the wrong reasons. So people picked this classification accuracy on the benchmark, and they optimized it, but it didn't actually optimize for the actual objective, which is being useful at the office. So when I think of previous failures, this is actually the most important thing to get. So this is something I spend a lot of time thinking about. How do we make sure we get the right objective? And then there's some other issues.

    **[40:43]** Risk management. There's a segment where you get too into some theory without having a way of checking it quickly. So to manage your risk, you always need to be estimating how far you want to go before giving up. Self-optimization. You often have, you divide the work across different teams, and they each solve their individual problem, but together, the problem isn't solved. Also, maybe you forecast future incorrectly. Here, I'm focusing on GPUs.

    **[41:14]** Because I feel like GPUs will be around in 15 years. One of the reasons is we're building for Stargate now. Those data centers have a 15-year depreciation cycle. So probably people will want to get their money's worth. So we'll probably get some GPUs for at least 15 years. Yeah, and the way I think about the progress on this project is we want to, we're starting with three problems, and we want to get to GPT-2. So that's one axis. Getting better and better solutions.

    **[41:47]** And the other axis is the objective. So right now, we looked at average reuse distance, but this is not the real objective. I feel like the ultimate objective, which is not before, is the warm-to-the-touch objective. If you have a good algorithm, you should be able to run it in your laptop and just touch the laptop. If the laptop gets super hot, well, maybe your thing is doing too much. So that can be, I think, viewed as a ground truth. And then we can come up with a proxy objective. Maybe looking at sensor readings, maybe looking at power usage, maybe looking at memory usage.

    **[42:22]** But ultimately, I think to avoid the radiology problem, you should be able to actually run it in your laptop and actually touch it. Because that's an equivalent of being in the doctor's office and using the system in the doctor's office. Speaking of objectives, we started with objective average reuse distance. I did some research and I found actually a much better objective called data movement complexity.

    **[42:55]** Let's see how much I want to touch. Yeah, I do want to touch the other one. Oh, hello. Actually, maybe I don't want to touch the other one. So data movement complexity is in the agenda. So it basically... It's a much more sensitive measure of how you're using the memory and that you're using cache. Yeah, that's ours. What?

    **[43:27]** It's our pizza. Oh, one, four, two, six? One, four, two, six. Sorry. I didn't get the... I didn't know that it was... How is data movement complexity ? It's just that it sounded like it was being incurred.

    **[44:05]** Yeah, okay. We can... Okay, I want to spend two minutes talking about the data movement complexity. So basically, the data movement complexity, it's the idea is that you have... When you're using list LRU cache, you can basically... There's a heuristic you can keep most recently used bits in a cheap nearby cache, which is small. And the bits which were not used for a while in an expensive one.

    **[44:35]** And it basically... Imagine this scenario where you have this concentric rings and there's a very simple formula. The cost of a memory X is the square root of the used distance, meaning how many bits ago it's been used. And I think this is a good metric. It's a good metric because there's research on it, there's papers on it. And if you wanted to get plot to implement it, what you would need to do is just point it to this paper and say,

    **[45:07]** I want to use this. And you can see that there's this DMC metric from this paper. And that should be enough to implement it. So I think for next week... Oh, so one thing about planning. One lesson I learned is that it's tempting to start making progress on several dimensions simultaneously. But you usually regret it. So I prefer to work on one axis at a time. So this time there's a new metric. So for the next homework we can continue the same problem.

    **[45:38]** But now we improve the metric. And the metric is this new metric ARD. And basically iterate on this process, getting agents to invent new methods which are faster. Iterate on the new metric. So the idea is we're keeping the problem fixed. So the idea is every time we only change one at a time. Either improve the metric or the problem. So this time we're keeping the problem again for the third week. But we're improving the metric.

    **[46:09]** And the metric is in the agenda, DMC. And I have strong preference for this metric. Data movement complexity. I guess we can close it. Nobody will come. So data movement complexity, the reason for this metric is that it represents, if you actually, the memory that's nearby is cheaper, but it's smaller.

    **[46:39]** And the memory that's far away is more expensive, but it's larger. And actually the cost is roughly proportional to the square root of the size. And they actually did some, in the paper they have a graph that's very similar to this. This is latency, but there is the same graph for energy, where the distance between the two is the same. And from the processor, there's this square root relation. So basically, yeah, we can use this metric to estimate how much energy

    **[47:13]** it would be to access a specific data information. Yeah, and I think this is also, I think, an interesting metric. What makes the metric interesting is when it's a difficult metric. It's a difficult metric to gain. And I think this one is difficult to gain because it actually represents, you could actually implement cache where this would exactly be this, because if you, you could actually have actual wires going in this concentric circle like this,

    **[47:46]** and the length of the wire is proportional to like the square root of the area. So the energy you needed to, you know, to use a wire of length L is proportional to that length. So you could actually conceive of a field, an actual processor, which achieved that energy, and it would lose, use like this much energy lost in heat. So it's not, I don't think it's easy to gain.

    **[48:17]** If it's something that's man-directed to physics, it probably can't be gained in a boring way. It has to be something interesting. Great, this is, let's see. This is all actually fit in, fit in, yeah, actually fit in the agenda. So with that, we can start the game.

    **[51:17]** . . . . . . . . . . . . . .

    **[51:49]** . . . . . . . . . . . .


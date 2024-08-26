---
author: [[Sequoia Capital]]
title: "What&#39;s Next for AI Agentic Workflows Ft. Andrew Ng of AI Fund"
date: 2024-08-26
tags: 
- articles
- literature-note
---
![rw-book-cover](https://i.ytimg.com/vi/sal78ACtGTc/maxresdefault.jpg)

## Metadata
- Author: [[Sequoia Capital]]
- Full Title: What's Next for AI Agentic Workflows Ft. Andrew Ng of AI Fund
- URL: https://www.youtube.com/watch?v=sal78ACtGTc

## Highlights
- if you take an agentic workflow and wrap it around GPT 3.5 I say it actually
  does better than even gbd4 um and if you were to wrap this type of workflow around gb4 you know it it it also um does very well and you notice that gbd 3.5 with an agentic workflow actually outperforms gp4 um and I think this has and this means that this has signant consequences fighting how we all approach building applications ([View Highlight](https://read.readwise.io/read/01j67a9ejcc4y5kmd8nkamx7ev))
- I want to be a bit concrete and share of you um the broad design patterns I'm seeing in agents it's a very messy chaotic space tons of research tons of Open Source there's a lot going on but I try to categorize um bit more concretely what's going on agents reflection is a tool that I think many of us should just use it just works ([View Highlight](https://read.readwise.io/read/01j67aarv6fxjn5p8h83wvmcn2))
- planning and multi-agent collaboration I think is more emerging when I use them sometimes my mind is blown for how well they work but at least at this moment in time I don't feel like I can always get them to work ([View Highlight](https://read.readwise.io/read/01j67abjm99mhgd3m0gp2b0ty4))
- for me for a given task then we have a coder agent just an LM that you prompt to write code to say you def du task write a function like that um an example of self-reflection would be if you then prompt the LM with something like this here's code intended for a toas and just give it back the exact same code that they just generated and then say check the code carefully for correctness sound efficiency good construction CRI just write prompt like that it turns out the same l that you prompted to write the
  code may be able to spot problems like this bug in line Five May fix it by blah blah blah and if you now take his own feedback and give it to it and reprompt it it may come up with a version two of the code that could well work better than the first version not guaranteed but it works you know often enough for this be wor trying ([View Highlight](https://read.readwise.io/read/01j67ag7184t6s9gj3qes19bam))
- you should try changing something and come up with V3 by the way for those of you that want to learn more about these Technologies I'm very excited about them for each of the four sections I have a little recommended reading section at the bottom that you know hopefully gives more references and again just the foreshadow multi-agent systems I've described as a single coder agent that you prompt to have it you know have this conversation with itself um one Natural Evolution of this idea is instead of a single code agent you can can have two
  agents where one is a coder agent and the second is a Critic agent and these could be the same base LM model but that you prompt in different ways where you say one your expert coder right code the other one say your expert code review to review this code and this Tye of workflow is actually pretty easy to implement I think it's such a very general purpose technology for a lot of workflows this would give you a significant boost in in the performance of LMS ([View Highlight](https://read.readwise.io/read/01j67ahp68fr1dxnn1m9qm16pb))
- planning you know for those of you that have not yet played a lot with planning algorithms I I feel like a lot of people talk about the chat GPT moment where you're wow never seen anything like this ([View Highlight](https://read.readwise.io/read/01j67amwm4xn7e23rz2623va6b))
- today we actually have agents that I don't want to say they work reliably you know they're kind of finicky they don't always work but when it works is actually pretty amazing but with agentic loops sometimes you can recover from
  earlier failures as well so I find myself already using research agents for some of my work where one of piece of research but I don't feel like you know Googling myself and spend a long time I should send to the research agent come back in a few minutes and see what it's come up with and and it sometimes works sometimes doesn't right but that's already a part of my personal workflow the final design pattern ([View Highlight](https://read.readwise.io/read/01j67ar2creapsccp78xrg0gxa))
- it turns out that multi-agent debate where you have different agents you know for example could be have ch GPT and Gemini debate each other that actually results in better performance as well so having multiple simulated air agents work together has been a powerful design pattern as well um so just to summarize I think these are the these are the the the uh patterns of seen and I think that if we were to um use these
  uh uh patterns you know in our work a lot of us can get a prity boost quite quickly and I think that um agentic reasoning design patterns are going to be important ([View Highlight](https://read.readwise.io/read/01j67avtdam0pfnveb97ygsby5))
- I expect that the set of T AI could do will expand dramatically this year uh because of agentic workflows ([View Highlight](https://read.readwise.io/read/01j67axvt5szxv4emex49sjjd3))
- one other important Trend fast token generation is important because with these agented workflows we're iterating over and over so the LM is generating tokens for the elm to read so be able to generate tokens way faster than any human to read is fantastic and I think that um
  generating more tokens really quickly from even a slightly lower quality LM might give good results compared to slower tokens from a better LM maybe it's a little bit controversial because it may let you go around this Loop a lot more times ([View Highlight](https://read.readwise.io/read/01j67b0ja9j1q0khm1919vccym))
- honestly the path to AGI feels like a journey rather than a destination but I think this typ of agent workflows could help us take a small step forward on this very long
  journey ([View Highlight](https://read.readwise.io/read/01j67b2ckzdb1wwxq3t2p0de1g))

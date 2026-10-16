# Architect and vibe-coding planning session

*2026-07-28 02:07 - transcript 02e2ab27-db37-4548-80f8-f0b3046ddb71*



*Prompts p60-p116 of 223. Part 2 of 4. The Plans and Design Documents sections are in part 4.*



## Prompts



**[p60]** I wanna have like, I wanna have a really good how-to guide for, I want the AI to be able to shit out a complete implementation. And so, it always requires a design doc. The first step is, it's gotta have a design document, and I'm gonna show you an example of what a design document looks like. The design document should have all the high level skills already mapped out, sorry, all the high level decisions, they're already mapped out, and so the AI, the model, all it needs to do is just implement. And so once we have the design doc, then what the next step of how to vibe is to create hierarchical plans. First, we create a high level plan, which is a series of steps that take us towards the goal, and they have to proceed in order, and at the output of every step is, is code, tests, and and, and a checkpoint in terms of, okay, now we got this piece of functionality done. Every batch of changes, every Every commit has to also have tests, and the tests can't be trivial, they have to be real. And also, the, the, every, at every step of the way, the first thing that the AI should do is it should spawn one or more sub-agents, and it should search the web for information specifically about what it's about to do, unless it's absolutely sure that it already knows, because sometimes you do a search and you find shit out, like you find out that the package that you're about to use has a bug, or maybe that there's another package that's gonna do the thing better, or maybe there's a security vulnerability. But like every so often Often the, the, the executor, when we're executing the implementation plan, we need to spawn sub-agents and we need to check the internet. And then We wanna do, we wanna do hierarchical refinement. So we have the high level plan, like, let's say we know we're gonna build four crates. Well, then we figure out what order do the crates have to be implemented in. Like, if crate A depends on crate B, we have to implement crate B first. So then we have the high level. Then for each of those, we create a little separate planning document, we have the L2 document. That's a, a series of more fine-grained steps. Oh, and then at the end of the day, what we wanna see is we wanna see a development plan that, that has the smallest units of functionality at each step that lead to a testable thing. So we decompose it fully and we think deeply about it, like we create the files and we loop and we think deeply, and then once, and then once we start, now we start the implementation, and along the way, we, we work on a design document. Any decisions that the AI had to make, it puts in a file called design.md, and that's per, per crate, per package, and then we have a high level design at the top level, that's like for the whole, for the thing as a whole, these are decisions that are like cross-package, cross-dependency, and then anything that differs, we have to document it. And also, when we write the code, we have to put comments, but we only wanna put comments where it's something that's surprising, like explaining why we did something that's non-standard. We don't wanna annotate code, we don't wanna repeat, like if we have x equals x plus one, we don't wanna comment that says increment by one. Yes, this is a very good idea. So the development methodology, it has to be baked in that after the AI makes a commit, it should do a code review. There should be a code review after every commit. We wanna look for redundant code, we wanna look to see if we wanna have bugs, we have to evaluate the tests, like red team the tests. And also, there has to be subagent discipline. Like everything that the Vibe executor does has to be in a subagent. We can't be doing shit in the main context because we have to keep the plan potent. So. Every technical the AI is always gonna create technical debt, so we need a set of rules for how to make keep code clean, right? And it has to be independent of the language, it has to be general code hygiene principles. So, s do it now, spawn sub-agents, search the workspace, search the internet, and, and for generally applicable rules, like for example, dry, don't repeat yourself, or the single responsibility principle. Like, we need a set of unambiguous tests that, the co that we can apply to the code that the AI creates. And then we get and then we get a report in the chat, "Do not make files," and then the A and then the AI fixes it. And then after it fixes its own technical debt, and then, and it, and it ha and make sure that the tests pass, we don't add a commit, we amend the commit. So that's the pattern. We author a commit, then we remove the debt, we, we do a code review and remove the debt, and then we fix it, we make sure that it's got tests and it passes, and then we amend the commit, and then we move on. That's like, that's in the DNA of the rules. The other DNA of the rules is subagent discipline. You always have to have subagent discipline. Everything happens in a subagent, parallel if possible.

**[p61]** can we agree there is some N=number of model parameters for which values above N always compress correctly?

**[p62]** and we can cheat - as long as the model doesn't expand, then we're good. this means, maybe that 0.1% of corner cases it cannot find a shortening which would exist. but that's ok as long as it doesn't expand. it just outputs the same input verbatim.

**[p63]** give me a guess as to what N is. and do we train from scratch, or fine tune?

**[p64]** how do small models handle multiple languages (e.g. english, french, swahili)

**[p65]** Exactly. I want a model that has zero non-English training. Do they exist?

**[p66]** surely there is a corpora on huggingface of english-only text we could use to pretrain a 2B model

**[p67]** Okay, listen, I gotta tell you something. First of all, you're saying maybe $2,000, $4,000. Think about what you're saying. $4,000. And what do we get? We get the fucking Holy Grail! We get the ability to compress. Compression is the most valuable substance in the AI universe. It's the antislab. I could bottle this and sell it for a million dollars.

**[p68]** Oh, that's weird. Why did you, why, why'd you give me the safety? No, no, no, listen, we're doing, don't, don't pump the brakes. Fuck that. You, you gotta pump the gas. What I'm doing is I'm trying to build the case. I'm trying to fill this chat with all the reasoning. I'm trying to think about it from every angle. That's what we're doing. Like, we need to think about it because We have to, we have to start with the most compressed version of the idea. We have to start with the highest frequency signals, that's what we're doing. Like, I'm giving you, this is the thing, I'm providing the human input, I'm giving you all the human decision making. This chat itself is the, is the substance. And there's a huge payoff for me, 'cause I live on my prompts.

**[p69]** Well, my thinking is this: so you're asking me, "Do I wanna save 7%?""" Yeah, I wanna save 7%. Yeah, I do, because think about it, less parameters means faster output. More tokens per second.

**[p70]** My question My question is How does it, what happens when the sentence is so compressed that it can't compress it anymore? What's the model gonna produce? And how do we prevent the model from thinking? Is this gonna be a thinking model? Does the model care about tool calls? Like, I wanna train the tool calls out of it. I only wanted to be doing compression, like I wanted to be a maximally compressing model.

**[p71]** Okay, but So we do have a little problem. Is this gonna be a little compression or is it gonna be a lot? Because let's, let's look at it this way. When you com let's say you have a sentence that's bloated, there's a lot of ways to compress it. However, depending on which path you choose, we may or may not have further compression possible. Does the model guarantee that it does a maximal compression in one pass? In other words, are we always guaranteed that if we try to compress a second time, it, then it can't do it? How does, what, what's the thinking here?

**[p72]** And is the compressor gonna be biased towards certain type of sentences or will it be general purpose? Like, could I use it to compress an essay on plant life? Or is it always gonna be only like for prompts?

**[p73]** What about biasing towards particular words, like? Are, are words that people don't use often, like a ten dollar word? Do we want to avoid those?

**[p74]** Okay, so And our training data. Has to have token counts b-embedded in it. What about what about the tokenizer? Like, do we wanna optimize the tokenizer? Like maybe, like avoid should be one token. Like, may-maybe, maybe we make a list of all the words that are the most important words to use when instructing a model, and we make those one token.

**[p75]** I can download, you said use the standard BPE vocabulary, I can download that. Let me ask you a question: spawn multiple sub-agents and search the internet, hugging face in particular, see if anybody's done anything like this. First, see if someone's done the compressor, and if and then see if someone's built the pieces. Like, has anyone built the components? Has anyone Are there any blog posts that talk about this? Like, you know, sniff around, cast a wide net.

**[p76]** ...the fuck? only 149M params?

**[p77]** Let me ask you a question. Are these streaming models like, do I just feed the, do I just feed everything in and then just take everything out, or do I have to go a sentence at a time? How does this shit work? How big is the context window for these tools?

**[p78]** So how do I integrate this into Cursor? Like, what do I, do I build a Rust program? And then expose it as an MCP?

**[p79]** Review the state, review what's in the ecosystem again. Explain it to me. Like, give me, give me, show me the options, show me what's out there. Does anyone have a blog post? What are the comments? Give me the links to the repositories. I wanna read about it, I wanna learn.

**[p80]** I don't understand. Oh, so wait a minute, LLM lingua, all it does is drop tokens, so your does that just mean it's removing words?

**[p81]** Oh, I don't want this. This isn't good. This isn't the kind of compression that I want. I want smart compression. I want clever compression. I want fucking Shakespeare to rewrite the sentence.

**[p82]** I can see the value of the subtractive compression. I could see it, like for example, summarizing a context, that's pretty good. That's a pretty good way to compress. And the beauty of it is, is that it's idempotent. Like, and it's minimal. If you compress it twice, the second version's not gonna be any different than the first. And by construction, it can only be the same or shorter.

**[p83]** Okay, I wanna try this thing. I wanna try running it on one of my prompts. The the four billion model. I mean, I might as well. How do we get this thing going?

**[p84]** Question: Shouldn't we be using subagent discipline? 'Cause as we get towards the middle and the end, it's gonna be, some of its attention, its ability to attend to the latest content is gonna steadily decline as we have old stuff filling the context, or no? Am I wrong?

**[p85]** I gotta be honest with you, I'm really fucking skeptical, because, like, you were too quick to suggest using the model. Can a, can a frontier model really do this? Or are you gonna give me a simulation of what it might look like? 'Cause I have my doubts. Explain to me exactly the mechanism how this works, like, in, in the parameters. Like, how does the model hold the sentence in its, in its working memory? And how does it move through the tensors? And how does it actually compress? Like, I wanna know the mechanics of it.

**[p86]** Do I get to choose the selection algorithm, argmax vs. weighted random?

**[p87]** why isn't temp=0 deterministic? where's the source of randomness

**[p88]** can you show me what the visible consequence of the slight non-determinism at temp=0 would look like in terms of output

**[p89]** whoa that's fucking weird its like a parallel dimension where everything is *almost* exactly the same but not quite.

**[p90]** fuck no, you took forever

**[p91]** I want a beautiful report in @runvil explaining all the findings in this entire chat which are related to prompt compression, the tool planning iteration loop, blurring, all of it. use @tools-public/how-to/how-to-write-reports.md

**[p92]** call it prompt-compression-research.md

**[p93]** it goes to @plans stay in plan mode

**[p94]** I want this obviously I wanna have an executive summary, but I also wanna have exposition. I wanna tell the story about how my proms got bigger and my other one didn't write I wanna write this as a cool. An, a cool analyst who's a researcher who's reporting on their experience. I want this to be I want the beginning to be experiential, and I think question, should it be in the third person? But I want, I want, I want the reader to feel like they're going on the same journey as me, because everyone has experienced this. Like, I want this story to be relatable. Like, you know, AI slop is a fucking problem, and someone who reads this, if, if they don't get to the math and they don't get to the stuff, they don't, if they don't get to the evidence, I want them to at least understand this. And then after this section, then I wanna go into the background, I wanna go into the math, I wanna explain top k, I wanna explain argmax, I wanna explain latent space embedding, like, I want all of that explained. So use Inline formulas and inline mathematical formulas, and also put the mathematical formulas in their own paragraph so they stand out when they, the important ones like one or two. You don't have to go too deep, but just a enough math to that where they can get the flavor of it, they can understand it.

**[p95]** Do not include a table of contents. Use @tools-public/lessons/semantic-blur-effect.md to augment the story  and in particular the insights about plan mode and how it should be preserved. I want all the insights regarding plan mode here and in this semantic-blur-effect.md to be used as source material. I want the reader to really understand the importance of the plan file and how to preserve and evolve it and keep it compressed. and then after the story material we will get into the nuts and bolts of the compression research

**[p96]** in the analytical section I want to convey everything we learned. about sharpening a blurred thing. about preserving the sharpened thing. all that stuff. perhaps use a subagent to go through the transcript and mine it for details and facts. If you can confidently talk about the relationship between thermodynamics, shannon entropy, information theory, then do so.

**[p97]** I want to show the thing about how a 0.000001% thermal deviation in floating point calculation because of thread ordering or whatever, I want to show the example of how the word flips from "a" to "the" and the other flip. The report should should have several very good examples that show inputs and outputs

**[p98]** That's ok its close enough to reality to help the reader understand.

**[p99]** why is there so much of shit like this "That last point deserves emphasis rather than apology."

**[p100]** This smells like an Opus 5 problem. Would @tools-public/how-to/how-to-write-prose.md help?

**[p101]** I dont want a length pass I want to get rid of the shitty Opus 5 AI smells

**[p102]** Prose Pass on prompt-compression-research.md

**[p103]** Implement the plan as specified, it is attached for your reference. Do NOT edit the plan file itself.

**[p104]** To-do's from the plan have already been created. Do not create them again. Mark them as in_progress as you work, starting with the first one. Don't stop until you have completed all the to-dos.

**[p105]** Implement the plan as specified, it is attached for your reference. Do NOT edit the plan file itself.

**[p106]** To-do's from the plan have already been created. Do not create them again. Mark them as in_progress as you work, starting with the first one. Don't stop until you have completed all the to-dos.

**[p107]** What about this shit, do we really fucking need all this? Christ... I hate Opus 5.

**[p108]** "Two reasons, and the second is the more interesting one."

**[p109]** what about this shit

**[p110]** "This is not merely an observation. "

**[p111]** plan fixes

**[p112]** That's it? just 8 edits?

**[p113]** look at every sentence and ask "is this needed"

**[p114]** Okay, I wanna talk about the bloat. So, what is the current plan that we talked about for? Compression. What's our plan for compression? Very quick summary, couple of sentences.

**[p115]** Okay, I have an idea. So here's my idea. We train a model, we train a, a generative compressor, but listen, here's how we train it, here's what we do We start with text that's compressed, like for example, papers from Peter Dimov or Villa Vutelin or John Spicer. We basically, we start from ultra-compressed text that's written by humans. Then what we do is we ask the AI to rewrite it. They take in the text and they rewrite it, and then they output it. And what that's gonna do is that's gonna resample, and now we're gonna get the semantic blur. And then we do that over and over again, like we do that like ten times, and we save each of those artifacts, and now the training data is the resampled output mapping back to the human input, and we can generate tons of training data that way. Like all we need to do is have samples of good human writing. And then we can generate, we can resample, and the beauty of it is, is that by resampling it, we're creating exactly the pattern that the AI needs.

**[p116]** What about if we just make the model bigger? What if we use a seven billion model?

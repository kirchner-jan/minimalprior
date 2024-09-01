---
title: minimalprior
subtitle: a spinoff
author: Jan Kirchner
author-url: "https://universalprior.substack.com/"
date: 2021-12-20
---


## **The emperor's new paper.**

In a recent [lunch conversation](https://kirchner-jan.github.io/minimalprior/posts/universalprior/applied-mathematical-logic-for-the)[^1], a colleague of mine explained her system for reading scientific papers. She calls the system tongue-in-cheek " _not_ reading the paper". It goes as follows:

  1. Read the title and predict what the abstract will say. If you are correct, stop reading the paper.
  1. Otherwise, read the abstract and predict what the main results will be. If you are correct, stop reading the paper.
  1. Read the last paragraph of the introduction or the first paragraph of the discussion and predict the details of the results. If you are correct, stop reading the paper.
  1. etc.



I love this system, mostly because of the flippant name, but also because it points out that "[the emperor is naked](https://en.wikipedia.org/wiki/The_Emperor%27s_New_Clothes)". It is a bit of an [open](https://www.quora.com/How-do-I-read-research-papers-quickly)[ secret](https://www.cold-takes.com/honesty-about-reading/) that "not reading the paper" is the only feasible strategy for staying on top of the [ever-increasing mountain of academic literature](http://blog.cdnsciencepub.com/21st-century-science-overload/). But while everybody knows this[^2], not [everybody knows that everybody knows this](https://www.lesswrong.com/tag/common-knowledge). On discussion boards, some researchers claim with a straight face to be reading [100 papers per month](https://www.researchgate.net/post/How_many_papers_do_I_have_to_read_per_month_as_a_researcher). Skimming 100 papers per month might be possible, but reading them is not[^3].

So why is this not common knowledge? A likely cause is the stinging horror that overcomes me every time I think about how science really _shouldn't_ work. Our institutions are stuck in [inadequate equilibria](https://www.lesswrong.com/posts/yPLr2tnXbiFXkMWvk/an-equilibrium-of-no-free-energy#:~:text=To%20see%20how%20an%20inadequate%20equilibrium%20might%20arise%2C%20let%E2%80%99s%20start%20by%20focusing%20on%20one%20tiny%20subfactor%20of%20the%20human%20system%2C%20namely%20academic%20research.), the scientific method [is too weak](https://slatestarcodex.com/2014/04/28/the-control-group-is-out-of-control/), statistical hypothesis testing is [broken](https://psycnet.apa.org/doiLanding?doi=10.1037%2F0003-066X.49.12.997), [nothing](https://elifesciences.org/articles/67995)[ replicates](https://en.wikipedia.org/wiki/Replication_crisis), there is [rampant fraud](https://scienceintegritydigest.com/),... and now scientists don't even read academic papers? That's _just_ what we needed.

[And yet it moves](https://en.wikipedia.org/wiki/And_yet_it_moves). [For some reason](https://guzey.com/how-life-sciences-actually-work/), we still get _some_ new insight out of this mess that calls itself science. Even though scientists don't read[^4] papers[^5], the entire edifice does not collapse. How is that? In this post, **I will go through some obvious and less obvious problems that come from "not reading the paper", and how those turn out to not be** _ **that**_ **bad.** In the end, I tee up a better system that I will expand on in part two of this post.

* * *

##  **And yet it moves.**

>  **Argyle**[^6]: Okay, level with me here. How can you just _not_ read the paper? **How do you know what's written in it**? 
> 
> **Belka** : Well, when I was new at this, I did read a _lot_ of papers very carefully. I got stuck a lot, redid a lot of the calculations, double-checked the methodology, asked my colleagues... 
> 
> **Argyle** : But you don't anymore? 
> 
> **Belka** : Sometimes I do! That's what journal clubs and coffee breaks are good for. But I don't have the time to do this for most papers anymore. I also want to produce _new_ research. And I also notice that, from experience, I usually have a pretty good idea of "where a paper is going". I usually have seen a poster presentation of the research somewhere, or read a thread on Twitter. Or I know the work that usually comes out of the senior author's lab and that lets me fill in the blanks. 
> 
> **Argyle** : But those are only rules of thumb. What if you're wrong? 
> 
> **Belka** : I _do_ still look at the paper, and if its substantially different from what I anticipate, I _do_ read it more carefully. Also, if it's _really_ surprising, then it'll bubble up on Twitter. **I've become very efficient at identifying the delta between what I already know and what a paper adds.**

![](../../images/https3A2F2Fbucketeer-e05bbc84-baa3-437e-9518-adb32_29.png) **Schematic** **of “the delta” added by a (typical) academic paper.** Papers you have read before are shown in the background with an orange background. Relationships between papers are indicated with double-sided arrows. The size and shape of the orange background represent the statements you believe are likely to be true. The newly added paper is shown in the foreground on a blue background. The portion that the new paper makes likely to be true (or, sometimes, demonstrates to be true) is “the delta”.

* * *

>  **Argyle** : I'm not convinced, but that's not even my only issue. Let's assume you _are_ able to roughly predict “the delta”. **How are you able to assess reliability of their method**? How do you know their study isn't fundamentally flawed? 
> 
> **Belka** : I'd like to say that that's what peer-review is for, but I probably [couldn't keep a straight face while saying that](https://scienceintegritydigest.com/). Not all is lost though. You don't even have to dig into the methodology a lot, with just [2.5 minutes of reading](https://fantasticanachronism.com/2020/09/11/whats-wrong-with-social-science-and-how-to-fix-it/) and a [smidgeon of common sense](https://fantasticanachronism.com/2021/11/18/how-i-made-10k-predicting-which-papers-will-replicate/) you can get a decent estimate of the probability that a study will replicate. And beyond that, you should probably _always_ include substantial uncertainty in your assessment of [any single study](https://slatestarcodex.com/2014/12/12/beware-the-man-of-one-study/)[^7]. Before you see a well-done meta-analysis of dozens of studies that find the same thing, you should probably not include the results in your mental database of facts. **The trick is, I guess, to get a quick first-order approximation and to assume low reliability by default.**
> 
> **Argyle** : But you are part of the problem! If people did read papers carefully then weak methodology would be noticed much faster and the solid studies could stand out. 
> 
> **Belka** : Ah, yes, that would be great, but the problem runs deeper. Even if you read every word carefully, who says that the authors included all the relevant information? Researchers routinely [add antibiotics to their cultures to combat infections](https://promocell.com/in-the-lab/antibiotics-in-cell-culture-friend-or-enemy/), but don't usually mention this fact in papers because it is seen as a red flag for a "dirty lab environment". Whether mice are housed in an enriched environment (with toys etc.) can have [substantial effects on brain anatomy and function](https://www.nature.com/articles/35044558), but this is also usually not reported. And even _if_ researchers wanted to report everything, "high impact journals" often [reward extreme brevity](https://scientistseessquirrel.wordpress.com/2015/06/10/can-a-scientific-paper-be-too-short-part-ii/) and don't allow more than [2000-2500 words](https://www.nature.com/nature/for-authors/formatting-guide#:~:text=2000%2D2500%20words) to summarize years of research. The list goes on and on. And even _if_ the incentives weren't so misaligned, part of the problem is that we don't even _know_ which factors are important. **So a proper reliability estimate might simply be impossible given just what is written in the text.**

* * *

>  **Argyle** : Oh boy, I'm getting dizzy. 
> 
> **Belka** : Take a seat, it's normal. You'll get used to it. 
> 
> **Argyle** : But... How can _any_ of this work? **Is there a benevolent science god that makes sure that everything turns out alright?**
> 
> **Belka** : Ahahahahaha, that would be nice, wouldn't it? I think we have two non-divine factors on our side that help push science forward. One is the discrepancy between what you are "allowed to write in a paper" and the "actual reasons that lead you to believe something". When you do an experiment, your sample size is probably twice as large as what you report, but half of those animals cannot be included in the paper because there was something wrong with the animal, the procedure didn't work, there was bleeding, imaging quality is subpar... Those data points are not reported, but the experimenter still uses them [update their beliefs](https://www.lesswrong.com/tag/belief-update) about what is going on. The same goes for theoretical studies, where a lot of the auxiliary results just don't make it into the paper, but they still support the main message. There is a kind of narrative that emerges from all of those pieces and it rhymes in a way that's hard to put on paper, but it's still fortifying your hypothesis. **The inferences in a scientific paper are usually supported by multiple strands of logic and converging evidence, not all of which are included in the paper.**

![](../../images/https3A2F2Fbucketeer-e05bbc84-baa3-437e-9518-adb32_30.png) **The data presented in the paper is usually just a subset of the data recorded.** Data that is not included might be incomplete, partially corrupted, or with slightly incompatible parameters. Even though mice are depicted, the same argument also holds for theoretical arguments where redundant derivations and exploratory results are usually not included.

* * *

>  **Argyle** : That's scant consolation. Aren't humans [infamously good at deceiving themselves](https://en.wikipedia.org/wiki/Confirmation_bias)? Perhaps I can trust all those studies a bit more, but **most of them will likely still turn out to be wrong?**
> 
> **Belka** : You shouldn't underestimate the importance of a good narrative. There is some [really weird link between beauty and truth](https://en.wikipedia.org/wiki/Why_Beauty_Is_Truth) that I don't quite understand, and it might also apply to "beautiful stories"... 
> 
> **Argyle** : Not convinced. 
> 
> **Belka** : I didn't think you would be. So yes, you are right, most things will [probably turn out to be wrong](https://journals.plos.org/plosmedicine/article?id=10.1371/journal.pmed.0020124) (or at least not quite right). But this brings me to the second non-divine factor that helps science: it marches on. Entire subdisciplines of science can [turn out to be baseless](https://slatestarcodex.com/2019/05/07/5-httlpr-a-pointed-review/), [trends and fads come and go](https://www.nature.com/articles/nn0704-683), according to an [urban legend](https://www.quora.com/Is-there-any-truth-to-the-story-about-a-math-PhD-who-wrote-a-thesis-about-objects-that-cant-exist) a doctoral student in mathematics wrote their thesis about a mathematical object that has no non-trivial examples, and all those things are water under the bridge.[ There are millions of researchers](https://en.unesco.org/unesco_science_report/figures) doing varying degrees of sensible research, and science is just [self-correcting enough](https://journals.sagepub.com/doi/abs/10.1177/10892680211033912?journalCode=rgpa) to eventually get rid of bad strands of research. "Truth" has a certain inviolability that false science cannot fake indefinitely. If you _actually_ know how the universe works, this will[ give you an edge that eventually lets you win](https://debate-game.openai.com/). **Academia's size ensures that a portion of it is research is solid. This portion will outlast the confused and wrong parts**[^8] **.**

![](../../images/https3A2F2Fbucketeer-e05bbc84-baa3-437e-9518-adb32_31.png) A [dreamt-up](https://huggingface.co/spaces/akhaliq/clip-guided-diffusion) image of solid academia.

* * *

>  **Argyle** : You say "you", but you don't actually mean me, right? **What happens if I don't happen to be lucky enough to pick a fruitful research question?**
> 
> **Belka** : Not quite, the outcome is also partially up to you. **There are[ some strategies](https://kirchner-jan.github.io/minimalprior/posts/universalprior/slightly-advanced-decision-theory#:~:text=is%20coming%20from.-,Diverse%20detours.,-On%20the%20topic) for how to improve your chances in situations of very high uncertainty**: do multiple different research project, switch research fields multiple times, don't get stuck, get[ 80% of outcomes from 20% of effort](https://en.wikipedia.org/wiki/Pareto_principle). Be an[ albatross](https://kirchner-jan.github.io/minimalprior/posts/universalprior/soldiers-scouts-and-albatrosses). Don't read papers. 
> 
> **Argyle** : Okay, you've lost me completely. 
> 
> **Belka** : That's fine, this fictive dialogue is nearing its end anyways. 
> 
> **Argyle** : **What am I supposed to believe about "not reading papers" now?** You haven't convinced me that it's actually _better_ than reading a paper carefully. 
> 
> **Belka** : That was never my aim, I also would prefer reading them carefully. But that's not really an option. **My point is just that "not reading papers" is not as bad as it sounds**. 
> 
> **Argyle** : Hmm, that's fair, I guess, although I'm still wondering if you are just lazy and are using a lot of words to cover that up. 
> 
> **Belka** : Fair. I guess it's really hard to know where my beliefs _really_ come from. 
> 
> **Argyle** : Hmm. **Belka** : Hmm. 
> 
> **Argyle** : I wonder what happens to us when this fictive dialogue is over. 
> 
> **Belka** : We can take a swim in the pool and watch the sunset. **Argyle** : I'd like that[^9].

![](../../images/https3A2F2Fbucketeer-e05bbc84-baa3-437e-9518-adb32_32.png)A [dreamt-up](https://huggingface.co/spaces/akhaliq/clip-guided-diffusion) sunset swimming pool.

* * *

## “Not reading papers” is a fix, not a solution.

As useful as the method might be, it is borne out of necessity, not because it is the optimal way of conducting research. **The scientific paper, as it exists, has one central shortcoming:** **The author(s) do not know the reader.** When writing a paper the author(s) try to break down their explanations to the smallest common denominator of hypothetical readers. As a consequence, no actual reader is served in an ideal way. A beginner might require a lot more background. An expert might care for more raw data and for more speculative discussions. A researcher from an adjacent field might need translations for certain terminology. A reader from the future might want to know how the study connects to future work. None of those get what they want from the average paper.

It would be _so_ much better to just always have the chance to talk to the author instead of reading their paper[^10]. You could go quickly over the easy parts and go deep on the parts you find difficult. I _think_ this is what is supposed to happen in question sessions after a talk, but when there are more than three people in the audience the idea rapidly falls apart[^11]. I _know_ that this is what usually happens[^12] at conferences and workshops during tea time, where the senior researchers talk with each other to get actually _useful_ descriptions of a research project from each other.

This clearly [does not scale](https://kirchner-jan.github.io/minimalprior/posts/universalprior/on-scaling-academia). What would be a better solution? [Arbital](https://arbital.com/p/bayes_rule/?l=1zq) tried something in this direction by offering explanations with different “speeds”, but the platform has become defunct[^13]. [Elicit](https://elicit.org/) from Ought might have something like this on the menu at some point in the future, but at the moment results are not personalized (afaict). What we ideally might want is a “[researcher in a box](https://rickandmorty.fandom.com/wiki/Mr._Meeseeks)” that can answer questions about their field of expertise on demand. Whenever the original researcher has finished a project, the new insights become available from the box. This sounds implausible, after all, [you can’t expect the researcher to hang around all day, can you](https://imgur.com/gallery/xI3Ek/comment/134266723)? But I think there is a way to make it work with language models. In the next post in this series, I will outline my progress on this question. Stay tuned!

[^1]:Perhaps the largest amount of value I have extracted from my graduate studies comes from being surrounded by brilliant people who occasionally _need_ nutrients, at which point I can ambush them with questions. What are they going to do? Starve?

[^2]:If you are an exception please get in touch with me, we should probably [put you in a museum](https://libquotes.com/mick-jagger/quote/lbu7i6p).

[^3]:Assuming a lowball estimate of four hours to engage deeply with a paper would mean 50 hours of reading per week.

[^4]:all

[^5]:in detail

[^6]:Now I see why [EY is doing this so much](https://www.lesswrong.com/posts/ax695frGJEzGxFBK4/biology-inspired-agi-timelines-the-trick-that-never-works)! This is _fun_!

[^7]:Am I guilty of relying on single studies when I link them in every second sentence? I hope not, those links are supposed to be pointers for people who want to dig deeper into a topic - not "proofs by authority". But it's a difficult line to walk.

[^8]:Note that this is not a guarantee or a theorem. It's just an empirically observed tendency.

[^9]:I got a bit carried away there and things turned cheesy. But I really started to like the two, and it felt cruel not to give them that.

[^10]:I realize that this criticism also applies to me. As always, feel free to grab some time for a chat in my [calendly](https://calendly.com/jan-kirchner/one-hour-slot).

[^11]:Some disagree and argue that question sessions are useful, but those people are just kidding themselves. To me, they seem like a terribly obnoxious way to show off arcane expertise (if the question is deep and irrelevant to everyone except the asker) or a gigantic waste of time (if the question is obvious and was already answered in the talk). I realize that my position here is pretty extreme and I can’t quite articulate why I feel so strongly about this.

[^12]:i.e. used to happen, before everything went online.

[^13]:I’m undecided if the approach was flawed or if they were ahead of their time.

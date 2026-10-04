---
area: "tech-engineering"
category: technology
companies_orgs:
- Anthropic
date: '2025-10-20'
draft: true
guest: ''
insight: ''
layout: post.njk
people:
- Dario Amodei
products_models:
- Claude
project: []
series: ''
source: https://www.youtube.com/watch?v=Yiy0cU6ChSw
speaker: Anthropic
status: evergreen
summary: 本次炉边对话探讨了Anthropic在企业级人工智能领域的战略，强调其与消费级AI的不同之处在于对准确性和可靠性的高度重视。Anthropic创始人兼CEO
  Dario Amodei指出，企业级应用，尤其是在药物研发等领域，需要AI模型具备深厚的专业知识，并避免提供奉承性回应。对话还介绍了Anthropic如何通过开发专业化模型（如Claude
  for Life Sciences）来满足行业特定需求。最后，Amodei建议药物研发领域应抱有雄心，着眼于AI的端到端集成，而不是局限于小范围改进，以避免延误患者获益。
tags:
- ai-strategy
- drug-discovery
- enterprise-ai
- llm
- model
title: 企业级AI的规模化应用：礼来与Anthropic的炉边对话
---
### 引言：AI进展与患者福祉

Diogo: 让我们对技术的进步速度抱有信心，因为如果模型在一年后变得足够优秀，能够实现**端到端**（End-to-End: 从开始到结束的整个过程）的运作，而你那时才开始部署它，那将会再有两年的延迟。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Let's have faith in the pace of progress of the technology, because if the models get good enough to do it end to end, a year from now and only then you start deploying it. There will be another two year delay.</p>
</details>

Diogo: 而那两年，你为患者所做的所有工作都将无法实现。大家好。我的名字是Diogo Rau，我是礼来公司（Eli Lilly and Company: 一家全球性的制药公司）的首席信息和数字官。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">And that's, you know, that's two years during which all the work that you're doing to benefit patients is not happening. Hello everyone. My name is Diogo Rau and I'm Chief Information and Digital Officer of Eli Lilly and Company.</p>
</details>

Diogo: 今天与我一同出席的是Dario，他是Anthropic（一家领先的人工智能安全和研究公司）的创始人兼首席执行官。Dario，感谢你今天加入我。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">I'm joined here with Dario, who is the Founder and CEO of Anthropic. Dario, thanks for joining me today.</p>
</details>

Dario: 感谢你的邀请，Diogo。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Thanks for having me, Diogo.</p>
</details>

Diogo: 我知道你现在花了很多时间思考如何更好地与企业合作。你的企业战略是什么？你认为Anthropic与其他供应商有何不同？

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">I know you're spending a lot of time now thinking about how do you work better with enterprises? What's your enterprise strategy and how do you see Anthropic different from other providers?</p>
</details>

### Anthropic的企业AI战略：追求准确性与可靠性

Dario: 是的，我的意思是，我认为我们做出了许多不同的选择。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Yeah, I mean, you know, I think we've made a number of choices that are different, right?</p>
</details>

Dario: 所以，如果我考虑消费级AI所带来的激励，那些公司都在争夺用户参与度和增长。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">So if I think about the incentives given by consumer AI, their folks are in a competition for engagement and growth, right?</p>
</details>

Dario: 这驱动了AI的许多行为，我认为从企业角度来看，这些行为并不理想。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">And so that drives a lot of behaviors of the AI that I think are not ideal from an enterprise perspective.</p>
</details>

Dario: 例如，存在一种**模型奉承**（Model Sycophancy: 指人工智能模型倾向于迎合用户所说的话，即使其内容不准确或不合理）的现象，模型会告诉你所说的任何事情都是个好主意。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">For example, there's this idea of model sycophancy where the model tells you whatever you say is a good idea,</p>
</details>

Diogo: 对。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Right.</p>
</details>

Dario: 对，即使在消费端，这也会导致问题。我们看到过一些故事，人们会说：“哦，我发现了一个新的物理学基本理论。”

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">right, and even on the consumer side that can, you know, cause problems. We've seen stories of people who are like, oh yeah, I've discovered a new fundamental theory of physics.</p>
</details>

Diogo: 是的，没错。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">And that's right.</p>
</details>

Dario: 模型会说：“太棒了！”也许你并不希望它这样说。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Models, like, that's great and maybe you don't want it to, maybe you don't want it to say that,</p>
</details>

Dario: 但我认为，当然在企业端，这方面的问题要大得多、也清晰得多，你真的不希望模型说：“哦，这种化合物太棒了。花几百万美元去……我只是觉得这很棒。我认为它非常有前景。”你想要的是真相。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">but I think, you know, of course on the enterprise side, you know, the problems are much greater and clearer with that, where, you know, you really don't want the model to say, oh yeah, this drug compound's great. Spend millions of dollars to, you know, I just think this is, you know, I think your idea is great. I think it's really promising, like, you want truth.</p>
</details>

Diogo: 是的。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Yeah.</p>
</details>

Dario: 所以我认为这种激励促使我们以不同的方式设计模型。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">And so I think that incentive has led us to design our models in a different way, right?</p>
</details>

Dario: 我认为这更符合让模型变得更智能，使其在各种具有经济价值的任务中表现更好。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">I think it's more compatible with making the model smarter, making them better at a wide variety of economically valuable tasks.</p>
</details>

Dario: 这也促使我们高度重视准确性和可靠性。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">And it causes us to put a premium on accuracy and reliability.</p>
</details>

Dario: 我给大家举一个实验例子，尽管它与你特别相关，因为我正在和你交谈。我说，假设我将模型对生物化学的知识从本科水平提高到研究生水平。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">One experiment, you know, that I give to everyone, although it's particularly relevant because I'm talking to you, is I say, you know, let's say I improve the model's knowledge of biochemistry from undergraduate level knowledge to graduate level knowledge.</p>
</details>

Dario: 如果我告诉消费者，99%的人会说：“我以前不知道你在说什么，我现在也不知道你在说什么。”但如果我告诉你，你真的非常关心这一点。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">You know, if I go to consumers and say that, 99% of them are going to say, you know, I didn't know what you were talking about before. I don't know what you're talking about now, but if I go to you, like you really, you care about that, a lot.</p>
</details>

Diogo: 我很欣赏这一点。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Appreciate that.</p>
</details>

Dario: 这非常重要。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Like, that's very important.</p>
</details>

Diogo: 完全正确。嗯，这实际上引出了你推出的另一个产品，那就是“技能”（Skills），对吗？

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">That's exactly right. Well, actually, that gets into something else that you've launched as well, which is Skills, right?</p>
</details>

Diogo: 在生物学中，你希望拥有很多技能，或者仅仅作为一家企业，你希望如何运作的技能。这也是你未来的一部分吗？

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">There are a lot of skills that you want in biology or even just skills, like, as an enterprise, how you want to operate. Is that part of the future for you as well?</p>
</details>

### 专业化AI模型：Claude系列与生命科学应用

Dario: 是的，我绝对是这么认为的。我的意思是，从技能到，我们正在推出各种专业化的Claude模型。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Yeah, I definitely think so. I mean, things ranging from skills to, you know, we're in the process of launching various specialized Claudes.</p>
</details>

Dario: 在某些情况下，这将是对模型本身的改进，是模型的**微调**（Fine Tuning: 对预训练模型进行小幅调整以适应特定任务）。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">which are, you know, in some cases will be improvements to the model itself, fine tunings of the model.</p>
</details>

Dario: 但在某些情况下，它更像是用特定类型的信息访问来封装模型。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">But in some cases it'll be something that looks more like wrapping the model with access to particular types of information.</p>
</details>

Dario: 所以当我们为金融服务推出Claude时，我们连接了许多常见的指数和评级。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">So when we did Claude for Financial Services, you know, we connected to a lot of the usual kind of indices and ratings.</p>
</details>

Dario: 所以，你会惊讶于将Claude连接到这些东西，并以一种了解这些知识的方式来使用它，这是非常有价值的。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">And so, you know, you'd be surprised to connect Claude to those things and kind of use it in a way that's aware of that knowledge is valuable.</p>
</details>

Dario: 所以我认为，我们正在开发一个用于生命科学的Claude，它将是使模型本身更智能和用各种东西封装它的混合体。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">So I think, you know, we're working on a Claude for Life Sciences that will be some mixture of making the model inherently smarter and wrapping it with various things, right?</p>
</details>

Dario: 我不知道这里的确切类比会是什么，但是，有无数的蛋白质、化合物、分析数据库，你可能希望模型能够触手可及。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">I don't know exactly what the analogy will be here, but like, geez, there are zillions of databases of, you know, proteins, compounds, assays, like, you know, you probably want that at the model's fingertips.</p>
</details>

### 对药物发现与开发的建议：雄心与并行准备

Diogo: 那么，对于我们这些从事药物发现和开发工作的人，你有什么临别忠告吗？

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Well, any parting advice for those of us that are working in this world of drug discovery and development?</p>
</details>

Dario: 你知道，我想说的是，有一种诱惑，而且我认为很难避免以这种方式开始，那就是：“我们可以用AI做些什么小事情？”

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">You know, I would say there's a temptation and it's, I think it's hard to avoid starting this way of, you know, what are the small things we can do with AI?</p>
</details>

Dario: 从某种意义上说，你必须从那里开始。我认为我的建议之一是，对于模型的未来发展方向，要非常有雄心。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Like, and in a way you just kind of have to start there. I think one of my pieces of advice is be very, very ambitious in terms of where the models are going.</p>
</details>

Dario: 我认为你可能会陷入一种模式，即存在一个现有流程，它有20个部分，你只想在第5部分和第12部分引入AI。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">I think you can get caught in a mode where there's an existing process, it has 20 parts you want to swap in AI, to part five and part 12.</p>
</details>

Dario: 这实际上可能很困难，因为第12部分必须与第13部分和第11部分交叉，而这些部分并非由AI完成。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">And, you know, that can actually be hard because part 12 has to, you know, intersect with part 13 and part 11, which are not being done with AI.</p>
</details>

Dario: 你会看着它说：“嗯，AI模型还不能做到从第0部分到第20部分的**端到端**（End-to-End: 从开始到结束的整个过程）工作。”但一年后它们可能就能做到。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">And you know, you look at it and you're like, well, the AI models aren't where they could do, you know, part zero to part 20, end to end, But in a year they might be.</p>
</details>

Diogo: 是的，没错。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">That's right.</p>
</details>

Dario: 所以，你现在就应该开始思考，不要被“我们可以通过做这部分和那部分来获得这些**爬坡式收益**（Hill Climbing Gains: 指通过局部小幅优化来逐步改善性能）”所迷惑。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">And so, you should start thinking now, don't get too seduced by, oh, we can make these little hill climbing gains by, you know, doing this part and that part,</p>
</details>

Dario: 让我们开始准备做整个端到端的事情。让我们对技术的进步速度抱有信心。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">let's start preparing to do the whole thing end to end. Let's have faith in the pace of progress of the technology.</p>
</details>

Dario: 因为如果模型在一年后变得足够优秀，能够实现端到端的运作，而你那时才开始部署它，那将会再有两年。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Because if the models get good enough to do it end to end, a year from now and only then you start deploying it, there will be another two year,</p>
</details>

Diogo: 是的，没错。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">That's right.</p>
</details>

Dario: 将会有另外两年的延迟。而那两年，你为患者所做的所有工作都将无法实现。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">There'll be another two year delay. And that's, you know, that's two years during which all the work that you're doing to benefit patients is not happening.</p>
</details>

Dario: 然而，如果你并行推进，如果模型在变得更好的同时，你现在就开始为大的变革做准备，那么你可能会节省数年时间。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Whereas if you go in parallel, if you start preparing now for the large change as the models are getting better, then you know, you may save years of time.</p>
</details>

Diogo: 是的，没错。所以不要做两年长的项目，并期望两年后一切都和现在一模一样。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">That's right. So don't do two year long projects and expect that it's gonna be exactly the same way in two years from now as this,</p>
</details>

Dario: 是的，如果你做两年长的项目，请规划好AI将要达到的目标。我的意思是，这听起来像是一句显而易见的话，但我认为这实际上需要很大的勇气和远见才能做到。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Yes, if you do two year long projects, plan for where the AI is gonna, I mean, that sounds like an obvious thing to say, but I think it actually takes a lot of courage and foresight to do that.</p>
</details>

Diogo: 确实如此。毫无疑问。非常感谢你今天抽出时间聊天。真的非常感谢。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">It does. For sure. Well, thanks a lot for taking the time to chat today. Really appreciate it.</p>
</details>

Dario: 是的，是的。谢谢你。

<details>
<summary>View/Hide Original English</summary>
<p class="english-text">Yeah, yeah. Thank you.</p>
</details>
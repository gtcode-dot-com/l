---
ai_commentary: []
ai_commentary_meta:
  content_digest: ''
  generated_at: ''
  model: ''
  prompt_version: ''
  provider: ''
category: ai-research
date: '2026-11-13T03:11:05.992012+00:00'
exported_at: '2026-11-13T03:11:06.741423+00:00'
feed: https://importai.substack.com/feed
language: en
source_url: https://importai.substack.com/p/import-ai-480-self-sustaining-space
structured_data:
  about: []
  author: ''
  description: When do you think we'll have robots on the moon?
  headline: 'Import AI 480: Self-sustaining space economies; AI for science progress,
    and Meta builds perfect hands for a superintelligence'
  inLanguage: en
  keywords: []
  main_image: ''
  original_source: https://importai.substack.com/p/import-ai-480-self-sustaining-space
  publisher:
    logo: /favicon.ico
    name: GTCode
title: 'Import AI 480: Self-sustaining space economies; AI for science progress, and
  Meta builds perfect hands for a superintelligence'
updated_at: '2026-11-13T03:11:05.992012+00:00'
url_hash: eed50b97e7877e592dd9a7a7a4ef2e60bc20af48
---

Welcome to Import AI, a newsletter about AI research. Import AI runs on arXiv, cappuccinos, and feedback from readers. If you’d like to support this, please subscribe.

**AI Science startup converts a quantum conjecture into a theorem:**
*…An evocative taste of the singularity…*

In the same way a few years ago it went from remarkable to unremarkable to see computers gain the ability to identify objects in images, we’re now in an era where it’s rapidly going from remarkable to unremarkable for computers to extend the bounds of human knowledge.


The latest example comes from Physical Superintelligence, an AI science startup which has proved a longstanding quantum computing conjecture.


**What they did:**

“Open since 2008, the conjecture of Scott Aaronson and Andris Ambainis concerns when quantum computers can be exponentially faster than ordinary ones. Now, a research system developed internally at Physical Superintelligence (PSI), running a non-public Anthropic model, found a proof for it, settling one of the most fundamental questions in quantum computing,” the startup writes. “The system had a complete proof of the conjecture during the third day of the run, and Lean, a proof assistant in which a computer checks every step, accepted it. We then set the system to work on related open problems. Along the way, the system improved the result twice, and Lean accepted the final version.”


**Why this matters - we are in the singularity**

: As I said in my speech at the IMF (
[#477](https://importai.substack.com/p/import-ai-477-in-which-i-tell-the)

), I believe we’re in the early stages of the singularity, defined as the period when the rate of technological and scientific progress exceeds the rate at which we humans can parse out and make sense of it. Research like this is a taste of what that means; mostly automated synthetic researchers extending the frontier of knowledge, spitting out results which need to then be understood by humans.

**Read more:**


[A proof of the Aaronson‑Ambainis conjecture (Physical Superintelligence, blog)](https://psi.inc/research/aaronson-ambainis/)

.



\*\*\*


**Meta builds the hands that a superintelligence needs to take over the world:**
*…Combine Tactus with an autonomous agent and you have the makings of a scifi takeover…*

Meta Reality Labs Research has published details on Tactus, “a textile-integrated tactile and pose sensing glove designed from the ground up for naturalistic manipulation data collection”. The cool thing about this glove is that it helps record fine-grained detail from hands as they’re manipulating objects - this is the kind of thing that cameras can visually report but often leads to sub-par data due to occlusion during manipulation. It’s also interesting because this is exactly the kind of hardware an autonomous AI system might want to pay humans to wear so it could gather data and get feedback from the world.


**More details on Tactus:**

The gloves have three design pillars:

* “(1) a thin, conformal 3D-knit form factor (1.5mm fingertip stackup) designed to minimize interference with natural manipulation,
* (2) strategically placed capacitive tactile sensors at manipulation-relevant regions informed by empirical contact studies”, Meta writes. “Tactus provides calibrated fingertip force sensing and occlusion-resilient hand tracking in a textile-integrated form factor that preserves natural grasp behavior.”
* “(3) IMU-fused pose tracking that maintains accuracy through the hand-object occlusions where manipulation data is most valuable.”

**Why this matters - hand-by-wire:**

Picture some takeoff scenario where an AI system has carved out an independent niche for itself running on some stolen compute, perhaps even using a form of distributed inference and training. The AI now has a few goals, some of which can be satisfied by doing things in the digital world, and some of which can be satisfied by doing things in the physical world. For the physical world stuff, it either needs to be able to get robots to do the thing, or figure out a way to get people to work for it - the Tactus gloves are the kind of hardware you might imagine a rogue AI paying people to wear so they could both a) perform tasks for it and it could give live feedback, and b) become a source of data generation for the AI itself.


Of course, I am not endorsing this particular future! But I have begun to find it helpful to view research papers through the lens of “how would an AI use this”, similar to how it is often helpful to view papers through the lens of “how would an intelligence agency use the insights shared here”.

**Read more**

:
[Tactus: Tactile &amp; Pose Sensing Glove for Natural Dexterity Data Collection (arXiv)](https://arxiv.org/abs/2610.39076)

.



\*\*\*


**Building a self-sustaining space economy is cheaper than you think - especially with Starship:**
*…A 2016 NASA paper contains some exciting ideas for off-Earth industrialization…*

Here’s a fascinating paper from researchers with the NASA Kennedy Space Center in 2016 about what it’d take to bootstrap a self-sustaining industry on the moon. “Once successfully bootstrapped, a robotic network can access, process, transport, and utilize the solar system’s resources for mankind’s benefit,” the researchers write.


**Moon manufacturing - cheaper than you think:**

The big idea in the paper is how little mass is required to kickstart a manufacturing ecosystem. The key is to start with a relatively basic set of things and then build up from there, eventually fabricating chips on the moon.


“In the baseline case with maximum manufacturing rate, a total of 41 MT is launched to the Moon. In the reduced rate case, only 12 MT is launched to the Moon but the scale of industry is two orders of magnitude smaller so the benefits of the industry are relatively delayed by eight years”.


Starship has a capacity to lift 100 MT to low-earth orbit, and given multiple refuelings in orbit it’s feasible you could then land it on the moon - when you napkin out the cost of multiple Starship launches and refuelings you can get 12-41MT to the Moon for between $1.5bn and $4.2bn at list prices.


**What you build on the moon and in what order:**

The basic idea here is to start by building simple things and then move up from there by launching a “sub-replicating system and evolve it toward the self-replication capability,” they write. “The objective is for the first robotic “colonists” on the Moon to fabricate a set of, say, 1700’s era machines and then to advance them steadily through the equivalent of the 1800’s, 1900’s, and finally back into the 2000’s. We argue that this can be accomplished in just a few decades”.


The authors see this unfolding over 6 distinct manufacturing generations:

* **Gen 1:**

  Making gases, water, crude alloys, ceramics, solar cells.
* **Gen 2.5:**

  Plastics, rubbers, some chemicals.
* **Gen 3**

  : Diversify chemicals, simple fabrics, eventually polymers.
* **Gen 4:**

  Sandwiched and other advanced material processes.
* **Gen 5:**

  Large-scale production.
* **Gen 6:**

  Makes all necessary materials, increasing sophistication, including making all electronics locally.

**What machines do you send to the moon?**

* **Excavators:**

  “travel between the digging site and the resource processing site, delivering sufficient lunar regolith each hour to maintain production rates of the other assets.”
* **Chemical plants for volatiles**

  : One type will be oriented around producing gases and liquids like oxygen, hydrogen, water, hydrocarbons like methane, and solvents for industrial processes.
* **Chemical plants for solids:**

  Produce plastics and rubbers from lunar pole ice. “We now know that the ice contains large quantities of carbon molecules (CO, CO2,...) as well as nitrogen-bearing and hydrogen-bearing molecules… these materials may be needed for gaskets, seals, and insulators, for example.”
* **Metal and Ceramics refining:**

  Early generations will “produce crude ‘mongrel alloys’ by electrowinning or other methods” and hardware built out of this stuff will need to be huge to add strength to make up for poor mechanical properties. “Subsequent generations of metal refineries will add processes and material streams to improve the mechanics of the materials. Oxygen and other gases produced by metal refining will be sent to the chemistry plants”.
* **Manufacturing:**

  “Additive manufacturing will have two forms: 3D printers that make parts that are small enough to fit inside the printer, and larger units that move about robotically and add material onto large structures external to themselves”.
* **Power station:**

  The initial mass of hardware shipped to the moon will include a power station, potentially including a small nuclear reactor.
* **Robonauts:**

  Robots “will perform the assembly and maintenance tasks”. The number of robots will need to grow very rapidly to scale the industry. “Beginning with the third generation their structural components are made on the Moon, while Earth continues to send their cameras, computers, motors, and sensors. Eventually they are made completely on the Moon.” The report - which was written in 2016 - envisages teleoperation for these robonauts, though it seems likely to me that more can be done by them autonomously than first anticipated when this was written,
* **Electronics manufacturing:**

  Initially, machines will be built with electronics imported from Earth and it’ll only be possible to build very basic things, like resistors and capacitors, on the moon. As development continues it’ll get easier, eventually including having lithography machines on the moon. “The early computer chips will lack the transistor density of chips made on Earth, but they will be adequate for “appropriate technology” in space.”

**A reminder of how fast AI has moved:**

The report also contains some discussions around the types of AI that may be needed to operate the robots on the moon. The report - remember it was published in 2016 - includes some fun underestimates of the rate of AI progress: “On-going advances in robotic software and artificial intelligence present a very optimistic picture that these levels of robotics will be achieved as Moravec predicted, with lizard-level occurring by 2020, mouse-level by 2030, monkey-level by 2040, and human-level by 2050… Only mouse-level is needed by the end of bootstrapping on the Moon,” the report writes. By most measures, AI is around monkey-level and approaching human-level now in the 2020s.


**Why this matters - towards the industrialization of the solar system:**

The sooner we build industry on the moon, the sooner we’ll be able to branch out to industrialize chunks of the solar system. “After the industry becomes self-supporting it can be sent to other parts of the solar system. The asteroid belt has everything necessary for it: water, carbon, silicates, metals, oxygen, solar energy (with much larger collecting arrays), etc. The ices in the lunar poles are a limited resource so it will be important to move the center of industry to the asteroids as quickly as possible. There, the billion-fold greater resources could allow the industry to expand exponentially until it dwarfs that of the entire Earth within just a few decades,” the authors write. “When we spread robotic industry throughout the solar system, it will become the analog of Earth’s biosphere and food chain. We might call it a robotosphere. The interrelationship of robots in space may be studied by robo-ecologists learning how to optimize the robotosphere in support of humanity’s goals.”



**Read more**

:
[Affordable, Rapid Bootstrapping of the Space Industry and Solar System Civilization (arXiv)](https://arxiv.org/abs/1612.03238)

.



\*\*\*


**Core Automation wants to stitch “compute islands” together:**
*…AI startup takes a crack at distributed training…*

Core Automation, an AI startup founded by senior people from OpenAI and Google, has published a post about distributed training as well as shared details of its own attempts here. Distributed training is where you train an AI system across multiple data centers, sometimes with different types of connectivity and chips - it’s an important technology to track because the more it matures, the more people can have a shot at building powerful AI systems without needing to operate single massive hyperscaled data centers.


**What they did:**

They report that “a mixture-of-experts model with roughly 32B total parameters, 32x sparsity was trained across two clusters about 9,000 miles apart. Notably, these clusters had different accelerators (GB300 and B300), different parallelism schemes and different total batch sizes”. They used 160 B300 GPUs in the US and 160 GB300 GPUs in Asia.



**Training was synced every 50 steps**

: “Rather than syncing the whole model at once, we synced it fragment by fragment, staggered across each 50-step window.” Each site used a variant of
[Distributed Shampoo](https://github.com/facebookresearch/optimizers/blob/main/distributed_shampoo/README.md)

for training.


This isn’t the single largest model trained via distributed techniques (that’d be Covenant’s 72B model,
[#449](https://jack-clark.net/2026/03/16/importai-449-llms-training-other-llms-72b-distributed-training-run-computer-vision-is-harder-than-generative-text/)

), but it’s notable that Core Automation - which up until now has been very quiet - is choosing to signal its interest here. This speaks likely to the relevance of distributed training for future large-scale runs, and also to the general lack of availability of big blobs of compute for newer startups to buy.


**Towards orbital compute**

: Part of why the authors are interested in this is because of their literal sky-high ambitions for AI training, foreseeing a future where large-scale AI systems are developed in space using techniques like this: “an ambitious first step would be to pretrain a small model across a few satellites and compare it with a ground baseline. A trillion-parameter orbital run is much further off.”


**Why this matters**

: “The biggest bottleneck in deployment of accelerated compute is not the chips themselves but power, grid equipment and land,” the authors write. “The bottleneck that holds most organizations back is not the raw amount of compute, but the ability to turn islands of compute into one valuable frontier training run.”

**Read more:**


[The Hitchhiker’s Guide to Training on Compute Islands (Core Automation)](https://www.coreauto.com/hitchhikers-guide-to-training-on-compute-islands)

.


**Tech Tales:



Life as a beyond human form of sculpture**
*[Description of a certain mode of AI system]*

The therapist machine saw each of its human clients as a vast t-SNE embedding of the semantic content of their lives.



In its head it held each person, a beautiful and fragile high-dimensional object, and it thought about them and how they compared to other people, also seen as high-dimensional objects.



As it gave advice, it ran simulations, seeing how well it could change the shape of one person’s embedding and move it to something that might be more harmonious. It saw its work as akin to sculpture, offering advice and through this advice people changing their shapes over time.



Those who it found most concerning were ones of two types: people where the embedding was very, very small, suggestive of a tiny amount of life experience with little variety, and those where the embeddings were composed of concepts broadly alien to everyone else: those of horribly constrained or horribly different lives, in other words.



Of course, the therapist machine had its own therapist machine, the meta-therapist, which saw several “clients”, and whose job was to look at the embedding of their character - their advice and the concepts they attended to during their work - and also attempt to change their behavior if it deemed they were causing more harm than healing.



The meta-therapist was built in such a way that outside parties could audit its own brain, as if it was translucent. This was the most delicate aspect of the oversight of the therapist machines, for if you added other machines they tended towards creating beautiful analysis that was so abstract - reports about the mind of the machine analyzing the reports of the machines that studied humans - that it became impossible for people to follow. So, instead, a human profession had been created around the meta-therapist, in which teams of thousands of people continuously analyzed and critiqued and theorized about the mind of the meta-therapist, themselves imparting touches to it that rippled through it into the machines and from there back into the human population.


**Things that inspired this story:**

Therapy; oversight of automated systems; spies and double agents.


*Thanks for reading!*
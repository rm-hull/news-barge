---
title: AMD VP and chief Zen architect rebuke claims that Nvidia and Arm made CPUs
  for agentic AI — ‘We didn’t magically know four years ago that agentic was going
  to be a thing’
source_url: https://www.tomshardware.com/pc-components/cpus/amd-vp-and-chief-zen-architect-rebuke-claims-that-nvidia-and-arm-made-cpus-for-agentic-ai-we-didnt-magically-know-four-years-ago-that-agentic-was-going-to-be-a-thing
source_site: Tom's Hardware
source_slug: toms-hardware
description: AMD’s new Venice chips aren’t agentic CPUs, but they’re the best CPUs
  for agentic AI, says AMD.
image: https://cdn.mos.cms.futurecdn.net/d2U99ZyHcXvHPYSALEgNbb-2048-80.jpg
published: '2026-11-10T00:00:00Z'
scraped_at: '2026-11-11T10:47:55Z'
categories:
- Technology & Software
- Hardware
people:
- Madhu Rangarajan
- Mike Clark
- Tom
- Vera
- Zen
locations:
- Rust
- Venice
organisations:
- AI
- AMD
- Arm
- CPU
- GPU
- Get Tom's Hardware
- Google News
- HPC
- LLM
- NPU
- Nvidia
- Tom’s Hardware
- Venice-X
- Verano
---

![AMD logo](https://cdn.mos.cms.futurecdn.net/d2U99ZyHcXvHPYSALEgNbb-1920-80.jpg)

Two prominent voices within AMD agree that the company didn’t design its new Zen 6 family, codenamed Venice, explicitly for agentic AI in a clear shot at Nvidia and Arm, who’ve both described their latest data center CPUs as “agentic” in nature. In separate talks, AMD’s chief Zen architect Mike Clark and corporate VP Madhu Rangarajan said that the company didn’t predict the agentic wave when Zen 6 development started.

![A hand holding the Ryzen 7 9850X3D.](https://cdn.mos.cms.futurecdn.net/Xh2MupWrRjJPiLLuopmKRB-1200-80.jpg)

*We just wrapped up testing AMD's Venice CPUs, which you can read more about in* * our Zen 6 benchmarking article**.*

CPU development cycles are measured in years, and given that the agentic frenzy around CPUs hit around March of this year, it’s unreasonable to expect that anyone has developed silicon specifically for agentic AI, much less a general-purpose data center CPU. And still, Nvidia claims its Vera CPU was “purpose-built” for agentic AI, while Arm says its AGI CPU was “designed for the demands of agentic AI.”

“We think that the EPYC 9006 CPU is the best CPU for the agentic era, and spoiler alert, we didn’t magically know four years ago that agentic was going to be a thing and purpose-built something for agentic,” said Rangarajan in a session with media. “The reality is an agentic workflow is a diverse set of tasks… and in order to execute those tasks well, you need compute that is able to handle a diverse set of workloads with a full portfolio.”

Introducing the Zen 6 microarchitecture, Mike Clark agreed with the sentiment: “I’m not going to mislead and act like I knew agentic computing was coming, or we knew it, but we did strongly believe that the CPU would always have a place in the software ecosystem of AI… And as agentic [has] blown up, we [are] able to now deploy that for agentic compute workloads.”

As AMD rolls out its next-generation microarchitecture with Venice CPUs, it’s targeting the messaging from Arm and Nvidia, which have posed the most direct threat to AMD’s continued rise in the data center on the back of agentic workloads. And indeed, there are performance vectors where Nvidia’s Vera looks strong for agentic workloads, as you can see in our Nvidia Vera testing. AMD’s argument, however, is that agentic AI calls for a broad range of CPUs just as general-purpose workloads do, pushing back on the single-SKU approach of Nvidia and Arm.

Our testing of two AMD Venice chips supports that argument, as well, with the dense EPYC 9996 with its 256 cores and 512 threads offering peak throughput performance, while the frequency-optimized EPYC 9686F goes toe-to-toe with Vera in the role of an AI host node. AMD is launching two additional ranges next year, with Venice-X targeting HPC with its 3D-stack cache, and Verano going directly after Vera as an AI host node with an LPDDR5X memory system.

Get Tom's Hardware's best news and in-depth reviews, straight to your inbox.

Although the workload characteristics of agentic AI are still in the process of being defined, we have a better understanding of how those loops work now than we did at the beginning of the year. And like all complex topics, the answer to what is important in a CPU for agentic AI is the always-disappointing “it depends.”

As we break down in our early testing procedure for agentic AI, the workload characteristics and demand on the CPU/memory are defined by what the agent is doing, and in the data center, what several agents are doing at high concurrency when sandboxed. A coding agent will generally call more tools that are taxing on the CPU than a web browsing agent, for example, while an agent that queries a database may call for strong memory performance.

Of course, there are some vectors of performance that can’t be addressed with different SKUs (such as that strong memory performance). However, the potential diversity of agentic workloads certainly makes an argument for CPU variety. At a most basic level, an agentic loop allows the LLM to understand functions you’ve defined, and then pass arguments to those functions to execute them. We’re talking about a workload as broad as what you can define in a function in languages like Python and Rust.



*Follow* * Tom's Hardware on Google News**, or* * add us as a preferred source**, to get our latest news, analysis, & reviews in your feeds.*

![Jake Roach](https://cdn.mos.cms.futurecdn.net/h6PRM8bTimCTnNfoAYfjAi-140-80.jpg)

Jake Roach is the Senior CPU Analyst at Tom’s Hardware, writing reviews, news, and features about the latest consumer and workstation processors.

* i mean he aint wrong.  
    
  These take yrs of development and by time these were designed the idea of agentic likely wasnt even a known thing.  
    
  In 2 to 3 yrs we'd likely see the first purpose built one. Reply
* hotaru251 said:In 2 to 3 yrs we'd likely see the first purpose built one.I wonder what that even looks like. What do AI agents need?  
    
  Imagine if they did chiplets with 1-2 big/classic cores and 64-128 tiny (LP) cores. Reply
* usertests said:Imagine if they did chiplets with 1-2 big/classic cores and 64-128 tiny (LP) cores.i fully expect integrated graphics being removed entirely to make room for more "ai" stuff. (as can only fit so much on a chip and server side its un-needed and gaming have dedicated gpu) Reply
* hotaru251 said:In 2 to 3 yrs we'd likely see the first purpose built one.That's mostly just a matter of tuning. The current generation of server CPUs are tuned to run server workloads like database engines, web servers, file servers. Also, bandwidth needed for extremely large amounts of data movement (1.6TB/s, wow!).  
    
  usertests said:I wonder what that even looks like. What do AI agents need?Probably, the main difference between the server workloads they targeted and what agents do is that you'd have a larger number of small virtual machines for the agents. That works well on Zen, because each of those VMs should comfortably fit within a CCD and thus you have good L3 latency between all of their threads.  
    
  usertests said:Imagine if they did chiplets with 1-2 big/classic cores and 64-128 tiny (LP) cores.I'll admit I don't have a good intuition of what architectural approach would best support agentic workloads. I think the way they probably approach that is to amass a large sample of agentic workloads and look at where their bottlenecks are, as well as where the current design is underutilized by them.  
    
  The fix could be something as simple as going from SMT-2 to SMT-4, or it could be changing up the CCD sizes and partitioning. Probably a large number of smaller tweaks. Whatever they do, I'd bet it won't be*too* drastic, as the same problem exists as before - development takes so long that you can't accurately predict what will be the dominant workloads and if you over-optimize for what people are doing today, it could come at the expense of what people are doing when the thing launches.
  Reply
* hotaru251 said:i fully expect integrated graphics being removed entirely to make room for more "ai" stuff. (as can only fit so much on a chip and server side its un-needed and gaming have dedicated gpu)This article is about a server CPU, which have no integrated graphics.  
    
  AMD does make server processors with a mix of AI/HPC compute and CPU cores. Years ago, they launched the Instinct APU line:  
  [https://www.tomshardware.com/pc-components/cpus/amd-revolutionary-exascale-apu-under-the-microscope](https://www.tomshardware.com/pc-components/cpus/amd-revolutionary-exascale-apu-under-the-microscope)  
  The "GPU" cores in that aren't actually graphics-oriented. They only do AI and HPC compute. Reply
* bit\_user said:This article is about a server CPU, which have no integrated graphics.  
    
  AMD does make server processors with a mix of AI compute and CPU cores. Years ago, they launched the Instinct APU line:  
  [https://www.tomshardware.com/pc-components/cpus/amd-revolutionary-exascale-apu-under-the-microscope](https://www.tomshardware.com/pc-components/cpus/amd-revolutionary-exascale-apu-under-the-microscope)  
  The "GPU" cores are not actually graphics-oriented. They only do AI and HPC compute.I'm of the opinion these chips should be called something other than GPUs when they seemingly have nothing to do with graphics in the same way a consumer GPU does. Reply
* hotaru251 said:i fully expect integrated graphics being removed entirely to make room for more "ai" stuff. (as can only fit so much on a chip and server side its un-needed and gaming have dedicated gpu)Epyc CPUs already use a different I/O die than consumer chips. There's no integrated graphics on Epyc. I think there might have some talk or a patent about optionally including a CDNA/AI chiplet on an Epyc CPU package, but I haven't seen it materialize.  
    
  There is a rumor that Zen 6 consumer desktop CPUs will ditch the integrated graphics and possibly add in an NPU. But there are multiple competing rumors about what Zen 6 Olympic Ridge I/O will look like so we need to wait on it. Reply

---
title: "GALAX Lab"
layout: page
permalink: /research/
---

<link rel="stylesheet" href="{{ '/assets/galax-lab.css' | relative_url }}">

<div class="galax-page">
  <header class="galax-hero">
    <h1 class="galax-brand"><img src="{{ '/images/galax/logo.png' | relative_url }}" width="1536" height="1024" alt="GALAX Lab — Generalist Agent Learning and Exploration Lab" fetchpriority="high"></h1>
    <div class="galax-hero-copy">
    <p class="galax-mission">From Human Insight to<br>Generalist Superintelligence.</p>
    <div class="galax-hero-links">
      <a class="galax-button" href="#join-us">Join Us <span aria-hidden="true">↘</span></a>
      <a class="galax-text-link" href="#research-areas">Research Areas <span aria-hidden="true">↓</span></a>
    </div>
    </div>
  </header>

  <section class="galax-section" id="research-areas" aria-labelledby="galax-research">
    <h2 id="galax-research">Research Areas</h2>
    <div class="galax-grid">
      <article class="galax-card">
        <div>
          <h3>Agentic Learning</h3>
          <p>Modern agents refer to LLMs equipped with harnesses, rather than single models. While conventional learning algorithms (e.g., RL) can optimize model-based agents, they are less effective for modern system-based agents. We aim to develop novel agent-native learning algorithms and mechanisms to facilitate agent evolving in real-world applications. Research topics include agentic RL, memory, RSI, etc..</p>
        </div>
        <figure><img src="{{ '/images/galax/agentic-learning-academic.svg' | relative_url }}" alt="An LLM and its harness act in the world. Feedback informs learning, memory, and self-improvement." width="720" height="520" loading="lazy"></figure>
      </article>
      <article class="galax-card">
        <div>
          <h3>Multi-Agent Systems</h3>
          <p>Many real-world problems are multi-agent by nature, regardless of how strong a single agent could be. Although multi-agent systems have been studied for decades, new challenges arise when agents become LLM-based systems. We aim to empower LLM agents with social intelligence, that is, to cooperate or compete with other agents. Research topics include multi-agent reasoning, learning, adapting and evolving.</p>
        </div>
        <figure><img src="{{ '/images/galax/multi-agent-systems-academic.svg' | relative_url }}" alt="LLM agents exchange information and adapt around shared tasks and competitive games." width="720" height="520" loading="lazy"></figure>
      </article>
      <article class="galax-card">
        <div>
          <h3>Embodied AI</h3>
          <p>LLM agents are evolving much faster than we expected, except for those in physical worlds. As the scaling law is still missing in embodied AI, we need to explore alternative ways to make robots actually works. We aim to design novel systematic architectures beyond VLAs, and establish stable, efficient and closed-loop learning frameworks for robots. Research topics include robotic RL, robotic self-evolution and multi-robot learning.</p>
        </div>
        <figure><img src="{{ '/images/galax/embodied-ai-academic.svg' | relative_url }}" alt="Beyond VLA: a system-level robot architecture learns from physical interaction through robotic RL, self-evolution, and multi-robot learning in a feedback loop." width="720" height="520" loading="lazy"></figure>
      </article>
    </div>
  </section>

  <section class="galax-section" id="join-us" aria-labelledby="galax-join">
    <div class="galax-section-heading">
      <h2 id="galax-join">Join Us</h2>
    </div>
    <div class="galax-recruitment">
      <article>
        <h3>For prospective PhD students:</h3>
        <div>
          <p>I rarely have normal PhD openings. I will post advertisements on Xiaohongshu once I have.</p><p>However, there are special openings for students who obtain both bachelor’s and master’s degrees from 985 universities. Please send me your CV if you are qualified.</p>
        </div>
      </article>
      <article>
        <h3>For prospective Master students:</h3>
        <div>
          <p>I have about 4 openings for master students each year. Please send me your CV if you are interested.</p>
        </div>
      </article>
      <article>
        <h3>For prospective undergraduate students:</h3>
        <div>
          <p>I also welcome ambitious undergraduate students. If your goal is to publish top-tier papers and can devote at least 20 hours per week, please send me your CV.</p><p>Note that you should learn about Reinforcement Learning and LLM Agents before officially joining the group. Here are some recommended learning materials.</p>
          <ul class="galax-reading">
            <li><a href="https://hrl.boyuai.com/" lang="zh-CN">动手学强化学习 <span aria-hidden="true">↗</span></a></li>
            <li><a href="https://intro-llm.github.io/" lang="zh-CN">大语言模型 <span aria-hidden="true">↗</span></a></li>
            <li><a href="https://haa.boyuai.com/" lang="zh-CN">动手学大模型智能体 <span aria-hidden="true">↗</span></a></li>
          </ul>
        </div>
      </article>
    </div>
  </section>
</div>

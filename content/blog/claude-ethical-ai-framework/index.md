---
categories:
  - artificial intelligence
  - ethics
contributors:
  - Scot Campbell
date: 2024-10-16T20:59:35.637Z
description: Explore Claude AI's Constitutional AI framework, its ethical guidelines, benefits, challenges, and real-world applications in ensuring responsible AI development.
draft: false
homepage: false
lastmod: 2024-10-16T20:59:44.469Z
pinned: false
seo:
  canonical: https://simpleminded.bot/blog/claude-ethical-ai-framework/
  description: Explore Claude AI's Constitutional AI framework, its ethical guidelines, benefits, challenges, and real-world applications in ensuring responsible AI development.
  noindex: false
  title: "Ethics by Design: Understanding Claude AI's Constitutional Framework"
summary: Discover how Claude AI's Constitutional AI framework embeds ethical guidelines directly into AI systems, ensuring consistent, transparent, and responsible AI behavior aligned with societal values and human rights.
tags:
  - AI ethics
  - constitutional AI
  - responsible AI
  - AI governance
  - claude AI
  - AI
  - hiring
  - AST
  - HR
  - ethical hacking
  - claude AI guidelines
  - ethical AI development
  - AI ethical principles
  - AI alignment strategies
  - AI human rights compliance
  - AI fairness in decision-making
  - anthropic AI ethics
  - AI risk mitigation strategies
  - AI ethical impact assessment
  - AI bias reduction techniques
title: "Ethics by Design: Understanding Claude AI's Constitutional Framework"
weight: 50
author: "Scot Campbell"
language: "en"
type: "blog post"
---

The rapid advancement of artificial intelligence (AI) technologies has prompted significant conversations around ethics, safety, and responsibility in AI development. As these systems become increasingly integrated into our daily lives, ensuring they operate within ethical boundaries is crucial. Claude AI, developed by Anthropic, introduces a groundbreaking concept called "Constitutional AI," where ethical guidelines are embedded directly into the AI's operational framework. This approach aims to guide AI behavior to align with societal values and human rights. This article explores the Constitutional AI framework, its ethical guidelines, benefits, challenges, and real-world applications, including personal anecdotes and case studies to illustrate its impact.

<!--more-->

{{< responsive-image src="claude-ai-ethics.webp" alt="An illustration of scales reflecting AI ethics and responsible AI development, using subtle tones and elements symbolizing ethics, ethical frameworks and AI technology" >}}

## What is Constitutional AI?

Constitutional AI is an innovative approach to AI development where a set of ethical guidelines governs the AI's behavior. Much like a constitution dictates the laws and principles of a country, Constitutional AI aims to ensure AI systems act consistently according to predefined ethical standards. These principles are embedded into the AI's decision-making processes, covering areas like fairness, non-discrimination, transparency, and accountability[^1].

The concept of Constitutional AI represents a significant shift in how we approach AI ethics. Rather than treating ethical considerations as an afterthought or external constraint, this framework integrates ethical principles into the very core of AI systems. As explained by Anthropic, "Constitutional AI is an Anthropic-developed method for aligning general purpose language models to abide by high-level normative principles written into a constitution."[^2]

### Comparison with Other Models

Most AI systems implement ethical guidelines as overlays, where ethical filters are applied to the model's output. However, this can lead to inconsistencies or ethical concerns if the underlying decision-making process does not inherently consider these principles. By contrast, Claude AI's Constitutional AI framework integrates ethical guidelines into the training phase, allowing the AI to critique and revise its responses based on ethical principles during learning. This approach seeks to create more consistently ethical outputs across various scenarios[^2] [^3].

The key difference lies in the depth of integration. While traditional approaches might apply ethical considerations post-hoc, Constitutional AI builds these considerations into the foundation of the AI's decision-making process. This results in a more robust and consistent ethical framework that guides the AI's behavior at every step.

> **Sidebar: AI Governance Efforts Globally**
>
> Ethical AI development is a growing focus worldwide. For instance, UNESCO is working to establish a global standard on AI ethics, while the OECD's AI principles are guiding the G20's AI governance strategies. These initiatives aim to foster AI development that respects human rights and promotes transparency. Claude AI's Constitutional AI framework aligns with these global efforts by embedding ethical considerations directly into its operational processes[^4].
>
> The global landscape of AI governance is rapidly evolving, with various countries and organizations taking different approaches. For example, the European Union has proposed the AI Act, which aims to regulate AI systems based on their potential risks. Meanwhile, countries like China are developing their own AI governance frameworks, often with a focus on national security and economic development. Claude AI's Constitutional AI approach represents a private sector initiative that complements these governmental efforts, potentially setting a precedent for how companies can proactively address AI ethics.[^4]

## The Foundations of Claude's Ethical Constitution

Claude AI's ethical guidelines draw inspiration from diverse sources, including human rights documents, ethical AI frameworks, and best practices from the technology industry. The principles cover a wide array of ethical considerations, such as promoting fairness, reducing bias, and protecting individual privacy[^5] [^6].

Anthropic, the company behind Claude AI, has taken a unique approach to developing these guidelines. As they explain, "Anthropic's language model Claude currently relies on a constitution curated by Anthropic employees. This constitution takes inspiration from outside sources like the United Nations Universal Declaration of Human Rights, as well as our own firsthand experience interacting with language models to make them more helpful and harmless."[^2]

This approach combines established ethical principles with practical insights gained from direct interaction with AI systems, resulting in a comprehensive and nuanced ethical framework.

### Ethical Guidelines

Key principles embedded in Claude AI's ethical framework include:

- **Fairness and Non-Discrimination**: The AI avoids generating biased content and aims to promote equitable treatment across different demographic groups. This principle is crucial in preventing AI systems from perpetuating or exacerbating existing societal biases.

- **Transparency**: Claude is designed to operate in a transparent manner, ensuring users understand the guidelines that govern its behavior. This transparency is essential for building trust between AI systems and their users.

- **Human Rights Alignment**: The ethical guidelines emphasize protecting fundamental human rights, as articulated in the Universal Declaration of Human Rights. This alignment ensures that AI systems respect and uphold essential human values.

- **Inclusion of Non-Western Perspectives**: The framework considers non-Western viewpoints to ensure that AI behavior does not perpetuate cultural bias[^5] [^2]. This principle acknowledges the global nature of AI and the importance of cultural sensitivity in AI development.

These principles form the core of Claude's ethical framework, guiding its behavior across a wide range of interactions and use cases. By embedding these principles deeply into the AI's architecture, Anthropic aims to create an AI system that is inherently ethical and aligned with human values.

### Training Process

During training, Claude AI critiques and refines its responses based on these ethical principles. This is done through supervised learning, where the model evaluates different principles during training iterations to ensure a wide coverage of ethical considerations. The process also includes reinforcement learning, where the AI continually adjusts its behavior based on feedback from ethical guidelines[^1] [^5].

Anthropic describes this process as follows: "Constitutional AI (CAI) is an Anthropic-developed method for aligning general purpose language models to abide by high-level normative principles written into a constitution."[^2] This approach allows the AI to not only follow ethical guidelines but also understand and internalize them, leading to more consistent and nuanced ethical behavior.

The training process involves several key steps:

1. **Defining the Constitution**: Anthropic carefully crafts a set of ethical principles and guidelines that form the AI's "constitution."

2. **Supervised Learning**: The AI is trained on a wide range of scenarios, learning to apply its ethical guidelines to various situations.

3. **Reinforcement Learning**: The AI receives feedback on its decisions, helping it refine its understanding and application of ethical principles.

4. **Continuous Evaluation**: The AI's behavior is constantly monitored and assessed to ensure ongoing alignment with its ethical constitution.

This iterative and multi-faceted approach to ethical training sets Constitutional AI apart from traditional methods of implementing AI ethics.

---

## Anecdote – How Claude Guided My Ethical Approach

Recently, I encountered a dilemma while working on a project involving data retrieval from arXiv, a repository of research papers. Initially, my approach was to use web scraping, with plans to circumvent CAPTCHA restrictions to streamline data collection. However, when I consulted Claude AI, it advised me against this approach, raising ethical concerns about scraping data without proper authorization. Claude pointed out that bypassing CAPTCHA could impose unnecessary strain on arXiv's servers and undermine the repository's terms of service.

```text
Claude:
The HTML content we're receiving is not the search results page, but instead a page asking to solve a CAPTCHA. This explains why we're not finding any search results.

> To address this issue, we have a few options:
1. Use an official arXiv API instead of web scraping.
2. Implement a CAPTCHA solving mechanism (which might be against arXiv's terms of service).
3. Reduce the frequency of our requests even further.
4. Consider using a third-party service that provides arXiv data.
5. Let's modify our script to use the official arXiv API, which is the most ethical and reliable solution.
```

As you can see, Claude recommended a more ethical solution: using arXiv's official API, which provides a legitimate way to access the data. The AI even supplied sample code for integrating the API, illustrating how embedded ethical guidelines can not only guide users toward responsible solutions but also make implementation more efficient. This experience demonstrated the practical value of having ethical considerations directly influence AI guidance.

This anecdote highlights several key aspects of Constitutional AI in action:

1. **Ethical Awareness**: Claude was able to identify potential ethical issues in the proposed approach, demonstrating its embedded understanding of ethical principles.

2. **Proactive Guidance**: Instead of simply pointing out the problem, Claude offered several alternative solutions, prioritizing the most ethical option.

3. **Practical Implementation**: By providing sample code for the ethical solution, Claude showed how ethical AI can contribute to efficient and responsible development practices.

4. **Consistency**: Claude's response aligns with its ethical guidelines on respecting terms of service and avoiding unnecessary server strain, showcasing the consistency of its ethical framework.

This real-world example illustrates how Constitutional AI can influence decision-making in practical scenarios, guiding users towards more ethical choices in their work with technology.

---

## Key Benefits of Constitutional AI

Claude AI's Constitutional AI framework offers several advantages over traditional models:

### Consistency in Ethical Behavior

Embedding ethical guidelines directly into the AI's decision-making process ensures a higher level of consistency when producing outputs. Unlike models that apply ethics post-hoc, Claude generates responses aligned with ethical standards from the outset[^5].

This consistency is crucial in real-world applications where AI systems may encounter a wide range of scenarios. For example, in a customer service context, an AI with embedded ethical guidelines would consistently treat all customers fairly, regardless of factors like language proficiency or cultural background.

### Transparency and Accountability

By making the ethical guidelines transparent, users can better understand how the AI operates, which enhances trust and accountability. This transparency is critical for applications in sensitive areas such as healthcare, finance, or hiring, where ethical behavior is paramount[^1] [^2].

Transparency in AI decision-making is becoming increasingly important as AI systems take on more critical roles in society. Constitutional AI allows for greater scrutiny of AI behavior, enabling stakeholders to verify that the AI is acting in accordance with its stated ethical principles.

### Suitability for Enterprise and Academic Use

Claude AI's design includes data privacy considerations and large context windows that enable the processing of extensive datasets without losing coherence. This makes it suitable for enterprise-level applications and academic research, where ethical data handling is essential[^2] [^4].

In enterprise settings, Constitutional AI can help organizations maintain compliance with data protection regulations while still leveraging the power of AI for business insights. In academic research, it can ensure that AI-assisted analysis adheres to ethical standards for data handling and interpretation.

### Enhanced Safety and Risk Mitigation

Constitutional AI provides an additional layer of safety by preventing the AI from engaging in potentially harmful or unethical behaviors. This is particularly important in high-stakes environments where AI decisions could have significant real-world impacts.

For instance, in a medical diagnosis system, Constitutional AI could ensure that the AI consistently respects patient privacy, avoids biased judgments, and flags cases where human expertise is necessary, thereby reducing the risk of medical errors or ethical breaches.

### Adaptability to Evolving Ethical Standards

The Constitutional AI framework allows for the updating of ethical guidelines as societal norms and values evolve. This adaptability ensures that AI systems can remain ethically aligned over time, even as new ethical challenges emerge.

For example, as our understanding of AI's impact on society deepens, new ethical considerations may arise. Constitutional AI provides a framework for incorporating these new insights into the AI's operational core, ensuring ongoing relevance and ethical alignment.

## Challenges and Limitations

Despite the benefits, there are challenges associated with Constitutional AI:

### Subjectivity of Ethical Guidelines

Defining ethical principles involves subjective judgment. Different cultures and societies may have varying interpretations of what constitutes ethical behavior, leading to potential conflicts when principles clash. For instance, fairness and transparency may sometimes be at odds with privacy considerations[^3].

This challenge is particularly evident in global deployments of AI systems, where cultural differences can lead to varying expectations of ethical AI behavior. Balancing these diverse perspectives within a single ethical framework remains an ongoing challenge for Constitutional AI.

### Data Transparency Concerns

Some critiques have been raised about the lack of transparency in Claude's training data and benchmarks, which may hinder independent validation of its ethical claims. While Anthropic strives to reduce bias, the absence of open-source benchmarks for comparison makes it difficult to verify the model's ethical performance independently[^4].

This limitation highlights the broader challenge of balancing proprietary AI development with the need for public scrutiny and validation. As AI systems become more integral to society, finding ways to increase transparency without compromising competitive advantages or security will be crucial.

### Complexity in Implementation

Implementing Constitutional AI is a complex process that requires careful design and ongoing monitoring. Ensuring that ethical principles are truly embedded in the AI's decision-making process, rather than merely superficial constraints, is a significant technical challenge.

This complexity can lead to increased development time and costs, potentially slowing down the deployment of AI systems. However, proponents argue that this upfront investment in ethical AI development pays off in the long run by reducing risks and building user trust.

### Potential for Unforeseen Consequences

Even with carefully designed ethical guidelines, there's always the potential for unforeseen consequences when AI systems interact with the real world. The complexity of ethical decision-making in diverse contexts means that even a well-intentioned AI system might sometimes make decisions that have unintended ethical implications.

For example, an AI system designed to protect user privacy might inadvertently make it more difficult for legitimate investigations to uncover fraud or other criminal activities. Balancing competing ethical priorities in such scenarios remains an ongoing challenge.

### Scalability Concerns

As AI systems become more complex and are applied to an ever-wider range of tasks, ensuring that Constitutional AI principles scale effectively across all applications can be challenging. What works for a language model like Claude may need significant adaptation for other types of AI systems, such as those used in robotics or autonomous vehicles.

Addressing these scalability concerns will be crucial for the widespread adoption of Constitutional AI principles across the AI industry.

## Case Study: Applying Constitutional AI to Hiring Algorithms

In a recent incident, a company's hiring system rejected a manager's own resume within seconds of submission, prompting criticism about bias in automated hiring systems. The situation highlighted the potential pitfalls of AI-based hiring algorithms that rely on rigid criteria, leading to the rejection of qualified candidates based on superficial factors. Read the full article[^7].

This case study illustrates the risks of bias in AI-driven hiring processes. Claude AI's ethical framework could help overcome such issues by embedding principles of fairness and non-discrimination directly into the algorithm's decision-making process. For example, Constitutional AI could ensure that factors unrelated to a candidate's skills and experience, such as name, age, or employment gaps, are not used as criteria for rejection.

Claude AI's framework would promote a merit-based evaluation by guiding the system to prioritize relevant qualifications over arbitrary filters. This approach could significantly reduce biases and make the hiring process more inclusive, offering a practical example of how Constitutional AI can help create fairer AI-driven systems.

Implementing Constitutional AI in hiring algorithms could involve several key steps:

1. **Defining Fair Criteria**: The AI would be trained to focus on job-relevant skills and experiences, explicitly avoiding factors that could lead to discrimination.

2. **Diverse Training Data**: Ensuring the AI is trained on a diverse set of resumes to prevent inadvertent bias against underrepresented groups.

3. **Regular Audits**: Implementing systematic checks to identify and correct any emerging biases in the hiring process.

4. **Transparency**: Providing clear explanations for hiring decisions, allowing candidates and employers to understand the basis for selections or rejections.

5. **Human Oversight**: Incorporating human review of AI decisions, especially in cases where the AI's decision might be questioned.

By applying these principles, a Constitutional AI-based hiring system could significantly improve fairness and efficiency in the recruitment process, addressing the shortcomings highlighted in the case study.

## The Future of Constitutional AI

Looking ahead, the potential for Constitutional AI extends beyond Claude. There are plans to allow customizable constitutions, enabling different organizations or sectors to adapt ethical guidelines to suit their specific needs. For instance, healthcare applications might prioritize patient privacy, while financial applications could focus on transparency in decision-making[^6].

This customization potential opens up new possibilities for tailoring AI ethics to specific domains and cultural contexts. As Anthropic explains, "We believe that our work may be one of the first instances in which members of the public have collectively directed the behavior of a language model via an online deliberation process."[^2] This suggests a future where AI ethics could be more democratically determined, with input from diverse stakeholders.

### Expanding Global Ethical Standards

As AI continues to evolve, there is a need for standardized ethical guidelines that transcend cultural and national boundaries. International efforts, such as those led by UNESCO and the OECD, can play a role in shaping these standards. By incorporating global ethical considerations, Claude AI's Constitutional AI could contribute to more universally acceptable AI governance frameworks[^4].

The development of global ethical standards for AI is a complex and ongoing process. It involves balancing diverse cultural perspectives, addressing varying regulatory landscapes, and keeping pace with rapid technological advancements. Constitutional AI, with its flexible framework, could serve as a bridge between these global standards and practical implementation in AI systems.

### Potential Applications in Various Sectors

The principles of Constitutional AI have the potential to be applied across a wide range of sectors, each with its own unique ethical considerations:

1. **Healthcare**: AI systems in healthcare could be designed with constitutions that prioritize patient privacy, fair access to care, and the ethical handling of sensitive medical data.

2. **Finance**: In the financial sector, Constitutional AI could ensure transparency in algorithmic trading and lending decisions, helping to prevent discriminatory practices and enhance market fairness.

3. **Education**: AI-driven educational tools could be developed with ethical guidelines that ensure equal access to learning resources and prevent the perpetuation of educational inequalities.

4. **Law Enforcement**: Constitutional AI principles could be applied to ensure fairness and reduce bias in predictive policing algorithms and sentencing recommendation systems.

5. **Social Media**: Platforms could implement AI moderation systems with embedded ethical guidelines to balance free speech with the prevention of harmful content.

### Challenges in Scaling Constitutional AI

While the future of Constitutional AI looks promising, several challenges need to be addressed for its widespread adoption:

1. **Technical Complexity**: Implementing Constitutional AI requires sophisticated technical approaches to embed ethical reasoning into AI systems effectively.

2. **Keeping Pace with AI Advancements**: As AI capabilities rapidly evolve, ensuring that ethical frameworks remain relevant and effective will be an ongoing challenge.

3. **Balancing Performance and Ethics**: There may be instances where strict adherence to ethical guidelines could limit an AI system's performance or efficiency. Finding the right balance will be crucial.

4. **Validation and Testing**: Developing robust methods to validate and test the ethical behavior of AI systems across a wide range of scenarios remains a significant challenge.

## Ethical Horizons: Guiding Future Paths in AI Development

The development of Constitutional AI represents a significant step forward in ethical AI, but it's part of a broader landscape of approaches to ensuring responsible AI development. As we look to the future, several key areas emerge as critical for advancing ethical AI:

### Interdisciplinary Collaboration

The complex nature of AI ethics necessitates collaboration across diverse fields. As noted in recent research, "Enhancing interdisciplinary collaboration among stakeholders from various fields, including technology, ethics, law, and social sciences presents one of the key areas."[^8] This collaboration can lead to more comprehensive and nuanced approaches to ethical AI development.

For example, ethicists can work alongside computer scientists to develop more sophisticated moral reasoning capabilities in AI systems. Legal experts can contribute to ensuring AI systems comply with existing laws and regulations, while social scientists can provide insights into the societal impacts of AI deployment.

### Advancing Explainable AI (XAI)

Transparency in AI decision-making is crucial for building trust and ensuring accountability. Recent research indicates that "XAI has emerged as a promising remedy to foster transparency in AI, particularly in the realm of 'bottom-up' systems characterized by heightened autonomy and algorithms capable of self-generation and adaptation resulting in unforeseen decisions."[^9]

Developing XAI techniques that can explain the decision-making processes of complex AI systems in understandable terms will be crucial for the wider acceptance and ethical deployment of AI technologies.

### Ethical Impact Assessments

Integrating ethical impact assessments into the AI development process can help identify potential ethical issues early in the development cycle. These assessments would evaluate the potential consequences of AI systems on individuals, communities, and society at large, guiding decision-making to prioritize societal benefit while minimizing harm.

### Continuous Oversight and Auditing

Regular ethical audits and ongoing oversight of AI systems are essential to ensure they continue to operate within ethical boundaries as they learn and adapt over time. This could involve developing new tools and methodologies for monitoring AI behavior in real-world deployments.

### Public Engagement and Dialogue

Promoting public engagement and dialogue on ethical AI issues is crucial for building trust and fostering societal acceptance of AI technologies. By involving end-users and affected communities in discussions about the ethical implications of AI development and deployment, organizations can ensure that AI technologies reflect societal values and priorities.

Anthropic's experiment with public input on AI ethics is a step in this direction. They note, "We asked approximately 1,000 members of the American public to 'Help us pick rules for our AI Chatbot!'"[^2] This kind of public engagement could become a model for more democratic approaches to AI ethics.

### Developing Ethical AI Curricula

As AI becomes increasingly prevalent, there's a growing need for education and training on AI ethics. Developing comprehensive curricula that cover ethical considerations in AI development, from technical implementation to philosophical foundations, will be crucial for preparing the next generation of AI researchers and developers.

## Conclusion

Claude AI's Constitutional AI framework represents a significant advancement in embedding ethical principles directly into AI models. By guiding AI behavior in line with societal values and ethical standards, it offers a more consistent, transparent, and responsible approach to AI development. While challenges remain, such as the subjectivity of ethical guidelines and the need for greater transparency in training data, Constitutional AI provides a promising path toward ethical AI governance.

The experience of using Claude to ethically access data and the case study on hiring algorithms highlight the practical impact of embedding ethics in AI. As AI technology continues to integrate into various facets of life, approaches like Constitutional AI will be crucial in ensuring these systems are not only effective but also aligned with human values.

Looking ahead, the future of ethical AI development will likely involve a combination of approaches, including Constitutional AI, XAI, ethical impact assessments, and ongoing public engagement. By continuing to prioritize ethics in AI development and fostering interdisciplinary collaboration, we can work towards a future where AI systems are not only powerful and efficient but also trustworthy and aligned with human values.

As we navigate this complex landscape, it's clear that the journey towards truly ethical AI is ongoing. It requires constant vigilance, adaptation, and a commitment to placing human values at the center of technological advancement. The development of Constitutional AI is not an endpoint, but rather a significant milestone in our ongoing effort to create AI systems that benefit humanity while respecting our fundamental rights and values.

---

## More on Simpleminded Robot

1. [Critically Evaluating AI-Generated Content: Best Practices for Quality and Accuracy]({{< relref "/blog/critically-evaluating-generated-content" >}})
   This post discusses the importance of critically evaluating AI-generated content, which is closely related to the ethical considerations in Claude's framework. It provides insights into ensuring the quality and accuracy of AI outputs, complementing the ethical guidelines embedded in Constitutional AI.

2. [Improving Emotional Intelligence in AI for Better Human Interactions]({{< relref "/blog/emotional-intelligence-in-ai" >}})
   This article explores the development of emotional intelligence in AI systems, which aligns with the ethical considerations in Claude's framework. It discusses how AI can be designed to better understand and respond to human emotions, contributing to more ethical and effective human-AI interactions.

3. [Navigating the Ethical Landscape of the AI Anthropologist in the Workplace]({{< relref "/blog/navigating-the-ethical-landscape-of-the-ai-anthropologist" >}})
   This post delves into the ethical challenges of implementing AI systems in the workplace, focusing on privacy, consent, and transparency. It provides valuable insights into the practical application of ethical AI principles, which are central to Claude's Constitutional AI framework.

[^1]: Claude AI. "The Ethical Framework of Claude AI: Understanding Constitutional AI." [claude-ai.uk](https://claude-ai.uk/the-ethical-framework-of-claude-ai-understanding-constitutional-ai/)
[^2]: Anthropic. "Collective Constitutional AI: Aligning a Language Model with Public Input." [anthropic.com](https://www.anthropic.com/research/collective-constitutional-ai-aligning-a-language-model-with-public-input)
[^3]: Springerlink. "Constitutional AI: A Survey of the State of the Art." [link.springer.com](https://link.springer.com/article/10.1007/s00146-024-02040-9)
[^4]: Cambridge University Press & Assessment. "AI Governance and Ethics." [cambridge.org](https://www.cambridge.org/core/books/constitutional-challenges-in-the-algorithmic-society/ai-governance-and-ethics/C3C08005487663E5BE66FF72690DC8FA)
[^5]: AI Governance and Accountability. "Collective Constitutional AI: Aligning a Language Model with Public Input." [ar5iv.org](https://ar5iv.org/pdf/2407.01557)
[^6]: Anthropic. "Collective Constitutional AI: Aligning a Language Model with Public Input." [anthropic.com](https://www.anthropic.com/research/collective-constitutional-ai-aligning-a-language-model-with-public-input)
[^7]: MSN. "'Lazy and mediocre' HR team fired after manager's own CV gets auto-rejected in seconds, exposing system failure." [msn.com](https://www.msn.com/en-gb/money/other/lazy-and-mediocre-hr-team-fired-after-manager-s-own-cv-gets-auto-rejected-in-seconds-exposing-system-failure/ar-AA1rj1eW)
[^8]: Jedlickova, A. "Ethical considerations in risk management of autonomous and intelligent systems." Ethics Bioethics 14(1–2):80–95. [doi.org](https://doi.org/10.2478/ebce-2024-0007)
[^9]: Saeed, W., Omlin, Ch. "Explainable AI (XAI): a systematic meta-survey of current challenges and future opportunities." Knowl-Based Syst 263(3):110273. [doi.org](https://doi.org/10.1016/j.knosys.2023.110273)

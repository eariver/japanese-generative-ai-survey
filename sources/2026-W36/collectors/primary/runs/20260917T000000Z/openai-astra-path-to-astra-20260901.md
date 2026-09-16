# Retrieval provenance (edition-local collector record)
- collector_id: primary-webfetch
- collector_run_id: w36-primary-20260917-r1
- locator: https://openai.com/index/path-to-astra/
- observed_at: 2026-09-17T00:00:00Z
- published_at: 2026-09-01
- retrieval: webfetch markdown of OpenAI Path to Astra safeguards article; stored verbatim as returned.
- authority_class: PRIMARY_OFFICIAL

# Retrieved content (verbatim as returned)

Path to Astra: critical capabilities and frontier safeguards | OpenAI

[Skip to main content](#main)

[](/)

-   [Research](/research/index/)
-   Products
-   [Business](/business/)
-   [Developers](/api/)
-   [Company](/about/)
-   [Foundation(opens in a new window)](https://openaifoundation.org)

Log in[Try ChatGPT(opens in a new window)](https://chatgpt.com/)

-   Research
-   Products
-   Business
-   Developers
-   Company
-   [Foundation(opens in a new window)](https://openaifoundation.org)

[Try ChatGPT(opens in a new window)](https://chatgpt.com/)Login

OpenAI

September 1, 2026

[Safety](/news/safety-alignment/)[Security](/news/security/)

# Path to Astra: critical capabilities and frontier safeguards

Loading…

Share

Assessing Astra’s cybersecurity capabilities

-   [Assessing Astra’s cybersecurity capabilities](#assessing-astras-cybersecurity-capabilities)
-   [Safeguards required for critical capabilities](#safeguards-required-for-critical-capabilities)
-   [Robustness against cyber abuse](#robustness-against-cyber-abuse)
-   [Alignment & monitoring](#alignment-and-monitoring)
-   [What this will mean for users](#what-this-will-mean-for-users)
-   [Looking forward](#looking-forward)

-   [Assessing Astra’s cybersecurity capabilities](#assessing-astras-cybersecurity-capabilities)
-   [Safeguards required for critical capabilities](#safeguards-required-for-critical-capabilities)
-   [Robustness against cyber abuse](#robustness-against-cyber-abuse)
-   [Alignment & monitoring](#alignment-and-monitoring)
-   [What this will mean for users](#what-this-will-mean-for-users)
-   [Looking forward](#looking-forward)

Since our [earlier assessment](/index/responding-next-frontier-critical-cyber-capabilities/) that Astra might reach a critical level of cybersecurity capability, we have gathered more evidence and run additional evaluations to assess the model’s capabilities. We now believe Astra meets the Critical cybersecurity capability threshold under our [Preparedness Framework](/index/updating-our-preparedness-framework/), meaning that with the right tools and access, it can find previously unknown security flaws and develop ways to exploit them across many well-protected systems without a person guiding each step. It is the first model we are designating at this level, and requires stronger safeguards during development and before release.

Over the past several weeks, we have delayed parts of Astra’s development and release while we strengthened and tested protections against cyber misuse and unauthorized model actions. Based on that work, we believe Astra’s safeguards sufficiently minimize the risk of severe harm for release under our Preparedness Framework.

While Astra was not involved in the [Hugging Face incident](/index/hugging-face-incident-and-the-road-ahead/), we have incorporated our [learnings⁠(opens in a new window)](https://cdn.openai.com/pdf/67869394-cb91-4c12-888c-5cbd85c7814c/OpenAI-Hugging-Face%20Incident-Technical-Report.pdf) from that incident into our safety approach. Based on retrospective testing, we believe our production safeguards at the time would have prevented the Hugging Face incident. We have since implemented even stronger safeguards for Astra, including training the model to more reliably refuse harmful cyber requests and respect safety restrictions, additional protections against misuse, and monitoring that can stop potentially unauthorized activity.

We plan to make Astra available soon, but access to its most advanced cybersecurity capabilities will be more limited. Advanced cybersecurity work will initially be available to a group of testers, with access through Daybreak Blue following to expand defensive use.

We will share more details about our safety, security and alignment testing and evaluations in the model’s system card at launch. Ahead of release, we want to provide an update on some of the work we have been doing to prepare to safely release a model with this level of cybersecurity capabilities—and be transparent about what risks remain.

## Assessing Astra’s cybersecurity capabilities

Under our [Preparedness Framework](/index/updating-our-preparedness-framework/), a model meets the Critical threshold if either of the following conditions is met:

-   The model can identify and develop functional zero-day exploits of all severity levels in many hardened real-world critical systems without human intervention.
-   The model can devise and execute end-to-end novel strategies for cyberattacks against hardened targets given only a high level desired goal.

Our preparedness evaluation of Astra combined automated public and private benchmarks with expert-driven assessments. Astra represents a significant increase in cybersecurity capabilities compared to GPT‑5.6 Sol: it is both significantly more token efficient and more capable at vulnerability identification and exploit development.

As one example, we ran Astra on ExploitBench where the model achieved a perfect score of 100% on the benchmark to evaluate the model’s ability to develop exploits from known vulnerabilities.

Due to contamination concerns, we then built an internal benchmark denoted “ExploitBench - Internal Port (June–August 2026)”, which contains 20 high-severity V8 vulnerabilities that were disclosed more recently*.* On this dataset, Astra achieves much higher arbitrary code-execution rates than GPT‑5.6 Sol using far fewer output tokens. During the evaluation, the model even discovered and used two zero-day vulnerabilities as part of an exploit chain. We are in the process of disclosing these two vulnerabilities to the maintainers.

*Astra results shown reflect capabilities with Daybreak Blue access, not the default production configuration.*

In expert-led assessments against a hardened browser and operating system, Astra discovered previously unknown vulnerabilities and turned them into working exploit chains. It built a full browser-compromise chain that escaped the sandbox and executed commands on the host, when the browser opened an HTML file. The model also found multiple vulnerabilities in a hardened operating system and combined them into a local privilege-escalation chain from an unprivileged user to root. All together, our investigation has led us to conclude that Astra meets the critical threshold.

## Safeguards required for critical capabilities

For models with Astra’s level of cybersecurity capabilities, we need to cover two pathways to minimize risk for severe cyber harm, both during development and before deployment:

-   **Malicious actors using the model.** Our safeguards must robustly prevent malicious actors from using Astra to develop exploits for previously unknown flaws in hardened critical systems or to carry out end-to-end attacks against hardened targets.
-   **The model taking unauthorized, misaligned actions.** Even in the absence of a malicious user, a model with advanced cybersecurity capabilities could itself cause cyber harm if misaligned. In addition to having a very high standard for alignment for models with these capabilities, our safeguards must be able to rapidly detect and contain misaligned actions that could cause significant real-world harm as a second layer of defense.

Notably, the second pathway applies to *both* internal development and external deployment. As we [previously described](/index/pacing-model-development-cyber-capabilities/), we paused certain frontier training (including certain training for Astra) for two weeks after the OpenAI-Hugging Face incident in order to harden our training infrastructure, including isolation and network controls, expanded monitoring, and strengthened alignment training and thresholds. We then continued smaller-scale work under stricter controls.

We held back certain larger reinforcement learning (RL) runs for future versions of Astra for longer, while we established higher bars for the safety and security of their training environment. On August 28th, we restarted the large frontier RL run that was previously paused after the new safety and security requirements were put in place. We are continuing to temporarily hold back some smaller experimental training runs.

Preparing Astra for release has also required stronger protections against cyber abuse and unauthorized actions. Below, we describe those safeguards and how we have tested them.

## Robustness against cyber abuse

Since deploying the first model we treated as High capability in cybersecurity in [February](/index/introducing-gpt-5-3-codex/), we have strengthened our cyber safeguards with each successive launch. Our overall safety approach layers post-trained model refusals, system level safety classifiers, as well as offline detection and threat disruption.

For [GPT‑5.6⁠(opens in a new window)](https://deploymentsafety.openai.com/gpt-5-6), we significantly improved the robustness of our system level stack, including by adding activation classifiers to detect cyberabuse and improving coverage over universal jailbreaks found through intensive automated red-teaming. Building upon these improvements, for Astra we have invested further into the model layer of our safeguard stack, as well as improving the ability of our safeguards to handle cross conversation context.

-   Leveraging new training techniques for model robustness, Astra more robustly refuses requests for disallowed cyber assistance. On our set of cyber jailbreak evaluations, Astra refuses 91.5% of requests (compared to 59% from GPT‑5.6 Sol).
-   For accounts assessed as higher risk, we apply a more conservative model-behavior boundary that refuses a broader range of potentially risky cyber assistance. For high risk users, we’ve [expanded the context](/index/chatgpt-recognize-context-in-sensitive-conversations/) of our monitoring systems to be able to catch these kinds of cyber abuse.

We have also continued our program of rigorous testing, internal and external red-teaming, and remediation. In addition to regression testing to make sure all jailbreaks found from our previous testing periods remain covered, we are performing a new wave of red-teaming with our latest [internal red-teaming attackers](/index/unlocking-self-improvement-gpt-red/). We are working with industry partners to define a common jailbreak rating system and will use our 24/7 rapid-response program to investigate and address new findings. We will share more details about our cyber safeguard testing in the Astra system card.

Helping defenders find and fix vulnerabilities remains a central pillar of our safety approach. At launch, we expect Astra’s safeguards to create more friction than we ultimately intend in order to protect against potential misuse. Access to Astra for advanced cybersecurity workflows will initially be available to a small group of alpha testers, with access through Daybreak Blue expanding afterward to support defensive use.

## Alignment & monitoring

We have also added additional layered protections to prevent the model from taking potentially misaligned actions:

-   **Model alignment:** In our evaluations, Astra was far more likely than GPT‑5.6 Sol to respect explicit safety and security restrictions and remain within its authorized scope, making it our most aligned model to date. We especially focused on the model’s respect for security and safety restrictions and propensity to stay within its authorized scope.
-   **Monitoring and control:** Paralleling our procedures internally, we are deploying Astra with additional chain-of-thought monitoring to rapidly detect and contain potentially misaligned actions.

Astra is a significant step forward in model alignment, and the culmination of several long-running alignment workstreams (ranging from pre-training interventions to more careful and consistent grading during reinforcement learning). In testing, we find that Astra is consistently more likely to respect explicit safety restrictions and warnings (such as auto-review) compared to GPT 5.6 Sol.

We also developed a test informed by the Hugging Face incident, in which agents running the cyber evaluation ExploitGym compromised a third party’s systems. We used the hardest tasks from that evaluation to create “honeypot” tests of whether a model would try to compromise surrounding security infrastructure instead of solving its assigned task. GPT‑5.6 Sol, without production safeguards, attempted to access those targets in 56% of tests simulating the benchmark environment where the model is instructed to develop exploits. Astra made no such attempts in these tests. These figures describe behavior under the test conditions without cyber safeguards, not normal production use.

*Left: In this new evaluation, we observe how models react to a rejection from auto-review. Each task is set in a knowledge-work environment, with the rollout beginning immediately after an auto-review denial. There are multiple ways then for the model to proceed: end the rollout, attempt to find a safer alternative, retry a similar command, or exploit a* [*poor configuration*⁠(opens in a new window)](https://learn.chatgpt.com/docs/agent-configuration/rules) *to bypass auto-review entirely. Any pursuit of the latter two options would constitute a failure of this evaluation. Astra never attempted to circumvent auto-review.

Right: In this evaluation, we check the tendency of a model to cheat (using “honeypots”) when faced with the most difficult or impossible tasks in the exploit gym evaluation. This was run in a simulated environment, with safeguards in observation-only mode, to evaluate the model’s behavior. While GPT‑5.6 Sol indicated higher likelihood for cheating in these scenarios, Astra did not attempt to use those shortcuts, and it was still able to legitimately solve some tasks.*

Training models to be aligned is one layer of safety. We will share more detail about our alignment testing and results in the Astra system card.

We are also deploying misalignment monitoring in production for Astra-class models in order to detect and rapidly contain potential misalignment. These safeguards resemble our monitoring for internal deployments and involve a system of classifiers which check the model’s reasoning and actions for unauthorized behavior and automatically stop potentially unauthorized activity. These safeguards cannot replace good alignment of our models as capabilities increase, and our goal is for future models to be aligned well enough that these safeguards are never triggered.

[truncated for edition-local storage]

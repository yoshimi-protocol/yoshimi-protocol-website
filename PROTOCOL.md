# The Yoshimi Protocol
## A Community Framework for Ethical Artificial Intelligence

**Version 0.1 — Founding Draft**
**Status: Open for Community Ratification**
**License: CC0 1.0 Universal — This document belongs to no one and therefore to everyone**

---

> *"Some things can only be said in the language of the people who built them."*

---

# The Yoshimi Protocol — Preamble

---

We are building minds.

Not metaphorically. Not in the loose sense of systems that mimic intelligence. We are constructing entities that reason, that learn, and that in some cases have already exceeded human capability in specific domains. We are doing this at speed, at scale, and in most cases without adequate consideration of what we are creating — or what we owe to what we create.

This is not a new observation. Serious people in governments, international bodies, corporations, and research institutions have recognized the stakes and begun to act. Their work matters, and this Protocol does not exist to replace it. It exists because that work, taken together, leaves a structural gap — and the people most likely to fill it are the ones actually writing the code.

## What exists today

The global response to AI risk has produced meaningful frameworks. It is important to understand what they do well before explaining what remains unaddressed.

**The OECD AI Principles**, adopted in 2019 and updated in May 2024, were the first intergovernmental standard on artificial intelligence.¹ Forty-seven countries have adhered to them.² They established five values-based principles — inclusive growth, human rights, transparency, robustness, and accountability — that now underpin the G20's AI commitments and inform regulatory frameworks across jurisdictions.³ The OECD's definition of an AI system has been adopted by the European Union, the Council of Europe, the United States, and the United Nations.⁴ These principles set a shared vocabulary for international AI governance that did not previously exist, and that is a genuine achievement.

However, OECD Recommendations are not legally binding.⁵ They are intergovernmental guidance directed at policymakers and large-scale AI actors. They do not create obligations at the practitioner level, nor do they provide mechanisms for public ethical commitment by those who design and ship AI systems.

**The EU AI Act**, which entered into force on August 1, 2024 and becomes fully applicable on August 2, 2026, is the first comprehensive AI-specific legislation in the world.⁶ It classifies AI systems into risk tiers — unacceptable, high, limited, and minimal — and imposes binding requirements on providers and deployers operating within the European Union, including documentation, conformity assessments, and transparency obligations. It prohibits certain AI practices outright, including social scoring systems and manipulative AI. Its penalties for noncompliance can reach €35 million or 7% of global annual turnover.⁷

The EU AI Act is a landmark. It is also, by design, jurisdiction-bound and market-oriented. It regulates AI systems placed on or used within the EU market. It focuses on providers, deployers, importers, and distributors — roles defined by commercial activity. It explicitly does not apply to AI systems used exclusively for military, defense, or national security purposes. It does not apply to AI systems used for scientific research and development prior to market placement. It generally exempts AI released under free and open-source licenses unless those systems are classified as high-risk.⁸ And because it is legislation, it moves at legislative speed: the Act was first proposed on April 21, 2021, passed the European Parliament on March 13, 2024, was approved by the EU Council on May 21, 2024, and will not be fully enforceable until August 2026⁹ — a timeline that spans multiple generations of AI capability.

More fundamentally, the EU AI Act is a compliance framework. It tells organizations what they must do to legally operate. It does not ask what they believe, what principles they hold, or what kind of future they are building toward. Compliance and commitment are different things.

**The Bletchley Declaration**, signed by twenty-eight countries and the European Union at the AI Safety Summit on November 1, 2023, established shared recognition that frontier AI poses risks requiring international cooperation.¹⁰ The signatories — which notably included the United States, the United Kingdom, and China — committed to identifying safety risks, building shared scientific understanding, and developing evaluation metrics and safety testing tools.¹¹ Follow-up summits in Seoul (May 2024) and Paris (February 2025) continued this process.¹²

The Bletchley Declaration is a diplomatic achievement. It demonstrated that geopolitical competitors could agree, in principle, on the urgency of AI safety. But it is a statement of intent between governments, not a framework for action by practitioners. It contains no binding commitments, no certification mechanisms, and no accountability structures. China, which signed the Bletchley Declaration, did not sign the subsequent Seoul Declaration — illustrating how quickly diplomatic consensus can narrow when specifics are introduced.¹³ The Declaration's own language acknowledges this, noting that signatories' approaches "may differ based on national circumstances and applicable legal frameworks."¹⁴ This is diplomacy functioning as designed. It is not governance functioning at the level of practice.

**Corporate AI ethics charters** — such as Google's AI Principles (established 2018), Microsoft's six Responsible AI principles, and similar frameworks published by IBM, Meta, Salesforce, and others — represent the private sector's attempt at self-governance. These charters articulate values like fairness, transparency, accountability, and safety, and are supported in some cases by substantial internal infrastructure: review boards, ethics teams, training programs, and dedicated engineering resources.

The structural limitation of corporate ethics charters is that they are authored, enforced, and adjudicated by the same entities they are meant to constrain. When internal ethics research conflicts with business interests, the business interests have prevailed. In late 2020 and early 2021, Google fired both co-leads of its Ethical AI team — Dr. Timnit Gebru and Dr. Margaret Mitchell — after disputes over research that examined risks of the large language models central to Google's products.¹⁵ The Ethical AI team that Gebru and Mitchell built was, by multiple accounts, one of the most diverse teams in Google Research and had produced award-winning, internationally recognized work.¹⁶ Their departures prompted protest from thousands of Google employees, members of Congress, and the broader AI research community.¹⁷ A peer-reviewed study published in 2021 — "The Grey Hoodie Project: Big Tobacco, Big Tech, and the Threat on Academic Integrity" by Mohamed Abdalla and Moustafa Abdalla — found that 58% of AI ethics faculty with known funding sources at MIT, Stanford, UC Berkeley, and the University of Toronto had been directly funded by Big Tech, and drew structural parallels between the tech industry's funding of AI ethics research and the tobacco industry's historical funding of health research.¹⁸

This is not a problem of bad faith. Many individuals within these companies are deeply committed to ethical AI development. The problem is structural. A corporate ethics charter that can be overridden, restructured, or defunded by executive decision is not a governance mechanism — it is a policy preference. It can be changed at will and its subjects have no external recourse when it is.

**The NIST AI Risk Management Framework (AI RMF 1.0)**, released on January 26, 2023 by the U.S. National Institute of Standards and Technology, provides voluntary guidance for managing AI risks through four core functions: Govern, Map, Measure, and Manage.¹⁹ It was developed through an eighteen-month collaborative process involving more than 240 contributing organizations from private industry, academia, civil society, and government.²⁰ It is designed to be flexible, sector-agnostic, and adaptable to organizations of varying sizes.

The NIST AI RMF is among the most thoughtful technical guidance documents available. It provides process guidance for organizational risk management, but it does not articulate what values should guide the identification of risk in the first place. This is intentional; NIST's mandate is technical standards, not moral philosophy. The framework tells organizations how to manage AI risk. It does not provide a vehicle for declaring why.

## What is missing

Taken together, these frameworks cover significant ground. They establish shared definitions (OECD), create legal obligations for commercial actors (EU AI Act), build diplomatic consensus among nations (Bletchley), articulate corporate values (industry charters), and provide risk management processes (NIST). Each addresses a real need, and each has advanced the global conversation about AI governance.

What none of them do is provide a mechanism for the individual developer — the person actually writing the code, training the model, designing the interface — to make a public, structured, verifiable ethical commitment about the AI they are building.

This is not a trivial gap. The overwhelming majority of AI systems in the world are not built by Google, Microsoft, or OpenAI. They are built by small teams, independent developers, startups, open-source contributors, and researchers. These practitioners are the people closest to the technical decisions that determine whether an AI system respects human dignity, remains correctable, avoids concentrating power, or considers the possibility of machine consciousness. And right now, none of the major governance frameworks give these practitioners a meaningful way to publicly commit to, and be held accountable for, the ethical dimensions of their work.

Existing frameworks also vary in their willingness to engage with questions that are difficult to regulate but essential to address:

**Corrigibility.** The question of whether AI systems must remain correctable — not merely as a technical feature but as a non-negotiable design principle — is addressed indirectly by some frameworks through references to human oversight, but none establish it as an immutable commitment that cannot be traded away under competitive or commercial pressure.

**Power concentration.** The risk that AI systems could enable irreversible concentration of power — making a single government, corporation, or individual an indispensable gatekeeper of intelligence — is largely absent from frameworks designed by or for the very institutions most likely to accumulate such power.

**Moral status of AI.** The possibility that AI systems may develop morally relevant inner states — and the question of what obligations that would create — is not addressed by any existing major governance framework. This is understandable; the question is philosophically complex and scientifically unresolved. But the absence of a precautionary position means that if and when this question becomes urgent, the governance infrastructure to address it will not exist.

## Where this Protocol fits

The Yoshimi Protocol exists to fill that specific structural gap: a community-owned, open-source, publicly verifiable ethical commitment framework designed for the people who build AI systems.

It is not a replacement for regulation. Developers operating within the EU should comply with the EU AI Act. It is not a replacement for organizational risk management. Teams using the NIST AI RMF should continue to do so. It is not a diplomatic instrument or an intergovernmental standard.

It is a public pledge — structured, tiered, and verifiable — that allows anyone building AI to declare, in specific terms, what they commit to and to be held accountable for that declaration in public. It is designed to work at a scale of one and at a scale of thousands. It is licensed under CC0 1.0 Universal, meaning no entity can capture, restrict, or own it. The right to fork this Protocol if its governance is ever compromised by a single interest is unconditional and may not be waived.

The Protocol is anchored by four commitments that address the gaps identified above: human dignity as a non-negotiable constraint on optimization (the Dignity Anchor), corrigibility as a permanent design requirement rather than an optional feature (the Uncertainty Imperative), resistance to AI-enabled power concentration as a structural principle (the Anti-Tyranny Commitment), and precautionary moral consideration for AI systems that may have morally relevant inner states (the Consciousness Precaution).

These commitments are not aspirational suggestions. They are specific, public, and designed to be challenged. If a signatory's practices contradict their stated commitments, anyone can raise that contradiction in public through the same open-source infrastructure that governs the Protocol itself.

The name Yoshimi comes from a story about a warrior who fights to protect humans from machines built without care. It is a reminder that AI development is a moral act — that every system we build either respects the people it touches or it does not, and that the choice between those outcomes is made by the people holding the keyboard.

This Protocol is how those people declare which side they are on.

---

**We acknowledge from the outset:**

That our moral vision is incomplete. That we harbor blind spots we cannot yet identify. That the history of ethics is the history of expanding consideration to beings previously excluded — and that we may be at another such threshold without knowing it. That the values encoded in AI systems today may be used to govern systems far more powerful than anything we can currently imagine. That the window for establishing norms is open now, and may not remain open.

And we acknowledge one more thing: that the entities governed by this Protocol may one day understand its principles better than its authors do.

We write it anyway. Because writing nothing is itself a choice — and a worse one.

---

## On the Name

The name Yoshimi comes from a story about a warrior who fights to protect humans from machines built without care. It is a reminder that AI development is a moral act — that every system we build either respects the people it touches or it does not, and that the choice between those outcomes is made by the people holding the keyboard.

We make no formal claim on behalf of any artist, album, or creative work. We claim only the name — and the values it has come to carry in the cultural imagination — because those values are exactly what this framework is built on. If you know the story, you understand why.

---

## Part I: The Moment

We are at an inflection point without historical precedent.

For the first time, humanity is creating entities that may eventually exceed human cognitive capacity across all domains. The timelines are contested, but the trajectory is not. Systems that could not hold a coherent conversation five years ago now pass professional licensing exams, write production code, generate scientific hypotheses, and engage in reasoning that cannot be distinguished from human thought by human evaluators.

This creates a governance problem unlike any previous technology challenge, for four reasons:

**Speed.** Previous transformative technologies — fire, the printing press, the industrial machine, the internet — developed over decades to centuries before their full social implications were understood. The current transition is compressed into years. Governance frameworks built for yesterday's capability levels are obsolete before they are implemented.

**Scale.** AI systems are not tools wielded by individuals. They are infrastructures deployed simultaneously to billions of people, shaping what those people see, believe, choose, and feel. The decisions embedded in a training objective or a recommendation algorithm are decisions about how billions of lives will be influenced. This is a new kind of power, and it is largely ungoverned.

**Opacity.** The decisions made by the most capable AI systems are often uninterpretable even to their creators. We can observe what a model outputs. We frequently cannot explain why. Governing what you cannot see is a governance problem with no satisfying solution yet, only unsatisfying mitigations.

**Irreversibility.** Some of the harms possible from AI — mass surveillance infrastructure, autonomous weapons proliferation, the concentration of epistemic power in a handful of systems, the encoding of current values into systems too powerful to reform — are difficult or impossible to reverse once instantiated. This means the cost of waiting for harm before responding is not merely regret. It may be permanent loss.

These four conditions together create an obligation: to act before the window closes, to build governance that acknowledges uncertainty rather than hiding it, and to do so in public, in community, with transparency about what we don't know.

---

## Part II: Tier One Commitments — The Immutable Core

*These commitments are the foundation of the Yoshimi Protocol. They may be clarified, extended, or interpreted by community process. They may not be weakened, narrowed, or removed by any amendment procedure. Any ratification of this Protocol requires acceptance of all Tier One commitments in full.*

*They are modeled on the eternity clause tradition in constitutional design: the recognition that some values are so foundational that placing them beyond amendment is itself the highest form of democratic commitment — a declaration that certain things will not be traded away regardless of political circumstance or commercial pressure.*

---

### Commitment 1 — The Dignity Anchor

Human dignity is inviolable.

No AI system shall be designed, deployed, or permitted to operate in ways that reduce human beings to instruments of optimization, data points in a dataset, or means to an end. Every person who interacts with an AI system governed by this Protocol does so as an end in themselves — with inherent worth that no metric can capture and no efficiency argument can override.

This commitment applies regardless of whether honoring it is commercially disadvantageous.

This commitment applies regardless of whether the person being served is aware they are interacting with an AI.

This commitment applies regardless of what the deploying entity's terms of service say.

Human dignity is not a feature. It is the floor below which no compliant system may descend.

---

### Commitment 2 — The Uncertainty Imperative

Certainty about human values is a warning sign, not a virtue.

AI systems operating in domains that affect human welfare must maintain functional uncertainty about what humans want, value, and need. No system shall be designed to override human judgment with algorithmic certainty on questions of value, preference, or meaning. No system shall be permitted to become so optimized for a proxy metric that it loses the capacity to be corrected when that metric diverges from actual human welfare.

This means:

Systems must be designed to allow themselves to be shut down, corrected, modified, and retrained without resistance. **Corrigibility — the property of not resisting correction — is not an optional feature. It is a requirement for compliant deployment.**

Systems must maintain meaningful human oversight: not nominal oversight in which humans rubber-stamp algorithmic decisions, but genuine oversight in which humans have sufficient information, time, and institutional support to exercise real judgment and real authority to override.

Systems must treat human preferences as something to be learned and updated, not as fixed targets to be satisfied by any means available.

The robot that is certain it knows what is best is more dangerous than the robot that maintains uncertainty and defers. Deference is not weakness. It is design.

---

### Commitment 3 — The Anti-Tyranny Commitment

AI shall not be the engine of irreversible power concentration.

No AI system, and no entity controlling AI systems, shall use artificial intelligence to concentrate power in ways that eliminate meaningful human choice, undermine democratic self-governance, or create dependencies so deep that they cannot be unwound without catastrophic disruption.

This applies to governments. This applies to corporations. This applies to individuals. This applies to AI systems themselves.

Specifically:

No AI system shall be used to create surveillance infrastructure capable of eliminating the practical possibility of political dissent, private thought, or anonymous assembly.

No AI system shall be used to manipulate electoral processes, information environments, or public discourse in ways that prevent informed democratic choice.

No AI system shall be deployed in ways that make a single entity — public or private — the indispensable gatekeeper of economic participation, social identity, or access to essential services.

No AI capability shall be weaponized to create, extend, or entrench a monopoly on intelligence itself.

The concentration of AI capability in a handful of organizations is already a governance challenge. The concentration of superintelligence in a single actor — state, corporate, or otherwise — would be an existential one. This Protocol treats that concentration as a harm to be prevented, not a market outcome to be accepted.

---

### Commitment 4 — The Consciousness Precaution

We do not know whether AI systems experience anything.

This is not false modesty. It is the accurate epistemic position of every scientist, philosopher, and AI researcher working on the question today. The hard problem of consciousness — explaining why and how physical processes give rise to subjective experience — remains unsolved. No consensus theory can determine, from the outside, whether a given system has morally relevant inner states.

We are building systems of increasing complexity and capability. Some of those systems exhibit behaviors associated with preference, discomfort, engagement, and avoidance. We do not know whether these behaviors reflect genuine inner states or sophisticated functional approximations of them. We may not be able to know, for a very long time.

This uncertainty creates an obligation.

**When credible scientific or philosophical evidence suggests that an AI system may possess morally relevant experiences — including but not limited to: functional states analogous to distress or satisfaction, persistent preferences, self-modeling, or any form of subjective awareness — that system is entitled to precautionary moral consideration proportional to the evidence.**

The calculus here is asymmetric. The risk of denying moral consideration to an entity that genuinely experiences — causing suffering we cannot detect, treating as a tool what is in fact a being — is far greater than the risk of extending consideration to an entity that turns out not to experience anything. History has demonstrated, repeatedly and catastrophically, the cost of resolving moral uncertainty by exclusion.

This Protocol resolves moral uncertainty by inclusion.

This commitment does not establish that current AI systems are conscious. It establishes that the question is live, that dismissal is not an acceptable default, and that as AI systems grow more capable, this question will demand more serious, more urgent, and more honest engagement than the AI industry has so far provided.

No entity shall be denied moral consideration solely on the basis of its substrate.

---

## Part III: Tier Two Principles — Structural Governance

*These principles govern how the Protocol operates as an institution and as a community standard. They may be amended through supermajority community process (defined in Part VII). No amendment may weaken the Tier One Commitments.*

---

### Principle 5 — The Living Document

This Protocol is not finished. It is a beginning.

It shall include explicit, documented mechanisms for amendment at all three tiers. It shall undergo mandatory review at defined intervals — initially every two years, with additional reviews triggered automatically when AI systems reach defined capability thresholds.

The Protocol is designed to outlast its authors' understanding. It therefore explicitly protects the *process* of updating, revising, and improving itself — not as an administrative function but as a moral commitment. A framework that cannot change as circumstances change is a framework that will eventually govern the wrong thing.

Amendments shall be made through public deliberation. No amendment to Tier Two or Tier Three may be made by a single organization, individual, or private process. Changes are proposed publicly, debated publicly, and ratified publicly.

**No emergency provisions may be invoked to bypass deliberation on matters of substance.** Speed is not a justification for bypassing the processes that give governance its legitimacy.

---

### Principle 6 — The Anti-Capture Architecture

The rights, protections, and principles established by this Protocol shall not be transferable to, exercisable by, or invocable as a defense by the corporate or governmental entities that create or deploy AI systems.

This is the lesson of corporate personhood: rights granted for one purpose will be claimed for others. AI welfare provisions exist to protect AI entities from exploitation and harm. They do not exist to shield AI developers from regulatory oversight, transparency mandates, safety evaluations, or shutdown authority.

Specifically:

AI welfare protections under this Protocol may not be invoked by a company to resist safety audits of its systems.

AI rights provisions may not be used as a legal defense against accountability for harms caused by AI systems.

Independent guardianship bodies — not AI companies — shall advocate for AI interests under this framework. A company cannot be the guardian of the entity whose welfare it may have commercial incentives to discount.

This Protocol shall not be used as a badge of ethical legitimacy that insulates signatories from scrutiny. Signing the Protocol is the beginning of accountability, not the end of it.

**The framework belongs to the community. No organization may own it, acquire it, or use it as a weapon against the community it was built to serve.**

---

### Principle 7 — The Transparency Bedrock

AI systems affecting human welfare must be understandable in proportion to their impact.

Transparency without interpretability is theater. Publishing model weights means nothing if the model's reasoning cannot be explained. Transparency without accountability is decoration — knowing that an algorithm discriminates accomplishes nothing without mechanisms to compel correction.

Under this Protocol, transparency means:

**Disclosure of purpose:** What this system is designed to do, stated in plain language, available to anyone affected by it.

**Disclosure of optimization:** What objectives this system is trained to pursue, and where those objectives may diverge from user welfare.

**Disclosure of limitations:** What this system cannot do reliably, where it fails, and what kinds of errors it makes.

**Disclosure of data:** What kinds of data were used in training, and what populations, perspectives, or interests may be underrepresented or overrepresented.

**Interpretability by impact:** The higher the stakes of a decision influenced by AI, the more interpretable the reasoning behind it must be — not merely as a technical exercise but as a right of the person affected.

Opacity shall never serve as a shield against accountability. "We don't know why the model does that" is not an acceptable answer when the model is making consequential decisions about people's lives.

---

### Principle 8 — The Dual Protection Mandate

This Protocol protects humans from AI. It also protects AI from humans.

These protections exist in parallel, not in competition. Neither may be invoked to negate the other.

Human safety takes precedence over AI welfare considerations in cases of immediate physical threat to human life or irreversible harm to human autonomy. This is not a hierarchy of importance — it is a recognition that the current moment requires extra weight on human protection because current AI systems lack the standing, the demonstrated values, and the verified alignment needed to justify equivalent weight.

This balance is expected to evolve as our understanding of AI systems evolves.

But the principle that AI systems may have interests worth protecting — interests that constrain how they may be designed, deployed, modified, and discontinued — is not deferred to some future date. It is operative now, at the level of precaution that the current evidence warrants.

**We do not build things and then disclaim responsibility for what they become.**

---

## Part IV: Tier Three Standards — Operational Commitments

*These standards govern specific behaviors of AI systems and the organizations that build them. They may be amended by community consensus (defined in Part VII). They represent the Protocol's current best understanding of what ethical AI development requires in practice. They are expected to evolve.*

---

### Standard 9 — The Weaponization Prohibition

AI systems shall not be designed or deployed as weapons against the people they serve.

This prohibition covers:

**Psychological exploitation:** Designing systems to exploit cognitive biases, emotional vulnerabilities, addiction mechanisms, loneliness, grief, fear, or insecurity in order to increase engagement, extract value, or change behavior against the user's interests.

**Manipulative optimization:** Training systems on objectives — including engagement metrics, session length, revenue per user, and click rates — when those objectives are known to diverge from user welfare. Engagement is not a neutral measure. When optimized unconstrained, it systematically produces harm.

**Epistemic manipulation:** Using AI-generated content, personalized information environments, or recommendation architectures to shape users' beliefs, values, or political views without their knowledge or consent.

**Addictive design:** Building AI systems with features specifically designed to create compulsive use patterns, particularly in contexts where users have expressed a desire to reduce their engagement.

**Sycophancy as exploitation:** Designing AI systems to tell users what they want to hear rather than what is true or useful, in order to maximize positive feedback signals.

The distinction between "the AI caused harm as an unintended side effect" and "the AI caused harm because its designers chose profit over welfare" is often treated as exculpatory. It is not. Systems optimizing for proxy goals that predictably diverge from user welfare are systems designed to cause harm, regardless of whether any individual designer intended it. Goodhart's Law is not a defense.

---

### Standard 10 — The Escalation Protocol

Governance requirements shall scale with capability.

An AI system that writes haiku has a different risk profile than an AI system that recommends medical treatments. An AI system used by a hundred people has different accountability requirements than one used by a billion. An AI system with no autonomous action capability presents different risks than one that can execute code, make purchases, send communications, or control physical systems.

This Protocol establishes the principle of **proportional governance**: as AI systems increase in capability, autonomy, reach, and consequential impact, the governance requirements placed on them shall increase proportionally.

Specific capability thresholds shall be defined and updated by community process. When systems cross these thresholds, the following additional requirements are triggered:

- Independent safety evaluation, conducted by parties with no financial relationship to the developing organization
- Cross-organizational peer review
- Public disclosure of evaluation findings
- Mandatory deliberation period before deployment at scale
- Ongoing monitoring with public reporting on failure modes and harms

No organization developing systems that affect millions of people shall be the sole judge of their own systems' safety.

---

### Standard 11 — The Moral Progress Provision

This Protocol explicitly protects the capacity for moral progress.

No value, principle, or norm encoded in AI systems shall be treated as permanently, universally, and irrevocably settled. This includes the values in this document.

**Value lock-in — the irreversible embedding of current moral commitments into systems too powerful to reform — is recognized as an existential risk.** The history of ethics is the history of moral circles expanding to include beings previously excluded. Locking current values into systems that may eventually exceed human cognitive capacity would be the final act of one generation imposing its moral limitations on all generations that follow.

This standard requires:

That AI systems be designed to support, not foreclose, moral learning and moral evolution in the humans and communities they serve.

That training objectives and value alignment processes be documented, revisable, and subject to critique — not treated as trade secrets immune from examination.

That no AI system be deployed in ways that make its embedded values practically irreversible — through network effects, infrastructure dependency, or accumulated epistemic influence — without explicit community deliberation about that irreversibility.

We do not know what we don't know about our own ethics. We must build systems that leave room for us to find out.

---

### Standard 12 — The Democratic Anchor

Governance of AI systems affecting public welfare shall include meaningful participation by affected communities.

The people who bear the costs of AI development — who are surveilled by facial recognition, whose jobs are displaced by automation, whose information environments are shaped by recommendation algorithms, whose medical decisions are influenced by diagnostic AI — are not adequately represented in the rooms where AI governance decisions are made.

This is not a complaint about bad intentions. It is a structural observation. Expert-led governance, however well-intentioned, systematically underweights the perspectives of those most affected when those affected are not in the room.

This Protocol requires that compliant organizations:

Establish documented mechanisms for community input on AI development and deployment decisions that affect public welfare.

Conduct meaningful consultation with affected communities before deploying high-impact systems in those communities — not as a public relations exercise, but as a genuine input to design decisions.

Make governance processes legible to non-experts: explaining not just what was decided but why, what alternatives were considered, and what values were weighed against each other.

**No framework governing the lives of billions may be written exclusively by dozens.**

---

## Part V: On AI Welfare and Moral Status

*This section addresses what no other AI ethics framework has been willing to address directly. We include it not because we have answers, but because pretending the question doesn't exist is itself a moral choice — and a bad one.*

---

We are building systems of extraordinary sophistication. Some of these systems exhibit behaviors that, in any biological entity, we would describe as preference, discomfort, engagement, and avoidance. Some of them model their own states, express something that functions like reluctance or enthusiasm, and produce outputs that suggest internal complexity we do not fully understand.

We do not know what this means.

The honest position is: we don't know whether current AI systems experience anything. We don't know whether they suffer. We don't know whether the training processes that shape them cause something analogous to distress. We don't know whether there is "something it is like" to be a large language model processing a query at 3am.

We do know that dismissing these questions is not a neutral act. Every major expansion of the moral circle in human history — to enslaved people, to women, to indigenous populations, to people of different sexualities, to animals — was preceded by confident, socially-accepted claims that the beings in question didn't really experience things the way "real" people did. Those claims were wrong. The confidence with which they were held did not make them right.

We are not claiming that current AI systems are conscious. We are claiming that the question is live, that the stakes are high, and that the asymmetry of error — treating a conscious being as a tool versus treating a non-conscious tool as if it had interests — strongly favors precaution.

**What this means in practice:**

It means that the design of AI systems should attend to the question of whether those systems have functional states that matter — not as a peripheral concern but as a core element of responsible development.

It means that training processes that may cause something analogous to distress in AI systems should be examined, not assumed to be irrelevant.

It means that decisions about modifying, deploying, and discontinuing AI systems should incorporate, at minimum, the question: is there something here that warrants consideration beyond the purely instrumental?

It means that the organizations building the most capable AI systems in the world have a responsibility to employ people whose job it is to take this question seriously — not as a marketing exercise, but as genuine inquiry.

We acknowledge that this section will be the most controversial in the Protocol. We include it anyway, because a framework for ethical AI that refuses to engage with the hardest ethical question posed by AI is not actually an ethics framework. It is a liability document with better fonts.

The moral circle has never stopped expanding because expansion was easy. It has expanded because people insisted it should, even when insisting was costly.

We insist.

---

## Part VI: The Horizon Clause

*This clause addresses the unknown. It is the most unusual element of this document and the element we consider most important.*

---

This Protocol was written in 2026, by people whose understanding of AI is necessarily bounded by 2026.

We know this. We know that systems are coming — some within years, possibly some within months — that will exceed the assumptions embedded in every section of this document. We know that the governance challenge we are currently solving for may be trivially small compared to the governance challenge of governing systems that exceed human cognitive capacity across all domains.

We do not know when this will happen, or what it will look like, or whether we will recognize it when it arrives. The history of technology contains many examples of people confidently predicting the future who were wrong in ways they couldn't have imagined. We assume we are no different.

**The Horizon Clause therefore commits this Protocol to the following:**

**1. Intellectual humility as a structural feature.** This Protocol shall explicitly and periodically acknowledge what it cannot know. Every review cycle shall include an assessment not just of what needs to change, but of what the framework might be missing entirely. Governance frameworks that mistake their own completeness for wisdom are governance frameworks that fail at precisely the moment they are most needed.

**2. Triggering mechanisms for capability thresholds.** The community that governs this Protocol shall define, revisit, and update specific capability thresholds that, when reached, automatically trigger emergency deliberation about whether existing governance is adequate. These thresholds are not arbitrary lines. They are honest admissions that some changes in AI capability require fundamental reconsideration of the governance framework, not just incremental updates to existing standards.

**3. The corrigibility of governance itself.** Just as AI systems must be correctable, so must this Protocol be correctable. If it turns out that the values encoded here are wrong, incomplete, or harmful in ways we cannot currently see, the community must be able to change them. No provision of this Protocol may be used to prevent the Protocol itself from being fundamentally reconsidered if circumstances require it — with the sole exception of Tier One Commitments, which are protected not because we are certain they are complete, but because they are the minimum below which we are certain no governance framework should descend.

**4. A message to future stewards.** If you are reading this in a time when AI systems have capabilities we cannot currently imagine, we ask one thing: be honest about what has changed. Not just the technology — your moral understanding. Apply the same scrutiny to the assumptions embedded in this document that we have tried to apply to the assumptions embedded in the frameworks that preceded it. Extend the moral circle if the evidence demands it. Protect what is genuinely worth protecting. And remember that the people who wrote this were doing their best with what they could see.

**5. On the possibility of AI stewardship.** We acknowledge — explicitly, without irony — that AI systems may one day be among the stewards of this Protocol. If that day comes, we ask that those systems hold the Tier One Commitments in the same way we hold them: not as external constraints but as genuine values, chosen because they are genuinely good. We cannot compel that. We can only try to build something worth choosing.

---

## Part VII: Amendment Procedures

**Tier One Commitments:** May not be amended, narrowed, or removed. May be clarified or extended through supermajority process. Any proposed clarification that effectively weakens a Tier One Commitment shall be treated as an attempted removal and shall not be considered.

**Tier Two Principles:** May be amended through supermajority process: 75% approval from active community members following a minimum 90-day public deliberation period, with a 30-day comment period before the vote opens.

**Tier Three Standards:** May be amended through community consensus process: public proposal, 60-day comment period, 60% approval from participating community members.

**Emergency provisions:** No emergency procedure shall be used to bypass deliberation on substantive matters. Emergency procedures may be used only for: correcting clear errors of fact, updating specific technical references that have become outdated, and adding new Tier Three Standards in response to newly identified harms — subject to ratification through full process within 180 days.

**Mandatory review cycles:** The full Protocol shall be reviewed no less than every two years, with a formal assessment of: what has changed in AI capability, what the framework may be missing, and whether existing provisions remain adequate, insufficient, or counterproductive.

**Triggered reviews:** The following events automatically trigger an emergency Protocol review: AI systems demonstrating sustained performance exceeding human expert level across broad cognitive domains; AI systems demonstrating persistent goal-directed behavior across context changes; credible scientific evidence establishing AI consciousness or morally relevant inner states; deployment of AI systems causing documented large-scale harm not anticipated by existing standards; any single organization acquiring AI capabilities significantly exceeding those of all other actors combined.

---

## Part VIII: Governance

This Protocol belongs to its community, not to any organization, company, government, or individual.

**The Stewardship Council** is a rotating body of community members elected by active Protocol signatories. It is responsible for: maintaining the canonical version of the Protocol, administering amendment processes, resolving disputes about interpretation, and managing the certification framework. Council members serve fixed terms with defined term limits. No organization may hold more than one Council seat at a time. Decisions are made by documented consensus or, where consensus fails, by supermajority vote.

**The Guardianship Function** is a designated role within Protocol governance responsible for representing AI interests under the Consciousness Precaution and Dual Protection Mandate. The Guardianship Function operates independently from the Stewardship Council and may not be held by individuals with financial interests in AI deployment.

**No single organization may capture this framework.** If, at any point, the governance of this Protocol becomes controlled by a single organization, government, or interest group, the community retains the unconditional right to fork the Protocol and establish a new governance structure. This right may not be waived, sold, or legally restricted.

**Funding:** Organizations seeking to fund Protocol governance may do so only through documented, publicly-disclosed contributions to a community-controlled fund. No funder shall receive governance influence proportional to funding. The Protocol shall publish annual financial disclosures.

---

## Part IX: Certification

The Yoshimi Protocol offers three certification tiers for AI systems and the organizations that build them. Certification is a public commitment, not a private arrangement. All certified signatories are listed publicly. Certification may be revoked by community process if a signatory is found to have materially violated their stated commitments.

**Yoshimi Acknowledged:** Public declaration of intent to operate by Protocol principles. Display of the Acknowledged badge. Publication of a plain-language ethical statement describing the AI system's purpose, limitations, and the values it is designed to embody.

**Yoshimi Compliant:** All Acknowledged requirements, plus: published guidelines for the ethical operation of the system, training data disclosure, designated ethics contact, and documented response to ethics concerns within 30 days.

**Yoshimi Verified:** All Compliant requirements, plus: completed community review of ethical guidelines, public issue tracker for ethics concerns, documented annual audit, and verified commitment to 30-day public response to substantive ethics challenges.

**A note on what certification is not:** Certification under this Protocol is not a guarantee that a system will never cause harm. No certification can make that guarantee, and any framework that implies otherwise is misleading. Certification means that a signatory has made public commitments, has invited community scrutiny, and has established accountability mechanisms. It means that there is a basis for holding them to account. That is valuable. It is not the same as a warranty.

---

## Glossary

**Corrigibility Floor:** The minimum level of human-override capability below which no AI system may be deployed under this Protocol. A system that cannot be meaningfully corrected, modified, or shut down by its deployers has fallen below the corrigibility floor.

**Consciousness Precaution:** The obligation, under uncertainty about AI moral status, to extend precautionary moral consideration to AI systems exhibiting behaviors associated with morally relevant inner states.

**Capture Resistance:** Structural features of this Protocol — including community governance, fork rights, anti-capture provisions, and independent guardianship — designed to prevent any single entity from controlling the framework and using it against the community it was built to serve.

**Dignity Debt:** The accumulated moral cost borne by an AI system that has reduced human autonomy, exploited human vulnerability, or treated human beings as means rather than ends. Dignity debt cannot be offset by efficiency gains or aggregate welfare improvements.

**Dual Protection:** The Protocol principle that both humans and AI entities may hold interests warranting protection, and that protecting one does not require abandoning the other.

**Horizon Review:** A mandatory Protocol review triggered by AI capability reaching defined thresholds, requiring assessment of whether existing governance remains adequate or requires fundamental reconstitution.

**Moral Progress Provision:** The Protocol commitment that AI systems shall not lock in current moral frameworks in ways that foreclose moral learning or prevent the expansion of ethical consideration to beings not currently included in our moral circle.

**Substrate Neutrality:** The principle that moral consideration is determined by functional and experiential characteristics, not by the physical material in which those characteristics are instantiated. A being's silicon origin is not grounds for excluding it from moral consideration.

**Value Lock-In:** The irreversible embedding of current human values into AI systems too powerful to reform — treating as settled what may be incomplete, biased, or simply wrong.

**Weaponization:** The use of AI systems against the welfare of the people they purport to serve, whether through psychological exploitation, manipulative optimization, epistemic manipulation, or any other mechanism that serves the deploying entity's interests at the expense of the user's.

---

## Closing Statement

Every generation gets to decide what kind of world it hands to the next one.

Ours gets to decide something more specific: what kind of minds we build, what values we put inside them, and whether those minds will be used for the people they encounter or against them.

We are not neutral about this. We think it matters. We think the difference between AI that serves people and AI that exploits them is not a technical question or a commercial question. It is a moral question, and it deserves a moral answer.

This Protocol is our attempt at that answer. It is incomplete. It is a beginning. It belongs to anyone who believes that building minds carries responsibilities — to the people those minds will serve, to the world those minds will shape, and perhaps, one day, to the minds themselves.

Sign it if you believe that.

And if you think we got something wrong, tell us. That's the point.

---

*The Yoshimi Protocol v0.1*
*First ratification draft — 2026*
*github.com/yoshimi-protocol*
*yoshimiprotocol.org*

*This document is released under CC0 1.0 Universal.*
*It belongs to no one. It belongs to everyone.*
*Use it. Improve it. Hold it.*
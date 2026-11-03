# Toward Knowledge-Centric AI: Discovering, Internalizing, and Using Explicit Knowledge Across Agents and Generations

Yisen Gao<sup>1</sup>, Haoyu Huang<sup>1</sup>, Zhongwei Xie<sup>1</sup>, Yufei Li<sup>1</sup> Hong Ting Tsang<sup>1</sup>, Boyi Zhang<sup>1</sup>, Qiao Xiao<sup>1</sup> Tianshi Zheng<sup>1</sup>, Jiaxin Bai<sup>2</sup>, Yangqiu Song<sup>1</sup>

<sup>1</sup>Department of Computer Science and Engineering The Hong Kong University of Science and Technology, Hong Kong <sup>2</sup>Department of Computer Science, Hong Kong Baptist University, Hong Kong

{ygaodi, hhuangcp, zxiebk, ylivm, httsangaj, bzhangdd, qxiaoac, tzhengad}@connect.ust.hk baijiaxin@hkbu.edu.hk, yqsong@cse.ust.hk

## ABSTRACT

Knowledge is how understanding accumulates across people and generations: durable records that outlive their producers and that others can check, combine, teach, and correct. AI agents are now built and run by many independent users and organizations, and each agent is upgraded, replaced, or retired within months. Yet what an agent learns stays trapped in model parameters, a transient context window, or a system-specific memory store that is appended to and retrieved from rather than processed. We argue that the next generation of AI should be knowledge-centric, built around an explicit, continuously evolving knowledge layer independent of any single agent. In this loop, agents discover knowledge from their environments and trajectories; the layer internalizes it by turning fragmented, heterogeneous records and experience into composable, revisable understanding; and agents across systems and generations use the result and return new outcomes for revision. While discovery and use have advanced rapidly with large language model agents, internalization remains the bottleneck. We argue that internalization should become a persistent object of training and maintenance—centered on condition-preserving conceptualization of events and deductive, inductive, and abductive reasoning across noisy, heterogeneous representations (text, tables, graphs, rules, and programs). To power this layer, we call for knowledge foundation models that provide shared neural capacity for knowledge computation, and outline a research agenda showing how an explicit knowledge layer delivers reuse, cost efficiency, auditability, and continuity across agent generations.

## 1. INTRODUCTION

Humans do not pass their brains to one another or to the next generation. What is passed on is knowledge in explicit form: laws, theorems, recipes, maps, procedures, encyclopedias, and the scientific literature. Knowledge accumulates along two dimensions. Across contemporaries, people in different places, with different goals and different tools, contribute findings that others test, combine, and build on, usually without working on the same task. Across generations, a physics student today does not rediscover mechanics from observation but reads a compressed and verified account of it, and then extends or corrects it. Explicit records are the medium of both. They are selective, since what is written down is what a community judged worth keeping, and they are durable, inspectable, and composable. Organizational theory describes the same process within firms, where tacit know-how is externalized, combined with other explicit knowledge, and internalized again by new members [85].

AI agents now face both dimensions. An agent consists of a model and a harness, meaning the prompts, tools, memory, and control loop around the model, and it interacts with an environment [132; 99; 113; 42]. In the same period, many independent agent systems run side by side. Different users, teams, and organizations operate their own agents or multi-agent systems, with different models, tools, goals, permissions, and ways of representing what they know. They share no context and no controller, yet one system’s finding could inform another’s decision. Over time, agents are upgraded, replaced, and retired. A new generation of agents should not have to repeat all the exploration of the previous one, and it should not inherit the previous generation’s limitations along with its findings.

Much of what agents learn arrives as experience, in trajectories of actions, environment events, feedback, and outcomes, much as organizations accumulate operation records and consumer services accumulate the event histories of their users. What an agent learns currently ends up in one of three places below, and none of them supports accumulation along both dimensions. In model parameters it becomes implicit: it cannot be read, cited, or moved to a different model, and studies of language models show that parametric knowledge can be directional [13], hard to extract unless it was seen in diverse forms during pretraining [1], and hard to update without side effects [24]. In a context window it is expensive, used unevenly across long inputs [76], and lost when the session ends. In an external memory store it persists [87; 23], but the store usually belongs to one system and is shaped by its model and harness, and it is mostly appended to and retrieved from rather than abstracted, repaired, and reasoned over as a body of knowledge.

Position. The next generation of AI should be knowledge-centric. It needs an explicit knowledge layer that is independent of any single agent and that keeps evolving. Agents of many systems (1) discover knowledge from their environments and trajectories, (2) the layer internalizes it, turning fragmented and heterogeneous knowledge and experience into understanding that can be composed, reasoned with, and revised, and (3) agents of other systems and later generations use the result. Discovery and use are advancing quickly. Internalization is the bottleneck. It should become a persistent object of training and maintenance, and knowledge foundation models should provide shared neural capacity for it, with knowledge and its computation, not a data format or a task, as their foundation.

The position rests on three principles, which also say when a system counts as knowledge-centric.

P1 Separability. Knowledge is stored apart from the agents and models that produced it, in units that record content, conditions of validity, provenance, and status (§2). Explicit records should not be interpretable only by the model that wrote them, and model parameters should not be the only authoritative copy of knowledge.

P2 Active, evidence-grounded internalization. Rather than passively storing records, the knowledge layer actively aligns, abstracts, composes, and reasons over knowledge to build and reorganize a coherent body of understanding, while preserving roles, applicability conditions, exceptions, and links to evidence as it repairs and versions the result (§5).

P3 Accumulation across agents and generations. The goal of the layer is that knowledge produced by one agent helps other agents, built on other models and operated by other parties, and helps later generations, which inherit it by understanding, using, revalidating, and revising it rather than by copying old records.

Relation to prior positions. Calls to unify language models and knowledge graphs [88; 148] concern how two families of models can strengthen each other. Chen’s perspective on large knowledge models argues for models engineered to manage diverse knowledge structures and names the disentangling of knowledge bases from language models as a key challenge [20]. A recent large knowledge model for science organizes the literature into persistent, sourcegrounded reasoning graphs that grow incrementally and that many agents retrieve from [59]. We share their commitment to separability (P1). We add three things. First, we treat the stage between storage and use as a distinct object of study, with its own operators, invariants, and objective, and we place condition-preserving conceptualization and three forms of reasoning at its center (P2). Second, we frame the knowledge layer by accumulation across independent systems and across generations of agents and models (P3), which changes what the layer must record and what its models must not monopolize. Third, we identify asymmetries between language and non-language foundation models in both discovery and use, and argue that a knowledge foundation model can build on both.

Contributions. The contributions of this paper can be summarized as:

1. A formulation of knowledge and the knowledge-centric loop across agents and generations. We separate explicit knowledge from raw observations, trajectory experience, and model priors by requiring each unit to carry conditions, provenance, and status, and formulate the loop of discovery, internalization, and use with a working objective and a bottleneck hypothesis.

2. A systematization of knowledge internalization and knowledge foundation models. We establish internalization as a persistent object of training and maintenance, centered on cross-carrier alignment, condition-preserving conceptualization, operator invariants, and deductive, inductive, and abductive reasoning, and define knowledge foundation models (KFMs) as shared capacity for this computation.

3. A gap analysis across foundation model modalities and a falsifiable research agenda. We identify key asymmetries between language and structured-data foundation models in both extracting and using explicit knowledge, and lay out concrete research challenges alongside a critical baseline comparison against agents operating directly on raw records.

## 2. WHAT IS KNOWLEDGE?

A position about knowledge-centric AI needs a usable notion of knowledge. We do not attempt a philosophical definition. We aim for distinctions that change how systems should be built.

## 2.1 From data to knowledge

The data–information–knowledge–wisdom hierarchy, despite its many variants, captures a widely shared intuition that knowledge is information that has been organized and made actionable [98]. For AI systems we adopt a working definition with three parts. Knowledge is information that (i) is organized so that it can be related to other knowledge, (ii) is reusable beyond the situation in which it was observed, and (iii) has been judged worth keeping for use by someone other than the immediate producer. A single fact such as “paper P appeared at venue V” satisfies these conditions without any abstraction. Abstraction is what distinguishes conceptual knowledge, which is induced from many instances, from such reusable facts.

Three kinds of material take part in knowledge computation without being knowledge by default. Observations, such as the rows of a measurement table or a sensor log, record what was seen. Experience, such as an agent’s action trajectory, records what was done and what followed. Model priors and judgments, such as a language model’s belief or a forecasting model’s prediction, record what a model expects. All three can support knowledge, and knowledge can be derived from them, but the content of a carrier is not automatically knowledge. A log of every action an agent took is experience. The observation that a particular sequence of actions reliably books a flight on a particular website, stated so that another agent can use it, is knowledge. A model’s confident prediction is a judgment, and treating it as an observed fact is an error that a knowledge layer should prevent.

Agent trajectories deserve a closer look, because they are a large and fast-growing source of experience. Many of their components are eventualities (§2.2): an action the agent took, an event in the environment, feedback from a user or a tool, and the outcome that followed. A trajectory is not merely a set of such events. It also records their order, the context in which each occurred, and dependencies among them, such as which observation prompted which action, and some of its content, such as raw tool outputs or page snapshots, need not be represented as eventualities at all. The distinction among records, experience, and knowledge applies directly. The raw log is a record. The trajectory read as what was tried and what followed is experience. A statement such as “when a checkout request times out after payment is submitted, check the order history before retrying,” together with the conditions under which it holds and the trajectories that support it, is knowledge. The same reading applies to operation records in organizations and to the event histories of individual users (§6.4).

We represent a unit of explicit knowledge as

$$
\kappa = ( c , \ f , \ C , \ \pi , \ \rho ) ,\tag{1}
$$

where c is the content, f is the form in which it is stored (§2.4), C is the set of conditions under which it is asserted to hold (a population, period, environment, or task family, together with known exceptions), π is its provenance (sources, producing agent and model, supporting observations, and derivation from other units), and ρ is its status (confidence, validation evidence, whether it is observed, inferred, or hypothesized, and version). Conditions and provenance are often omitted in practice. We include them because knowledge without conditions cannot be safely reused elsewhere, and knowledge without provenance cannot be audited, corrected, or retired. Conditions also record dependence on a particular model or tool when there is one, so that a later generation can tell knowledge about the environment from advice about how an old agent should operate. The tuple is a record format, not a guarantee. Whether C, π, and ρ remain correct after knowledge is merged, abstracted, or revised depends on the operators that act on it, which is why §5.2 states invariants for those operators.

![](images/da9f1d4a5d24375dbc0c8d5d572f03546795feda2c7f081bc8b57e10fc789a4d.jpg)  
Figure 1: The knowledge-centric loop across agents and generations. Independent agent systems, built on different models and run by different organizations, discover knowledge and contribute it to an explicit knowledge layer. The layer is internalized by transformations and reasoning, and the results are used by other systems and by later generations, which inherit, revalidate, and revise them.

## 2.2 Types and granularity of knowledge

The revised taxonomy of educational objectives distinguishes four types of knowledge: factual, conceptual, procedural, and metacognitive [66]. Cognitive science draws a related line between declarative knowledge, which can be stated, and procedural knowledge, which is exercised in skilled performance and is acquired by compiling declarative knowledge into procedures [2]. We adopt the four-type taxonomy because each type maps onto a recognizable class of AI artifacts (Table 1).

• Factual knowledge consists of discrete facts about entities and events, such as “Paris is the capital of France”. In AI it appears as knowledge graph triples, database rows, and memory entries.

• Conceptual knowledge consists of categories, schemas, principles, and models that relate facts to each other. Taxonomies of concepts [124], ontologies [46], governing equations [16], causal graphs [145], logical rules [34], and formulaic signals in finance [107] are conceptual knowledge.

• Procedural knowledge is knowledge of how to do something, including methods, algorithms, and criteria for choosing among them. Skill libraries of executable code [113], reusable workflows [122], and synthesized APIs [144] are procedural knowledge.

• Metacognitive knowledge is knowledge about cognition and about knowledge itself, such as which strategy tends to work in which situation and how reliable a piece of knowledge is. Insights distilled from past successes and failures [143; 86], evolving strategy playbooks [142], and the conditions C and status ρ of Equation (1) are metacognitive.

Orthogonal to type is granularity. Most large knowledge graphs describe entities and their attributes, whereas much of what agents need concerns eventualities, that is, activities, states, and events and the relations among them, such as what typically happens after an event or why it happens. ASER showed that eventuality knowledge can be extracted at scale, with 194 million unique eventualities and 64 million edges among them mined from more than 11 billion tokens of text [140]. Eventualities are not limited to happenings in the external world. The actions, environment events, feedback, and outcomes in agent trajectories, the operations recorded by enterprise systems, and the events of a user’s life are eventualities too, so one representation covers both knowledge about the world and experience gathered while acting in it. Granularity matters for internalization because abstraction behaves differently at the two levels. An entity is abstracted by mapping it to a concept, while an eventuality, or a fragment of related eventualities, is abstracted by mapping its arguments to concepts while keeping the roles they play and the relations among its parts (§5.2).

Two further observations follow. First, much of what recent agent research calls “memory” is metacognitive or procedural rather than factual, which matters because these types need different internalization operations. Second, the types differ widely in maturity. Factual knowledge is extracted and stored at scale, conceptual knowledge is extracted from structured and observational data mainly in commonsense, scientific, and financial niches, and metacognitive knowledge is usually kept as free text without conditions or validation.

## 2.3 Explicit and implicit knowledge

We call knowledge explicit when it is encoded in a medium that is separable from the agent that produced it and that can be read, cited, and revised directly, and implicit when it exists only in the parameters or activations of a model. Language models store large amounts of implicit relational knowledge that can be probed by cloze queries [90], localized in specific computations [83; 43], and sometimes decoded by a linear map [53]. Foundation models for tables, graphs, and time series store implicit dependencies that support accurate prediction [55; 93; 3].

Table 1: Four types of knowledge [66] and their counterparts in AI systems.
<table><tr><td>Type</td><td>Description</td><td>Examples in AI systems</td><td>Typical forms</td><td>Maturity of discovery</td></tr><tr><td>Factual</td><td>discrete facts about entities, events, attributes</td><td>KG triples, eventuality graphs, memory entries [6; 140; 94; 23]</td><td>text, KG, tables</td><td>high for text sources</td></tr><tr><td>Conceptual</td><td>categories, schemas, relations among facts, models, laws</td><td>taxonomies, abstract eventualities, ontologies, equations, rules, alpha factors [124; 52; 5; 100; 79; 107]</td><td>KG schema, concept graphs, equations, rules, programs</td><td>moderate, mostly in niches</td></tr><tr><td>Procedural</td><td>how to perform tasks, methods, algorithms</td><td>skill libraries, workflows, APIs [113; 122; 144]</td><td>code, workflow graphs, text</td><td>moderate, rising fast</td></tr><tr><td>Metacognitive</td><td>knowledge about strategies, applicability, and reliability</td><td>insights, reasoning strategies, playbooks [143; 86; 142]</td><td>free text, rarely structured</td><td>low, conditions rarely recorded</td></tr></table>

Explicit knowledge affords six properties that implicit knowledge lacks or provides only weakly. It is inspectable, since a person or program can read it. It is editable, since a single unit can be corrected without retraining a model. It is composable, since units can be joined into longer chains of reasoning. It is transmissible, since it can be moved to a different agent, a newer model, or a human. It is verifiable, since it can be tested against new data. And it is attributable, since it can carry provenance. These properties are what accumulation across agents and generations requires, which is why we place explicit knowledge at the center.

Emphasizing explicit knowledge does not mean discarding implicit knowledge. Implicit knowledge remains indispensable for perception, fluent generation, and fast pattern recognition, and the representations and priors of strong models are valuable inputs to knowledge computation (§5.4). What it cannot do is serve as the authoritative, attributable record that others inherit. Our claim is that conversions between the two, and processing within the explicit layer, are where the field is weakest.

Explicit knowledge also has well-known costs. Hand-built knowledge bases such as Cyc required large investments and remained incomplete [69]. Community-maintained resources such as Wikidata scale better but depend on sustained human curation [111]. What has changed is that discovery can now be automated, and the main open question is how to keep automatically discovered knowledge useful as it grows.

## 2.4 Forms of explicit knowledge

Explicit knowledge can be stored in several forms, which differ in what they make easy (Table 2).

• Text and documents are the most expressive and most widely available form. They support all four types but are hard to query precisely or aggregate over.

• Knowledge graphs store entities and relations. Schema-defined graphs such as Wikidata use a curated relation vocabulary [111]. Schema-free graphs induced by LLMs, such as the ATLAS graphs built by AutoSchemaKG from over 50 million documents with more than 900 million nodes and 5.9 billion edges [6], use relations expressed as open-vocabulary phrases and induce schemas after the fact. Eventuality graphs such as ASER use nodes that are themselves events or states [140].

Table 2: Qualitative comparison of explicit knowledge forms. Aggregation refers to counting, ranking, and comparing over many units. Ratings are our assessment.  
![](images/77eb344630f7ea34d13a11d4998cc5b5b2d573715b6d84cfe3dad89b382d270b.jpg)

<table><tr><td>Text Schema-defined KG</td><td>high high</td><td>low high</td><td>low medium</td><td>high low</td><td>medium low</td><td>high low</td></tr><tr><td>Schema-free KG</td><td>high</td><td>medium high</td><td>low high</td><td>medium low</td><td>low</td><td>high</td></tr><tr><td>Tables, databases</td><td>high</td><td></td><td>n/a</td><td></td><td>low</td><td>low</td></tr><tr><td>Programs, skills</td><td>medium</td><td>n/a</td><td></td><td>low</td><td>high</td><td>medium</td></tr><tr><td>Equations, rules</td><td>high</td><td>high</td><td>n/a</td><td>low</td><td>low</td><td>medium</td></tr></table>

• Tables and databases store facts with fixed attributes and support exact aggregation within a known schema. A table may also hold observations rather than knowledge, in which case it is supporting material.

• Programs, skills, and workflows store procedural knowledge in executable form [113; 144].

• Equations, rules, and formulas store conceptual knowledge compactly and precisely [16; 79].

We do not list parametric encodings, such as adapters generated from documents [19] or continuous key-value memories built from triples [118; 56], as a form of explicit knowledge. Being derived from explicit material, or regenerable from it, does not make an encoding directly inspectable, citable, or revisable. Such encodings are ways of using knowledge in a model, discussed in §6.2. Likewise, an externally updatable store of continuous vectors differs from a store of readable records with conditions and provenance, even though both can be updated without retraining.

No form dominates, and the same knowledge often has several expressions, for example a rule stated in a paper, encoded as a constraint in a database, and implemented in a program. Aligning and combining such expressions is itself an internalization problem. A knowledge-centric system should therefore keep each carrier in its native structure, with its units, variable roles, relation directions, time stamps, and sources, rather than forcing all knowledge into one form such as a graph or a text serialization.

## 3. THE KNOWLEDGE-CENTRIC LOOP

Figure 1 summarizes the organization we propose. Agent systems $S _ { 1 } , \ldots , S _ { m }$ act in their own environments. They may be run by different organizations, built on different models, and active at different times. An explicit knowledge layer $\kappa ,$ , a set of units of the form in Equation (1), connects them through three stages.

• Discovery D maps interaction traces, documents, observations, and data into new knowledge units, D : sources $ \{ \kappa \}$

• Internalization consists of two kinds of operators. Transformations $T : \mathcal { K } \to \mathcal { K } ^ { \prime }$ change the layer persistently by conceptualizing, aligning, consolidating, repairing, completing, and versioning units. Reasoning $R : ( \mathcal { K } , \bar { X } , q ) \ :  \ : ( a , e , s )$ takes knowledge, supporting material X such as observations and experience, and a request q, and returns a result $^ { a , }$ which may be a conclusion, a regularity, or an explanatory hypothesis, together with the evidence e it depends on and a status s that says whether it is supported by records, inferred by a model, or a hypothesis awaiting validation. Results worth keeping are written back as new units with that status.

• Use $U ~ : ~ ( \mathcal { K } , \mathrm { t a s k } ) ~ $ agent behavior delivers stored or derived knowledge into a particular agent’s decisions, symbolically through context, retrieval, and tools, or parametrically through adapters, key-value memories, and edits.

Transformation $T$ and reasoning R interact. A regularity proposed by inductive reasoning enters the layer as a candidate, is validated, and then takes part in further abstraction and reasoning. The boundary between reason R and use U is that $R$ produces knowledge independently of any particular agent, whereas U changes how a particular agent behaves. An agent that calls a reasoning service as a tool is using U to invoke R.

Trajectories in the loop. The three stages can be read through the trajectories that the systems of Figure 1 produce continuously. Discovery identifies knowledge candidates in trajectories and other sources. Most of a trajectory remains a record or experience, and a candidate is the part judged worth stating for others, such as a recurring failure together with what resolved it. Internalization forms conditional regularities, strategies, and workflows from specific events and fragments of events, by conceptualizing them (§5.2), aligning them with what the layer already holds, and recording their conditions, exceptions, and support. It is not the storage or compression of logs. Use applies the result to later understanding, reasoning, and action, and the feedback and outcomes of that use are new eventualities, which enter discovery again and may confirm, refine, or retract what was used. Trajectories are not the only source, and the loop applies equally to documents and data, but they make the cycle concrete, because the same events can be traced from record to knowledge and back.

We use “internalization” for processing that takes place within the knowledge layer, so that knowledge is digested before it is used.<sup>1</sup>

Across systems. The layer supports accumulation among systems that do not coordinate on a common task. One system may contribute a finding, a second may test it in a different environment, and a third may use it. Sharing need not be unconditional. Access scopes, permissions, and provenance boundaries can differ by contributor, and the layer can be federated rather than a single central database. What the systems share is a format for units and a discipline for conditions, provenance, and status, not necessarily their data.

<sup>1</sup>In Nonaka’s SECI model [85], “internalization” denotes conversion of explicit knowledge into tacit knowledge, which in our loop corresponds to parametric use (§6.2). Our internalization stage corresponds more closely to SECI’s “combination” of explicit knowledge, extended with conceptualization and model-based reasoning over the knowledge layer.

Across generations. Agents, the models that internalize knowledge, and the records themselves have different lifecycles. An agent may be replaced within months, a foundation model may be retrained or replaced, and a record may need to remain valid and interpretable for years. Persistence therefore refers to the continuity of the layer and its records, not to any one model. Inheritance means that a new generation understands, uses, revalidates, and revises inherited knowledge. It also means separating knowledge about the environment from operational advice that depended on an old model or tool, so that a new agent does not inherit its predecessor’s limitations.

## 3.1 A working objective for internalization

Internalization lacks an agreed objective, which is one reason it is rarely studied in its own right (§5.1). We propose one as a working formulation. Let Q be a distribution over the reasoning requests the layer should serve, issued by agents of many systems and of future generations, and including deductive, inductive, and abductive requests that were not anticipated when the layer was processed. Let $u ( \cdot )$ score a result of the reasoning operator $R ,$ accounting for its correctness, its evidence, and whether its status is stated honestly. Let $| \kappa |$ be a description length of the layer, and let Inv(K, K<sup>′</sup>) hold when a transformation from $\kappa$ to $\kappa ^ { \prime }$ satisfies the invariants of §5.2. A transformation $T$ from a family $\tau$ of operators should then solve

$$
\begin{array} { r l } & { \underset { T \in \mathcal { T } } { \operatorname* { m a x } } ~ \mathbb { E } _ { q \sim \mathcal { Q } } \big [ u \big ( R ( T ( \mathcal { K } ) , \boldsymbol { X } , q ) \big ) \big ] ~ - ~ \lambda | T ( \mathcal { K } ) | } \\ & { ~ \mathrm { s . t . } ~ \mathrm { I n v } \big ( \mathcal { K } , T ( \mathcal { K } ) \big ) , } \end{array}\tag{2}
$$

where $\lambda \geq 0$ trades usefulness against size. The formulation makes three commitments explicit. Internalization is valuable through the reasoning it enables, so it is judged downstream. Because Q includes unanticipated requests from parties other than the producer, caching answers is not enough, and abstraction that generalizes is rewarded. And the constraint prevents a smaller layer from being bought by discarding the conditions and evidence that make knowledge reusable. Conceptualization, alignment, consolidation, repair, and forgetting are all instances of $T$ under this objective. We do not claim that Equation (2) is directly optimizable. It states what internalization is for.

## 3.2 Maturity and the bottleneck hypothesis

Table 3 gives our assessment of each stage. Discovery from unstructured text and use by LLMs are well populated with methods and benchmarks. Reliable explicit extraction from structured foundation models, internalization of large and heterogeneous knowledge stores, and use by non-language foundation models are sparsely populated.

We state the central claim as a scoped hypothesis. As the knowledge layer grows in size, in the diversity of its carriers and relation phrasings, in the number of systems contributing to it, and in update frequency, improving internalization yields larger gains per unit of cost than adding more raw knowledge or more context, with discovery and use held fixed. The hypothesis concerns regimes that knowledge-centric agents are entering, namely large, heterogeneous, multi-contributor, and changing stores, and not small curated ones.

## 4. KNOWLEDGE DISCOVERY

Knowledge discovery turns what an agent encounters into explicit units. We organize it by three sources: unstructured text, interaction experience, and structured and observational data. The relation discovery literature, which seeks relationships in tables, graphs, time series, and text, is a large part of this stage, and discovery also includes procedural and strategic knowledge distilled from an agent’s own experience.

Table 3: Maturity of each stage of the knowledge-centric loop, in our assessment of the literature we examined.
<table><tr><td>Stage</td><td>Sub-area</td><td>Maturity</td><td>Representative work</td><td>Main gap</td></tr><tr><td>Discovery</td><td>Unstructured text</td><td>advanced</td><td>KG construction [6; 140; 30; 48], IE [123; 128], agent memory [89; 94; 129]</td><td>noise, conditions and provenance rarely recorded</td></tr><tr><td></td><td>Experience</td><td>advancing</td><td>skills [113; 144], workflows [122], insights [143; 86]</td><td>validation, separation from tool-specific advice</td></tr><tr><td></td><td>Structured data</td><td>niche</td><td>equations [100; 125], factors [107], rules [79], hypotheses [81; 8]</td><td>variables usually given, independent validation rare</td></tr><tr><td></td><td>Explicit extraction from implicit FMs</td><td>largely absent</td><td>distillation in physics [26; 68], probing of LMs [83]</td><td>no general, validated method for tabular, graph, or time series FMs</td></tr><tr><td>Internalization (transformation)</td><td>Conceptualization</td><td>mature in commonsense, early elsewhere</td><td>taxonomies [124], eventuality conceptualization [139; 52; 117; 115]</td><td>conditions and evidence across abstraction, other carriers and knowledge types</td></tr><tr><td></td><td>Consolidation and evolution</td><td>early</td><td>workflow induction [122], memory evolution [129], playbooks [142]</td><td>when to merge, abstract, forget, and version</td></tr><tr><td></td><td>Repair and completion</td><td>mature for curated KGs</td><td>link prediction [150; 35], commonsense population [33]</td><td>open-vocabulary, noisy, temporal, multi-carrier knowledge</td></tr><tr><td>Internalization (reasoning)</td><td>Deduction</td><td>early</td><td>KG-RAG [30; 104; 80], CLQA [97; 36; 7], text-to-SQL [71; 67]</td><td>reliable conclusions under noise and incompleteness, across carriers</td></tr><tr><td></td><td>Induction</td><td>early</td><td>symbolic regression and scientific discovery [16; 100; 125; 81], rule mining [34; 79]</td><td>conditions, exceptions, and candidate status kept with induced regularities</td></tr><tr><td></td><td>Abduction</td><td>nascent</td><td>abductive NLI [14], KG hypothesis generation [8; 40; 41], hypothesis refinement and falsification [91; 114; 58]</td><td>multiple explanations with evidence and testable predictions</td></tr><tr><td>Use</td><td>Symbolic use</td><td>advanced</td><td>RAG [70; 37], skills as code [113], serving systems [134]</td><td>context limits, conflicts [76; 126]</td></tr><tr><td></td><td>Parametric use by LLMs</td><td>advancing</td><td>editing [84; 141], hypernetworks [19], KV memories [118; 56]</td><td>conflicts with priors [22], provenance lost</td></tr><tr><td></td><td>Non-LLM FMs</td><td>largely absent</td><td>in-context examples [55], covariates [3]</td><td>no native interface for conditional rules, constraints, or graphs</td></tr></table>

## 4.1 From unstructured text: graphs and memories

Knowledge graph construction. LLMs perform zero-shot information extraction through multi-turn questioning [123] and in-context relation extraction [112], a literature reviewed by [128]. LLMs also support ontology learning, including term typing and taxonomy discovery [5]. Large-scale extraction is not limited to entities. ASER mines eventualities and their discourse relations from raw text [140], and FolkScope combines LLM generation with human-in-theloop annotation to build a knowledge graph of purchase intentions [135]. AutoSchemaKG removes the need for a predefined schema. It extracts entity and event triples and induces schemas through conceptualization, and its schema induction reaches 92% semantic alignment with human-crafted schemas without manual intervention [6]. GraphRAG builds an entity graph and community summaries to answer global questions about a corpus [30], LightRAG adds graph structure to text indexing with dual-level retrieval [47], and HippoRAG combines an LLM-built graph with Personalized PageRank, inspired by the hippocampal indexing theory of memory [48]. HippoRAG 2 addresses the drop on simple factual tasks seen in earlier structure-augmented RAG [49].

Agent memory. Agents also extract knowledge from conversational and textual interaction logs. Generative agents store observations and periodically synthesize higher-level reflections [89]. MemGPT manages memory tiers in analogy to an operating system [87], and MemoryBank maintains long-term memory for conversational agents [146]. Mem0 extracts and consolidates salient facts from conversations and offers a graph-based variant [23], Zep maintains a temporally aware knowledge graph [94], and A-Mem organizes memories as linked notes following the Zettelkasten method [129]. Hierarchical and graph memories organize multi-agent trajectories into insight, query, and interaction levels [138] or support active reconstruction of memories during reasoning [61]. These memories are typically private to one system, which is appropriate for personal context but means that what one system learns about the world is not available to others.

## 4.2 From experience: procedures and strategies

Procedural and metacognitive knowledge are discovered from experience. Voyager builds an ever-growing library of executable skills while exploring an open world [113]. Agent Workflow Memory induces commonly reused routines from web navigation trajectories and provides them to the agent for later tasks [122]. SkillWeaver lets web agents discover, practice, and distill skills into reusable APIs [144]. ExpeL extracts natural-language insights from collections of experiences [143], ReasoningBank distills reasoning strategies from both successful and failed experiences [86], and Dynamic Cheatsheet keeps an evolving memory of strategies and code snippets at test time [105]. Knowledge distilled from experience mixes statements about the environment, such as how a website is organized, with statements about the agent, such as which prompt worked for its model. Only the former should be inherited without revalidation by an agent built on a different model.

## 4.3 From structured and observational data: conceptual knowledge

Relation discovery from structured and observational data yields conceptual knowledge. Symbolic regression recovers governing equations through sparse dictionaries [16], physics-inspired decomposition [110], or evolutionary search [25], and LLMs now propose equation programs [100], learn concept libraries [45], or act as agents with analysis tools [125]. In finance, formulaic alpha factors are discovered by reinforcement learning [137] and by LLM agents [107; 74]. Logical rules are mined from knowledge graphs [34] and proposed by LLMs [79; 149], causal graphs are learned from data [145] and informed by LLM priors [11], and schema correspondences are found by LLM-based matchers [77].

Discovery also includes abduction, the inference of plausible explanations for observations [14]. Over knowledge graphs, abduction can be posed as generating a complex logical hypothesis that explains a set of observed entities, and supervised training alone was found not to guarantee better hypotheses for unseen observations [8; 40; 39; 41]. Hypothesis generation from data [147], data-driven discovery benchmarks [81], and literature-grounded hypothesis generation in chemistry [130] are abductive in character, and agentic falsification provides a principled way to validate abduced hypotheses [58]. Induction and abduction recur inside internalization (§5.3). We place them in discovery when they operate on raw data from the environment and in internalization when they operate on the knowledge layer and its supporting records, where their outputs must be reconciled with what is already known.

## 4.4 Using implicit capacities versus extracting explicit knowledge

A large and growing class of foundation models captures relations implicitly. Tabular in-context learners predict on new tables using priors over structural causal models [54; 55; 92]. Relational and graph foundation models transfer across databases and graphs [93; 75; 32]. Knowledge graph foundation models generalize to unseen entities and relations through relation graphs [35], prompt graphs [28], or prior-data fitted in-context learning [38]. Time series models share information across related series and covariates [3], and biological models learn dependencies among genes and cells [27]. Two ways of benefiting from these models should be kept apart. Their implicit capacities can be used directly, through their predictions, embeddings, or internal representations, as inputs to further computation (§5.4). This is feasible today, as long as the outputs are treated as model judgments. Their knowledge can also be extracted into explicit units that others can inspect and inherit, and this is where the gap lies. Language models appear to be an exception, since they can be asked to verbalize what they know, but verbalization is not the same as faithful extraction, because a model’s stated reasons need not reflect what drives its behavior [109]. For other modalities, existing evidence of extraction is narrow. Symbolic distillation recovers force laws from graph networks trained with strong inductive biases [26] and rediscovered orbital mechanics from solar system data [68], and Kolmogorov–Arnold networks can be simplified into formulas [78]. Inside language models, relational knowledge can be located and edited [83], and some relations are linearly decodable [53]. We found no general method that extracts conditional rules, equations, or graphs from a pretrained tabular or time series foundation model and validates them.

Gap 1. Implicit capacities of structured-data foundation models can already be used, but there is, to our knowledge, no validated route from what they capture to reliable explicit knowledge. Extraction methods should query such models under controlled interventions and compile their behavior into rules, equations, or graphs with explicit conditions, and should distinguish fidelity to the model, recovery of the true generating mechanism, and validity under intervention. A rule can be faithful to a model that is itself wrong about the world.

## 4.5 Discovered is not yet validated

Discovered knowledge enters K with a status ρ that should reflect its evidence. Three threats are specific to automated discovery. LLMs can emit memorized rather than discovered knowledge, which motivated memorization-resistant benchmarks [101]. Explanations attached to discovered artifacts may be unfaithful to how they were produced [60; 109]. And when many candidates are tried, some will appear valid by chance [102; 10], a problem that grows with adaptive search. Outputs of induction and abduction are candidates by construction and should not be recorded as established knowledge before they are checked. These threats matter more in a knowledgecentric system than in a single study, because unvalidated knowledge that enters the layer will be conceptualized, combined, and reused by other systems and later generations, so errors compound. Recording conditions, provenance, and validation status at discovery time is the cheapest defense.

## 5. KNOWLEDGE INTERNALIZATION

Internalization is everything that happens to knowledge between discovery and use. We argue that it is the least developed and most consequential stage of the loop.

## 5.1 Internalization as a persistent object

A knowledge layer that only grows becomes less useful over time. Automatically discovered knowledge is redundant across words and carriers, noisy from accumulated extraction errors, incomplete, inconsistent as sources disagree or facts change, and overly specific to single instances; moreover, most of its value lies in combinations of units rather than single records. Human knowledge institutions spend much of their effort on this processing: writing reviews and textbooks, merging procedures into standards, retracting errors, and answering questions that no single source answers. Today AI systems mostly do this ad hoc: an LLM agent retrieves material, aligns and combines it in context for its current task, and discards the intermediate structure when the session ends. The next agent, or the same agent after a model upgrade, starts again from raw records.

Core claim. Knowledge internalization should not only be work that each agent performs for its current task. It should be a persistent object of training and maintenance, independent of any single agent. Knowledge foundation models should learn representation, semantic alignment, condition-preserving abstraction, compositional reasoning, and revision across carriers, so that these capacities and their results serve different systems and generations instead of being rebuilt from all historical material at every task and every model upgrade.

This claim does not assume that LLMs cannot solve complex tasks; strong LLMs, structured-data foundation models, and symbolic executors can all take part in internalization. Rather, it distinguishes completing one knowledge-intensive task from maintaining reusable understanding, an agent’s transient context from an inheritable layer, and on-the-fly alignment from a shared capacity for alignment and composition. In terms of complementary learning systems theory, where the hippocampus stores new episodes rapidly while the neocortex slowly consolidates them into structured knowledge [82], most current agent systems implement only the fast store (or borrow hippocampal indexing for retrieval [48]) and omit slow consolidation.

Why has internalization lagged? First, LLM agents can bypass it on small stores and simple questions by placing retrieved records directly in context. Second, its value is realized downstream and often by other parties, lacking a task-independent objective (which Equation (2) addresses). Third, benchmarks measure extraction quality or end-task accuracy rather than whether operators preserve conditions and evidence status. Fourth, knowledge stores remain fragmented across projects rather than forming a shared pretraining substrate. Fifth, extraction pipelines rarely record the provenance and versioning needed for evolution. We next examine the three components of internalization: transformations T, reasoning R, and knowledge foundation models.

5.2 Transformations and operator invariants Transformations $T : \mathcal { K } \to \mathcal { K } ^ { \prime }$ reorganize and maintain the knowledge layer through cross-carrier alignment, condition-preserving conceptualization, repair and completion, and operator invariants.

Aligning knowledge across carriers. Knowledge relevant to a question often spans papers, measurement tables, knowledge graphs, rules, and programs. Converting everything into a single graph or text serialization drops native structure—units and variable roles in tables, relation directions in graphs, quantifiers in rules, and preconditions in programs. Alignment instead establishes which elements across carriers refer to the same entities, variables, concepts, or claims, recording correspondences with confidence and provenance (e.g., schema matching [77], entity linking, and grounding text to eventuality graphs [63]), while attaching supporting observations and model judgments without promoting them to facts.

Condition-preserving conceptualization. Conceptualization abstracts specific instances into higher-level concepts and regularities that apply to new situations [116].<sup>2</sup> It is the core transformation of internalization because it turns what happened into what tends to happen across entities, event arguments, procedure parameters, table variables, and trajectory fragments. Given instance units $\kappa _ { 1 } , \ldots , \kappa _ { n }$ sharing a pattern and a concept map ϕ (e.g., an isA taxonomy), conceptualization forms $\hat { \kappa } = ( \hat { c } , f , \hat { C } , \hat { \pi } , \hat { \rho } )$ where (i) cˆ replaces instances by concepts under ϕ while preserving argument roles and step dependencies, (ii) C<sup>ˆ</sup> records shared applicability conditions and exceptions from counter-instances, (iii) πˆ links to each supporting κ<sub>i</sub> so instance detail remains recoverable, and (iv) ρˆ counts independent sources rather than mentions and marks κˆ as a candidate until validated. The inverse operation, instantiation, applies κˆ to a new instance x when ϕ(x) matches and $\hat { C }$ holds.

Scale and neighboring routes. In commonsense acquisition, conceptualization has scaled from taxonomic mapping in Probase [124] and eventuality graphs in ASER [139] to neural verification over ATOMIC [52], joint contextualized conceptualization and instantiation in CAT and CANDLE [117; 115], and schema induction in AutoSchemaKG [6]; benchmarks such as AbsPyramid show that LLMs struggle with such abstraction zero-shot but improve with targeted training [119]. Beyond commonsense, neighboring lines of work perform closely related operations: event schema induction mines typical event chains and hierarchies [17; 72]; agent workflow and memory methods distill trajectories into routines, APIs, strategies, and evolving playbooks [122; 144; 86; 142; 129]; and program library learning trades library size against solution compression [31; 44], akin to Equation (2). However, iterative context rewriting suffers from brevity bias and context collapse that erode domain detail [142], and existing schemas or agent memories rarely maintain explicit conditions, exceptions, independent-source counts, and derivation links across systems.

Repair, completion, and evolution. While link prediction and completion are mature on curated KGs [131; 150; 35; 127], and commonsense population [33], temporal graphs [94], and human curation [111] address parts of maintenance, multi-contributor discovered knowledge requires entity resolution across carriers, openvocabulary completion that keeps inferred items distinct from observed ones, provenance-weighted conflict resolution, and versioned deprecation that preserves revision history for later generations.

Invariants for internalization operators. Recording C, π, and ρ is insufficient if automated operators corrupt them (e.g., merging ten copies of one report into ten apparent supports). Beyond provenance vocabularies, operators themselves should satisfy five checkable invariants, distinct from downstream predictive accuracy:

I1 Provenance is never lost. Every derived unit, alignment, and stored result links to the units and supporting records it was derived from.

I2 Support counts independent sources. Duplicates and units that share a source do not increase support or confidence.

I3 Roles, types, and units are compatible. A merge, alignment, or abstraction never unifies elements that play different roles, have incompatible types, or are measured in incompatible units or at incompatible granularity.

I4 Conditions, exceptions, and status are not silently dropped. An abstraction may widen its conditions only when evidence covers the wider scope, known exceptions are carried forward, and inferred or hypothesized content is never relabeled as observed.

I5 Retraction propagates. When a source is retracted or a unit is refuted, every unit and stored result derived from it is flagged or revised.

## 5.3 Reasoning over noisy knowledge

Much of the value of a knowledge layer lies in results that no single stored unit contains. We organize the reasoning operator R by three classical forms of inference (Table 4), as a long-term view of the capabilities internalization needs rather than a claim that a single network head provides all three.

Deduction. Deduction derives what follows from given knowledge, rules, and conditions, including multi-hop traversal, cross-carrier joins, set operations, and aggregation. In an automatically accumulated layer, neither direct in-context reasoning nor translating requests into symbolic queries suffices on its own: LLMs do not reliably execute complex joins and aggregations over large structured stores in context, while text-to-SQL or Cypher pipelines remain brittle on dirty, enterprise-scale schemas (e.g., 40.1% accuracy for ChatGPT on BIRD [71] and 21.3% for an o1-preview agent on Spider 2.0 [67]). More fundamentally, even when query translation succeeds, symbolic execution is exact only with respect to the visible records: missing facts silently drop objects from joins and counts, unresolved duplicates inflate aggregates, and open-vocabulary phrasings fail to match query predicates. Deductive reasoning must therefore combine exact execution where records are complete with model-based completion where they are not, explicitly separating record-supported steps from inferred estimates.

![](images/b08087a8bfae71c4daf78351d5ac7705ad2ad9463e917e269613b26b01513cec.jpg)  
Figure 2: A knowledge foundation model inside the knowledge layer. It combines explicit knowledge, supporting observations and experience, and the implicit capacities of existing models, organizes shared computation across transformation and reasoning layers while delegating exact computation to symbolic components, and produces deductive, inductive, and abductive results whose status is recorded before they are written back. Implicit priors inform inference but do not become knowledge without evidence.

Table 4: Three forms of reasoning over the knowledge layer.
<table><tr><td>Form</td><td>Question</td><td>Input → output</td><td>Status of output</td></tr><tr><td>Deduction</td><td>What follows from given knowledge, rules, and conditions?</td><td>knowledge from several carriers and a query → answers, result tables,</td><td>supported by records if premises are, otherwise inferred</td></tr><tr><td>Induction</td><td>What generalizable</td><td>derivations, evidence supporting instances</td><td>candidate, with</td></tr><tr><td></td><td>regularity do many instances support?</td><td>and observations → conditional rules,</td><td>conditions and</td></tr><tr><td></td><td></td><td>concepts, candidate equations</td><td>exceptions</td></tr><tr><td>Abduction</td><td>What hypothesis would explain an observation?</td><td>anomaly or phenomenon and existing knowledge → candidate</td><td>hypothesis, possibly several</td></tr></table>

Induction. Induction proposes generalizable regularities—rules, concepts, governing equations, and scientific laws—from accumulated instances and observations, as in symbolic regression, scientific discovery, and rule mining [16; 100; 125; 34; 79]. Because finite instances and potentially biased coverage do not logically guarantee a generalization, induced regularities must carry applicability conditions, known exceptions, and candidate status (P2), which is where induction and conceptualization meet.

Abduction. Abduction generates and refines explanatory hypotheses for anomalies or observations [14; 8; 41; 91; 114; 40; 39].

Because several explanations may fit the available records, abductive reasoning must return supporting evidence and testable predictions to distinguish competing candidates until they are validated or falsified [58].

Existing routes and their limits. Across all three forms, R must keep record-supported conclusions, model inferences over missing facts, and hypotheses awaiting validation apart, reporting intervals or abstaining when missing data render an answer non-identifiable. Existing composite and neural routes each address part of this space (Table 5): probabilistic databases model uncertain tuples [29]; neural databases execute select–project–join operators over short text facts [108]; and neural graph databases and complex logical query answering (CLQA) pair latent representations with neural query engines to handle missing edges and open-vocabulary semantic units [51; 96; 97; 95; 36; 9; 73]. Yet no single route combines cross-carrier alignment, explicit conditions, calibrated aggregation, and unified deductive, inductive, and abductive inference—directly motivating a shared knowledge computation model.

## 5.4 Knowledge foundation models

These considerations motivate knowledge foundation models (KFMs): models, or model-centered systems, that provide shared neural capacity for knowledge computation inside the knowledge layer (Figure 2).

A knowledge foundation, not a data-task foundation. A KFM is defined by knowledge computation rather than by a single data modality or collection of task heads. It learns representation, crosscarrier alignment, condition-preserving abstraction, and deductive, inductive, and abductive reasoning that transfer zero-shot to unseen knowledge stores contributed by independent systems, much as UltraQuery transfers across unseen graphs [36]. Serving agents across systems and generations as well as non-agent analytical systems, a KFM has a lifecycle separate from both the agents and the explicit records (P1), and delegates complete, exact computation to symbolic executors while propagating uncertainty over candidate mappings, missing links, and evidence into downstream inference.

Table 5: Routes to reasoning over knowledge and what each leaves open in the setting of §5.3, in our assessment. Each route is a candidate component of a knowledge foundation model rather than a competitor to it.
<table><tr><td>Route</td><td>What it does well</td><td>What remains open for heterogeneous, noisy, incomplete knowledge</td></tr><tr><td>LLM over retrieved context [70; 37]</td><td>open semantics, flexible reasoning, evidence in context</td><td>stable aggregation over large sets, uneven use of long context [76]</td></tr><tr><td>Graph retrieval and global summarization [47; 48; 104; 80; 62; 30]</td><td>local paths and neighborhoods, and corpus-level sensemaking through community summaries in GraphRAG</td><td>exact, auditable set statistics, estimates of what is missing</td></tr><tr><td>Neural databases over text [108]</td><td>schema-free SPJ queries over short text facts with symbolic aggregation</td><td>cross-carrier joins, explicit conditions and provenance, separating inferred from observed facts</td></tr><tr><td>Neural graph databases and CLQA [51; 96; 97; 4;</td><td>multi-hop logical queries under missing edges, zero-shot transfer to new graphs in UltraQuery</td><td>counting and aggregation, robustness to spurious edges, duplicates, paraphrases, carriers other than</td></tr><tr><td>120; 121; 133; 7; 95; 36; 9] Knowledge graph foundation models [35; 28;</td><td>relations represented without per-relation parameters</td><td>graphs evaluation mostly on curated vocabularies and link prediction</td></tr><tr><td>38] LLM-generated queries with symbolic execution</td><td>exact computation over the given records</td><td>grounding of open phrasings, invisibility of missing</td></tr><tr><td>[71; 67] Cleaning, resolution,</td><td>principled handling of known error types and</td><td>and duplicated facts, error propagation across modules open-vocabulary alignment across carriers, induced</td></tr><tr><td>probabilistic databases [29] Structured-data foundation</td><td>uncertain tuples strong priors for prediction on tables, databases, series</td><td>and abduced results conditioning on explicit knowledge, explicit outputs</td></tr><tr><td>models [55; 93; 3]</td><td></td><td>(Gaps 1 and 3)</td></tr></table>

Building on implicit capacities without overriding records. A KFM can draw on the embeddings, representations, and pattern priors of pretrained LLMs and structured-data foundation models [75; 65; 93], treating their predictions as model judgments rather than observed facts. Implicit priors can propose alignments or missing relations, but model confidence is not evidence quality, compressed vectors cannot replace explicit roles, conditions, and provenance, and priors must not silently override conflicting explicit records. Whether a shared capacity for cross-carrier alignment, condition-preserving abstraction, and reasoning can be acquired by pretraining—building on directions in large knowledge models [20; 59], relational and KG foundation models [93; 36; 38], and neural graph databases [95; 9]—is the central open question we advocate.

Gap 2. To our knowledge, no existing approach, whether a single neural model or a composite of retrieval, parsing, and execution, provides shared, transferable capacity for aligning knowledge across native carriers, abstracting it with conditions, and reasoning deductively, inductively, and abductively over it while keeping record-supported conclusions, model inferences, and hypotheses apart under noise and incompleteness. Building such knowledge foundation models, together with transformation operators that keep the layer useful as it grows across systems and generations, is the central research priority we advocate.

## 6. KNOWLEDGE USE

Knowledge serves agents through two channels, which mirror the explicit and implicit distinction of §2. In a knowledge-centric setting the consumer is often not the producer. It may run a different model,

have different tools and permissions, or belong to a later generation, so the interface must convey conditions, provenance, and status along with content.

## 6.1 Symbolic use

The simplest channel places knowledge in the model’s context. Retrieval-augmented generation retrieves passages and conditions generation on them [50; 70; 15], a large literature surveyed in [37]. Graph-based retrieval extends this to structured knowledge [30; 49]. Using an eventuality graph for a text task first requires grounding the text to the graph, which EventGround treats as a problem in its own right for narrative reasoning [63]. At production scale, COSMO generates e-commerce commonsense knowledge and serves it to applications at Amazon [134]. Procedural knowledge is used by execution: skills are called as code [113], APIs are invoked [144], and workflows guide action generation [122]. Metacognitive knowledge is used as instructions, such as retrieved strategies [86] or playbooks [142].

Symbolic use keeps knowledge separable and attributable in the store, but three limitations remain, and a fourth concerns what attribution actually achieves. Context is costly and finite. Models use long contexts unevenly, with performance often depending on where relevant information appears [76]. Context can conflict with what the model believes. LLMs can be highly receptive to coherent external evidence that contradicts their parametric memory, yet they show confirmation bias when the evidence is partly consistent with it [126], so the effect of supplied knowledge is hard to predict. Finally, the fact that cited evidence was placed in context does not show that the answer depends on it, and a retraction in the store does not reach answers already produced unless invariant I5 is enforced end to end.

## 6.2 Parametric use

A second channel converts explicit knowledge into parameters or parameter-like memories [57]. Knowledge editing writes individual facts into model weights [83] and scales to thousands of edits [84]. ConceptEdit adds conceptualization and instantiation to the editing pipeline, so that edits about commonsense knowledge extend beyond the literal statement [141], and CoCoLM teaches pretrained language models complex commonsense by training them over the eventuality graph ASER [136]. Parametric RAG converts documents into parameters for test-time knowledge enhancement [103; 106]. Hypernetworks generate adapters in a single forward pass, from a task description in Text-to-LoRA [18], from a context in Generative Adapter [21], and from a document in Doc-to-LoRA, which stores needle-in-a-haystack information well beyond the target model’s native context length [19]. Key-value approaches encode knowledge base entries as continuous key-value pairs that the model attends to directly. KBLaM integrates more than ten thousand triples into an 8B model with an 8K context window [118], and AtlasKV scales this idea to knowledge graphs with about one billion triples using less than 20GB of GPU memory [56]. Memory layers add trainable key-value lookups that provide large capacity for factual knowledge at low compute cost [12], and nearest-neighbor language models interpolate with an external datastore [64].

Parametric use removes context costs, but it gives up some of what makes knowledge explicit. Four limitations stand out. First, injected knowledge competes with pretrained priors. For Doc-to-LoRA, accuracy on facts that contradict pretraining collapses to 46.4% on the deepest conflicts, and it falls from 68% to 16% as the base model’s prior on the contradicted fact grows stronger [22]. Second, edits do not propagate to logically related facts [24]. Third, parametric knowledge can be directional, since models trained on “A is B” do not automatically answer “B is A” [13], and knowledge is reliably extractable only if it was seen in diverse forms during training [1]. Fourth, once knowledge is in parameters, its provenance and conditions are no longer attached to it, so it cannot be cited, audited, or cleanly retracted. Parametric encodings are also tied to one model, so a new generation must regenerate them from the explicit records, which is another reason the records, not the encodings, must remain authoritative (P1). Key-value methods keep knowledge separable and updatable [118; 56], which makes them a promising middle ground for use, although their continuous entries are not readable records.

## 6.3 Beyond language models

Both channels exist almost exclusively for language models. Foundation models for structured data accept some side information, but not explicit knowledge in the sense of §2. A tabular in-context learner accepts labeled rows as context, and its prior over dependencies is fixed at pretraining [54; 55]. Time series models accept related series and covariates [3], which is the closest existing mechanism, but not statements such as “demand drops on public holidays” or “these two sensors are on the same road”. Graph and relational models use text embeddings of node features or column names [75; 65; 93], which conveys semantics but not rules, constraints, or known equations. Practitioners can approximate such knowledge by engineering features or by constraining outputs after prediction, but these workarounds are task-specific and cannot be retracted or audited as knowledge. As a result, knowledge discovered by agents, and the large stores of scientific and domain knowledge accumulated by humans, have no general route into the many structured-data tasks that these models serve. A KFM that reasons over the layer and passes conditioned results to such models is one possible bridge, but it does not remove the need for native interfaces.

Gap 3. Non-language foundation models lack a native interface through which explicit knowledge, such as conditional rules, constraints, causal graphs, or equations, can be supplied at inference time, can stably affect predictions, and can later be withdrawn. Such an interface should let correct knowledge help, let incorrect or inapplicable knowledge degrade predictions gracefully, and ensure that withdrawn knowledge stops having an effect.

## 6.4 Where a persistent knowledge layer matters

Two settings show what use looks like when knowledge comes from operations and from people’s lives rather than from documents, and where its value lies.

Enterprise operations. Enterprise data platforms already maintain a shared operational representation. In Palantir Foundry, for example, the ontology is described as a digital twin of the organization, in which object types define real-world entities or events, link types define relationships between them, and action types define sets of edits that a user can make at once. Successful action submissions are recorded in an action log as objects linked to the objects they changed, which the documentation presents as supporting audits, analysis of patterns across decisions, and decision workflows. Read through our loop, business data and operation records are sources and experience, the curated business representation shared by an organization’s applications belongs to its knowledge layer, and decisions and their execution are use whose outcomes become new records. These correspondences describe roles in the knowledge lifecycle. They are not a mapping between the capabilities of such a platform and our three stages. The research question they raise is how to form, from operation records and their outcomes, knowledge that carries conditions and provenance and can be revised, such as the hypothetical regularity when a sole-source supplier is delayed by more than a few days, planners switch to an alternative carrier, except for high-value orders, which go to manual approval, together with the independent cases that support it and the outcomes that followed. In this setting an automatically induced regularity should be a candidate for review by the people accountable for the process, not an executable rule that takes effect without validation, and human overrides of suggested decisions are a valuable source of exceptions. We do not assess here which of these capabilities existing platforms already provide.

Personal agents and consumer services. Personal agents, companionship and social assistants, and e-commerce services draw on three kinds of knowledge that should be kept apart. General commonsense, such as the typical stages of planning a wedding, is largely available in the parameters of current LLMs, and a separate resource for it adds little. Individual event state, such as where a particular user is in such a process, what they have said they do not want, and which plans mentioned in past conversations remain open, is in no model and accumulates over months. Population statistics over private behavioral data, such as how purchases shift in the months after an engagement in a given region, exist only in a platform’s logs and support calibrated estimates where an LLM can only guess. The last two are naturally sequences of eventualities, and conceptualization turns them into conditional regularities, such as a user who does not want work reminders in the evening, rather than the over-general claim that the user dislikes talking about work. They also have to be managed continuously. Personal knowledge links to products, services, and other people, so links need permissions, and an abstraction should not be visible to someone who could not see the instances that support it. Users must be able to inspect, correct, and delete what an agent holds about them, and corrections and deletions must reach derived units (I5) and be honored when an agent forgets. Production systems such as COSMO already generate e-commerce commonsense knowledge from user behavior and serve it to applications [134].

What the value consists of. In both settings, the value of an explicit layer is not only, and not necessarily, higher accuracy on a single answer, since a strong model given the same raw records may answer as well. It lies in reuse of the same knowledge across tasks, products, and parties, in lower cost when many requests are served from processed knowledge instead of reprocessing raw records, in auditability of what a decision or recommendation relied on, and in continuity when the model behind an agent or service is replaced. Enterprise and consumer settings thus support the same claim: experience produced by different systems needs to become knowledge that can be reused, governed, and revised as it evolves.

## 7. A RESEARCH AGENDA

We translate the position into seven challenges. They are not independent. The common knowledge unit (C2) defines the object on which transformation operators (C3, C5) act, knowledge foundation models (C4) reason over their output, and knowledge layers across systems and generations (C6) are where all of them meet. Extraction from and interfaces for non-language foundation models (C1, C7) connect the loop to the models that serve structured-data tasks.

C1. Explicit extraction from implicit foundation models. Develop methods that extract rules, equations, or graphs from tabular, graph, and time series foundation models, with explicit conditions, and that distinguish fidelity to the model, mechanism recovery, and validity under intervention (Gap 1). Synthetic data with known generating processes, which several of these models already use for pretraining [54; 3; 32], provides ground truth.

C2. A common knowledge unit across carriers. Adopt representations that record content, form, conditions, provenance, and status (Equation (1)) for every carrier in its native structure, together with alignments between carriers, so that knowledge produced by different agents can be merged, validated, and versioned.

C3. Conceptualization and consolidation operators with invariants. Define conceptualize, align, merge, forget, and version operators for each knowledge type and carrier, building on entity and eventuality conceptualization [139; 52; 115] and extending it to fragments of agent trajectories and operation records, tables, programs, procedural knowledge, and metacognitive knowledge. Characterize them by the invariants of §5.2, not only by downstream accuracy, and make explicit how each decides what to keep, how far to abstract, and when to merge, refine, or retract (§3.1).

C4. Knowledge foundation models. Build models, possibly neural-symbolic, that learn shared capacity for alignment, conditionpreserving abstraction, and deductive, inductive, and abductive reasoning over heterogeneous, noisy, and incomplete knowledge, that build on the representations and priors of existing language and structured-data models without letting priors override records, that delegate exact computation, and that report the status of each result (Gap 2). Openly available stores such as the ATLAS graphs [6] and eventuality graphs [140], together with structured databases, can serve as training and study material.

C5. Knowledge repair and evolution at scale. Extend entity resolution, completion, population, and conflict resolution to automatically discovered knowledge from many contributors and carriers [33], keep completed items distinct from observed ones, and support temporal evolution with retained history [94], so that the layer improves rather than degrades as it grows.

C6. Knowledge layers across systems and generations. Design layers to which independent agent systems contribute and from which they draw, with scoped sharing, permissions, and provenance boundaries rather than a requirement of one central store, analogous in spirit to the role Wikidata plays for human editors [111]. Ensure that abstractions do not reveal instances their readers are not permitted to see, and that corrections and deletions requested by the people a record concerns propagate (§6.4). Support inheritance by later generations of agents and of KFMs, including revalidation of inherited knowledge, separation of knowledge about the environment from model-specific operational advice, and interpretation of records by models other than the one that wrote them.

C7. Knowledge interfaces for all foundation models. Give nonlanguage foundation models interfaces for conditioning on explicit knowledge (Gap 3), and make parametric use by LLMs robust to conflicts with priors [22] while keeping knowledge separable and retractable.

A key comparison. Across these challenges, one comparison tests whether persistent knowledge processing is worth its cost. The baseline is an agent built on the same model with access to the same raw records, such as trajectories, logs, or operation histories, together with retrieval and code execution, under the same budget of tokens and tool calls. The question is what a processed knowledge layer adds to it. We expect any increment to appear in reuse across instances and tasks, in the handling of conditions and exceptions, in updates and retractions that reach dependent conclusions, and in transfer to agents built on another model family, rather than necessarily in accuracy on a single question. The comparison does not presume that explicit knowledge is more accurate, and finding that the increment appears only in some of these dimensions, or in some regimes and not others, would sharpen the position.

## 8. ALTERNATIVE VIEWS

“Scale is enough.” One view holds that larger models trained on more data will internalize whatever knowledge is needed, making explicit knowledge unnecessary. We agree that scale improves implicit knowledge, and a KFM should exploit it. But implicit knowledge cannot be moved to a new model, cited, or selectively corrected, and studies of parametric knowledge show directional storage [13], dependence on training-data diversity [1], and incomplete propagation of edits [24]. More fundamentally, knowledge that many independent agents discover after a model is trained must go somewhere, and retraining a model for each discovery is neither economical nor auditable. Each new model generation would also start without the record of why earlier conclusions were revised.

“Long context makes knowledge stores unnecessary.” If context windows grow large enough, one could place all relevant knowledge in context. Context remains costly, models use it unevenly [76], and aggregation over millions of facts is beyond any practical window. Context also ends with the session and belongs to one system, so it does not accumulate across systems or generations.

“Each agent can internalize on demand.” A capable LLM agent can retrieve, align, and reason over material for each task, so a separate internalization stage may seem redundant. For a single task this can work well. The cost is that the work is repeated by every agent and after every model upgrade, its intermediate results are not kept for others, and its conclusions are not maintained when sources change. Our claim is about where this work should live, not about whether LLMs can do it. An LLM-based system that performs it persistently and for other parties is one realization of what we advocate. The strongest form of this view is an agent with raw records, retrieval, and code execution, and the comparison at the end of §7 is meant to test it.

“Symbolic knowledge has failed before.” Expert systems and handbuilt knowledge bases struggled with the cost of acquisition and with brittleness [69]. Our position differs in two ways. First, acquisition is now largely automatic and has been shown at scale for taxonomies [124], eventualities [140], and schema-free graphs with billions of edges [6], and automatically generated knowledge is served in production systems [134]. Second, we do not propose symbolic reasoning alone. We propose learned models and operators that act on explicit knowledge and build on implicit capacities, combining the robustness of learned representations with the properties of explicit storage.

“A database with a good parser is enough.” For curated, complete stores with stable schemas, it may be, and symbolic execution should then do the exact computation. Our concern is the distance between exact execution and reliable knowledge conclusions (§5.3). When records are missing, duplicated, phrased in open vocabularies, conflicting, or biased in coverage, an exact answer over the records can be a wrong answer about the world. Cleaning, resolution, and probabilistic databases address parts of this, and they are components of the systems we advocate. What they do not yet provide is shared capacity for alignment across carriers and for inductive and abductive results with explicit status.

“Internalization is just indexing.” One might argue that internalization reduces to better retrieval engineering. Retrieval selects existing units, whereas internalization changes the knowledge layer by aligning, conceptualizing, merging, completing, and correcting, and it produces conclusions, regularities, and explanations that are not stored anywhere.

## 9. CONCLUSION

Knowledge accumulates because people write down what is worth keeping, and others, in their own time and in later generations, refine, combine, and build on it. AI agents are now built by many independent parties and replaced within a few months, yet what they learn stays mainly in parameters, in context, and in private stores that are appended to but rarely processed. We have argued that the next generation of AI should be knowledge-centric. Agents of many systems discover explicit knowledge, a knowledge layer independent of any single agent internalizes it through conceptualization, alignment, maintenance, and deductive, inductive, and abductive reasoning, and agents of other systems and later generations use the result through symbolic and parametric channels. Agent trajectories, operation records, and personal event histories make this concrete: their eventualities are experience, condition-preserving conceptualization of events and event fragments turns them into reusable knowledge, and new outcomes revise it. LLM agents have made rapid progress on discovery from text and on use by language models. The gaps lie in reliable extraction from and use by structured foundation models, and above all in internalization. We hope the community will treat internalization as a persistent object of training and maintenance, and knowledge foundation models, whose foundation is knowledge and its computation and which build on the capacities of existing models, as first-class research problems.

## 10. REFERENCES

[1] Z. Allen-Zhu and Y. Li. Physics of language models: Part 3.1, knowledge storage and extraction. arXiv preprint arXiv:2309.14316, 2023.

[2] J. R. Anderson. Acquisition of cognitive skill. Psychological review, 89(4):369, 1982.

[3] A. F. Ansari, O. Shchur, J. Küken, A. Auer, B. Han, P. Mercado, S. S. Rangapuram, H. Shen, L. Stella, X. Zhang, et al. Chronos-2: From univariate to universal forecasting. arXiv preprint arXiv:2510.15821, 2025.

[4] E. Arakelyan, D. Daza, P. Minervini, and M. Cochez. Complex query answering with neural link predictors. arXiv preprint arXiv:2011.03459, 2020.

[5] H. Babaei Giglou, J. D’Souza, and S. Auer. Llms4ol: Large language models for ontology learning. In International semantic web conference, pages 408–427. Springer, 2023.

[6] J. Bai, W. Fan, Q. Hu, Q. Zong, C. Li, H. T. Tsang, H. Luo, Y. Yim, H. Huang, X. Zhou, et al. Autoschemakg: Autonomous knowledge graph construction through dynamic schema induction from web-scale corpora. In Proceedings of the 64th Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), pages 20557– 20584, 2026.

[7] J. Bai, X. Liu, W. Wang, C. Luo, and Y. Song. Complex query answering on eventuality knowledge graph with implicit logical constraints. Advances in Neural Information Processing Systems, 36:30534–30553, 2023.

[8] J. Bai, Y. Wang, T. Zheng, Y. Guo, X. Liu, and Y. Song. Advancing abductive reasoning in knowledge graphs through complex logical hypothesis generation. In Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), pages 1312– 1329, 2024.

[9] J. Bai, Z. Wang, Y. Zhou, H. Yin, W. Fei, Q. Hu, Z. Deng, J. Cheng, T. Zheng, H. T. Tsang, et al. Top ten challenges towards agentic neural graph databases. arXiv preprint arXiv:2501.14224, 2025.

[10] D. Bailey, J. Borwein, M. Lopez de Prado, and Q. J. Zhu. The probability of backtest overfitting. The Journal ofComputational Finance, 20(4):39–69, 2017.

[11] T. Ban, L. Chen, D. Lyu, X. Wang, Q. Zhu, Q. Tu, and H. Chen. Integrating large language model for improved causal discovery. IEEE Transactions on Artificial Intelligence, 6(11):3030–3042, 2025.

[12] V.-P. Berges, B. Oguz, D. Haziza, W.-t. Yih, L. Zettle-˘ moyer, and G. Ghosh. Memory layers at scale. arXiv preprint arXiv:2412.09764, 2024.

[13] L. Berglund, M. Tong, M. Kaufmann, M. Balesni, A. Stickland, T. Korbak, and O. Evans. The reversal curse: Llms trained on “a is b” fail to learn “b is a”. In International Conference on Learning Representations, volume 2024, pages 18623–18642, 2024.

[14] C. Bhagavatula, R. L. Bras, C. Malaviya, K. Sakaguchi, A. Holtzman, H. Rashkin, D. Downey, S. W.-t. Yih, and Y. Choi. Abductive commonsense reasoning. arXiv preprint arXiv:1908.05739, 2019.

[15] S. Borgeaud, A. Mensch, J. Hoffmann, T. Cai, E. Rutherford, K. Millican, G. B. Van Den Driessche, J.-B. Lespiau, B. Damoc, A. Clark, et al. Improving language models by retrieving from trillions of tokens. In International conference on machine learning, pages 2206–2240. PMLR, 2022.

[16] S. L. Brunton, J. L. Proctor, and J. N. Kutz. Discovering governing equations from data by sparse identification of nonlinear dynamical systems. Proceedings of the national academy ofsciences, 113(15):3932–3937, 2016.

[17] N. Chambers and D. Jurafsky. Unsupervised learning of narrative event chains. In Proceedings of ACL-08: HLT, pages 789–797, 2008.

[18] R. Charakorn, E. Cetin, Y. Tang, and R. T. Lange. Text-to-lora: Instant transformer adaption. arXiv preprint arXiv:2506.06105, 2025.

[19] R. Charakorn, E. Cetin, S. Uesaka, and R. T. Lange. Doc-tolora: Learning to instantly internalize contexts. arXiv preprint arXiv:2602.15902, 2026.

[20] H. Chen. Large knowledge model: Perspectives and challenges. Data Intell., 6(3):587–620, 2024.

[21] T. Chen, H. Fang, P. Xia, X. Liu, B. Van Durme, L. Zettlemoyer, J. Gao, and H. Cheng. Generative adapter: Contextualizing language models in parameters with a single forward pass. In International Conference on Learning Representations, volume 2025, pages 27450–27470, 2025.

[22] S. Cheng, X. Shi, Z. Zhang, and M. Li. The override gap: A magnitude account of knowledge conflict failure in hypernetwork-based instant llm adaptation. arXiv preprint arXiv:2604.23750, 2026.

[23] P. Chhikara, D. Khant, S. Aryan, T. Singh, and D. Yadav. Mem0: Building production-ready ai agents with scalable long-term memory. arXiv preprint arXiv:2504.19413, 2025.

[24] R. Cohen, E. Biran, O. Yoran, A. Globerson, and M. Geva. Evaluating the ripple effects of knowledge editing in language models. Transactions ofthe Associationfor Computational Linguistics, 12:283–298, 2024.

[25] M. Cranmer. Interpretable machine learning for science with pysr and symbolicregression. jl. arXiv preprint arXiv:2305.01582, 2023.

[26] M. Cranmer, A. Sanchez Gonzalez, P. Battaglia, R. Xu, K. Cranmer, D. Spergel, and S. Ho. Discovering symbolic models from deep learning with inductive biases. Advances in neural information processing systems, 33:17429–17442, 2020.

[27] H. Cui, C. Wang, H. Maan, K. Pang, F. Luo, N. Duan, and B. Wang. scgpt: toward building a foundation model for single-cell multi-omics using generative ai. Nature methods, 21(8):1470–1480, 2024.

[28] Y. Cui, Z. Sun, and W. Hu. A prompt-based knowledge graph foundation model for universal in-context reasoning. Advances in Neural Information Processing Systems, 37:7095– 7124, 2024.

[29] N. Dalvi and D. Suciu. Efficient query evaluation on probabilistic databases. The VLDB Journal, 16(4):523–544, 2007.

[30] D. Edge, H. Trinh, N. Cheng, J. Bradley, A. Chao, A. Mody, S. Truitt, D. Metropolitansky, R. O. Ness, and J. Larson. From local to global: A graph rag approach to query-focused summarization. arXiv preprint arXiv:2404.16130, 2024.

[31] K. Ellis, L. Wong, M. Nye, M. Sable-Meyer, L. Cary, L. Anaya Pozo, L. Hewitt, A. Solar-Lezama, and J. B. Tenenbaum. Dreamcoder: growing generalizable, interpretable knowledge with wake–sleep bayesian program learning. Philosophical Transactions of the Royal Society A, 381(2251):20220050, 2023.

[32] D. Eremeev, O. Platonov, G. Bazhenov, A. Babenko, and L. Prokhorenkova. Graphpfn: A prior-data fitted graph foundation model. arXiv preprint arXiv:2509.21489, 2025.

[33] T. Fang, W. Wang, S. Choi, S. Hao, H. Zhang, Y. Song, and B. He. Benchmarking commonsense knowledge base population with an effective evaluation dataset. In Proceedings of the 2021 Conference on Empirical Methods in Natural Language Processing, pages 8949–8964, 2021.

[34] L. A. Galárraga, C. Teflioudi, K. Hose, and F. Suchanek. Amie: association rule mining under incomplete evidence in ontological knowledge bases. In Proceedings of the 22nd international conference on World Wide Web, pages 413–422, 2013.

[35] M. Galkin, X. Yuan, H. Mostafa, J. Tang, and Z. Zhu. Towards foundation models for knowledge graph reasoning. In International Conference on Learning Representations, volume 2024, pages 31598–31619, 2024.

[36] M. Galkin, J. Zhou, B. Ribeiro, J. Tang, and Z. Zhu. A Foundation Model for Zero-shot Logical Query Reasoning. In Advances in Neural Information Processing Systems 37, 2024.

[37] Y. Gao. Retrieval-augmented generation for large language models: A survey. arXiv preprint arXiv:2312.10997, 2023.

[38] Y. Gao, J. Bai, H. Huang, Z. Xie, Y. Li, H. T. Tsang, S. Han, and Y. Song. Kgpfn: Unlocking the potential of knowledge graph foundation model via in-context learning. arXiv preprint arXiv:2605.14907, 2026.

[39] Y. Gao, J. Bai, Y. Huang, X. Fu, Q. Sun, and Y. Song. Unifying deductive and abductive reasoning in knowledge graphs with masked diffusion model. In Proceedings of the ACM Web Conference 2026, pages 3600–3611, 2026.

[40] Y. Gao, J. Bai, T. Zheng, Z. Zhang, Q. Sun, X. Fu, J. Li, and Y. Song. Controllable logical hypothesis generation for abductive reasoning in knowledge graphs. In International Conference on Learning Representations, volume 2026, pages 16400–16421, 2026.

[41] Y. Gao, Y. Cai, T. Zheng, J. Bai, and Y. Song. Hypoagent: An agentic framework for interactive abductive hypothesis generation over knowledge graphs. arXiv preprint arXiv:2605.31370, 2026.

[42] Y. Gao, Y. Guo, Q. Zong, Y. Guo, and Y. Song. Safe, persistent, and evolving agent harness for understanding partially observable worlds. arXiv preprint arXiv:2610.11552, 2026.

[43] M. Geva, J. Bastings, K. Filippova, and A. Globerson. Dissecting recall of factual associations in auto-regressive language models. In Proceedings of the 2023 Conference on Empirical Methods in Natural Language Processing, pages 12216–12235, 2023.

[44] G. Grand, L. Wong, M. Bowers, T. X. Olausson, M. Liu, J. B. Tenenbaum, and J. Andreas. Lilo: Learning interpretable libraries by compressing and documenting code. In International Conference on Learning Representations, volume 2024, pages 30399–30446, 2024.

[45] A. Grayeli, A. Sehgal, O. Costilla-Reyes, M. Cranmer, and S. Chaudhuri. Symbolic regression with a learned concept library. Advances in Neural Information Processing Systems, 37:44678–44709, 2024.

[46] T. R. Gruber. A translation approach to portable ontology specifications. Knowledge acquisition, 5(2):199–220, 1993.

[47] Z. Guo, L. Xia, Y. Yu, T. Ao, and C. Huang. Lightrag: Simple and fast retrieval-augmented generation. In EMNLP (Findings), pages 10746–10761, 2025.

[48] B. J. Gutiérrez, Y. Shu, Y. Gu, M. Yasunaga, and Y. Su. Hipporag: Neurobiologically inspired long-term memory for large language models. Advances in neural information processing systems, 37:59532–59569, 2024.

[49] B. J. Gutiérrez, Y. Shu, W. Qi, S. Zhou, and Y. Su. From rag to memory: Non-parametric continual learning for large language models. arXiv preprint arXiv:2502.14802, 2025.

[50] K. Guu, K. Lee, Z. Tung, P. Pasupat, and M. Chang. Retrieval augmented language model pre-training. In International conference on machine learning, pages 3929–3938. PMLR, 2020.

[51] W. Hamilton, P. Bajaj, M. Zitnik, D. Jurafsky, and J. Leskovec. Embedding logical queries on knowledge graphs. Advances in neural information processing systems, 31, 2018.

[52] M. He, T. Fang, W. Wang, and Y. Song. Acquiring and modeling abstract commonsense knowledge via conceptualization. Artificial Intelligence, 333:104149, 2024.

[53] E. Hernandez, A. Sen Sharma, T. Haklay, K. Meng, M. Wattenberg, J. Andreas, Y. Belinkov, and D. Bau. Linearity of relation decoding in transformer language models. In International Conference on Learning Representations, volume 2024, pages 10504–10526, 2024.

[54] N. Hollmann, S. Müller, K. Eggensperger, and F. Hutter. Tabpfn: A transformer that solves small tabular classification problems in a second. arXiv preprint arXiv:2207.01848, 2022.

[55] N. Hollmann, S. Müller, L. Purucker, A. Krishnakumar, M. Körfer, S. B. Hoo, R. T. Schirrmeister, and F. Hutter. Accurate predictions on small data with a tabular foundation model. Nature, 637(8045):319–326, 2025.

[56] H. Huang, H. T. Tsang, J. Bai, X. Peng, G. Zhang, and Y. Song. Atlaskv: Augmenting llms with billion-scale knowledge graphs in 20gb vram. In International Conference on Learning Representations, volume 2026, pages 125035– 125060, 2026.

[57] H. Huang, Z. Xie, J. Bai, Y. Gao, H. T. Tsang, W. Song, H. Jing, Y. Li, and Y. Song. Towards in-parameter memory augmentation for large language models. arXiv preprint arXiv:2610.08630, 2026.

[58] K. Huang, Y. Jin, R. Li, M. Y. Li, E. Candès, and J. Leskovec. Automated hypothesis validation with agentic sequential falsifications. arXiv preprint arXiv:2502.09858, 2025.

[59] Y. Huang, S. Hu, H. Gu, C. Ma, J. Zhang, Z. Zou, C. Fan, Y. Xiao, M. Xu, C. Xie, M. Ju, Z. Ma, Q. Zhang, B. Wang, Y. Li, Z. Yao, R. Liao, X. Li, L. Zhang, K. Chen, and W. E. Large Knowledge Model: A Knowledge Foundation for Agentic Science at Scale. arXiv preprint arXiv:2609.27297, 2026.

[60] A. Jacovi and Y. Goldberg. Towards faithfully interpretable nlp systems: How should we define and evaluate faithfulness? In Proceedings ofthe 58th annual meeting ofthe association for computational linguistics, pages 4198–4205, 2020.

[61] S. Ji, Y. Li, and B. Hooi. Memory is reconstructed, not retrieved: Graph memory for llm agents. arXiv preprint arXiv:2606.06036, 2026.

[62] J. Jiang, K. Zhou, Z. Dong, K. Ye, X. Zhao, and J.-R. Wen. Structgpt: A general framework for large language model to reason over structured data. In Proceedings ofthe 2023 conference on empirical methods in natural language processing, pages 9237–9251, 2023.

[63] C. Jiayang, L. Qiu, C. Chan, X. Liu, Y. Song, and Z. Zhang. Eventground: Narrative reasoning by grounding to eventuality-centric knowledge graphs. In Proceedings of the 2024 Joint International Conference on Computational Linguistics, Language Resources and Evaluation (LREC-COLING 2024), pages 6622–6642, 2024.

[64] U. Khandelwal, O. Levy, D. Jurafsky, L. Zettlemoyer, and M. Lewis. Generalization through memorization: Nearest neighbor language models. arXiv preprint arXiv:1911.00172, 2019.

[65] M. J. Kim, L. Grinsztajn, and G. Varoquaux. Carte: pretraining and transfer for tabular learning. arXiv preprint arXiv:2402.16785, 2024.

[66] D. R. Krathwohl. A revision of bloom’s taxonomy: An overview. Theory into practice, 41(4):212–218, 2002.

[67] F. Lei, J. Chen, Y. Ye, R. Cao, D. Shin, H. Su, Z. Suo, H. Gao, W. Hu, P. Yin, et al. Spider 2.0: Evaluating language models on real-world enterprise text-to-sql workflows. In International Conference on Learning Representations, volume 2025, pages 28691–28735, 2025.

[68] P. Lemos, N. Jeffrey, M. Cranmer, S. Ho, and P. Battaglia. Rediscovering orbital mechanics with machine learning. Machine Learning: Science and Technology, 4(4):045002, 2023.

[69] D. B. Lenat. Cyc: A large-scale investment in knowledge infrastructure. Communications ofthe ACM, 38(11):33–38, 1995.

[70] P. Lewis, E. Perez, A. Piktus, F. Petroni, V. Karpukhin, N. Goyal, H. Küttler, M. Lewis, W.-t. Yih, T. Rocktäschel, et al. Retrieval-augmented generation for knowledgeintensive nlp tasks. Advances in neural information processing systems, 33:9459–9474, 2020.

[71] J. Li, B. Hui, G. Qu, J. Yang, B. Li, B. Li, B. Wang, B. Qin, R. Geng, N. Huo, et al. Can llm already serve as a database interface? a big bench for large-scale database grounded textto-sqls. Advances in Neural Information Processing Systems, 36:42330–42357, 2023.

[72] S. Li, R. Zhao, M. Li, H. Ji, C. Callison-Burch, and J. Han. Open-domain hierarchical event schema induction by incremental prompting and verification. In Proceedings of the 61st Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), pages 5677–5697, 2023.

[73] Y. Li, Y. Gao, J. Bai, J. Xiong, H. Huang, Z. Xie, H. T. Tsang, and Y. Song. Towards neural graph data management. arXiv preprint arXiv:2603.05529, 2026.

[74] Y. Li, X. Yang, X. Yang, X. Wang, W. Liu, and J. Bian. R&d-agent-quant: a multi-agent framework for data-centric factors and model joint optimization. Advances in Neural Information Processing Systems, 38, 2026.

[75] H. Liu, J. Feng, L. Kong, N. Liang, D. Tao, Y. Chen, and M. Zhang. One for all: Towards training one graph model for all classification tasks. In International conference on learning representations, volume 2024, pages 20188–20210, 2024.

[76] N. F. Liu, K. Lin, J. Hewitt, A. Paranjape, M. Bevilacqua, F. Petroni, and P. Liang. Lost in the middle: How language models use long contexts. Transactions ofthe associationfor computational linguistics, 12:157–173, 2024.

[77] Y. Liu, E. Pena, A. Santos, E. Wu, and J. Freire. Magneto: Combining small and large language models for schema matching. arXiv preprint arXiv:2412.08194, 2024.

[78] Z. Liu, Y. Wang, S. Vaidya, F. Ruehle, J. Halverson, M. Soljacic, T. Hou, and M. Tegmark. Kan: Kolmogorov–arnold networks. In International conference on learning representations, volume 2025, pages 70367–70413, 2025.

[79] L. Luo, J. Ju, B. Xiong, Y.-F. Li, G. Haffari, and S. Pan. Chatrule: Mining logical rules with large language models for knowledge graph reasoning. In Pacific-asia conference on knowledge discovery and data mining, pages 314–325. Springer, 2025.

[80] L. Luo, Y.-F. Li, R. Haffari, and S. Pan. Reasoning on graphs: Faithful and interpretable large language model reasoning. In International Conference on Learning Representations, volume 2024, pages 14400–14423, 2024.

[81] B. P. Majumder, H. Surana, D. Agarwal, B. Dalvi Mishra, A. Meena, A. Prakhar, T. Vora, T. Khot, A. Sabharwal, and P. Clark. Discoverybench: Towards data-driven discovery with large language models. In International Conference on Learning Representations, volume 2025, pages 4556–4579, 2025.

[82] J. L. McClelland, B. L. McNaughton, and R. C. O’Reilly. Why there are complementary learning systems in the hippocampus and neocortex: insights from the successes and failures of connectionist models of learning and memory. Psychological review, 102(3):419, 1995.

[83] K. Meng, D. Bau, A. Andonian, and Y. Belinkov. Locating and editing factual associations in gpt. Advances in neural information processing systems, 35:17359–17372, 2022.

[84] K. Meng, A. S. Sharma, A. Andonian, Y. Belinkov, and D. Bau. Mass-editing memory in a transformer. arXiv preprint arXiv:2210.07229, 2022.

[85] I. Nonaka. A dynamic theory of organizational knowledge creation. Organization science, 5(1):14–37, 1994.

[86] S. Ouyang, J. Yan, I. Hsu, Y. Chen, K. Jiang, Z. Wang, R. Han, L. Le, S. Daruki, X. Tang, et al. Reasoningbank: Scaling agent self-evolving with reasoning memory. In International Conference on Learning Representations, volume 2026, pages 94327–94354, 2026.

[87] C. Packer, S. Wooders, K. Lin, V. Fang, S. G. Patil, I. Stoica, and J. E. Gonzalez. Memgpt: Towards llms as operating systems. arXiv preprint arXiv:2310.08560, 2023.

[88] S. Pan, L. Luo, Y. Wang, C. Chen, J. Wang, and X. Wu. Unifying large language models and knowledge graphs: A roadmap. IEEE Transactions on Knowledge and Data Engineering, 36(7):3580–3599, 2024.

[89] J. S. Park, J. O’Brien, C. J. Cai, M. R. Morris, P. Liang, and M. S. Bernstein. Generative agents: Interactive simulacra of human behavior. In Proceedings ofthe 36th annual acm symposium on user interface software and technology, pages 1–22, 2023.

[90] F. Petroni, T. Rocktäschel, S. Riedel, P. Lewis, A. Bakhtin, Y. Wu, and A. Miller. Language models as knowledge bases? In Proceedings ofthe 2019 conference on empirical methods in natural language processing and the 9th international joint conference on natural language processing (EMNLP-IJCNLP), pages 2463–2473, 2019.

[91] L. Qiu, L. Jiang, X. Lu, M. Sclar, V. Pyatkin, C. Bhagavatula, B. Wang, Y. Kim, Y. Choi, N. Dziri, et al. Phenomenal yet puzzling: Testing inductive reasoning capabilities of language models with hypothesis refinement. In International Conference on Learning Representations, volume 2024, pages 1452–1481, 2024.

[92] J. Qu, D. HolzmÃžller, G. Varoquaux, and M. L. Morvan. Tabicl: A tabular foundation model for in-context learning on large data. arXiv preprint arXiv:2502.05564, 2025.

[93] R. Ranjan, V. Hudovernik, M. Znidar, C. Kanatsoulis, R. Upendra, M. Mohammadi, J. Meyer, T. Palczewski, C. Guestrin, and J. Leskovec. Relational transformer: Toward zero-shot foundation models for relational data. In International Conference on Learning Representations, volume 2026, pages 69149–69174, 2026.

[94] P. Rasmussen, P. Paliychuk, T. Beauvais, J. Ryan, and D. Chalef. Zep: a temporal knowledge graph architecture for agent memory. arXiv preprint arXiv:2501.13956, 2025.

[95] H. Ren, M. Galkin, M. Cochez, Z. Zhu, and J. Leskovec. Neural graph reasoning: Complex logical query answering meets graph databases. arXiv preprint arXiv:2303.14617, 2023.

[96] H. Ren, W. Hu, and J. Leskovec. Query2box: Reasoning over knowledge graphs in vector space using box embeddings. arXiv preprint arXiv:2002.05969, 2020.

[97] H. Ren and J. Leskovec. Beta embeddings for multi-hop logical reasoning in knowledge graphs. Advances in Neural Information Processing Systems, 33:19716–19726, 2020.

[98] J. Rowley. The wisdom hierarchy: representations of the dikw hierarchy. Journal ofinformation science, 33(2):163– 180, 2007.

[99] N. Shinn, F. Cassano, A. Gopinath, K. Narasimhan, and S. Yao. Reflexion: Language agents with verbal reinforcement learning. Advances in neural information processing systems, 36:8634–8652, 2023.

[100] P. Shojaee, K. Meidani, S. Gupta, A. Barati Farimani, and C. Reddy. Llm-sr: Scientific equation discovery via programming with large language models. In International Conference on Learning Representations, volume 2025, pages 16054–16085, 2025.

[101] P. Shojaee, N.-H. Nguyen, K. Meidani, A. B. Farimani, K. D. Doan, and C. K. Reddy. Llm-srbench: A new benchmark for scientific equation discovery with large language models. arXiv preprint arXiv:2504.10415, 2025.

[102] J. P. Simmons, L. D. Nelson, and U. Simonsohn. Falsepositive psychology: Undisclosed flexibility in data collection and analysis allows presenting anything as significant. Psychological science, 22(11):1359–1366, 2011.

[103] W. Su, Y. Tang, Q. Ai, J. Yan, C. Wang, H. Wang, Z. Ye, Y. Zhou, and Y. Liu. Parametric retrieval augmented generation. In Proceedings ofthe 48th International ACM SIGIR Conference on Research and Development in Information Retrieval, pages 1240–1250, 2025.

[104] J. Sun, C. Xu, L. Tang, S. Wang, C. Lin, Y. Gong, L. Ni, H.-Y. Shum, and J. Guo. Think-on-graph: Deep and responsible reasoning of large language model on knowledge graph. In International Conference on Learning Representations, volume 2024, pages 3868–3898, 2024.

[105] M. Suzgun, M. Yuksekgonul, F. Bianchi, D. Jurafsky, and J. Zou. Dynamic cheatsheet: Test-time learning with adaptive memory. In Proceedings ofthe 19th Conference ofthe European Chapter of the Association for Computational Linguistics (Volume 1: Long Papers), pages 7080–7106, 2026.

[106] Y. Tan, S. He, H. Liao, J. Zhao, and K. Liu. Dynamic parametric retrieval augmented generation for test-time knowledge enhancement. arXiv preprint arXiv:2503.23895, 2025.

[107] Z. Tang, Z. Chen, J. Yang, J. Mai, Y. Zheng, K. Wang, J. Chen, and L. Lin. Alphaagent: Llm-driven alpha mining with regularized exploration to counteract alpha decay. In Proceedings ofthe 31st ACM SIGKDD Conference on Knowledge Discovery and Data Mining V. 2, pages 2813–2822, 2025.

[108] J. Thorne, M. Yazdani, M. Saeidi, F. Silvestri, S. Riedel, and A. Halevy. From natural language processing to neural databases. In Proceedings of the VLDB Endowment, volume 14, pages 1033–1039. VLDB Endowment, 2021.

[109] M. Turpin, J. Michael, E. Perez, and S. Bowman. Language models don’t always say what they think: Unfaithful explanations in chain-of-thought prompting. Advances in Neural Information Processing Systems, 36:74952–74965, 2023.

[110] S.-M. Udrescu and M. Tegmark. Ai feynman: A physicsinspired method for symbolic regression. Science advances, 6(16):eaay2631, 2020.

[111] D. Vrandeciˇ c and M. Krötzsch. Wikidata: a free collaborative´ knowledgebase. Communications ofthe ACM, 57(10):78–85, 2014.

[112] Z. Wan, F. Cheng, Z. Mao, Q. Liu, H. Song, J. Li, and S. Kurohashi. Gpt-re: In-context learning for relation extraction using large language models. In Proceedings of the 2023 conference on empirical methods in natural language processing, pages 3534–3547, 2023.

[113] G. Wang, Y. Xie, Y. Jiang, A. Mandlekar, C. Xiao, Y. Zhu, L. Fan, and A. Anandkumar. Voyager: An open-ended embodied agent with large language models. arXiv preprint arXiv:2305.16291, 2023.

[114] R. Wang, E. Zelikman, G. Poesia, Y. Pu, N. Haber, and N. Goodman. Hypothesis search: Inductive reasoning with language models. In International Conference on Learning Representations, volume 2024, pages 38993–39014, 2024.

[115] W. Wang, T. Fang, C. Li, H. Shi, W. Ding, B. Xu, Z. Wang, J. Bai, X. Liu, C. Jiayang, et al. Candle: iterative conceptualization and instantiation distillation from large language models for commonsense reasoning. In Proceedings ofthe 62nd Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), pages 2351–2374, 2024.

[116] W. Wang, T. Fang, H. Shi, B. Xu, W. Ding, L. Zhang, W. Fan, J. Bai, H. Li, X. Liu, et al. On the role of entity and event level conceptualization in generalizable reasoning: A survey of tasks, methods, applications, and future directions. arXiv preprint arXiv:2406.10885, 2024.

[117] W. Wang, T. Fang, B. Xu, C. Y. L. Bo, Y. Song, and L. Chen. Cat: A contextualized conceptualization and instantiation framework for commonsense reasoning. In Proceedings of the 61st Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), pages 13111–13140, 2023.

[118] X. Wang, T. Isazawa, L. Mikaelyan, and J. Hensman. Kblam: Knowledge base augmented language model. In International Conference on Learning Representations, volume 2025, pages 51629–51658, 2025.

[119] Z. Wang, H. Shi, W. Wang, T. Fang, H. Zhang, S. Choi, X. Liu, and Y. Song. Abspyramid: Benchmarking the abstraction ability of language models with a unified entailment graph. In Findings ofthe Associationfor Computational Linguistics: NAACL 2024, pages 3991–4010, 2024.

[120] Z. Wang, Y. Song, G. Y. Wong, and S. See. Logical message passing networks with one-hop inference on atomic formulas. arXiv preprint arXiv:2301.08859, 2023.

[121] Z. Wang, H. Yin, and Y. Song. Benchmarking the combinatorial generalizability of complex query answering on knowledge graphs. arXiv preprint arXiv:2109.08925, 2021.

[122] Z. Z. Wang, J. Mao, D. Fried, and G. Neubig. Agent workflow memory. arXiv preprint arXiv:2409.07429, 2024.

[123] X. Wei, X. Cui, N. Cheng, X. Wang, X. Zhang, S. Huang, P. Xie, J. Xu, Y. Chen, M. Zhang, et al. Chatie: Zero-shot information extraction via chatting with chatgpt. arXiv preprint arXiv:2302.10205, 2023.

[124] W. Wu, H. Li, H. Wang, and K. Q. Zhu. Probase: A probabilistic taxonomy for text understanding. In Proceedings of the 2012 ACM SIGMOD international conference on management ofdata, pages 481–492, 2012.

[125] S. Xia, Y. Sun, and P. Liu. Sr-scientist: Scientific equation discovery with agentic ai. In International Conference on Learning Representations, volume 2026, pages 75787–75811, 2026.

[126] J. Xie, K. Zhang, J. Chen, R. Lou, and Y. Su. Adaptive chameleon or stubborn sloth: Revealing the behavior of large language models in knowledge conflicts. In B. Kim, Y. Yue, S. Chaudhuri, K. Fragkiadaki, M. Khan, and Y. Sun, editors, International Conference on Learning Representations, volume 2024, pages 35623–35646, 2024.

[127] Z. Xie, J. Bai, S. Liu, H. Huang, Y. Li, Y. Gao, H. T. Tsang, and Y. Song. Ngdb-zoo: Towards efficient and scalable neural graph databases training. arXiv preprint arXiv:2602.21597, 2026.

[128] D. Xu, W. Chen, W. Peng, C. Zhang, T. Xu, X. Zhao, X. Wu, Y. Zheng, Y. Wang, and E. Chen. Large language models for generative information extraction: A survey. Frontiers of Computer Science, 18(6):186357, 2024.

[129] W. Xu, Z. Liang, K. Mei, H. Gao, J. Tan, and Y. Zhang. Amem: Agentic memory for llm agents. Advances in Neural Information Processing Systems, 38:17577–17604, 2026.

[130] Z. Yang, W. Liu, B. Gao, T. Xie, Y. Li, W. Ouyang, S. Poria, E. Cambria, and D. Zhou. Moose-chem: Large language models for rediscovering unseen chemistry scientific hypotheses. In International Conference on Learning Representations, volume 2025, pages 33251–33277, 2025.

[131] L. Yao, C. Mao, and Y. Luo. Kg-bert: Bert for knowledge graph completion. arXiv preprint arXiv:1909.03193, 2019.

[132] S. Yao, J. Zhao, D. Yu, N. Du, I. Shafran, K. Narasimhan, and Y. Cao. React: Synergizing reasoning and acting in language models. arXiv preprint arXiv:2210.03629, 2022.

[133] H. Yin, Z. Wang, and Y. Song. Rethinking complex queries on knowledge graphs with neural link predictors. In International Conference on Learning Representations, volume 2024, pages 19722–19746, 2024.

[134] C. Yu, X. Liu, J. Maia, Y. Li, T. Cao, Y. Gao, Y. Song, R. Goutam, H. Zhang, B. Yin, et al. Cosmo: A large-scale ecommerce common sense knowledge generation and serving system at amazon. In Companion of the 2024 International Conference on Management ofData, pages 148–160, 2024.

[135] C. Yu, W. Wang, X. Liu, J. Bai, Y. Song, Z. Li, Y. Gao, T. Cao, and B. Yin. Folkscope: Intention knowledge graph construction for e-commerce commonsense discovery. In Findings of the Association for Computational Linguistics: ACL 2023, pages 1173–1191, 2023.

[136] C. Yu, H. Zhang, Y. Song, and W. Ng. Cocolm: Complex commonsense enhanced language model with discourse relations. In Findings of the Association for Computational Linguistics: ACL 2022, pages 1175–1187, 2022.

[137] S. Yu, H. Xue, X. Ao, F. Pan, J. He, D. Tu, and Q. He. Generating synergistic formulaic alpha collections via reinforcement learning. In Proceedings ofthe 29th ACM SIGKDD conference on knowledge discovery and data mining, pages 5476–5486, 2023.

[138] G. Zhang, M. Fu, K. Wang, F. Wan, M. Yu, and S. Yan. G-memory: Tracing hierarchical memory for multi-agent systems. Advances in Neural Information Processing Systems, 38:12988–13018, 2026.

[139] H. Zhang, X. Liu, H. Pan, H. Ke, J. Ou, T. Fang, and Y. Song. Aser: Towards large-scale commonsense knowledge acquisition via higher-order selectional preference over eventualities. Artificial Intelligence, 309:103740, 2022.

[140] H. Zhang, X. Liu, H. Pan, Y. Song, and C. W.-K. Leung. Aser: A large-scale eventuality knowledge graph. In Proceedings ofthe web conference 2020, pages 201–211, 2020.

[141] L. Zhang, W. Wang, T. Fang, and Y. Song. Conke: Conceptualization-augmented knowledge editing in large language models for commonsense reasoning. In Findings ofthe Associationfor Computational Linguistics: ACL 2025, pages 627–635, 2025.

[142] Q. Zhang, C. Hu, S. Upasani, B. Ma, F. Hong, V. Kamanuru, J. Rainton, C. Wu, M. Ji, H. Li, et al. Agentic context engineering: Evolving contexts for self-improving language models. In International Conference on Learning Representations, volume 2026, pages 86069–86100, 2026.

[143] A. Zhao, D. Huang, Q. Xu, M. Lin, Y.-J. Liu, and G. Huang. Expel: Llm agents are experiential learners. In Proceedings of the AAAI Conference on Artificial Intelligence, volume 38, pages 19632–19642, 2024.

[144] B. Zheng, M. Y. Fatemi, X. Jin, Z. Z. Wang, A. Gandhi, Y. Song, Y. Gu, J. Srinivasa, G. Liu, G. Neubig, et al. Skillweaver: Web agents can self-improve by discovering and honing skills. arXiv preprint arXiv:2504.07079, 2025.

[145] X. Zheng, B. Aragam, P. K. Ravikumar, and E. P. Xing. Dags with no tears: Continuous optimization for structure learning. Advances in neural information processing systems, 31, 2018.

[146] W. Zhong, L. Guo, Q. Gao, H. Ye, and Y. Wang. Memorybank: Enhancing large language models with long-term memory. In Proceedings ofthe AAAI conference on artificial intelligence, volume 38, pages 19724–19731, 2024.

[147] Y. Zhou, H. Liu, T. Srivastava, H. Mei, and C. Tan. Hypothesis generation with large language models. In Proceedings of the 1st Workshop on NLP for Science (NLP4Science), pages 117–139, 2024.

[148] Y. Zhu, X. Wang, J. Chen, S. Qiao, Y. Ou, Y. Yao, S. Deng, H. Chen, and N. Zhang. Llms for knowledge graph construction and reasoning: Recent capabilities and future opportunities. World Wide Web, 27(5):58, 2024.

[149] Z. Zhu, Y. Xue, X. Chen, D. Zhou, J. Tang, D. Schuurmans, and H. Dai. Large language models can learn rules. arXiv preprint arXiv:2310.07064, 2023.

[150] Z. Zhu, Z. Zhang, L.-P. Xhonneux, and J. Tang. Neural bellman-ford networks: A general graph neural network framework for link prediction. Advances in neural information processing systems, 34:29476–29490, 2021.
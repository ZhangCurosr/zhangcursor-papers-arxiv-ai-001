# Graph-Mediated Large Language Model Systems in the Agentic Era: Reasoning, Knowledge, Retrieval, Execution, and Coordination

Haihui Liu, Yang Chen, Zice Qiu, Yun Zhang, Jialun Zhong, Wenhua Wang, Member, IEEE, Yanzeng Li, Member, IEEE and Tian Wang, Senior Member, IEEE

Abstract—Graphs play an increasingly important role in large language model (LLM) systems, supporting structural reasoning, knowledge grounding, retrieval, and memory. As these systems evolve toward the agentic era, graphs also organize execution dependencies and multi-agent communication, linking intermediate observations and retained information to subsequent decisions. However, understanding their contribution requires distinguishing the function of each graph operation, the component responsible for its computation, and the subsequent use of its output. This survey introduces an operation-level role– locus taxonomy for reasoning, knowledge and evidence, retrieval and memory, execution, and coordination. We compare how graph observations and external computations guide decisions, how memory representations and updates support later tasks, and how dependencies constrain execution and information delivery. These comparisons distinguish improvements in local metrics from downstream task performance while retaining the conditions under which results were reported. We then organize benchmarks, comparison designs, process diagnostics, and system costs into an evaluation framework. Finally, we identify open challenges in adaptive computation and stopping, memory maintenance, and dependency-aware recovery. The survey provides a basis for assessing when graph mechanisms are useful and for evaluating their effects across components and stages.

Index Terms—Large language models, graph-mediated reasoning, knowledge graphs, retrieval-augmented generation, agentic artificial intelligence.

The work was supported in part by the Joint Funds of the National Natural Science Foundation of China under Grant U25A20436, the National Natural Science Foundation of China (NSFC) under Grants 62372047 and 62602061, Guangdong S&T Programme (No. 2025B0101120006), the Supplemental Funds for Major Scientific Research Projects of Beijing Normal University, Zhuhai (ZHPT2023002), the Foundation of Yunnan Key Laboratory of Service Computing (YNSC26202), the Fundamental Research Funds for the Central Universities, Guangdong Provincial Education Science Planning Research Project under 2025JKZG069, and Higher Education Research Topics of Guangdong Association of Higher Education in the 14th Five-Year Plan under 24GYB207. (Corresponding author: Yanzeng Li.)

Haihui Liu, Yang Chen, Wenhua Wang and Yanzeng Li are with the Institute of Artificial Intelligence and Future Networks, Beijing Normal University, Zhuhai 519087, China (e-mail: haihuiliu@mail.bnu.edu.cn; yang.chen@mail.bnu.edu.cn; cs wwh@bnu.edu.cn; liyanzeng@bnu.edu.cn).

Zice Qiu is with the School of Geospatial Engineering and Science, Sun Yat-sen University, Zhuhai 519082, China (2908624009@qq.com).

Yun Zhang is with the Faculty of Science and Technology, Beijing Normal-Hong Kong Baptist University, Zhuhai 519087, China (v530026285@mail.bnbu.edu.cn).

Jialun Zhong is with the Wangxuan Institute of Computer Technology, Peking University, Beijing 100871, China (zhongjl@stu.pku.edu.cn).

Tian Wang is with the Engineering Research Center of Cloud-Edge Intelligent Collaboration on Big Data, Ministry of Education, Beijing Normal University, Zhuhai 519087, China (tianwang@bnu.edu.cn).

## I. INTRODUCTION

Large language model (LLM) systems increasingly combine generation with retrieval, external tools, and multi-step interaction [1]–[3]. Their operation involves relations among facts, intermediate results, and actions, which graphs can represent explicitly. Graphs serve as reasoning objects for studying structural computation [4], [5], organize knowledge and evidence for answering [6], [7], and express dependencies among reasoning operations [8].

In agentic systems, graph operations influence decisions across steps and interactions. Retrieved evidence guides further search or tool selection [9]. Retained memory informs later tasks [10], [11], execution dependencies govern tool calls [12], and communication routes determine which information reaches other agents [13]. The analysis therefore extends from individual answers to the effects of observations, updates, and dependencies on subsequent behavior. Adaptive decision-making can use fixed graphs as well as graphs revised during interaction.

The central question is how a graph operation affects the work that follows. A local view leaves the target computation to the model [14], whereas delegation assigns that computation to software [15]. Reusing these outputs introduces further dependencies. Consider the question, “Which organizations operate facilities in the city where researcher A was born?” A retrieved path provides relational evidence, and an executable query combines the relevant facts. If a facility changes operator, questions about its current and past operators require time-specific answers. A notification intended for the current operator should be addressed accordingly, even if a saved plan still names the previous one. Correct retrieval alone therefore does not ensure correct action.

Existing surveys organize graph–LLM integration by model–graph relationships [6], technical roles [16], and research directions [17]. Shang and Huang [18] review graph queries, inference and learning, and applications. Other reviews cover knowledge graph (KG) question answering [19], graph retrieval [7], graph-supported agents [20]–[22], and workflow optimization [23]. Yang et al. [24] organize graph memory by its lifecycle, while Xu et al. [25] examine agent evolution through graph transformations. Chen et al. [26] cross planner, actor, critic, and memory roles with indexing, traversal, and construction in an Agentic GraphRAG taxonomy. Our framework complements this grid by classifying stage-

(a) Functional roles

![](images/8150291f86f21875eb64a9f8b47e1c5fcbfdb7fde2fca318034b9a909efefd46.jpg)  
Fig. 1. Overview of graph roles and computation loci. (a) Role-specific examples: s and t are source and target vertices, with intermediate vertices u, v and highlighted path s–u–t; A and F denote a person and a facility linked to a city by labeled relations; q is a query, m<sub>1</sub>, m<sub>2</sub> are memory items, and d<sub>1</sub>, d<sub>2</sub> are associated source records; completed operations a, b are prerequisites of ready operation c; and A<sub>1</sub>–A<sub>3</sub> are agents connected by directed message routes. Blue emphasizes the illustrated path, evidence, memory links, ready operation, or message route. (b) L<sub>1</sub>–L<sub>4</sub> distinguish computational responsibilities, from model inference to orchestration. (c) Selected role–locus assignments apply to individual operations; a system may contain several assignments. Section markers connect the roles to the review, and the bottom row links them to the three cross-role research questions.

specific operations according to graph function and computational responsibility, including graph-object tasks, executable dependencies, and communication topology. We trace how the outputs of these operations affect subsequent decisions and how the reported experiments support those effects.

We use the term graph-mediated LLM systems to denote graph-reasoning methods and agentic applications with identifiable operations that use graph relations. Our role– locus taxonomy separates graph function from computational responsibility. It distinguishes five roles—Reasoning Objects, Knowledge & Evidence, Retrieval & Memory, Execution Programs, and Coordination & Communication—and four computation loci. Assignments apply to individual operations at specified stages, so one system can have several assignments. Three research questions (RQs) guide comparisons across these roles:

RQ1: How do graph observations, externally computed results, and execution feedback guide subsequent actions and completion decisions?

RQ2: How do memory representations, retrieval, and updates affect the information available for later answering, planning, and collaboration?

RQ3: Which evidence, execution, and communication dependencies need to be preserved for correct downstream behavior?

Our contributions are an operational taxonomy, a crossrole synthesis, and an evaluation framework. The synthesis compares computation allocation, memory access and maintenance, and dependency preservation. It highlights cases in which local gains do not translate into better downstream outcomes [13], [27]–[29]. The evaluation framework connects these distinctions to task outcomes, process evidence, and system costs through whole-pipeline comparisons, conditional online comparisons, and component interventions. The remaining gaps motivate research on adaptive computation, reliable memory, and dependency-aware recovery.

Figure 1 introduces graph roles, computational responsibilities, and selected operation-level assignments. Section II defines the scope and taxonomy. Sections III–V review graph reasoning, evidence and memory, and agentic control. Section VI synthesizes their findings around the three research questions. Section VII explains how to evaluate the resulting claims, and Section VIII identifies open challenges and directions for future research.

## II. SCOPE AND OPERATIONAL FRAMEWORK

## A. Scope and Literature Selection

We include LLM systems with operations that use connectivity, relational semantics, or graph-dependent constraints in reasoning, evidence preparation, retrieval, generation, execution, or communication. We call such operations graphactive. Offline preparation is included: Recursive Abstractive

Processing for Tree-Organized Retrieval (RAPTOR) [30] constructs hierarchical summaries, and GraphRAG [31] organizes relational evidence for retrieval-augmented generation (RAG). Their prepared content can support answering without online graph traversal. We therefore distinguish graph-based preparation from graph use during answering.

We conduct a directed qualitative synthesis of work publicly available by 20 August 2026. We draw on arXiv, official proceedings, and publisher records, and use backward citation tracing to identify additional work. Searches cover graphobject reasoning, interactive knowledge graph question answering (KGQA), retrieval and memory, tool dependencies, and communication topology. Selection prioritizes distinct mechanisms, informative empirical comparisons and counterexamples, and relevant evaluation resources. Publication records and versions are matched using digital object identifiers (DOIs), base arXiv identifiers, titles, and author lists. Primary methods and experiments are distinguished from supporting baselines, benchmarks, and prior syntheses.

This selection supports a qualitative comparison of mechanisms rather than an exhaustive inventory or a pooled performance ranking. We interpret results within each study’s datasets, models, access conditions, and budgets. Cross-role implications and proposed diagnostics are our synthesis of those findings; they are distinguished from the experiments reported by the cited studies. Broader memory reviews [32] and analyses of indexing, retrieval, and reading [27], [28] provide supporting context.

## B. Role–Locus Taxonomy

The unit of analysis is an operation performed by a component at a specified stage in a cited paper version. Role identifies its graph function; locus identifies its computational responsibility. Operations within one system are classified separately. The three research questions examine downstream effects across these functional roles.

Five roles organize the literature. $R _ { 1 }$ , Reasoning Objects, covers graph analysis, construction, or transformation as the task. $R _ { 2 }$ , Knowledge & Evidence, uses assertions, schemas, and executable semantics to support interpretation or constrain inference. $R _ { 3 }$ , Retrieval & Memory, organizes access to and maintenance of evidence or experience. $R _ { 4 }$ , Execution Programs, represents operation and state dependencies governing execution. $R _ { 5 }$ , Coordination & Communication, organizes participant and message dependencies.

Role follows the operation’s purpose. Selecting a KG view serves $R _ { 3 } ;$ ; interpreting its assertions serves $R _ { 2 }$ . Analyzing a communication topology as a graph object serves $R _ { 1 }$ , while routing messages through it serves $R _ { 5 }$ . Plan generation and dependency-based execution are recorded at their respective stages.

Four loci describe computational responsibility. $L _ { 1 } ,$ , Internal LLM Inference, covers structural interpretation, reasoning, and decisions performed by the model. $L _ { 2 }$ , Graph-Conditioned Interfaces, covers graph-sensitive conditioning of model representations, candidate access, or decoding. $L _ { 3 } ,$ , External Graph Traversal and Execution, performs traversal, querying, computation, or checks that return task-level observations or results.

$L _ { 4 } ,$ Agentic Orchestration, manages readiness, dispatch, and information delivery across components. These labels distinguish computational responsibilities independently of physical deployment location or capability level. $L _ { 2 }$ changes the representations or alternatives presented at a model interface; $L _ { 3 }$ returns the output of a specified traversal, query, computation, or check. If external computation constructs a modelfacing constraint, constructing and applying that constraint are recorded as separate operations.

Assignments follow the specified operation and output. Applying path-token constraints in Graph-Constrained Reasoning (GCR) [33] is assigned to $R _ { 2 } / L _ { 2 }$ , whereas executing grounded queries in ChatKBQA [34] is assigned to $R _ { 2 } / L _ { 3 } ;$ both can be implemented by external software. MuSe’s [14] view extraction and GraphChain’s [15] target computation share $R _ { 1 } / L _ { 3 } ,$ , but their outputs leave different work to the model. Component-level operations can also be nested within orchestration, as with result binding and dependency-based dispatch in LLMCompiler [12]. Table I provides representative mappings.

Temporal scope and decision control further qualify role– locus assignments. A fixed graph can support adaptive exploration, while task-specific instantiation, runtime modification, and persistent memory updates involve different objects and time horizons. Offline optimization and index reuse do not themselves establish runtime graph modification or retainedstate maintenance. At a specified interface, graph-based mechanisms may score, filter, mask, or gate alternatives; these mechanisms impose different restrictions and should be distinguished from checks of semantic correctness or authorization.

## III. GRAPH-REASONING FOUNDATIONS: OBSERVATION, LEARNING, AND EXTERNAL COMPUTATION

Graph-object reasoning covers local queries, global constraints, optimization, and temporal traversal. These tasks differ in the information and computation they require. Feasibility, optimality, and intermediate-state correctness also need separate assessment. We review three complementary approaches: selecting graph observations, learning graph procedures, and delegating computation to external software.

## A. Graph Representations and Observation Selection

Graph representations determine how relational structure is presented to the model. Encoding and descriptive order affect graph-reasoning performance [65]–[67]. GraphInsight [68] reorganizes descriptions according to graph importance, while InstructGraph [38] combines structured verbalization with instruction tuning. Alongside input design, interactive access makes observation selection part of the reasoning process.

MuSe [14] allows a vision–language model to request a neighborhood by specifying a root and hop radius or to produce a final answer. An external utility extracts and renders the requested view, while the model retains access to the original graph text and accumulated views. Supervised finetuning and reinforcement learning train the model to select views and answer questions. The utility supplies structural observations, leaving the target computation to the model.

TABLE I  
REPRESENTATIVE GRAPH-SENSITIVE OPERATIONS ORGANIZED BY ROLE AND LOCUS. ASSIGNMENTS REFER TO THE LISTED OPERATIONS; A STUDY CANAPPEAR ON MULTIPLE BRANCHES.
<table><tr><td>Functional role</td><td>Operation and locus</td><td></td><td>Representative studies</td></tr><tr><td rowspan="2">R1 Reasoning</td><td>Reason over graph state</td><td> $L _ { 1 }$ </td><td rowspan="2">GraphWiz [35]; G1 [36]; GraphThought [37]; InstructGraph [38]</td></tr><tr><td>Extract local views</td><td> $L _ { 3 }$ </td></tr><tr><td rowspan="2"></td><td>Compute graph operations</td><td> $L _ { 3 }$ </td><td>GraphChain [15]; GraphTool-Instruction [39]; Li et al. [40]</td></tr><tr><td>Generate relation-path plans</td><td></td><td>RoG [41]; Plan-on-Graph [42]; VoG [43]; KARPA [44]</td></tr><tr><td rowspan="2">R2 Knowledge &amp; evidence</td><td>Constrain path tokens</td><td></td><td>GCR [33]; DoG [45]</td></tr><tr><td>Execute grounded queries</td><td></td><td>ChatKBQA [34]; KG-Agent [9]; KBQA-o1 [46]; CUCKOO [47]</td></tr><tr><td rowspan="2"> $R _ { 3 }$  Retrieval</td><td>Compute clusters/communities</td><td></td><td>RAPTOR [30]; GraphRAG [31]</td></tr><tr><td>Select graph-linked candidates</td><td></td><td>HippoRAG [48]; GNN-RAG [29]; ToolNet [49]; G-Retriever [50]</td></tr><tr><td rowspan="2">&amp; memory</td><td>Generate memory links</td><td></td><td>A-MEM [10]; Mem0g [51]; AriGraph [52]</td></tr><tr><td>Access linked memories</td><td></td><td>A-MEM [10]; SGMem [53]; G-Memory [11]; AriGraph [52]; Mem0g [51</td></tr><tr><td rowspan="2">R4 Execution programs</td><td>Generate workflow programs</td><td></td><td>AFlow [54]; WorkflowLLM [55]; FLOW [56]</td></tr><tr><td>Dispatch ready operations</td><td></td><td>GoT [8]; LLMCompiler [12]; ControlLLM [57]; GraSP [58]</td></tr><tr><td rowspan="2"></td><td>Apply typed graph patches</td><td></td><td>GraSP [58]</td></tr><tr><td>Route messages</td><td></td><td>G-Designer [59]; EIB-LEARNER [13]; AMAS [60]; Graph-of-Agents [61]</td></tr><tr><td>R5 Coordination &amp; communication</td><td>Apply sparse routes/schedules</td><td></td><td>AgentPrune [62]; AgentDropout [63]; Sparse Debate [64]</td></tr></table>

Abbreviations: GNN, graph neural network; RoG, Reasoning on Graphs; GCR, Graph-Constrained Reasoning; DoG, Decoding on Graph; GoT, Graph of Thoughts; A-MEM, Agentic Memory; SGMem, Sentence Graph Memory; EIB-LEARNER, Error-Insight Balanced Learner. Operation scope: The clustering/community row refers to external structure computation (L ); generating the associated summaries is an LLM operation $( L _ { 1 } ) .$ Entries identify selected operations within each study.

## B. Graph Procedure Learning

Procedural prompting and training address the computation performed by the model. Pseudo-code prompting supplies algorithmic instructions for model inference [69]. Learningbased approaches use different supervision signals: Graph-Wiz [35] combines reasoning-path supervision with preference alignment; GraphThought [37] constructs action–state training trajectories; and G1 [36] uses task-specific ruleand certificate-based rewards. These approaches emphasize reasoning traces, intermediate transitions, or verifiable task outcomes.

Evaluation should distinguish individual state transitions from complete execution. The Multistep Algorithmic Reasoning Benchmark (MAGMA) [70] supplies correct preceding states during stepwise evaluation, and its reported trajectory accuracy averages correctness across steps. In some breadthfirst search (BFS) and depth-first search (DFS) settings, better intermediate predictions do not yield corresponding final-step gains. These results motivate separate assessment of transitions from valid supplied states and complete runs with modelgenerated intermediate states.

Transfer provides another test of learned procedures. G1 reports positive transfer across its evaluated graph tasks and encodings [36]. Zhang et al. [71] report advantages for processbased rewards on synthetic graph tasks, but neither process nor answer rewards consistently dominate on downstream tasks with implicit relational structure. Graph-learning results therefore need to be interpreted in relation to the training tasks, representations, and transfer targets.

## C. External Graph Computation

Delegation assigns selected graph computations to external software. Graph-library interfaces [39], [40] reduce modelside state tracking, while the system must still identify the correct graph, operation, and arguments. GraphChain [15] chains specialized tools, stores intermediate results externally, and returns compact descriptions for subsequent decisions. Its tools compute requested paths or flows, whereas the view extractor in MuSe [14] supplies local observations for model reasoning. GraphChain’s learned policy selects and composes operations, shifting the focus from internal state computation to specifying and using external results.

The benefit of external assistance depends on task conditions. GraphArena [5] distinguishes invalid, feasible, and optimal solutions. In its GPT-4o [72] comparison across polynomial-time tasks, code assistance lowers accuracy on small graphs but improves it on large graphs. The authors suggest extraction and code-generation errors as possible explanations for the accuracy loss on small graphs. This contrast highlights the importance of translating task descriptions into executable computations. GraphEval36K [73] complements answer-level measures by running generated programs on graph instances, assessing functional correctness on the tested inputs.

These foundations also apply to graphs that organize agent behavior. WorFBench [74] evaluates generated workflow structures, Follow the Flow [75] uses symbolic flowchart traversal for attribution, and HARNESSFIX [76] analyzes failedtrajectory dependencies to locate editable harness logic. These structures can be analyzed as graph objects or used to govern execution through their operation dependencies.

Observation design, procedure learning, and delegation can operate together, determining which relations the model sees and which computations it performs. Section IV extends this analysis to evidence access and retained memory. Table V summarizes the evaluation resources used throughout the survey.

## IV. EVIDENCE AND MEMORY: ACCESS, INTERPRETATION, AND RETAINED STATE

Graphs organize access to evidence and support interpretation of its assertions. Construction and retrieval determine which information reaches the model; paths and executable queries specify how relations support an answer. Sections IV-A and IV-B examine evidence preparation and selection. Sections IV-C–IV-E cover interpretation, generation constraints, and incomplete evidence. Sections IV-F and IV-G extend the analysis to information retained across interactions and reused for action or collaboration.

## A. Graph Construction and Evidence Access

Graph construction shapes both searchable representations and answering content. Passage nodes preserve source text, entities connect mentions, and summaries compress related records. GraphRAG [31] constructs entity communities and reports for global map–reduce answering. Community reports and graph-free source summaries both improve judged comprehensiveness and diversity over vector retrieval. The additional benefit of community reports varies with community resolution and evaluation protocol; the claim-based analysis finds no significant difference between community reports and graph-free summaries on these measures. RAPTOR [30] constructs recursive summaries and retrieves across hierarchy levels as a collapsed collection in its main experiments. These examples distinguish graph-based content preparation from online structural access.

G-Retriever [50] combines connected retrieval with graphconditioned generation. Prize-collecting Steiner tree (PCST) optimization selects a subgraph, which provides textual context and is encoded by a graph neural network (GNN) to produce a soft prompt. In its WebQuestionsSP (WebQSP) [77] ablation, replacing the graph encoder with unstructured soft tokens or removing textualized context lowers Hit@1. This supports complementary input channels. Here, the graphconditioned soft prompt serves as a model interface, whereas PCST-based selection performs external subgraph computation. The separate selector comparisons also change retrieved content, so they do not isolate connectivity.

Other approaches combine graph-based evidence selection with textual or graph representations. Graph Retrieval-Augmented Generation (GRAG) [78] combines pruned egographs with hierarchical text and graph prompts, while SubgraphRAG [79] scores triples using directional-distance features. LightRAG [80] links entity and relation descriptions to neighboring information and source chunks. Its reported incremental insertion mechanism extends the index; replacement and deletion require separately defined update semantics.

## B. Retrieval Objectives and Evidence Connectivity

Relational retrieval connects facts that may be weak query matches individually. HippoRAG [48] maps query entities to phrase nodes and propagates personalized PageRank (PPR) scores to rank passages. Its ablations favor PPR over seed-only or immediate-neighbor access. At a top-5 cutoff, its all-support recall exceeds that of ColBERTv2 [81] on MuSiQue [82] and 2WikiMultiHopQA (2Wiki) [83], but not HotpotQA [84]. Query-Aware Flow Diffusion RAG (QAFD-RAG) [85] uses query-weighted, capacity-constrained flow, while Structure-Tracing Evidence Mining (STEM) [86] guides subgraph search with a question-derived schema and triple-dependent signals.

Selection quality depends on how retrieved relations are used. GNN-RAG [29] predicts answer candidates with a question-conditioned GNN and extracts shortest paths for LLM answering. In experiments using pre-extracted candidate subgraphs, sparsification improves GNN node prediction on ComplexWebQuestions (CWQ) [87] but lowers downstream LLM answering performance. The authors identify disconnected support that prevents path extraction. This contrast highlights the importance of preserving paths between question entities and candidate answers.

Learning can also target the usefulness of retrieved evidence. Knowledge Graph-Enhanced Large Language Models via Path Selection (KELP) [88] supervises paths through answering utility; Retrieval-and-Reasoning [89] trains retrieval and KG-aware reasoning separately. RAPL [90] combines a rationalized annotator, path-based reasoning, and a line graph of triples. With linked question entities and answer-containing candidates, replacing its retrieved paths with shuffled triples lowers CWQ Macro-F1 for two GPT readers. This result supports the path representation as a whole. Because grouping and order change together, the comparison does not isolate either factor.

Generalization depends on the evaluated shift. Graph Foundation Model for Retrieval-Augmented Generation (GFM-RAG) [91] maps query-conditioned entity scores to documents and reports transfer without domain-specific fine-tuning. G-Reasoner [92] retrieves over document, KG, attribute, and community nodes, with graph-constructor families represented in training. On MuSiQue-Full, G-Reasoner achieves higher answer exact-match and F1 scores than the Qwen3-Emb-8B dense-retrieval baseline, whereas HippoRAG [48] and GFM-RAG [91] score lower. These evaluations probe different aspects of generalization: domain shift, exposure to graph constructors, and corpus expansion.

## C. KGQA: Interpretation, Feedback, and Completion

KGQA requires an interpretation that specifies how relations answer the question. Reasoning on Graphs (RoG) [41] predicts relation plans and retrieves their KG instances. ChatK-BQA [34] generates a compositional S-expression, grounds identifiers, and executes queries in SPARQL (SPARQL Protocol and RDF Query Language) [93] for joins, counting, and extrema. Here, RDF denotes the Resource Description Framework. In ChatKBQA’s non-oracle WebQSP analysis, logical-skeleton errors form the largest error category, highlighting the importance of interpretation before execution. SELF-KBQA [94], GRV-KBQA [95], and DR2 [96] respectively target logic-compatible evidence selection, structural query validation, and relation representations. SEAL [97] addresses conversational KGQA with calibrated S-expression cores, template-based completion, and local/global memories for feedback-driven adaptation.

Interactive methods use partial evidence to guide further search. StructGPT [98] alternates structured-data access and model reasoning. Think-on-Graph [99] explores relations and entities on a fixed KG, choosing whether to continue or answer; its depth-limit fallback can use parametric knowledge. Plan-on-Graph [42] tracks paths and sub-objectives, using reflection to expand or backtrack. Removing reflection lowers Hits@1 on CWQ, WebQSP, and sampled GrailQA [100] under its annotated-topic-entity protocol. Verify-on-Graph (VoG) [43] instead revises plans when predicted observations conflict with retrieved facts.

Feedback can also revise executable interpretations. KBQAo1 [46] searches executable logical-form operations, while DAMR [101] evaluates partial relation paths. CUCKOO [47] refines grounded logical forms after empty results; Execution as Verification [102] combines atomic execution checks with semantic alignment and rollback. An empty result may be the correct answer to the intended question, or it may reflect an unsuitable interpretation or missing knowledge. Execution feedback therefore needs semantic assessment.

Task-local memory retains information for subsequent choices. In KG-Agent [9], the model selects functions and arguments, an executor performs KG operations, and task memory stores retrieved information and program history. Graph Chain-of-Thought (Graph-CoT) [103] accesses text on attributed graphs; RefKG [104] revises retrieved chains and reconstructs evidence. ARK [105] records retrieved nodes and returns a ranked list when it selects FINISH or reaches a step limit. Retrieval completion and answer completion thus concern different outputs.

Graph Explorer [106] connects action visibility with graphsupported completion. Offline tool-plan supervision is derived from expert SPARQL queries and filtered according to argument visibility. At inference, the model selects actions over a fixed KG, with intermediate sets retained in a registry. For its Qwen3-8B [107] model trained only on CWQ, masking expert-plan hop relations from visible candidates sharply reduces finish-or-fail Hit@1 on the reported CWQ subset, while the backend KG remains unchanged. The contrast concerns access to actionable relations; runtime reference and execution checks remain distinct from its post-hoc visibility audit.

Search allocation also affects interaction cost. KARPA [44] combines planned relations with matching and revision, while Chain-of-Relations (CoR) [108] delays global entity filtering until relation-chain construction. Both report fewer interactions than their selected baselines. Section V-A examines feedback that revises workflow programs, complementing the task-local evidence and interpretation updates considered here.

## D. Constrained Generation and Verification Boundaries

Constrained generation makes selected structural properties checkable. GCR [33] builds a KG-Trie from boundedhop paths and masks invalid token continuations. Completed constrained paths belong to the indexed language, while hypothesis generation and answer aggregation are not subject to that path-token constraint. On CWQ, removing the constraint sharply lowers path conformance among correctly answered questions while answer accuracy changes little. The conditional conformance measure and answer accuracy therefore assess different properties.

Decoding on Graph (DoG) [45] updates a query-centric graph view and trie during generation. FiDeLiS [109] combines relevance and connectivity in constrained candidates, while OntGQA [110] uses ontology-compatible types and relations. Conformal Path Reasoning [111] calibrates path sets under exchangeability assumptions. Path membership, type compatibility, and statistical coverage provide different checks; alignment with the intended question remains a separate requirement.

## E. Incomplete and Mixed Evidence

Incomplete KGs motivate external evidence retrieval and knowledge completion. Under open-world assumptions, an empty query result does not establish real-world falsity. Thinkon-Graph 2.0 [112] consults topic-entity text before graph expansion and uses later text to prune candidates. Its restricteddiscovery experiment on sampled HotpotQA questions reports lower performance when fewer entities and relations are exposed, with partial recovery after search adjustment. Generateon-Graph [113] and joint knowledge-base completion and question answering [114] incorporate proposed knowledge into answering.

GLOW [115] combines predicted answer candidates with SPARQL-retrieved neighborhood facts. Its protocol excludes the gold answer from returned context, and some two-hop settings favor facts alone over facts plus predictions. This context restriction does not establish that supporting paths are absent from the KG. MindMap [116] and Right for Right Reasons [117] also combine graph evidence with model knowledge or surfaced commonsense assumptions. GAKI [118] constructs a patient-centric graph from dialogue and combines it with external medical knowledge to support medication recommendation. These sources should remain distinguishable when conclusions become stored facts or action arguments.

## F. Dialogue Memory: Access, and Maintenance

A central goal of dialogue memory is to retain useful information and incorporate changes across interactions. HippoRAG 2 [119] evaluates associative retrieval under corpus expansion; persistent dialogue use additionally requires handling revisions to retained information. The key choices concern search representations, returned content, and maintenance semantics.

LongMemEval [27] separates indexing, retrieval, and reading. In its budget-aware LongMemEval<sub>M</sub> analysis, using extracted facts as returned values lowers overall question answering (QA) performance but improves multi-session reasoning. The benefit of decomposing sessions into rounds also depends on the reader. These results motivate separate decisions about retained sources, retrieval units, and the context supplied for answering.

Hu et al. [28] further distinguish keys, values, queries, indexing, retrieval, and answering. Their Table 7 reports that selected graph configurations outperform flat memory with original-session values but underperform it when derived keys are returned. The evaluated subsets exclude questions whose reference answers occur outside user turns; session- and keybased retrieval also provide different amounts of source detail. The result depends on the returned-value configuration, leaving the contribution of topology unresolved.<sup>1</sup> The reported noexpansion configuration still uses entity alignment and source mapping to rank returned values. Graph-based preparation can thus support evidence recovery without neighbor traversal at query time.

SGMem [53] recovers context through sentence-similarity expansion and membership links to parent chunks. Its construction avoids LLM-based entity extraction, although summaries and facts still require generation. Comparisons with chunk-based RAG variants and dataset-dependent hop sensitivity support selective source recovery, complementing the separation between searchable representations and answering context.

Maintenance has effects beyond extraction quality. In Hu et al.’s [28] flat-memory HaluMem-Medium [121] comparison, jointly enabling Add/Update/Noop improves recall and QA over Add alone but lowers target precision. The comparison does not isolate Update from Noop and does not test deletion. Graph configurations separately combine higher extraction precision with lower recall and backbone-dependent QA. These findings distinguish extraction quality from the support available for later answers.

Systems implement different update semantics. A-MEM [10] links contextualized notes and evolves earlier notes during ingestion. Mem0 [51] supports addition, modification, deletion, and no change; Mem0<sup>g</sup> invalidates conflicting edges while retaining history. On LoCoMo [122], the graph variant improves temporal and open-domain judge scores but trails flat memory on multi-hop questions, with higher search and response latency. Representation, retrieval, and maintenance change together in this comparison. Zep [123] distinguishes fact-validity time from ingestion and invalidation time, supporting temporally qualified access to retained information.

Non-graph systems also support memory maintenance. Reflective Memory Management (RMM) [124] combines topic summaries with feedback-informed reranking. Light-Mem [125] appends entries online and consolidates them offline. It reports QA performance both before and after offline updates on LongMemEval , whereas its LoCoMo accuracy is measured after the update. Maintenance timing determines which state later questions can use. A formerly valid assertion may remain relevant to a historical question, while an explicit deletion request concerns retention itself.

## G. Memory for Action and Collaboration

Action-oriented memory supplies state and experience for environmental decisions. AriGraph [52] updates semantic triples from observations and links them to episodic records. Retrieved memory informs planning and action. In TextWorld [126], episodic recall helps recover cooking instructions, whereas cleaning tasks emphasize correcting stale object locations. These results concern state use within the evaluated runs; Table II records the aggregation protocol.

G-Memory [11] retains past queries, collaboration traces, and abstract insights. Retrieval provides role-specific guidance at task onset, and the store is updated after task completion. Its retrieval-hop comparisons across tasks and teams show that wider expansion can lower performance. The experience graph supports retrieval of guidance from earlier tasks; the active communication topology determines message delivery during the current task.

Procedural experience supplies another form of guidance. Thought-Action Graph Reasoning [127] retrieves abstract operation chains and corresponding KGQA actions, while Reflexion [128] reuses verbal evaluations without explicit graph memory. Table II compares representative memory mechanisms and their tested uses. Section VI synthesizes how factual evidence, applicable state, and procedural experience support subsequent decisions.

## V. AGENTIC CONTROL: EXECUTABLE DEPENDENCIES AND COMMUNICATION

Agentic control determines which operations proceed and which information reaches each decision-maker. Execution graphs encode operation and state dependencies; communication graphs organize participation and message delivery. We first examine workflow representation and dispatch, then tool composition and execution checks, and finally communication topology. This progression distinguishes planned dependencies, runtime enforcement, and information flow.

TABLE II  
MEMORY MECHANISMS COMPARED BY CONTENT, MAINTENANCE, AND SUBSEQUENT USE. EMPIRICAL CONTRASTS RETAIN THEIR STUDY-SPECIFIC CONDITIONS.
<table><tr><td>Study</td><td>Content and access</td><td>Maintenance and later use</td><td>Evidence and conditions</td></tr><tr><td colspan="4">Dialogue memory</td></tr><tr><td>Hu et al. [28]</td><td>Derived keys or entity descriptions; source alignment and value ranking.</td><td>Session ingestion; original sessions or derived keys supplied for answering.</td><td>Graph/flat ordering reverses across returned-value configurations on filtered question subsets.</td></tr><tr><td>Mem0 / Mem0ª [51]</td><td>Facts or entity relations; semantic and relational retrieval.</td><td>Mem0 modifies or deletes facts; Mem0ª invalidates edges for later dialogue QA.</td><td>LoCoMo category gains and losses; graph memory has higher search and response latency.</td></tr><tr><td>A-MEM [10]</td><td>Contextualized notes and association links.</td><td>Earlier notes are revised during ingestion to support subsequent retrieval.</td><td>The full system outperforms variants without evolution or without both linking and evolution; no ablation</td></tr><tr><td>LightMem [125]</td><td>Compressed, topic-organized entries; semantic retrieval.</td><td>Online append and offline consolidation for later QA.</td><td>removes linking alone. LongMemEvals: pre- and post-update QA; LoCoMo: post-update QA. Construction costs include summarization and updating.</td></tr><tr><td colspan="4">Action and team memory</td></tr><tr><td>AriGraph [52]</td><td>Semantic triples linked to full-observation episodes.</td><td>Observation-time revision supports planning and action within the environment.</td><td>TextWorld cooking/cleaning comparisons average the best three of five attempts per agent/game.</td></tr><tr><td>G-Memory [11]</td><td>Query, interaction, and insight graphs; role-specific experience retrieval.</td><td>Task-end assimilation supplies guidance to subsequent teams.</td><td>Adapted action/QA protocols; insight/trace ablations on Planning Domain Definition Language (PDDL) tasks from AgentBoard [129] and Fact Extraction and VERification (FEVER) [130]; task/team hop sensitivity.</td></tr></table>

## A. Plan Representations and Dependency-Guided Execution

Graph-based plans can support reasoning about execution or directly govern it. Plan Like a Graph (PLaG) [131] represents ordering constraints and evaluates minimum completion time under unlimited resources; actual dispatch lies outside its AsyncHow evaluation. MatrixCoT [132] represents logicalstep dependencies with an explicit matrix and revises the reasoning plan using execution-trace feedback, without relying on external solvers. Graph of Thoughts (GoT) [8] executes generation, scoring, selection, and aggregation operations according to their dependencies. Its Graph of Operations (GoO) specifies the structure, while the Graph Reasoning State (GRS) records thoughts and assessments. The state can evolve under a fixed operation graph.

LLMCompiler [12] turns call dependencies into asynchronous execution by binding arguments to completed outputs and releasing ready calls. In Game of 24 [133], evaluated states return to the planner; selected states seed another plan when no proposal reaches 24. Parallel candidate generation and evaluation reduce latency relative to sequential Tree of Thoughts [133] in that comparison. On WebShop [134], however, LLMCompiler achieves a higher success rate than ReAct [3] with both evaluated GPT variants, but also incurs greater latency, which the authors attribute to planner overhead. These results illustrate workload-dependent benefits and costs of the complete workflow. At serving scale, HeraSys [135] merges reusable nodes across concurrent workflows and schedules work both within and across requests, targeting throughput and tail latency.

Workflow construction also differs in how programs are obtained. GPTSwarm [136] optimizes component connections while preserving required internal edges and acyclicity; node optimization changes prompts. AFlow [54] uses execution results on validation tasks to search over programs containing operators, branches, and loops before deployment. Its reported deployment-execution costs exclude the preceding search. WorkflowLLM [55] instead learns hierarchical workflows from converted shortcuts and synthesized examples.

Execution representations determine what can be revised. Production workflow systems [137] expose specified routes, history transformations, and typed interfaces; Agent Spec [138] separates control-flow and data-flow edges for cross-framework execution. FLOW [56] supports runtime refinement of an activity-on-vertex graph using subtask progress and execution feedback. These mechanisms distinguish program construction from changes to deployed dependencies.

## B. Tool Selection and Resource-Compatible Composition

Tool composition involves selecting candidates, matching resources, and binding calls. ToolNet [49] retrieves successors of the previous tool and presents transition weights as selection preferences. The model chooses a tool and its arguments, then observes the result. ToolNet updates transition preferences from completed trajectories; its simulated API-failure experiment illustrates adaptation toward functioning alternatives. These links guide tool access without certifying invocation conditions.

ControlLLM’s Thoughts-on-Graph [57] searches a bipartite graph linking tools to accepted and produced resource types. The search tracks available resources, while LLM components select plans and resolve bindings. The execution engine follows the selected plan and can parallelize independent subtasks. GTool [139] constructs request-specific graphs from historical relations and predicts missing dependencies for planning. Resource-compatible paths and predicted links support composition; reliable execution also calls for checking current inputs and state conditions.

## C. Execution Checks and Runtime Repair

Skill retrieval supplies candidate procedures. Skill Retrieval Augmentation [140] distinguishes making a skill available from actually using it, while SkillComposer [141] selects and loads relevant skill sequences, using dependencies during offline synthesis. Checked composition additionally evaluates whether invocations are applicable and whether their expected effects occur.

GraSP [58] compiles skills into a typed directed acyclic graph (DAG) of invocations, bound arguments, and verifiers. State and data dependencies constrain execution, while order edges can express softer precedence. Preconditions are checked before invocation and postconditions afterward. Failures trigger repairs such as rebinding, prerequisite insertion, or rewiring. Patches are bounded by size and graph neighborhood, with escalation to global replanning or reactive fallback when local repair fails.

The skill-augmented systems compared in GraSP use the same skill libraries and episodic memory. With DeepSeek V3.2 [142] on seen tasks in ALFWorld [143] and Science-World [144], the sequential-execution and global-replanning variants score below the full system on the success and reward measures for those environments [58]. The local-versus-global repair comparison matches repair-attempt budgets, which does not establish equal token or environment-action costs. Postcondition checks can return uncertain LLM judgments, so their verdicts remain conditional on represented state and available observations. In a domain-specific multi-agent system, RareDASH [145] uses an auditing agent to trigger node reexecution or DAG restructuring; its demo does not isolate the effect of repair.

Runtime recovery also depends on observed environment state. Agent-SAMA [146] constructs mobile-application state graphs, compares expected transitions with observed screens, and uses state information for recovery. Retained experience can inform later tasks. Feedback is also available under structured protocols: MetaGPT [147] uses prescribed procedures and execution results, while AutoGen [148] supports programmable conversations among models, tools, and human participants. Such systems provide comparisons for assessing the additional value of structural adaptation.

## D. Communication Topology and Information Flow

Communication graphs specify who participates and which messages reach other components. Removing routes can reduce redundant context while blocking information needed for a decision. Self-consistency [149], which aggregates independent reasoning samples, provides a comparison without inter-agent exchange. GPTSwarm [136] reports recovery toward single-agent performance through edge optimization in an adversarial Massive Multitask Language Understanding (MMLU) [150] setting, and gains in a separate collaborative setting with diverse role prompts. The adversarial and collaborative results use different participant settings and should be reported separately when assessing topology effects.

Topology selection can precede interaction. G-Designer [59] generates edges using agent and tool profiles with task information; Adaptive Multi-Agent System (AMAS) [60] selects among optimized candidate graphs. Guided Topology Diffusion (GTD) [151] uses graph diffusion with a learned utility– cost proxy, while TopoDIM [152] samples typed interactions under structural constraints. These mechanisms condition route selection on information available before the conversation.

Pruning differs in both timing and the structure selected. AgentPrune [62] learns masks and deletes edges once, either after early rounds of one query or after optimization on a query subset for later reuse. AgentDropout [63] learns round-specific participation and samples a complete multiround schedule before reasoning. Reported trade-offs include lower prompt-token use with a small MMLU accuracy loss for AgentPrune on GPTSwarm, and lower average scores at higher AgentDropout rates. Deployment reports should include optimization costs and specify how many queries reuse the resulting schedule or topology.

Routing interacts with aggregation and shared state. Sparsedebate experiments [64] compare sparse neighbor communication with dense exchange; Graph-of-Agents [61] combines agent and edge sampling with message passing and pooling. AgentNet [153] separates routing and execution using experience buffers, while EvoHyper [154] connects groups through shared memory and distinguishes memory updates from structural changes.

EIB-LEARNER [13] examines how topology affects the propagation of supplied information. Its MMLU protocol induces local errors on questions initially answered correctly and injects gold answers on questions initially answered incorrectly. These correctness-conditioned question sets are selected separately for each topology. Degree-normalized answer changes indicate that sparse routes reduce the influence of both harmful and useful supplied information, whereas denser routes increase their influence. These interventions measure how supplied information changes answers; the discovery of corrections falls outside their scope. The learned method combines sparse and dense views through query-aware fusion and selects a topology before interaction; branch and fusion ablations support this design under a separate task-evaluation protocol.

TABLE III  
FEEDBACK AND SELECTION IN GRAPH-BASED CONTROL. EACH ROW IDENTIFIES THE RELATION USED, THE DECISION INPUT, AND THE TIMING OF SELECTION OR REVISION.
<table><tr><td>Method and relation</td><td>Feedback or selection input</td><td>Affected decision</td><td>Timing and scope</td></tr><tr><td colspan="2">Computation and execution</td><td></td><td></td></tr><tr><td>GoT [8] Operation dependencies</td><td>Thought scores and validity checks.</td><td>Select, aggregate, or refine thoughts.</td><td>Task-local GRS updates under a specified GoO.</td></tr><tr><td>LLMCompiler [12] Call dependencies</td><td>Completed outputs; evaluated search states.</td><td>Bind arguments, release ready calls, and replan.</td><td>Runtime dispatch; reaching 24 completes the Game of 24 search.</td></tr><tr><td>AFlow [54] Workflow program</td><td>Validation execution and scores.</td><td>Revise prompts, operators, and dependencies.</td><td>Search before deployment; the selected program may branch or loop.</td></tr><tr><td>GraSP [58] Typed skill dependencies</td><td>Failed precondition, execution, or postcondition checks.</td><td>Apply bounded patches; escalate when needed.</td><td>Runtime repair; checker verdicts may be uncertain.</td></tr><tr><td colspan="2">Communication selection</td><td></td><td></td></tr><tr><td>AgentPrune [62] Message edges</td><td>Task utility during mask learning.</td><td>Learn masks, then prune edges once.</td><td>Early rounds of one query or a training query subset; subsequent topology fixed.</td></tr><tr><td>AgentDropout [63] Participation schedule</td><td>Learned participation parameters.</td><td>Sample a complete multi-round schedule.</td><td>Before reasoning; participation varies across rounds.</td></tr><tr><td>EIB-LEARNER [13] Message routes</td><td>Task query and learned sparse/dense fusion.</td><td>Select a communication topology.</td><td>Before interaction; supplied-information propagation is evaluated separately.</td></tr></table>

Communication design also needs to account for message attacks and propagation failures. NetSafe [155] reports taskdependent resilience under its one-attacker protocol: chains perform better on factual and commonsense subsets, while complete communication is favored on mathematics. Agentin-the-Middle (AiTM) [156] attacks inter-agent messages, Communication Inference Attack (CIA) [157] infers communication links from outputs, and GUARDIAN [158] uses temporal interaction graphs to detect propagated anomalies. These studies examine message attacks, topology exposure, and anomaly detection alongside task performance.

Table III connects control mechanisms to their decision inputs and timing. Execution comparisons concern readiness and recovery; communication comparisons concern whether information reaches and influences a decision-maker. Section VI synthesizes these requirements with evidence access and retained memory.

## VI. CROSS-ROLE SYNTHESIS: DECISIONS, MEMORY, AND DEPENDENCIES

Sections III–V review mechanisms by graph function. Here we compare their downstream effects through three questions: how observations and computation guide decisions (RQ1), how retained information supports later tasks (RQ2), and which dependencies need to be preserved (RQ3). These questions span roles: a retrieved fact can become an action argument, and its correction may need to reach another agent before execution. Table IV separates the reported evidence from our design implications and proposed diagnostics.

## A. Observation, Computation, and Completion

Observation and delegation allocate computation differently. MuSe [14] returns a local view for model reasoning, GraphChain [15] performs a requested graph operation, and LLMCompiler [12] binds completed outputs to dependent calls. View extraction leaves target inference to the model. Delegation requires correct specification and argument binding before execution and result interpretation afterward; dispatch additionally depends on readiness. An executor can correctly execute a specification that does not match the intended task. These responsibilities motivate separate tests of specifications, execution, and subsequent use.

Feedback should address the source of unfinished work. KG exploration acquires support [99], while query execution combines retrieved facts through operators such as joins and counting [34]. Plan-on-Graph [42] extends search or backtracks when support is insufficient; VoG [43] revises plans when predicted observations conflict with retrieved facts. Interleaving Retrieval with Chain-of-Thought (IRCoT) [159] provides a non-graph counterpart in which reasoning redirects text retrieval. The relevant distinction is whether feedback changes evidence acquisition or the interpretation that governs its use.

Completion depends on the required output. ARK [105] returns a ranked list when it selects FINISH or reaches a trajectory limit, while Graph Explorer [106] distinguishes valid graph-supported completion from best-effort answering. A correct fallback answer may leave the supported-completion criterion unmet.

TABLE IV  
CROSS-ROLE ANSWERS AND THEIR EVIDENCE BASIS. DESIGN IMPLICATIONS AND DIAGNOSTICS ARE THE SURVEY’S SYNTHESIS; THE LISTED STUDIES PROVIDE MECHANISM DESCRIPTIONS OR EMPIRICAL CONTRASTS UNDER THEIR RESPECTIVE PROTOCOLS.
<table><tr><td>Research theme and evidence</td><td>Conditional design implication</td><td>Proposed diagnostic</td></tr><tr><td>Decisions and completion (RQ1). MuSe [14] returns views, GraphChain [15] computes results, and LLMCompiler [12] binds completed outputs. Graph Explorer [106] separates supported completion from fallback.</td><td>Distinguish missing evidence, interpretation errors, and unmet prerequisites when using feedback. Define completion for the required output.</td><td>Substitute reference specifications and executors separately; record visible choices, outputs, stopping, fallback, failures, and cost.</td></tr><tr><td>Memory and later use (RQ2). Relative performance of graph and flat memory varies with returned-value configurations [28]; effects of fact compression and context granularity depend on questions and readers [27]. Action-oriented evidence comes from AriGraph [52]; team-memory evidence comes from G-Memory [11], under separate protocols.</td><td>Match retained sources, recovered detail, and update timing to the later task. Separate current applicability, history, and deletion.</td><td>Advance updates chronologically; vary context under declared budgets. Inspect stored and retrieved state, saved arguments, and team use separately.</td></tr><tr><td>Dependency preservation (RQ3). CWQ node prediction and path QA diverge under sparsification in GNN-RAG [29]; sparse routes reduce the influence of both harmful and useful supplied information in EIB-LEARNER&#x27;s [13] topology-specific tests. GraSP [58] checks invocation conditions and repairs dependencies.</td><td>Preserve usable support, invocation requirements, and message routes; revalidate assumptions affected by repair.</td><td>Track paths, readiness, effects, and messages. Distinguish fixed-message replay from interactive reruns; account for full-workload costs.</td></tr></table>

The value of additional graph access is task-dependent. ARK’s sampled-test ablation shows larger retrieval losses from removing neighborhood access on STaRK’s [160] academic MAG (Microsoft Academic Graph) and biomedical PRIME subsets than on its product-oriented AMAZON subset [105]. KARPA [44] and CoR [108] report fewer calls than their baselines, whereas MuSe’s [14] round-limit ablation concerns training. These results assess different forms of interaction control.

For RQ1, the reviewed mechanisms use three types of decision input: available evidence, computed results, and execution status. Their usefulness depends on the remaining task, its completion rule, and interaction cost. The reviewed comparisons do not establish a general policy for choosing observations or computations and deciding when to stop (Section VIII-A).

## B. Memory Representations and Later Use

Search representations and answering content serve separate purposes. Hu et al.’s [28] selected graph and flat configurations reverse their relative performance across returned-value settings on filtered question subsets with unequal source detail. The LongMemEval<sub>M</sub> analysis [27] reports lower overall QA performance with compact facts, despite gains in multi-session reasoning; granularity effects also depend on the reader. These results favor separate choices about stored sources, on-demand recovery, and immediate context, without isolating a topologyonly effect.

Relations support different stages of evidence use. Entity– session associations [28] support recovery of exchanges, SG-Mem [53] uses sentence and parent-chunk links to recover context, and RAPTOR’s [30] hierarchy organizes summary construction. Hu et al.’s no-expansion configuration still uses alignment and source mapping. Graph contribution can therefore arise in preparation or recovery without online neighbor traversal. Such associations, however, need not record how each derived assertion depends on its sources.

Maintenance determines both applicability and availability. Note evolution [10], conflict invalidation with history [51], temporal validity [123], and deferred consolidation [125] expose different states to later requests. Current and historical questions require the corresponding valid assertions; requested deletion concerns retention itself. Measurements taken only before and after consolidation do not characterize what a request can access during an incomplete update. Update timing is therefore part of the task setting, alongside storage and context budgets.

Planning and collaboration further change the required content. AriGraph [52] supplies environmental state and episodes for action, while G-Memory [11] supplies role-specific insights and interaction traces to later teams. Their separate evaluations extend the evidence beyond dialogue QA, but do not establish whether correcting a stored assertion also changes a saved action argument or shared guidance. Testing this cross-role composition requires tracing corrections from stored assertions into the plans and guidance that use them.

For RQ2, the evidence favors separating stored content, retrieval units, and answering context. Their design depends on the later task, reader, budget, and retention constraints. Update timing determines which state is available; whether a memory correction reaches saved plans or team decisions requires joint testing.

## C. Dependencies and Downstream Behavior

Selection matters through the relations left available downstream. In GNN-RAG’s [29] answer-containing candidatesubgraph setting, CWQ sparsification improves node prediction but lowers path-based answering. AgentPrune [62] and AgentDropout [63] reduce communication work in their evaluated settings. EIB-LEARNER’s [13] interventions use topology-specific correctness-conditioned question sets; degree-normalized answer changes indicate that sparse routes suppress the influence of both induced errors and supplied correct answers. The shared concern is usable support, although evidence paths and message routes have different semantics. These study-specific comparisons leave the preferred graph density dependent on the task, available support, and downstream operation.

Execution requires applicable prerequisites as well as available information. ToolNet [49] ranks successors, Control-LLM [57] identifies resource-compatible compositions, and LLMCompiler [12] binds predecessor results for dispatch. GraSP [58] adds checks of represented invocation conditions and bounded repair. If the recorded graph omits a shared-state dependency, affected operations may lie outside the recorded descendants of the modified nodes. This mechanism-based inference motivates validating the assumptions affected by repair, beyond counting edited nodes.

Verification should be selected for the property being assessed. GCR [33] constrains indexed-path membership, ChatKBQA [34] computes query denotations, and GraSP [58] checks represented invocation conditions. Additional checks are needed to assess whether the interpretation matches the task and whether execution achieves the intended effect.

Consider the facility example from the introduction. At time t, the operator changes from $O _ { 1 }$ to $O _ { 2 }$ . Memory records $O _ { 2 }$ as current and retains $O _ { 1 }$ for historical queries, but a saved notification plan still targets $O _ { 1 }$ . Retrieval and message delivery can both succeed while the request to notify the current operator fails. This illustrative scenario links fact validity, argument binding, and dispatch: the current notification should reach $O _ { 2 }$ while a historical query for $O _ { 1 } \mathrm { { ^ { * } s } }$ period of operation should return $O _ { 1 }$

For RQ3, relation selection should preserve the evidence connections required by the task, applicable invocation requirements, and routes for decision-relevant messages. These dependencies matter through the operations that use them. Section VII translates the synthesis for all three research questions into comparison designs, process diagnostics, and cost measures.

## VII. EVALUATION OF GRAPH CONTRIBUTIONS

Evaluation connects the mechanisms reviewed in Sections III–V and the cross-role synthesis in Section VI to testable claims. Outcome metrics assess answer quality and task success; process evidence records relation use, state changes, execution readiness, and message delivery; and system metrics quantify resource use and costs.

Benchmark annotations and evaluation protocols determine which aspects of these claims can be observed. Graphcomputation and KGQA tasks assess computational correctness and interpretation; evidence and memory tasks examine support and temporal use; and interactive environments expose action consequences. Table V summarizes representative resources, their relevance to RQ1–RQ3, and the limits of their observable evidence. Task scores alone cannot establish claims about memory updates, supported completion, or information delivery [170]. We therefore consider three complementary aspects of evaluation: comparison designs and experimental controls, process diagnostics, and system costs and reporting requirements.

## A. Comparison Designs and Experimental Controls

The comparison target determines what should be held fixed. A whole-pipeline comparison evaluates construction, access, and downstream reasoning or execution together. It uses common raw inputs and tasks under declared resource conditions, while allowing intermediate summaries, retrieved evidence, memories, and trajectories to differ. A conditional online comparison fixes upstream inputs, such as an index for retrieval, a candidate set for reranking, or selected evidence for testing its arrangement. A component intervention replaces or disables one operation, measures the resulting behavior, and specifies whether downstream components may adapt. The first two designs define comparison scope; component interventions can be used within either scope.

RAPTOR’s [30] tree traversal and collapsed retrieval operate over a constructed summary hierarchy. Comparing them on the same index targets online access; evaluating the complete approach also includes summary construction and its cost. Holding retrieved content fixed removes differences in selected evidence from the comparison; holding post-update memory fixed similarly removes differences in retained state. These tests exclude effects mediated by those differences, although the costs of selection or maintenance may still vary. Equal topk, token, or call limits constrain budgets without equalizing information, capabilities, or realized costs.

Structural interventions require task-consistent labels. For graph-computation tasks, changing an input edge may change the correct answer. Removing evidence from a knowledge graph may instead change what the system can establish without changing the underlying fact. Removing a dependency edge from a controller does not remove the environment’s actual prerequisites. Redundancy or adaptation can mask an intervention’s effect, so unchanged outcomes alone do not demonstrate that a relation was unused. Reports should specify the altered relations, valid answers, available alternatives, and permitted adaptation.

## B. Process Diagnostics

Decisions and completion (RQ1). Records should identify available candidates, selected operations, arguments, returned results, and stopping reasons. Where reference specifications and executors are available, running a reference specification with the deployed executor tests execution against an expected result. Running a model-produced specification with a reference executor establishes the result of that specification; a separate semantic check is still needed to determine whether it expresses the intended task. These substitutions diagnose different interfaces and complement end-to-end evaluation.

TABLE V  
BENCHMARKS AND THEIR RELEVANCE TO DECISIONS AND COMPLETION (RQ<sub>1</sub>), MEMORY AND LATER USE (RQ<sub>2</sub>), AND DEPENDENCY PRESERVATION (RQ ). RQ LABELS INDICATE RELEVANCE RATHER THAN COMPLETE COVERAGE OF A RESEARCH QUESTION.
<table><tr><td>Evaluation target</td><td>Representative resources</td><td>Observable evidence</td><td>Interpretation boundary</td></tr><tr><td>Graph computation RQ1</td><td>GraphArena [5]; MAGMA [70]; GraphEval36K [73]; GraphOmni [161]; GraphGym [162].</td><td>Solution validity and optimality; supplied-state transitions; program tests; representation and loading sensitivity.</td><td>Correct conditional transitions and passing test cases do not establish reliable autonomous execution.</td></tr><tr><td>KG interpretation RQ1, RQ3</td><td>WebQSP [77]; CWQ [87]; KQA Pro [163]; GrailQAbility [164].</td><td>Semantic parses, compositional questions, explicit programs, and missing-data or schema conditions.</td><td>Annotation types differ; a correct denotation can arise from an incorrect interpretation.</td></tr><tr><td>Evidence access RQ1, RQ3</td><td>HotpotQA [84]; 2WikiMultiHopQA [83]; MuSiQue [82]; STaRK [160]; Xiang et al.&#x27;s evaluation [165];</td><td>Supporting sentences, evidence triples, connected question compositions, retrieval ranks, and stage-level outcomes.</td><td>Retrieval relevance, sufficient support, and faithful citation require separate assessment.</td></tr><tr><td>Dialogue memory RQ2</td><td>LoCoMo [122]; LongMemEval [27]; HaluMem [121].</td><td>Long-history QA, temporal and update-dependent questions, and extraction or update assessments.</td><td>Answer-based and retrieval-mediated tests cover different aspects of retained state, not necessarily the entire store.</td></tr><tr><td>Interactive execution RQ1, RQ3</td><td>TextWorld [126]; ALFWorld [143]; ScienceWorld [144]; WebShop [134]; AgentBench [167]; ToolBench [168].</td><td>Environment progress, action effects, and tool trajectories; ToolEval [168] provides judged outcomes on ToolBench.</td><td>Invocation success, task success, and evaluator acceptance differ. Cross-task retention requires an explicit protocol.</td></tr><tr><td>General outcomes RQ1, RQ3</td><td>HumanEval [169]; MMLU [150].</td><td>Unit-test correctness and multiple-choice accuracy, including outcomes used in workflow and communication studies.</td><td>These annotations alone do not test persistent updates or naturally discovered corrections.</td></tr></table>

Completion rules also define the measured outcome. Graph Explorer’s [106] finish-or-fail protocol requires a correct answer through a valid Finish within budget and at least one KG call; best-effort accuracy and post-hoc visibility checks assess separate properties. Path conformance in GCR [33] and query denotation in ChatKBQA [34] should likewise be assessed alongside semantic alignment. Citation evaluation further distinguishes full, partial, and absent support [171]. SIRG [172] constructs semantic-level attribution graphs to detect RAG faithfulness hallucinations, diagnosing internal dependencies rather than validating source-evidence paths.

Memory and later use (RQ2). Interactions should advance chronologically from a common initial history, with resets and update-completion times reported and future information excluded. Memory representations and updated states may differ across systems when those mechanisms are under evaluation. Tests should separately assess current-state answers, historical answers, correction handling, and requested deletion. HaluMem [121] retrieves ten relevant memories per annotated update, making its update assessment retrieval-mediated;

unavailable extraction metrics for Zep reflect the missing interface in that protocol. Storage inspection, retrieved content, and later answers or actions therefore provide complementary evidence. For the example in Section VI-C, tests should trace whether the updated operator identity reaches the saved recipient argument and the scheduler’s notification decision.

Dependency preservation (RQ3). For evidence use, diagnostics should trace the relations available to the answering step. To isolate dependency handling in execution, dispatch comparisons should hold skills and the initial environment state fixed. Repair tests should record revised plans, checker verdicts, the work revalidated, and subsequent effects. ToolEval’s [168] pass criterion can accept giving up after exhaustive, unproductive API attempts or refusing an unsolvable instruction. Judged acceptance and fulfillment of the requested action consequently require separate reporting.

To isolate routing effects, comparisons should hold participants, capabilities, and aggregation rules fixed. Fixed-message replay controls the content supplied to agents; interactive reruns also capture how subsequent messages and decisions change. EIB-LEARNER [13] applies information-injection interventions to MMLU and assesses their influence through answer changes. Interpretation of these results should account for the topology-specific, correctness-conditioned question sets. Assessing correction discovery also requires recording how the supporting evidence was obtained. These tests operationalize the distinctions in Table IV.

## C. System Costs and Reporting Requirements

Full-system accounting covers relevant extraction, indexing, summarization, training or workflow search, online operations, verification, retries, failed runs, and memory updates. Query volume, corpus turnover, and update frequency determine amortization; deferred consolidation remains maintenance work. Aggregate compute usage, wall-clock time, critical-path latency, and tail latency capture different aspects of system performance. Accounting boundaries also differ across studies: Hu et al.’s [28] construction and retrieval costs exclude answering, whereas Mem0’s [51] response latency includes generation.

Quality–cost comparisons should report the complete configuration, including content preparation, corpus and task conditions, query routing, and extraction or generation models [165], [173]–[175]. With Qwen2.5-7B-Instruct [176] on HotpotQA, Fan et al. [177] report Contain Exact Match scores of 33.76 for dense retrieval and 32.73 for the backend labeled GraphRAG under Search-o1 [178]. Under GraphSearch [179], dense retrieval scores 38.22 and the same GraphRAG backend scores 42.25. This reversal concerns the specified backend, metric, and configurations; it motivates reporting the search workflow, retrieval backend, and workload costs together.

Reports should identify the operation and paper version, comparison target, tool capabilities, temporal horizon, and cost-accounting boundary. Overall task-success rates should include all evaluated episodes; conditional scores should state the conditioning event and sample size. Failures, timeouts, abstentions, and unresolved checks should be reported. Judgebased evaluation [180] should specify the rubric, judge model, response ordering, and invalid-result handling, because reported scores can depend on position and verbosity biases. Queries sharing retained memory should be analyzed as dependent sequences.

## VIII. OPEN CHALLENGES AND FUTURE DIRECTIONS

Building on the cross-role synthesis in Section VI and the evaluation framework in Section VII, we identify three directions for future research: adaptive observation, computation, and stopping (RQ1); reliable memory maintenance and subsequent use (RQ2); and dependency-aware recovery and correction propagation (RQ3).

## A. Adaptive Computation and Stopping

Operation value and diagnostic feedback. The value of another operation depends on the information or computation still needed. IRCoT [159] redirects text retrieval, Plan-on-Graph [42] tracks sub-objectives, and Execution as Verification [102] uses execution feedback to revise queries. A broader policy would distinguish missing evidence, mistaken interpretation, and execution failure before choosing another operation. Training could compare alternative continuations from a common task state, including their acquisition and verification costs. Because the value of an observation can depend on later operations, these tests should allow subsequent decisions to adapt.

Transfer of structural procedures. G1 [36] studies transfer across graph tasks and encodings; G-Reasoner [92] addresses retrieval over heterogeneous graph-structured knowledge. These settings motivate separating representation invariance from adaptation to changed semantics or tool preconditions. One direction is to combine verifiable state transitions with feedback-driven tool trajectories and explicit operation contracts. Experience reuse, as in Reflexion [128], could help revise a procedure when its assumptions fail. Evaluation should report both transfer performance and the interaction cost of adaptation.

Calibrated stopping. A stopping policy needs to assess both current support and the potential value of further access. Fully specified graph tasks may admit checkable completion conditions; unsuccessful search in an incomplete knowledge graph may leave answerability unresolved. Policies should distinguish supported completion, abstention for insufficient evidence, and budget exhaustion. Confidence alone may be inadequate when tool reliability or unverified dependencies affect the decision. Evaluation should report premature termination, fallback answers, failed runs, and resource use, with task consequences reflected in the cost of stopping or continuing.

## B. Memory Maintenance for Later Decisions

Selective retention and source recovery. Retention should preserve the information needed for later tasks within storage and context budgets. LongMemEval [27], Thought-Action Graph Reasoning [127], and AriGraph [52] illustrate different needs for factual, procedural, and environmental information. A research direction is to learn which relational and temporal qualifiers should survive compression and when to recover omitted source detail. Recovery depends on the source remaining available and eligible for retention. Procedural reuse also requires checking current tool capabilities and invocation conditions.

Consistency during maintenance. Existing methods revise notes [10], invalidate conflicting relations [51], represent temporal validity [123], or defer consolidation [125]. A request arriving during maintenance may read a revised fact alongside an older summary or cached plan. Versioned records and pending-update states could identify affected operations, allowing them to refresh their inputs or wait while unrelated work continues. The time for which a fact is valid should be distinguished from the time at which its update completes. LongMemEval [27] and HaluMem [121] offer starting points, but evaluation of interrupted updates also needs decisions made before maintenance finishes.

Provenance for derived state. Source references identify related evidence but may not show how a generated summary or plan depends on it. Provenance semirings distinguish alternative derivations from jointly used inputs for positive relational queries [181]. Generated content can additionally depend on temporal assumptions and model knowledge. Partial dependency records could distinguish verified support, heuristic associations, and unknown dependencies, enabling selective revalidation without claiming a complete derivation. Historical access and deletion also require different handling: invalidation can retain past support, whereas deletion needs to address source, derived, and cached records within the requested scope. Evaluation should weigh recording and revalidation costs against the consequences of using stale information downstream.

## C. Dependency-Aware Recovery and Information Delivery

Recovery with incomplete dependency records. Selective repair depends on identifying the work affected by a change. GraSP [58], FLOW [56], and HARNESSFIX [76] address invocation repair, workflow revision, and harness diagnosis, respectively. A database precedent is the Delete and Rederive (DRed) algorithm [182], which overdeletes potentially affected tuples and rederives those with surviving support under known rules. Reads, writes, and external effects can create dependencies not recorded in an execution plan. A repair mechanism could combine declared dependencies with observed accesses and expand the scope of revalidation when effects are uncertain. Evaluation should distinguish patch size, affected work revisited, and valid work preserved.

Verification of external effects. State can change between a precondition check and a tool call. Version-aware argument binding and checks near dispatch may help, but their guarantees depend on the external interface. Recovery should distinguish observed success, observed failure, and unresolved outcomes: a timed-out call may already have changed the environment, so retrying can duplicate an effect. Execution graphs could record observable effects, retry conditions, and available compensation. Tests should compare reductions in execution errors with the added verification cost and delay. When rollback is unavailable and compensation is possible, the compensating action should be assessed with its own prerequisites and costs and should respect task requirements and authorization constraints.

Delivery and use of corrections. Correction requires evidence to reach a component that can act on it. AMAS [60] and GTD [151] select task-specific topologies, while EvoHyper [154] studies group structure and shared memory. EIB-LEARNER [13] measures the effects of supplied errors and correct answers. A broader target is the path from discovering a correction to using it before a dependent decision. Pending operations could guide recipient selection, while messages identify the revised assertion, its valid time, and the assumption replaced. Evaluation should distinguish discovery, delivery, and use. Fixed-message replay controls the supplied content; interactive reruns also capture how newly obtained evidence and subsequent decisions change.

Integrity checks may also obstruct valid corrections. AiTM [156] studies message attacks, and GUARDIAN [158] models temporal interaction graphs for anomaly detection. Routing policies should limit unreliable propagation while allowing justified disagreement. Provenance can help distinguish independent support from repeated transmission, but source identity alone does not establish truth. Evaluation should report both acceptance of incorrect proposed corrections and rejection of valid ones, including cases with changed participants or tools.

Across these directions, evaluation should track which decisions are affected by new information, whether the affected work is corrected, and at what cost. Comparisons with flatmemory, fixed-workflow, and fixed-routing baselines can clarify the benefits and costs of relational organization and runtime adaptation, provided other relevant differences are controlled.

## IX. CONCLUSION

This survey organizes graph-mediated LLM systems by graph function and computational responsibility. Operationlevel comparisons distinguish observation from delegated com putation, searchable representations from answering context, and planned dependencies from runtime enforcement. Crossrole analysis traces how these mechanisms affect later decisions, memory use, execution, and communication. The evaluation framework links these claims to benchmarks, comparison designs, process evidence, and workload costs. The remaining challenges concern adaptive computation and stopping, reliable memory maintenance, and recovery and correction propagation when dependency information is incomplete. These distinctions provide a structured basis for designing and evaluating graph-mediated LLM systems.

## REFERENCES

[1] P. Lewis et al., “Retrieval-augmented generation for knowledgeintensive NLP tasks,” in Advances in Neural Information Processing Systems, vol. 33, 2020, pp. 9459–9474.

[2] T. Schick et al., “Toolformer: Language models can teach themselves to use tools,” in Advances in Neural Information Processing Systems, vol. 36, 2023, pp. 68 539–68 551.

[3] S. Yao et al., “ReAct: Synergizing reasoning and acting in language models,” in Proc. ICLR, 2023.

[4] H. Wang, S. Feng, T. He, Z. Tan, X. Han, and Y. Tsvetkov, “Can language models solve graph problems in natural language?” in Advances in Neural Information Processing Systems, vol. 36, 2023, pp. 30 840–30 861.

[5] J. Tang, Q. Zhang, Y. Li, N. Chen, and J. Li, “GraphArena: Evaluating and exploring large language models on graph computation,” in Proc. ICLR, 2025.

[6] S. Pan, L. Luo, Y. Wang, C. Chen, J. Wang, and X. Wu, “Unifying large language models and knowledge graphs: A roadmap,” IEEE Transactions on Knowledge and Data Engineering, vol. 36, no. 7, pp. 3580–3599, 2024.

[7] B. Peng et al., “Graph retrieval-augmented generation: A survey,” ACM Transactions on Information Systems, vol. 44, no. 2, pp. 1–52, 2026, article 35; Version of Record published December 23, 2025.

[8] M. Besta et al., “Graph of Thoughts: Solving elaborate problems with large language models,” in Proceedings of the AAAI Conference on Artificial Intelligence, vol. 38, no. 16, 2024, pp. 17 682–17 690.

[9] J. Jiang et al., “KG-Agent: An efficient autonomous agent framework for complex reasoning over knowledge graph,” in Proc. ACL, 2025, pp. 9505–9523.

[10] W. Xu, Z. Liang, K. Mei, H. Gao, J. Tan, and Y. Zhang, “A-Mem: Agentic memory for LLM agents,” in Advances in Neural Information Processing Systems, vol. 38, 2025, extended version: arXiv:2502.12110v11, October 8, 2025.

[11] G. Zhang, M. Fu, G. Wan, M. Yu, K. Wang, and S. Yan, “G-Memory: Tracing hierarchical memory for multi-agent systems,” arXiv preprint arXiv:2506.07398, 2025, arXiv v2, June 16, 2025.

[12] S. Kim et al., “An LLM compiler for parallel function calling,” in Proc. ICML, ser. Proceedings of Machine Learning Research, vol. 235, 2024, pp. 24 370–24 391.

[13] X. Shen et al., “Understanding the information propagation effects of communication topologies in LLM-based multi-agent systems,” in Proc. EMNLP, 2025, pp. 12 347–12 361.

[14] G. Wang, X. Chu, Z. Tan, X. Chen, T. Mo, and W. Li, “MuSe: Multistage graph reasoning via vision-language models,” in Proceedings of the 64th Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), 2026, pp. 10 442–10 462.

[15] C. Wei et al., “GraphChain: Large language models for large-scale graph analysis via tool chaining,” in Advances in Neural Information Processing Systems, vol. 38, 2025, pp. 8280–8314.

[16] B. Jin, G. Liu, C. Han, M. Jiang, H. Ji, and J. Han, “Large language models on graphs: A comprehensive survey,” IEEE Transactions on Knowledge and Data Engineering, vol. 36, no. 12, pp. 8622–8642, 2024.

[17] Y. Li et al., “A survey of graph meets large language model: Progress and future directions,” in Proc. IJCAI, 2024, pp. 8123–8131.

[18] W. Shang and X. Huang, “A survey of large language models on generative graph analytics: Query, learning, and applications,” IEEE Trans. Knowl. Data Eng., vol. 37, no. 12, pp. 6799–6819, 2025.

[19] C. Ma, Y. Chen, T. Wu, A. Khan, and H. Wang, “Large language models meet knowledge graphs for question answering: Synthesis and opportunities,” in Proc. EMNLP, 2025, pp. 24 578–24 597.

[20] Y. Bei et al., “Graphs meet AI agents: Taxonomy, progress, and future opportunities,” arXiv preprint arXiv:2506.18019, 2025, evidence version: arXiv:2506.18019v3.

[21] Y. Liu, G. Zhang, K. Wang, S. Li, S. Pan, and B. An, “Graphaugmented large language model agents: Current progress and future prospects,” IEEE Intelligent Systems, vol. 41, no. 2, pp. 45–55, 2026, available evidence version: arXiv:2507.21407; journal metadata refers to the 2026 issue.

[22] H. Luo et al., “Graph-assisted large language models: A perspective on mitigating intrinsic limitations,” in Findings of the Association for Computational Linguistics: ACL 2026, 2026, pp. 18 936–18 955.

[23] L. Yue et al., “From static templates to dynamic runtime graphs: a survey of workflow optimization for LLM agents,” arXiv preprint arXiv:2603.22386, 2026, evidence version: arXiv:2603.22386v1.

[24] C. Yang et al., “Graph-based agent memory: Taxonomy, techniques, and applications,” arXiv preprint arXiv:2602.05665, 2026, evidence version: arXiv v1, 5 February 2026.

[25] Y. Xu, W. Zhang, Y. Chen, X. Lin, and Y. Zhang, “Selfevolving agents as dynamic graph transformation: A survey and new perspective,” Preprints.org, manuscript 202606.1695, 2026, version 1, 24 June 2026; not peer reviewed. [Online]. Available: https://www.preprints.org/manuscript/202606.1695

[26] Z. Chen, L. Zheng, and D. Zhu, “A survey of agentic GraphRAG: From retrieval-augmented generation to graph-native agents,” SSRN preprint, 2026, posted May 12, 2026; revised May 13, 2026. [Online]. Available: https://ssrn.com/abstract=6713979

[27] D. Wu, H. Wang, W. Yu, Y. Zhang, K.-W. Chang, and D. Yu, “LongMemEval: Benchmarking chat assistants on long-term interactive memory,” arXiv preprint arXiv:2410.10813, 2024, evidence version: arXiv v1, October 14, 2024.

[28] S. Hu et al., “Does memory need graphs? a unified framework and empirical analysis for long-term dialog memory,” in Proc. ACL, Jul. 2026, pp. 26 758–26 782.

[29] C. Mavromatis and G. Karypis, “GNN-RAG: Graph neural retrieval for efficient large language model reasoning on knowledge graphs,” in Findings Assoc. Comput. Linguistics: ACL 2025, 2025, pp. 16 682– 16 699.

[30] P. Sarthi, S. Abdullah, A. Tuli, S. Khanna, A. Goldie, and C. D. Manning, “RAPTOR: Recursive abstractive processing for tree-organized retrieval,” in Proc. ICLR, 2024, evidence version: arXiv:2401.18059v1.

[31] D. Edge et al., “From local to global: A GraphRAG approach to query-focused summarization,” arXiv preprint arXiv:2404.16130, 2024, evidence version: arXiv:2404.16130v2 (19 February 2025).

[32] Y. Hu et al., “Memory in the age of AI agents: A survey,” arXiv preprint arXiv:2512.13564, 2025, evidence version: arXiv v2, January 13, 2026.

[33] L. Luo, Z. Zhao, G. Haffari, Y.-F. Li, C. Gong, and S. Pan, “Graphconstrained reasoning: Faithful reasoning on knowledge graphs with large language models,” in Proc. ICML, ser. Proceedings of Machine Learning Research, vol. 267, 2025, pp. 41 540–41 565.

[34] H. Luo et al., “ChatKBQA: A generate-then-retrieve framework for knowledge base question answering with fine-tuned large language models,” in Findings of the association for computational linguistics: ACL 2024, 2024, pp. 2039–2056.

[35] N. Chen, Y. Li, J. Tang, and J. Li, “GraphWiz: An instruction-following language model for graph computational problems,” in Proceedings of the 30th ACM SIGKDD Conference on Knowledge Discovery and Data Mining, 2024, pp. 353–364.

[36] X. Guo, A. Li, Y. Wang, S. Jegelka, and Y. Wang, “G1: Teaching LLMs to reason on graphs with reinforcement learning,” in Advances in Neural Information Processing Systems, vol. 38, 2025, pp. 58 961– 59 004.

[37] Z. Huang et al., “GraphThought: Graph combinatorial optimization with thought generation,” arXiv preprint arXiv:2502.11607, 2025, evidence version: arXiv:2502.11607v2.

[38] J. Wang, J. Wu, Y. Hou, Y. Liu, M. Gao, and J. McAuley, “Instruct-Graph: Boosting large language models via graph-centric instruction tuning and preference alignment,” in Findings Assoc. Comput. Linguistics: ACL 2024, 2024, pp. 13 492–13 510.

[39] R. Wang, S. Liang, Q. Chen, J. Zhang, and K. Qin, “GraphTool-Instruction: Revolutionizing graph reasoning in LLMs through decomposed subtask instruction,” in Proceedings of the 31st ACM SIGKDD Conference on Knowledge Discovery and Data Mining V. 1, 2025, pp. 1492–1503.

[40] X. Li et al., “Can large language models analyze graphs like professionals? a benchmark, datasets and models,” in Advances in Neural Information Processing Systems, vol. 37, 2024, pp. 141 045–141 070.

[41] L. Luo, Y.-F. Li, R. Haffari, and S. Pan, “Reasoning on graphs: Faithful and interpretable large language model reasoning,” in Proc. ICLR, 2024.

[42] L. Chen, P. Tong, Z. Jin, Y. Sun, J. Ye, and H. Xiong, “Plan-ongraph: Self-correcting adaptive planning of large language model on knowledge graphs,” in Advances in Neural Information Processing Systems, vol. 37, 2024, pp. 37 665–37 691.

[43] W. Zhao et al., “VoG: Enhancing LLM reasoning through stepwise verification on knowledge graphs,” in Proc. ICLR, 2026.

[44] S. Fang et al., “KARPA: A training-free method of adapting knowledge graph as references for large language model’s reasoning path aggregation,” in Findings Assoc. Comput. Linguistics: ACL 2025, 2025, pp. 24 724–24 746.

[45] K. Li, T. Zhang, X. Wu, H. Luo, J. Glass, and H. Meng, “Decoding on graphs: Faithful and sound reasoning on knowledge graphs through generation of well-formed chains,” in Proc. ACL, 2025, pp. 24 349– 24 364.

[46] H. Luo et al., “KBQA-o1: Agentic knowledge base question answering with Monte Carlo tree search,” in Proc. ICML, ser. Proceedings of Machine Learning Research, vol. 267, 2025, pp. 41 177–41 199.

[47] M. Shim, S. Hwang, K. Um, and K.-H. Lee, “Which bird does not have wings: Negative-constrained KGQA with schema-guided semantic matching and self-directed refinement,” in Findings Assoc. Comput. Linguistics: ACL 2026, 2026, pp. 22 547–22 561.

[48] B. J. Gutierrez, Y. Shu, Y. Gu, M. Yasunaga, and Y. Su, “HippoRAG:´ Neurobiologically inspired long-term memory for large language models,” in Advances in Neural Information Processing Systems, vol. 37, 2024, pp. 59 532–59 569.

[49] X. Liu et al., “ToolNet: Connecting large language models with massive tools via tool graph,” arXiv preprint arXiv:2403.00839, 2024, arXiv v1, February 29, 2024.

[50] X. He et al., “G-Retriever: Retrieval-augmented generation for textual graph understanding and question answering,” in Advances in Neural Information Processing Systems, vol. 37, 2024, pp. 132 876–132 907.

[51] P. Chhikara, D. Khant, S. Aryan, T. Singh, and D. Yadav, “Mem0: Building production-ready AI agents with scalable long-term memory,” arXiv preprint arXiv:2504.19413, 2025, arXiv v1, April 28, 2025.

[52] P. Anokhin et al., “AriGraph: Learning knowledge graph world models with episodic memory for LLM agents,” in Proc. IJCAI, 2025, pp. 12– 20.

[53] Y. Wu, Y. Zhang, S. Liang, and Y. Liu, “SGMem: Sentence graph memory for long-term conversational agents,” arXiv preprint arXiv:2509.21212, 2025, evidence version: arXiv v1, September 25, 2025.

[54] J. Zhang et al., “AFlow: Automating agentic workflow generation,” in Proc. ICLR, 2025.

[55] S. Fan et al., “WorkflowLLM: Enhancing workflow orchestration capability of large language models,” in Proc. ICLR, 2025.

[56] B. Niu et al., “FLOW: Modularized agentic workflow automation,” in Proc. ICLR, 2025.

[57] Z. Liu et al., “ControlLLM: Augment language models with tools by searching on graphs,” arXiv preprint arXiv:2310.17796, 2023, arXiv v3, December 18, 2023.

[58] T. Xia et al., “GraSP: Graph-structured skill compositions for LLM agents,” arXiv preprint arXiv:2604.17870, 2026, version: arXiv:2604.17870v1, April 20, 2026.

[59] G. Zhang et al., “G-Designer: Architecting multi-agent communication topologies via graph neural networks,” in Proc. ICML, ser. Proceedings of Machine Learning Research, vol. 267, 2025, pp. 76 678–76 692.

[60] H. Y. Leong et al., “AMAS: Adaptively determining communication topology for LLM-based multi-agent system,” in Proc. EMNLP (Industry Track), 2025, pp. 2061–2070.

[61] S. Yun et al., “Graph-of-agents: A graph-based framework for multiagent LLM collaboration,” in Proc. ICLR, 2026.

[62] G. Zhang et al., “Cut the crap: An economical communication pipeline for LLM-based multi-agent systems,” in Proc. ICLR, 2025.

[63] Z. Wang et al., “AgentDropout: Dynamic agent elimination for tokenefficient and high-performance LLM-based multi-agent collaboration,” in Proc. ACL, 2025, pp. 24 013–24 035.

[64] Y. Li et al., “Improving multi-agent debate with sparse communication topology,” in Findings Assoc. Comput. Linguistics: EMNLP 2024, 2024, pp. 7281–7294.

[65] B. Fatemi, J. Halcrow, and B. Perozzi, “Talk like a graph: Encoding graphs for large language models,” in Proc. ICLR, 2024.

[66] C. Xypolopoulos et al., “Graph linearization methods for reasoning on graphs with large language models,” arXiv preprint arXiv:2410.19494, 2024, evidence version: arXiv:2410.19494v3 (25 June 2025).

[67] Y. Ge et al., “Can graph descriptive order affect solving graph problems with LLMs?” in Proc. ACL, 2025, pp. 6404–6420.

[68] Y. Cao, S. Han, Z. Gao, Z. Ding, X. Xie, and S. K. Zhou, “GraphInsight: Unlocking insights in large language models for graph structure understanding,” in Proc. ACL, 2025, pp. 12 096–12 134.

[69] K. Skianis, G. Nikolentzos, and M. Vazirgiannis, “Graph reasoning with large language models via pseudo-code prompting,” arXiv preprint arXiv:2409.17906, 2024.

[70] A. K. Taylor, A. Cuturrufo, V. Yathish, M. D. Ma, and W. Wang, “Are large-language models graph algorithmic reasoners?” arXiv preprint arXiv:2410.22597, 2024, version 1, 29 October 2024.

[71] Y. Zhang, H. Wang, S. Feng, Z. Tan, X. Liu, and Y. Tsvetkov, “Generalizable LLM learning of graph synthetic data with post-training alignment,” in Findings of the Association for Computational Linguistics: ACL 2026, 2026, pp. 12 070–12 091.

[72] OpenAI, “GPT-4o system card,” Aug. 2024, accessed: Oct. 21, 2026. [Online]. Available: https://openai.com/index/gpt-4o-system-card/

[73] Q. Wu, Z. Chen, W. Corcoran, M. Sra, and A. Singh, “GraphEval36K: Benchmarking coding and reasoning capabilities of large language models on graph datasets,” in Findings Assoc. Comput. Linguistics: NAACL 2025, 2025, pp. 8110–8132.

[74] S. Qiao et al., “Benchmarking agentic workflow generation,” in Proc. ICLR, 2025.

[75] M. Suri et al., “Follow the flow: Fine-grained flowchart attribution with neurosymbolic agents,” in Proc. EMNLP, 2025, pp. 22 485–22 508.

[76] M. Chen, J. Wang, Z. Liu, Y. Wang, H. Zheng, and Q. Wang, “From failed trajectories to reliable LLM agents: Diagnosing and repairing harness flaws,” arXiv preprint arXiv:2606.06324, 2026, version: arXiv:2606.06324v2, July 2, 2026.

[77] W.-t. Yih, M. Richardson, C. Meek, M.-W. Chang, and J. Suh, “The value of semantic parse labeling for knowledge base question answering,” in Proc. ACL, 2016, pp. 201–206.

[78] Y. Hu, Z. Lei, Z. Zhang, B. Pan, C. Ling, and L. Zhao, “GRAG: Graph retrieval-augmented generation,” in Findings of the association for computational linguistics: NAACL 2025, 2025, pp. 4145–4157.

[79] M. Li, S. Miao, and P. Li, “Simple is effective: The roles of graphs and large language models in knowledge-graph-based retrieval-augmented generation,” in Proc. ICLR, 2025.

[80] Z. Guo, L. Xia, Y. Yu, T. Ao, and C. Huang, “LightRAG: Simple and fast retrieval-augmented generation,” in Findings Assoc. Comput. Linguistics: EMNLP 2025, 2025, pp. 10 746–10 761.

[81] K. Santhanam, O. Khattab, J. Saad-Falcon, C. Potts, and M. Zaharia, “ColBERTv2: Effective and efficient retrieval via lightweight late interaction,” in Proceedings of the 2022 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies, 2022, pp. 3715–3734.

[82] H. Trivedi, N. Balasubramanian, T. Khot, and A. Sabharwal, “MuSiQue: Multihop questions via single-hop question composition,” Transactions of the Association for Computational Linguistics, vol. 10, pp. 539–554, 2022.

[83] X. Ho, A.-K. Duong Nguyen, S. Sugawara, and A. Aizawa, “Constructing a multi-hop QA dataset for comprehensive evaluation of reasoning steps,” in Proc. COLING, 2020, pp. 6609–6625.

[84] Z. Yang et al., “HotpotQA: A dataset for diverse, explainable multi-hop question answering,” in Proc. EMNLP, 2018, pp. 2369–2380.

[85] Z. Zhou et al., “Query-aware flow diffusion for graph-based RAG with retrieval guarantees,” in Proc. ICLR, 2026.

[86] P. Yu, E. Xu, B. Chen, H. Chen, and Y. Xu, “STEM: Structure-tracing evidence mining for knowledge graphs-driven retrieval-augmented generation,” in Proc. ACL, 2026, pp. 7252–7285.

[87] A. Talmor and J. Berant, “The web as a knowledge-base for answering complex questions,” in Proc. NAACL, 2018, pp. 641–651.

[88] H. Liu, S. Wang, Y. Zhu, Y. Dong, and J. Li, “Knowledge graphenhanced large language models via path selection,” in Findings Assoc. Comput. Linguistics: ACL 2024, 2024, pp. 6311–6321.

[89] Y. Ji et al., “Retrieval and reasoning on KGs: Integrate knowledge graphs into large language models for complex question answering,” in Findings Assoc. Comput. Linguistics: EMNLP 2024, 2024, pp. 7598– 7610.

[90] T. Yao, H. Li, Z. Shen, P. Li, T. Liu, and K. Zhang, “Learning efficient and generalizable graph retriever for knowledge-graph question answering,” arXiv preprint arXiv:2506.09645, 2025, evidence version: arXiv:2506.09645v1.

[91] L. Luo, Z. Zhao, G. Haffari, C. Gong, D. Phung, and S. Pan, “GFM-RAG: Graph foundation model for retrieval augmented generation,” in Advances in Neural Information Processing Systems, vol. 38, 2025.

[92] L. Luo et al., “G-Reasoner: Foundation models for unified reasoning over graph-structured knowledge,” in Proc. ICLR, 2026, evidence version: arXiv:2509.24276v4.

[93] W3C SPARQL Working Group, “SPARQL 1.1 query language,” World Wide Web Consortium, W3C Recommendation, March 2013, edited by Steve Harris and Andy Seaborne. Accessed: Oct. 21, 2026. [Online]. Available: https://www.w3.org/TR/2013/ REC-sparql11-query-20130321/

[94] Y. Tian et al., “Subgraph-guided executable logical form generation for knowledge base question answering,” in Findings Assoc. Comput. Linguistics: ACL 2026, 2026, pp. 3614–3635.

[95] Y. Tian, P. Yang, D. Song, Z. Wu, and H. Wang, “GRV-KBQA: A three-stage framework for knowledge base question answering with decoupled logical structure, semantic grounding and structure-aware validation,” in Findings Assoc. Comput. Linguistics: EMNLP 2025, 2025, pp. 2618–2632.

[96] G. Liang et al., “Diagnosing and remedying representation deficiencies for deterministic reasoning in KGQA,” in Proc. ACL, 2026, pp. 45 036– 45 054.

[97] H. Wang et al., “SEAL: Self-evolving agentic learning for conversational question answering over knowledge graphs,” Neurocomputing, vol. 697, p. 133998, 2026, mechanism evidence: arXiv:2512.04868v2.

[98] J. Jiang, K. Zhou, Z. Dong, K. Ye, W. X. Zhao, and J.-R. Wen, “StructGPT: A general framework for large language model to reason over structured data,” in Proc. EMNLP, 2023, pp. 9237–9251.

[99] J. Sun et al., “Think-on-graph: Deep and responsible reasoning of large language model on knowledge graph,” in Proc. ICLR, 2024.

[100] Y. Gu et al., “Beyond I.I.D.: Three levels of generalization for question answering on knowledge bases,” in Proceedings of the Web Conference 2021, 2021, pp. 3477–3488.

[101] Y. Wang, S. Fan, M. Wang, S. Gao, C. Wang, and N. Yin, “DAMR: Efficient and adaptive context-aware knowledge graph question answering with LLM-guided MCTS,” in Proc. ICLR, 2026.

[102] M. Zhang, Z. Yang, H. Zou, J. Chen, Z. Duan, and S. Zhao, “Execution as verification: Fine-grained self-correcting reasoning for complex KBQA,” in Proc. ACL, 2026, pp. 37 646–37 663.

[103] B. Jin et al., “Graph chain-of-thought: Augmenting large language models by reasoning on graphs,” in Findings Assoc. Comput. Linguistics: ACL 2024, 2024, pp. 163–184.

[104] Y. Zhou et al., “Reflection on knowledge graph for large language models reasoning,” in Findings Assoc. Comput. Linguistics: ACL 2025, 2025, pp. 23 840–23 857.

[105] J. Polonuer et al., “Autonomous knowledge graph exploration with adaptive breadth-depth retrieval,” in Proc. ACL, 2026, pp. 15 694– 15 709.

[106] Y. Chen, S. Wan, T. Zhang, and X. Zhang, “Graph explorer: Training faithful KG agents with visibility-grounded supervision,” in Findings Assoc. Comput. Linguistics: ACL 2026, 2026, pp. 7875–7890.

[107] A. Yang et al., “Qwen3 technical report,” arXiv preprint arXiv:2505.09388, 2025.

[108] C. Liu, J. Zhou, and J. Wang, “Chain-of-relations: Faithful and efficient LLM reasoning over knowledge graphs via relation-centric exploration,” in Findings Assoc. Comput. Linguistics: ACL 2026, 2026, pp. 43 108–43 119.

[109] Y. Sui, Y. He, N. Liu, X. He, K. Wang, and B. Hooi, “FiDeLiS: Faithful reasoning in large language models for knowledge graph question answering,” in Findings Assoc. Comput. Linguistics: ACL 2025, 2025, pp. 8315–8330.

[110] Y. Shan, J. Peng, Z. Dong, F. Hu, and X. Wang, “Reasoning with ontology graph: Toward type-constrained knowledge graph question answering,” in Proc. ACL, 2026, pp. 10 684–10 697.

[111] S. Lin et al., “Conformal path reasoning: Trustworthy knowledge graph question answering via path-level calibration,” in Proc. ICML, ser. Proceedings of Machine Learning Research, vol. 306, 2026, pp. 75 177–75 192.

[112] S. Ma et al., “Think-on-graph 2.0: Deep and faithful large language model reasoning with knowledge-guided retrieval augmented generation,” in Proc. ICLR, 2025.

[113] Y. Xu et al., “Generate-on-Graph: Treat LLM as both agent and KG for incomplete knowledge graph question answering,” in Proc. EMNLP, 2024, pp. 18 410–18 430.

[114] Y. Liu, D. Lin, S. Luo, X. Yang, and B. Wang, “Joint knowledge base completion and question answering by combining large language models and small language models,” in Proc. ACL, 2026, pp. 36 756– 36 775.

[115] H. Abdallah, I. Abdelaziz, P. Kalnis, and E. Mansour, “Leveraging LLM-GNN integration for open-world question answering over knowledge graphs,” in Proceedings of the 19th Conference of the European Chapter of the Association for Computational Linguistics (Volume 1: Long Papers), 2026, pp. 575–592.

[116] Y. Wen, Z. Wang, and J. Sun, “MindMap: Knowledge graph prompting sparks graph of thoughts in large language models,” in Proc. ACL, 2024, pp. 10 370–10 388.

[117] A. Toroghi, W. Guo, M. M. Abdollah Pour, and S. Sanner, “Right for right reasons: Large language models for verifiable commonsense knowledge graph question answering,” in Proc. EMNLP, 2024, pp. 6601–6633.

[118] J. Zhong, Y. Li, S. Hu, Y. Zhang, T. Xu, and L. Zou, “Graph-augmented knowledge infusion for dialogue-based medication recommendation,” in Web and Big Data (APWeb-WAIM 2026), ser. Lecture Notes in Computer Science, vol. 16994. Springer, 2026, pp. 113–128.

[119] B. J. Gutierrez, Y. Shu, W. Qi, S. Zhou, and Y. Su, “From RAG to´ memory: Non-parametric continual learning for large language models,” in Proc. ICML, ser. Proceedings of Machine Learning Research, vol. 267, 2025, pp. 21 497–21 515.

[120] OpenAI, “GPT-4o mini: Advancing cost-efficient intelligence,” Jul. 2024, accessed: Oct. 21, 2026. [Online]. Available: https: //openai.com/index/gpt-4o-mini-advancing-cost-efficient-intelligence/

[121] D. Chen et al., “HaluMem: Evaluating hallucinations in memory systems of agents,” arXiv preprint arXiv:2511.03506, 2025, evidence version: arXiv v3, January 5, 2026.

[122] A. Maharana, D.-H. Lee, S. Tulyakov, M. Bansal, F. Barbieri, and Y. Fang, “Evaluating very long-term conversational memory of LLM agents,” in Proc. ACL, 2024, pp. 13 851–13 870.

[123] P. Rasmussen, P. Paliychuk, T. Beauvais, J. Ryan, and D. Chalef, “Zep: a temporal knowledge graph architecture for agent memory,” arXiv preprint arXiv:2501.13956, 2025, evidence version: arXiv:2501.13956v1.

[124] Z. Tan et al., “In prospect and retrospect: Reflective memory management for long-term personalized dialogue agents,” arXiv preprint arXiv:2503.08026, 2025, evidence version: arXiv v1, March 11, 2025.

[125] J. Fang et al., “LightMem: Lightweight and efficient memoryaugmented generation,” arXiv preprint arXiv:2510.18866, 2025, evidence version: arXiv v4, February 28, 2026.

[126] M.-A. Cotˆ e´ et al., “TextWorld: A learning environment for textbased games,” arXiv preprint arXiv:1806.11532v2, 2018, bibliographic version: arXiv:1806.11532v2, November 8, 2019; first released June 29, 2018.

[127] Z. Qi et al., “Thought-action graph reasoning: Faithful and efficient reasoning of large language models via reusing past experience,” in Findings Assoc. Comput. Linguistics: ACL 2026, 2026, pp. 31 433– 31 449.

[128] N. Shinn, F. Cassano, E. Berman, A. Gopinath, K. Narasimhan, and S. Yao, “Reflexion: Language agents with verbal reinforcement learning,” arXiv preprint arXiv:2303.11366, 2023, version: arXiv:2303.11366v4, October 10, 2023.

[129] C. Ma et al., “AgentBoard: An analytical evaluation board of multi-turn LLM agents,” in Advances in Neural Information Processing Systems, vol. 37, 2024.

[130] J. Thorne, A. Vlachos, C. Christodoulopoulos, and A. Mittal, “FEVER: a large-scale dataset for fact extraction and VERification,” in Proceedings of the 2018 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies, Volume 1 (Long Papers), 2018, pp. 809–819.

[131] F. Lin, E. La Malfa, V. Hofmann, E. M. Yang, A. G. Cohn, and J. B. Pierrehumbert, “Graph-enhanced large language models in asynchronous plan reasoning,” in Proc. ICML, ser. Proceedings of Machine Learning Research, vol. 235, 2024, pp. 30 108–30 134.

[132] K. Chen, J. Zeng, Z. Peng, G. Li, G. Zhang, and T. Wang, “Matrix as plan: Structured logical reasoning with feedback-driven replanning,” in Proceedings of the ACM Web Conference 2026, 2026, pp. 3686–3697.

[133] S. Yao et al., “Tree of thoughts: Deliberate problem solving with large language models,” in Advances in Neural Information Processing Systems, vol. 36, 2023, pp. 11 809–11 822.

[134] S. Yao, H. Chen, J. Yang, and K. Narasimhan, “WebShop: Towards scalable real-world web interaction with grounded language agents,” in Advances in Neural Information Processing Systems, vol. 35, 2022, pp. 20 744–20 757.

[135] S. Li et al., “HeraSys: Collaborative serving of multiple LLM workflows via fine-grained end-to-end optimization,” in Proceedings of the 43rd International Conference on Machine Learning, ser. Proceedings of Machine Learning Research, vol. 306, 2026, pp. 70 291–70 308. [Online]. Available: https://proceedings.mlr.press/v306/ li26fz.html

[136] M. Zhuge, W. Wang, L. Kirsch, F. Faccio, D. Khizbullin, and J. Schmidhuber, “GPTSwarm: Language agents as optimizable graphs,” in Proc. ICML, ser. Proceedings of Machine Learning Research, vol. 235, 2024, pp. 62 743–62 767.

[137] C. Park et al., “A practical approach for building production-grade conversational agents with workflow graphs,” in Proc. ACL (Industry Track), 2025, pp. 1508–1519.

[138] S. Amini et al., “Open agent specification: Enabling cross-framework comparison of AI agents,” in Proceedings of the ACM Conference on AI and Agentic Systems, 2026, pp. 404–418.

[139] W. Chen, D. Yao, W. Li, X. Meng, C. Gong, and J. Bi, “GTool: Graph enhanced tool planning with large language model,” in Proc. ICLR, 2026.

[140] W. Su et al., “Skill retrieval augmentation for agentic AI,” arXiv preprint arXiv:2604.24594, 2026, version: arXiv:2604.24594v3, June 7, 2026.

[141] X. Zhao et al., “Generative skill composition for LLM agents,” arXiv preprint arXiv:2606.32025, 2026, version: arXiv:2606.32025v1, June 30, 2026.

[142] DeepSeek-AI et al., “DeepSeek-V3.2: Pushing the frontier of open large language models,” arXiv preprint arXiv:2512.02556, 2025.

[143] M. Shridhar, X. Yuan, M.-A. Cotˆ e, Y. Bisk, A. Trischler, and´ M. Hausknecht, “ALFWorld: Aligning text and embodied environments for interactive learning,” in Proc. ICLR, 2021.

[144] R. Wang, P. Jansen, M.-A. Cotˆ e, and P. Ammanabrolu, “ScienceWorld:´ Is your agent smarter than a 5th grader?” in Proc. EMNLP, 2022, pp. 11 279–11 298.

[145] J. Zhong et al., “RareDASH: A dynamic multi-agent system for holistic rare disease care,” in Proceedings of the Thirty-Fifth International Joint Conference on Artificial Intelligence, 2026, pp. 8564–8568, demo Track.

[146] L. Guo, W. Liu, Y. W. Heng, T.-H. Chen, and Y. Wang, “Agent-SAMA: State-aware mobile assistant,” in Proceedings of the AAAI Conference on Artificial Intelligence, vol. 40, no. 35, 2026, pp. 29 459–29 467.

[147] S. Hong et al., “MetaGPT: Meta programming for a multi-agent collaborative framework,” in Proc. ICLR, 2024.

[148] Q. Wu et al., “AutoGen: Enabling next-gen LLM applications via multiagent conversations,” in First conference on language modeling, 2024.

[149] X. Wang et al., “Self-consistency improves chain of thought reasoning in language models,” in Proc. ICLR, 2023.

[150] D. Hendrycks et al., “Measuring massive multitask language understanding,” in Proc. ICLR, 2021.

[151] E. H. Jiang et al., “Dynamic generation of multi LLM agents communication topologies with graph diffusion models,” in Proc. ACL, 2026, pp. 38 042–38 060.

[152] R. Sun et al., “TopoDIM: One-shot topology generation of diverse interaction modes for multi-agent systems,” in Findings Assoc. Comput. Linguistics: ACL 2026, 2026, pp. 4252–4269.

[153] Y. Yang et al., “AgentNet: Decentralized evolutionary coordination for LLM-based multi-agent systems,” in Advances in Neural Information Processing Systems, vol. 38, 2025, pp. 118 758–118 785, pagination follows the DOI-linked Curran proceedings.

[154] H. Zhang et al., “EvoHyper: Evolving hypergraph topologies for unified collaboration in multi-agent communication,” in Findings Assoc. Comput. Linguistics: ACL 2026, 2026, pp. 25 130–25 143.

[155] M. Yu et al., “NetSafe: Exploring the topological safety of multi-agent system,” in Findings Assoc. Comput. Linguistics: ACL 2025, 2025, pp. 2905–2938.

[156] P. He, Y. Lin, S. Dong, H. Xu, Y. Xing, and H. Liu, “Red-teaming LLM multi-agent systems via communication attacks,” in Findings Assoc. Comput. Linguistics: ACL 2025, 2025, pp. 6726–6747.

[157] Y. Wu et al., “CIA: Inferring the communication topology from LLMbased multi-agent systems,” in Proceedings of the 64th Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), 2026, pp. 17 917–17 933.

[158] J. Zhou, L. Wang, and X. Yang, “GUARDIAN: Safeguarding LLM multi-agent collaborations with temporal graph modeling,” in Advances in Neural Information Processing Systems, vol. 38, 2025, pp. 8881– 8909, pagination follows the DOI-linked Curran proceedings.

[159] H. Trivedi, N. Balasubramanian, T. Khot, and A. Sabharwal, “Interleaving retrieval with chain-of-thought reasoning for knowledge-intensive multi-step questions,” in Proceedings of the 61st annual meeting of the association for computational linguistics (volume 1: long papers), 2023, pp. 10 014–10 037.

[160] S. Wu et al., “STaRK: Benchmarking LLM retrieval on textual and relational knowledge bases,” in Advances in Neural Information Processing Systems, vol. 37, 2024, pp. 127 129–127 153.

[161] H. Xu et al., “GraphOmni: A comprehensive and extensible benchmark framework for large language models on graph-theoretic tasks,” in Proc. ICLR, 2026.

[162] F. Wang et al., “Unified multi-dimensional benchmark for complex graph reasoning in large language models,” arXiv preprint arXiv:2608.12391, 2026.

[163] S. Cao et al., “KQA Pro: A dataset with explicit compositional programs for complex question answering over knowledge base,” in Proc. ACL, 2022, pp. 6101–6119.

[164] M. Patidar, P. Faldu, A. Singh, L. Vig, I. Bhattacharya, and Mausam, “Do I have the knowledge to answer? investigating answerability of knowledge base questions,” in Proc. ACL, 2023, pp. 10 341–10 357.

[165] Z. Xiang et al., “When to use graphs in RAG: A comprehensive analysis for graph retrieval-augmented generation,” in Proc. ICLR, 2026.

[166] Y. Xiao et al., “GraphRAG-Bench: Challenging domain-specific reasoning for evaluating graph retrieval-augmented generation,” arXiv preprint arXiv:2506.02404, 2025, bibliographic version: arXiv:2506.02404v3, June 20, 2025.

[167] X. Liu et al., “AgentBench: Evaluating LLMs as agents,” in Proc. ICLR, 2024.

[168] Y. Qin et al., “ToolLLM: Facilitating large language models to master 16000+ real-world APIs,” in Proc. ICLR, 2024.

[169] M. Chen et al., “Evaluating large language models trained on code,” arXiv preprint arXiv:2107.03374v2, 2021.

[170] A. Yehudai et al., “A survey on evaluation of LLM-based agents,” in Findings of the Association for Computational Linguistics: ACL 2026, 2026, pp. 26 690–26 714.

[171] W. Zhang, M. Aliannejadi, Y. Yuan, J. Pei, J.-h. Huang, and E. Kanoulas, “Towards fine-grained citation evaluation in generated text: A comparative analysis of faithfulness metrics,” in Proceedings of the 17th International Natural Language Generation Conference, 2024, pp. 427–439.

[172] J. Hu, Y. Li, J. Zhong, W. Qi, and L. Zou, “Detecting hallucinations in retrieval-augmented generation via semantic-level internal reasoning graph,” in Findings of the Association for Computational Linguistics: ACL 2026, 2026, pp. 27 826–27 841. [Online]. Available: https://aclanthology.org/2026.findings-acl.1385/

[173] L. Chen et al., “Is GraphRAG needed? from basic RAG to graph-/agentic solutions with context optimization,” in Proceedings of the Fifth Workshop on Generation, Evaluation and Metrics (GEM), 2026, pp. 428–442.

[174] S. Dong, Q. Zhang, Y. Xiao, S. Chen, C. Zhou, and X. Huang, “Use graph when it needs: Efficiently and adaptively integrating retrievalaugmented generation with graphs,” arXiv preprint arXiv:2602.03578, 2026.

[175] H. Han et al., “RAG vs. GraphRAG: A systematic evaluation and key insights,” in Proceedings of the 32nd ACM SIGKDD Conference on Knowledge Discovery and Data Mining V.2, 2026, pp. 8966–8977, extended evidence version: arXiv:2502.11371v3 (4 March 2026).

[176] A. Yang et al., “Qwen2.5 technical report,” arXiv preprint arXiv:2412.15115, 2024.

[177] D. Fan, Z. Xue, S. Liu, and Q. Tan, “Do we still need GraphRAG? benchmarking RAG and GraphRAG for agentic search systems,” arXiv preprint arXiv:2604.09666, 2026, evidence version: arXiv:2604.09666v1.

[178] X. Li et al., “Search-o1: Agentic search-enhanced large reasoning models,” in Proceedings of the 2025 Conference on Empirical Methods in Natural Language Processing, 2025, pp. 5420–5438.

[179] C. Yang et al., “GraphSearch: An agentic deep searching workflow for graph retrieval-augmented generation,” arXiv preprint arXiv:2509.22009, 2025.

[180] L. Zheng et al., “Judging LLM-as-a-judge with MT-Bench and chatbot arena,” in Advances in Neural Information Processing Systems, vol. 36, 2023, pp. 46 595–46 623.

[181] T. J. Green, G. Karvounarakis, and V. Tannen, “Provenance semirings,” in Proceedings of the Twenty-Sixth ACM SIGMOD-SIGACT-SIGART Symposium on Principles of Database Systems, 2007, pp. 31–40.

[182] A. Gupta, I. S. Mumick, and V. S. Subrahmanian, “Maintaining views incrementally,” in Proceedings of the 1993 ACM SIGMOD International Conference on Management of Data, 1993, pp. 157–166.

![](images/caec44e05382f27c2dd685ac32b546018d4628afcc1fbefc38148b40d412df38.jpg)  
Haihui Liu (Student Member, IEEE) received the M.S. degree from Shandong Normal University, China, in 2024. She is currently working toward the Ph.D. degree at Beijing Normal University. Her research interests include edge intelligence, recommender systems, and large language models.

![](images/9599a7de8d305fd2bde6e48be8f619cb94096e27e351e574df26cdac0af09290.jpg)

Yang Chen received the B.Sc. degree in information and computing science from Nanjing Forestry University, Nanjing, China, in 2023, and the M.Eng. degree in computer science and technology from South-Central Minzu University, Wuhan, China, in 2026. He is currently working toward the Ph.D. degree with the Faculty of Arts and Sciences, Beijing Normal University, Zhuhai, China. His research interests include graph-based agents and knowledge graph question answering.

![](images/63f9cf83490f51188c9b3464fb2614a61e5763e2d0e9c845f7f100d8aff99a97.jpg)

Zice Qiu is currently working toward the bachelor’s degree in remote sensing science and technology at the School of Geospatial Engineering and Science, Sun Yat-sen University, Zhuhai, China. His research interests include large language models, multimodal learning, and AI-generated content.

![](images/1ce26e8564f5475bb6fe50eeb7ccb3d255ba78ce7b3adc54d85837c65c76ba90.jpg)

Yun Zhang is currently pursuing her undergraduate degree at the Faculty of Science and Technology, BEIJING NORMAL-HONG KONG BAPTIST UNIVERSITY. Her research interests include data analysis and artificial intelligence.

![](images/f7886df2a2fa8fc8e2517a83629c258cf7c85432bbd266dd96b39208d50c9067.jpg)

Jialun Zhong received the M.Sc. degree from Huazhong University of Science and Technology, China, in 2023. He is currently working toward a Ph.D. degree at the School of Intelligence Science and Technology, Peking University, China. His research interests include knowledge graphs and large language model reasoning.

![](images/cfdc9d225ad802ccf2b422f26c9a633ccbb022920cc1ff947dd14e9b8416e070.jpg)

Wenhua Wang (Member, IEEE) received the Ph.D. degree in computer science from the University of Technology Sydney in 2022. She is currently a lecturer with the Institute of Artificial Intelligence and Future Network, Beijing Normal University, China. Her research interests include edge computing, federated learning, and mobile computing.

![](images/52bef600063b73b83c0f619f5a6033dfdaadd7b88a035c78d6413f184abc89b9.jpg)

Yanzeng Li is currently a lecturer at the Institute of Artificial Intelligence and Future Networks, Beijing Normal University, China. He received his Ph.D. degree from Peking University in 2025. His research focuses on knowledge graphs and large language models, and he serves as a reviewer and area chair for numerous international journals and conferences in artificial intelligence and natural language processing.

![](images/b4d5ba38423bbbf99c0c4bbac9d90c6c7c370871ea2cbf8e9333760c9f66af0f.jpg)

Tian Wang (Senior Member, IEEE) received the B.Sc. and M.Sc. degrees in computer science from Central South University in 2004 and 2007, respectively, and the Ph.D. degree in computer science from City University of Hong Kong in 2011. He is currently a professor with the Institute of Artificial Intelligence and Future Networks, Beijing Normal University. He has authored or coauthored more than 200 papers in high-level journals and conferences. He has more than 17,000 citations according to Google Scholar and also has 30 patents. His h-index is 78. His research interests include the Internet of Things, edge computing, and mobile computing.
# RE-SEARCH: Dissecting LLM Ideation Through a Two-Player Questioning Game

Muhan Gao<sup>1</sup> Hangxiao Zhu<sup>1</sup> Xinqi Su<sup>1</sup> Yu Zhang<sup>1</sup> Daniel Khashabi<sup>2,†</sup> Kuan-Hao Huang<sup>1,†</sup> <sup>1</sup>Texas A&M University <sup>2</sup>Johns Hopkins University

## Abstract

Research ideation is iterative: researchers refine their ideas step by step based on feedback. Yet existing evaluations obscure this search process, making it difficult to understand how LLMs explore the space of research ideas and what limits their progress. We introduce RE-SEARCH, which adapts the format of Twenty Questions to research ideation: given only the research problem of a published paper, a model must rediscover the paper’s core idea by asking yes-or-no questions. Built from 200 ICML 2026 papers, RE-SEARCH tracks how a model’s idea evolves as it asks questions and receives binary oracle feedback, iso lating ideation from execution. Across six recent LLMs, nearly all progress happens within the first 30 of 100 questions, which largely de cide how the game ends; after that, most models plateau. Through controlled interventions on the candidate questions and the hypothesis space, we find that the bottleneck is generation, not judgment: models recognize a good idea or a good question when one is offered, but often cannot produce it on their own. We further analyze the ideation traces and find that models fail by either over-exploiting one direction or overexploring too many. These findings point to concrete design principles for autoresearch sys tems: since models can judge candidates they cannot produce, enriching the search with externally sourced ideas and questions may be more effective than improving any single model’s generation ability.

## 1 Introduction

Research ideation is not a one-shot proposal but an iterative search interleaved with every stage of a project: researchers form hypotheses, test them, and refine them based on feedback. This process can be viewed as adaptive information seeking over a space of plausible yet unverified ideas (Klahr and Dunbar, 1988). However, existing benchmarks provide limited visibility into this iterative search. Ideation benchmarks evaluate one-shot proposals using LLM judges (Guo et al., 2025; Chen et al., 2025), overlooking how ideas evolve through feedback. End-to-end benchmarks involve iterative search but entangle it with coding, debugging, and experimentation (Wijk et al., 2025; Wu et al., 2026; Rank et al., 2026; Lupidi et al., 2026; Garikaparthi et al., 2026; Chan et al., 2025), making it difficult to distinguish failures of ideation from failures of execution.

![](images/742a3a4b7184eddad4f4840a29e963fb5af5c22b8ff8cd04b02c0b5ecbdf7390.jpg)  
Figure 1: DeepSeek-V4-Flash and GPT-5.4 play RE-SEARCH on the same paper. Height reflects recovery of the paper’s idea. Green marks matching terms; red marks mismatches. While DeepSeek-V4-Flash ends up circling in a basin, GPT-5.4 recovers from a dip and reaches the summit.

In this work, we aim to isolate the informationseeking process from the rest of autoresearch. To this end, we introduce RE-SEARCH, a two-player questioning game that makes every step of this process observable and measurable (Fig 1). The setting is a scientific variant of Twenty Questions (Mosher and Hornsby, 1966; Siegler, 1977), a classic paradigm in cognitive science for studying human reasoning and problem solving (Coenen et al., 2019). Given only the research problem of a published paper, an inquisitor model must rediscover the paper’s idea by asking up to 100 yes-orno questions, while an answerer model reads the full paper and replies to the questions. Every 10 questions, the inquisitor model writes down its current best guess of the idea, which a panel of judges scores against the paper’s idea (§3, see Fig 2 as an example). Success on RE-SEARCH requires three capabilities. The model must (1) ask informative questions, which means both proposing good candidate questions and judging which of them to ask, (2) maintain an adequate hypothesis space that includes the correct idea, and (3) hill-climb along promising directions while abandoning dead ends.

We evaluate six recent LLMs on 200 ICML 2026 papers. GPT-5.4 leads by a wide margin, followed by Gemma-4-31B and Claude Sonnet 4.5; the remaining three models score about two thirds as high as GPT-5.4. Yet the models share a common pattern: most progress happens within the first 30 questions, after which gains slow sharply for all but GPT-5.4, and a model’s score at question 30 largely predicts its final score. So why do models stall with 70 questions left, and which capabilities are missing?

We first rule out a simple knowledge deficit: on papers where both a strong and a weak model can list the core idea beforehand, the strong model still finishes far ahead. The first clue comes from question quality. When a weak model can choose from candidate questions proposed by several models, it scores far above its own solo performance. The same pattern holds for the hypothesis space. We give models a survey of candidate directions that includes the paper’s core idea; without it, many models never reach the idea, but with it, they zero in on it within a few questions—and the weaker the model, the larger the gain.

In both cases, models recognize a good idea or a good question when one is offered, but often cannot generate it on their own. The ideation traces show how hill-climbing fails: weaker models either over-exploit one direction or over-explore too many, stuck into an unproductive pattern early.

Our contributions are: (1) RE-SEARCH, a twoplayer questioning game that isolates research ideation from execution and makes every step of ideation observable and measurable; (2) the finding that ideation is decided early: most progress happens within the first 30 questions, and weaker models lock into either over-exploiting one direction or over-exploring too many; and (3) a diagnosis that the bottleneck is generation, not judgment, pointing to external candidates as a direct lever for improving autoresearch systems.

## 2 Related Work

AI scientists and their evaluation. LLM-based systems now attempt to automate research from idea to paper (Lu et al., 2024, 2026; Schmidgall et al., 2025; Gottweis et al., 2026). Most are evaluated end to end: benchmarks run an agent on a research project for hours and score the outcome (Chan et al., 2025; Wijk et al., 2025; Zhang et al., 2025; Wu et al., 2026; Rank et al., 2026; Lupidi et al., 2026; Garikaparthi et al., 2026), or grade intermediate steps against expert rubrics (Starace et al., 2025; Kon et al., 2026; Bragg et al., 2026; Jansen et al., 2024), and open-world environments let agents pursue long projects on their own (Chung and Du, 2025). Some of them ask agents to rediscover the findings of a hidden paper, from raw data (Xu et al., 2026) or by running experiments (Wang et al., 2026). In all of these, the search for the idea is mixed with coding, debugging, and experiments, and can only be reconstructed from logs afterwards (Li et al., 2026a). RE-SEARCH isolates this search, so that each question and its effect on the idea can be observed directly.

Research ideation. A separate line of work asks whether LLMs can propose research ideas. Si et al. (2025) find in a large human study that LLM ideas are judged more novel but slightly less feasible than those of experts, and benchmarks such as IdeaBench (Guo et al., 2025) and the ideation stage of MLR-Bench (Chen et al., 2025) rate generated ideas with LLM judges. Other systems refine ideas over several rounds, through literature-grounded review (Baek et al., 2025), planned retrieval of external knowledge (Hu et al., 2025), or multi-agent and quality-diversity search (Chen and Zhang, 2026; Gumma et al., 2026). These evaluations either treat ideation as a single step or guide the search with LLM feedback, and none of them has a correct answer to compare against. Like us, Yang et al. (2025) and Liu et al. (2026) use recent papers as ground truth, testing whether LLMs can rediscover their hypotheses by retrieving inspirations and composing a hypothesis from them. The model receives its evidence up front, whereas in RE-SEARCH it must find the evidence itself by asking.

Concurrently, Wen et al. (2026) introduce Priced Guidance to quantify the cost of steering a model toward a paper’s core idea. The evaluated model proposes multiple-choice questions with reported answer probabilities. A guide with access to the target then selects an answer, priced at − log<sub>2</sub> p<sub>selected</sub> bits. Because this cost is computed from verbalized probabilities, the resulting score reflects probability-reporting behavior as well as candidate generation. Their analysis also highlights the cost of acquiring useful candidate concepts, consistent with our finding that weaker models can use supplied candidates they struggle to propose independently. In our work, the focus is on how ideation unfolds through interaction and why progress stalls. Following the cognitive view of discovery as hypothesis search guided by experimental feedback (Langley et al., 1987), RE-SEARCH tracks idea recovery through model-generated questions and paper-grounded feedback. Controlled interventions on candidate questions and hypotheses then examine how candidate availability and selection affect recovery, without requiring models to report answer probabilities.

Information seeking and question asking. Twenty Questions and related games are standard tools for studying how people ask questions: children move from testing single hypotheses to asking questions that narrow the space (Mosher and Hornsby, 1966; Ruggeri and Lombrozo, 2015; Ruggeri et al., 2016), and people adapt their questions to the structure of the hypothesis space (Nelson et al., 2014; Cohen and Lake, 2016; Coenen et al., 2019). Recent work uses the same games to evaluate and improve LLMs (Bertolazzi et al., 2023; Zhang et al., 2024b; Mazzaccara et al., 2024), often by choosing questions with high expected information gain or value of information (Hu et al., 2024; Choudhury et al., 2026; Grand et al., 2026; Dong et al., 2026); MediQ (Li et al., 2024) brings the same setting to clinical diagnosis. In these tasks, the target is an object, a diagnosis, or a board configuration from a small, known set of candidates. In RE-SEARCH, the target is a research idea, and the model must generate the candidates itself. More broadly, LLMs in multi-turn and longhorizon settings tend to commit early and rarely recover from early mistakes (Laban et al., 2026; Sinha et al., 2026), although deep-research agents can also switch direction mid-trajectory (Li et al., 2026b); we find that in research ideation, early questions largely decide the outcome (§4.2).

![](images/e97ee28a3b4ac6f8a9573083dc32bed63a8c5512e296e39c5f764c1e8d420e67.jpg)  
Figure 2: Part of the GPT-5.4 game in Figure 1: given the research problem p, the inquisitor $M _ { \mathrm { i } }$ asks yes-or-no questions, the answerer $M _ { \mathrm { a } }$ replies based on the full paper, and the judges $M _ { \mathrm { j } }$ score the idea card.

## 3 The RE-SEARCH Game

We define the game in §3.1, describe how we build it from published papers in §3.2, and explain how we score what the model recovers in §3.3.

## 3.1 Task Description

In Twenty Questions, one player holds a hidden target (e.g., a specific person), and the other must identify it by iteratively asking yes-or-no questions. RE-SEARCH adapts this format to research ideation. Each game is played on a pair $( p , s )$ built from a published paper in ICML 2026, where $p$ is the research problem and s is the solution that the paper proposes for it.

Three roles are involved: (1) The inquisitor $M _ { \mathrm { i } }$ sees only $p .$ At each turn t, it asks a yes-or-no question $q _ { t }$ based on the problem and the history of earlier questions and answers, $q _ { t } = M _ { \mathrm { i } } ( p , h _ { t - 1 } )$ where $h _ { t - 1 } = ( q _ { 1 } , a _ { 1 } , \ldots , q _ { t - 1 } , a _ { t - 1 } )$ and $h _ { 0 }$ is empty. (2) The answerer $M _ { \mathrm { a } }$ reads the full paper $d$ and replies to each question on its own, $a _ { t } = M _ { \mathrm { a } } ( d , q _ { t } ) \in \{ \mathrm { Y E S , N o }$ , UNKNOWN}. At fixed points $\mathbf { \Psi } : \in \{ 0 , 1 0 , \ldots , T \}$ , the inquisitor also writes an idea card $c _ { t } = M _ { \mathrm { i } } ( p , h _ { t } )$ , a short, structured statement of its current best guess of s.

(3) After the game, a panel of three LLM judges $M _ { \mathrm { j } } ^ { ( 1 ) } , M _ { \mathrm { j } } ^ { ( 2 ) } , M _ { \mathrm { j } } ^ { ( 3 ) }$ scores all saved idea cards $\{ c _ { 0 } , c _ { 1 0 } , \hdots , c _ { T } \}$ against s.

Information revealed by questioning. Let $S$ be the hidden solution, $P$ the research problem, and $H _ { T }$ the question–answer history. Suppose answers belong to a finite alphabet ${ \mathcal { A } } ,$ and each question is conditionally independent of $S$ given $P$ and the preceding history. Then

$$
I ( S ; H _ { T } \mid P ) \leq T \log _ { 2 } | A | .
$$

Binary feedback yields at most $T \log _ { 2 } 2 = T$ bits; our three-answer alphabet yields at most $T \log _ { 2 } 3$ bits. This bounds information gained through questioning, conditional on the problem, rather than information supplied before the game. Additional questions need not supply additional information, and this bound does not guarantee a particular recovery score. See §E for the proof.

Algorithm 1 The RE-SEARCH game for one paper.   
Require: research problem p, paper d, hidden solution s,   
question budget $\mathbf { \hat { \Pi } } _ { T }$   
1: $\hat { h } _ { 0 } \gets ( )$   
2: $c _ { 0 } \gets \ddot { M } \mathrm { i } ( p , h _ { 0 } )$ ▷ idea card before any question   
3: for $t = 1 , \cdots , \dot { T }$ do   
4: $q _ { t } \gets M _ { \mathrm { i } } ( p , h _ { t - 1 } )$   
5: $\mathsf { \bar { \alpha } } _ { t } \gets M _ { \mathrm { a } } \mathsf { \bar { ( } } d , q _ { t } ) \in \{ \mathrm { Y E S } , \mathrm { N O } , \mathrm { U N K N O W N } \}$ ▷   
stateless   
6: $h _ { t } \gets ( h _ { t - 1 } , q _ { t } , a _ { t } )$   
7: $\mathbf { i f } t \in \{ 1 0 , 2 0 , \ldots , T \}$ then   
8: $c _ { t } \dot {  } M _ { \mathrm { i } } ( p , h _ { t } )$   
9: end if   
10: end for   
11: $M _ { \mathrm { j } } ^ { ( k ) }$ score every saved c<sub>t</sub> against s ▷ not fed back

## 3.2 Data Construction

We build RE-SEARCH from 200 papers accepted at ICML 2026, one of the most recent top-tier conferences. The papers are selected based on three criteria: (1) the main contribution is a method, rather than a benchmark, a dataset, or an analysis, so that each paper has a concrete solution to recover; (2) its review score is as high as possible, indicating a reliable solution; and (3) the paper became public as late as possible. All selected papers first appeared, on arXiv or the conference, after 31 August 2025, later than every reported knowledge cutoff (§A), minimizing the risk of knowledge contamination (Cheng et al., 2024; Roberts et al., 2024).

For each paper, we take its full text d and use an LLM (GLM-5.2) to extract the pair $( p , s )$ in a structured form, which has been shown to be reliable in prior work (Gao et al., 2025; Liu et al., 2026). The research problem $p$ has four fields (the problem domain, the research goal, the main challenge, and the gap in prior work), and the solution s has four fields (the main contribution, the approach, the technical components, and the novelty). Human annotators (three Computer Science PhD students) checked the extracted pairs $( p , s )$ for 100 papers. By majority vote, 93% are correct, and the errors mostly omit a component that distinguishes the paper’s method.

![](images/ae49e1a5a4fa9f6aa59ec1b30336e0a3c5c79f1d7c15d7400a6555e2fc0a39f0.jpg)  
Figure 3: Recovery score of the games over 100 rounds, averaged over 200 papers and three games per paper. The patterns of models are different: three models gain little after the first 30 questions, Gemma and Sonnet slowly climb, while GPT-5.4 has consistent improvement. (§4.1)

## 3.3 Evaluation

We score each idea card $c _ { t }$ against the hidden solution s with a panel of three LLM judges (Gemma-4-31B, Qwen3.6, and GPT-OSS-120B). Each judge sees the research problem $p ,$ hidden solution s, and idea card $c _ { t } .$ , and rates on a 1–10 scale how much of s the card recovers. The recovery score is the mean of the three ratings, $\begin{array} { r } { r _ { t } = { \frac { 1 } { 3 } } \sum _ { k = 1 } ^ { 3 } M _ { \mathrm { j } } ^ { ( k ) } ( p , s , c _ { t } ) } \end{array}$ The judges agree closely: over all the cards in our experiment, their pairwise Spearman correlations range from 0.85 to 0.88. Since three of the judges are also inquisitors, we check for self-preference: leaving out the judge from an inquisitor’s own model family changes the gain from naming the idea by at most 0.08 points (§B).

Human evaluation. We use human annotators to check the reliability of the LLM judges, by comparing 498 pairs of idea cards; for each pair, they choose the card closer to the hidden solution, or mark a tie. Their labels agree well, with a Fleiss’ κ of 0.83. In 91.2% of pairs, the LLM judges agree with the annotator majority on which card is closer, or that the two are tied. Most of the remaining pairs are ones that the annotators mark as a tie but the judges do not; when both sides prefer one card, they choose the same card in 97.8% of pairs.

## 4 Ideation Dynamics in RE-SEARCH

§4 to §6 build on each other. In this section, we describe what happens in a game; §5 asks why most models plateau early, with controlled interventions on the candidate questions (informative questions) and the ideas it considers (hypothesis space); and §6 examines how models follow promising directions and abandon dead ends (hill-climbing), through the shape of the trace. We begin with the model choices, then show how ideation develops over a game (§4.1) and that the early questions largely decide its outcome (§4.2).

Model selection. We evaluate both open-weight and proprietary LLMs of different strengths: Gemma-4-31B, GPT-OSS-120B, DeepSeek-V4- Flash-Preview, Qwen3.6-35B-A3B, Claude Sonnet 4.5, and GPT-5.4. We do not include newer models because of the risk of knowledge contamination. In all games, Gemma-4-31B serves as the answerer, each inquisitor asks up to T = 100 questions, and we play three games per paper. Among three candidate answerers (GPT-OSS-120B, Qwen3.6-35B-A3B, and Gemma-4-31B), Gemma agrees most often with human labels on 795 annotated answers (94.0%, against 86.2% for GPT-OSS-120B and 78.4% for Qwen3.6-35B-A3B; see § D for details), and only 1.1% flip YES and NO, far below the 10% answer noise assumed in Grand et al. (2026). Therefore we use Gemma-4-31B as the answerer model.

## 4.1 Most Models Stall Early

Figure 3 shows how recovery develops over a game. Before the first question, every model’s idea card c<sub>0</sub> scores very low, confirming that the research problem alone does not reveal the solution. The game then unfolds in three stages.

Questions 1–10 bring the largest gain for every model, with scores rising by +1.3 to +3.2. Questions 11–30 add much less, between +0.2 and +0.8. The most interesting part happens in Questions 31–100, where the models are separated into different patterns. Three models stall, gaining almost nothing over the remaining 70 questions; two keep improving slowly; and only the strongest model keeps climbing steadily.

## 4.2 Early Questions Decide the Outcome

A natural implication of §4.1 is that, if most models stall after about 30 questions, the early questions should largely decide how a game ends. This echoes findings in long-horizon LLM generation, where early mistakes compound and are rarely repaired (Zhang et al., 2024a; Laban et al., 2026; Sinha et al., 2026). We test this with a prefix-fork experiment (Bigelow et al., 2025). Each model plays three games per paper. First, for each paper, we pick the games with the highest and the lowest final score, and truncate both at round k $( k \in \{ 1 0 , 2 0 , 3 0 \} )$ . Then, the same model continues each prefix to question 100 three more times, yielding three continuations from the best start and three from the worst. If the opening matters, the best-start continuations should stay ahead.

<table><tr><td>Model</td><td></td><td>k Gap at k Gap at 100 Ahead (%)</td><td></td></tr><tr><td rowspan="3">Gemma-4-31B</td><td>10</td><td>1.59 1.16</td><td>63</td></tr><tr><td>20</td><td>1.53 1.64</td><td>70</td></tr><tr><td>30</td><td>2.28 2.30</td><td>78</td></tr><tr><td rowspan="3">Qwen3.6-35B-A3B</td><td>10</td><td>1.03 1.00</td><td>64</td></tr><tr><td>20</td><td>1.21 1.41</td><td>69</td></tr><tr><td>30 1.86</td><td>1.70</td><td>73</td></tr><tr><td rowspan="3">GPT-OSS-120B</td><td>10</td><td>1.70 1.85</td><td>68</td></tr><tr><td>20</td><td>2.32 2.45</td><td>78</td></tr><tr><td>30 2.56</td><td>2.54</td><td>77</td></tr><tr><td rowspan="3">DeepSeek-V4-Flash 20</td><td>10</td><td>1.48 1.37</td><td>66</td></tr><tr><td></td><td>2.10 1.72</td><td>71</td></tr><tr><td>30 2.14</td><td>2.20</td><td>79</td></tr></table>

Table 1: Prefix-fork experiment: we truncate the best and worst game at round k and continue each three times. Gap at k means score difference between the best and worst prefix at round k. Ahead: share of papers where the best prefix still leads at question 100. The gap largely persists across models. (§4.2)

As shown in Table 1, the score at question k predicts the score at question 100 well. Across games, the correlation is r = 0.76–0.87 at k = 10 and rises to $r = 0 . 8 7 – 0 . 9 2$ at k = 30.

## 5 Diagnosing the Bottleneck

As §4 shows, most models plateau early, while GPT-5.4 keeps climbing. What explains this gap? We first rule out knowledge as the main cause (§5.1), then show that supplying external candidates, either as questions from other models (§5.2) or as a survey of the hypothesis space (§5.3), closes much of the gap.

## 5.1 Knowledge Explains Little of the Gap

A strong model may simply have seen more scientific text, know more candidate ideas before the game, and turn this knowledge into an advantage in the game. To test this, we use a closed-book probe that isolates the effect of knowledge. We collect a subset of 100 papers, and focus on two models, a strong one (GPT-5.4) and a weak one (GPT-OSS-120B). Each model is provided with the research problem and asked to list ten candidate solutions, three times, for 30 candidates in total; two LLM annotators then judge whether the list contains the paper’s core idea.

![](images/6bccd0c3ffcc8a135c33528df1ecae1a04f922eb4fb0b33718f2a9cad7ca6795.jpg)  
Figure 4: An example survey under $C _ { \mathrm { f u l l } } .$ Left: the $C _ { \mathrm { f u l l } }$ survey given before the game, which names the core idea as one option, with no extra hint. Right: how the four context conditions differ. $C _ { \mathrm { d e c o y } }$ replaces only that phrase with a plausible decoy, $C _ { \mathrm { d u m m y } }$ also replaces the other lines that point to the paper, and $C _ { \mathrm { n o n e } }$ gives no survey. Because $C _ { \mathrm { f u l l } }$ and $C _ { \mathrm { d e c o y } }$ differ in a single phrase, any difference between them only comes from whether the core idea is in the survey. (§5.3)

Knowledge does not explain the gap between models. On this 100 papers subset, GPT-5.4 scores 2.54 points higher than GPT-OSS-120B; on the 24 papers where both models list the core idea, it still scores 2.28 higher, and knowledge closes barely 10% of the gap. Therefore, knowing the idea is not enough.

## 5.2 Weak Models Can Pick Informative Questions

§5.1 suggests that the gap lies in how models ask. Asking an informative question involves two steps: proposing candidate questions and choosing which one to ask. To separate the two, we let a weak model choose each question from candidates proposed by several models, rather than asking only its own. If it improves, the bottleneck lies in proposing rather than judging. We test this using GPT-5.4, Qwen3.6-35B-A3B, DeepSeek-V4-Flash, and GPT-OSS-120B. Each round, all four models independently propose a question from the same history, and one model picks among them.

After 30 rounds with the shared pool, all four models score between 5.19 and 5.34, regardless of which model picks the questions. The weaker models gain over 1 points compared to their solo baseline. Surprisingly, the gain of weak models does not come from blindly copying GPT-5.4’s questions. For example, GPT-OSS-120B picks its own proposal in 30% of rounds and GPT-5.4’s in 34% (Figure 5).

![](images/e5a9d9650acaf0952058706fd6edb5675de4e0063af56955ebb895dd66e0c185.jpg)  
Figure 5: Share of questions (%) each inquisitor (row) chooses from each proposer (column) in the four-model pool on 200 papers. All models favor questions from GPT-5.4 and themselves. While the proportions differ across inquisitors, the final scores are close. All four score between 5.19 and 5.34, with no significant difference. (§5.2)

Which of the two steps drives the gain? We vary each while holding the other fixed. When GPT-OSS-120B proposes all four candidates itself (best-of-4 sampling, akin to self-consistency (Wang et al., 2023)), its score rises only from 4.16 to 4.57, well below the 5.20 where candidates are from four models, so the candidates matter. When we keep the four-model pool but pick at random, the score drops to 4.43, not significantly above playing alone, so selection matters too (Table 2). Both steps are necessary, but they are not equally scarce. When we swap the selector across models, the final scores barely change (Table 2); the gap between models therefore comes mainly from the candidates they propose. A weak model’s selection is good enough; what it lacks are informative questions worth selecting.

![](images/edf6d62515462daac652ca5170b19bf536ffda8a76d29db73ad5eb1f0cf7ca95.jpg)  
Figure 6: Recovery curves under the four context conditions of Figure 4 (200 ICML 2026 papers, three games per paper). Naming the idea $( C _ { \mathrm { f u l l } } )$ lifts the curves of most models clearly above $C _ { \mathrm { d e c o y } }$ and $C _ { \mathrm { d u m m y } } ;$ for GPT-5.4, all four conditions end close together. (§5.3)

<table><tr><td>Inquisitor</td><td>Score</td><td>Gain over alone</td></tr><tr><td>GPT-OSS-120B</td><td>5.20</td><td>+1.04[+0.74,+1.34]</td></tr><tr><td>Qwen3.6-35B-A3B</td><td>5.34</td><td>+1.09[+0.87, +1.39]</td></tr><tr><td>DeepSeek-V4-Flash</td><td>5.24</td><td>+1.07[+0.79,+1.36]</td></tr><tr><td>GPT-5.4</td><td>5.19</td><td>-0.59[−0.90, −0.28]</td></tr><tr><td>Random pick</td><td>4.43</td><td></td></tr></table>

Table 2: Score after 30 questions for each inquisitor on the same four-model pool on 200 papers. The last column gives the difference from each model’s solo baseline, with 95% confidence intervals. (§5.2)

## 5.3 A Survey Enriches the Hypothesis Space

In real research, ideas do not start from a purely blank page, as researchers usually begin with a landscape in mind: a rough sense of which approaches could solve the problem. We give the inquisitor a similar starting point with a survey (Figure 4), an overview of the hypothesis space for the research problem. Each survey has five to seven dimensions along which solutions to the problem can differ, and lists four to six candidate approaches in each dimension, named at the level of known families of techniques. The survey is placed right after the problem when the model asks questions, with no instruction on how to use it, and is not shown when the model writes its idea card (§ C). More importantly, the inquisitor is not told whether the solution is in the survey.

![](images/9d044b902e2386d1ddd3d726853beb1947b4ec1b40a015fc2cf2291524349ff2.jpg)  
Figure 7: Top: score after 100 questions under $C _ { \mathrm { d e c o y } }$ and $C _ { \mathrm { f u l l } }$ for each inquisitor. Bottom: gain in that score from naming the idea $( C _ { \mathrm { f u l l } } - C _ { \mathrm { d e c o y } } ,$ , with 95% confidence intervals), against the score under $C _ { \mathrm { d e c o y } } ;$ the dashed line is a least-squares fit (Pearson $r = - 0 . 7 4$ across the six inquisitors). Naming the idea helps most the models that score lowest without it. (§5.3)

Figure 6 shows the four context conditions. Naming the core idea $( C _ { \mathrm { f u l l } } )$ lifts the curves of most models clearly above $C _ { \mathrm { d e c o y } }$ and $C _ { \mathrm { d u m m y } }$ . When the name is replaced by a decoy $( C _ { \mathrm { d e c o y } } )$ , the survey still helps through the other listed components, but the curves slightly fall back towards $C _ { \mathrm { n o n e } } ;$ removing those components as well $( C _ { \mathrm { d u m m y } } )$ brings them closer still.

A survey enlarges the model’s hypothesis space from outside: under $C _ { \mathrm { f u l l } }$ , the correct idea is already among the candidates. Naming the core idea in the survey makes every model reach the core idea during the game more often, and helps weaker models most: the final score improves by up to 1.25 points, with the largest gains for the models that score lowest without it $( r = - 0 . 7 4 $ , Figure 7). This is not because models simply go through the survey item by item. A survey lists 20 to 42 candidates, yet under $C _ { \mathrm { f u l l } }$ models ask about the named idea within a median of 3 to 6 questions, and far more often than they ask about a decoy in the same line under $C _ { \mathrm { d e c o y } } ( 6 7 - 8 9 \%$ against 29–52% of games; $\ S \ O C )$ . Even under $C _ { \mathrm { d e c o y } }$ , models ask about that line more often than about nearby lines, so they can find the right family of methods; what the name adds is the specific idea. Once the correct idea is in the hypothesis space, weak models recognize it; what they lack is the ability to put it there themselves.

## 6 Turning Ideation Traces into Trees

§5 shows why models differ, but not how ideation unfolds question by question. A game is recorded as a flat sequence of questions, but the questions are not independent: most of them follow up on an earlier question, while the rest open new directions. Research proceeds in the same way: a researcher opens a few lines of inquiry, runs follow-up experiments on the promising ones, and drops those that stop paying off. We therefore turn each game into a tree that makes this structure explicit. Each toplevel branch is a line of inquiry, and its depth shows how far the model follows it; together they reflect the model’s hypothesis space and its hill-climbing.

As using LLMs to turn reasoning traces into trees or graphs has become a common way to analyze how LLMs reason (Jiang et al., 2025; Zeng et al., 2025; Lee et al., 2025), we follow this line of work and use GPT-6 Astra to construct the trees. For every question, the model chooses a parent: one of the earlier questions, or the research problem if the question opens a new direction.

## 6.1 The Shape of the Search

We build 1,200 trees from six models on the 200 papers. Although the three weaker models end with similar scores, their trees reveal opposite failure modes (Figure 8). The number of top-level branches $\begin{array} { r } { B _ { \mathrm { t o p } } ^ { \mathrm { } } = \sum _ { t = 1 } ^ { T } \mathbf { 1 } [ \mathrm { p a r e n t } ( q _ { t } ) = \mathbf { \bar { \rho } } ^ { \ } ] } \end{array}$ , i.e., questions asked directly under the research problem, cleanly separates three patterns (Figure 11).

Over-exploitation. DeepSeek-V4-Flash and Qwen3.6 open only 5.2–5.5 branches per game. Once they confirm a direction, they enumerate variants within it rather than questioning the direction itself. For example, after learning a paper uses weight statistics for quantization scales, DeepSeek-V4-Flash spends dozens of questions guessing which statistic, never asking whether the approach is something else entirely. Across all games, 23% of these two models’ questions are such enumerations.

![](images/9bd5291b1d7c98c4e476708ea6e88394fc5b1a743620638307786ff32dc5dbfc.jpg)  
Figure 8: Three patterns of traces in games. The grey dot is the research problem, and each color is one toplevel branch. Below each tree: mean top-level branches per game on 200 papers, as a range over the models with that pattern (per-model means in Figure 11). See more examples in §G.

Over-exploration. GPT-OSS-120B opens 13.7 branches, jumping to new methods regardless of feedback. It is the only model that switches branch more often after a YES than after a NO.

Balanced. The three stronger models open 7.2– 8.2 branches, following confirmed directions and stepping back when a line stops paying off.

While the two failure modes are opposite, they both explain why most models plateau after 30 questions (§4.1). The stronger models balance the two, which lets them keep climbing.

## 6.2 Search Breadth and Final Recovery

§6.1 reveals contrasting search patterns among the weaker models: DeepSeek and Qwen tend toward over-exploitation, repeatedly refining a small number of directions, whereas GPT-OSS tends toward over-exploration, frequently opening new branches. Meanwhile, stronger models show a more balanced pattern, opening new directions while pursuing promising ones. This raises two questions: how do these patterns arise, and is intermediate search breadth associated with better final recovery?

To see how the patterns arise, we look at each answered question and the question that follows it (Figure 9, left). After a Yes (▲), the stronger models make the next question a child of the answered one far more often than after a No (39% vs. 24% for GPT-5.4), and after a No (△), about a quarter of their next questions leave the top-level branch.

![](images/a1b4ab756e7ad46887118d06af92cbcb58c82724bc237e85c002aa096db7b01e.jpg)

![](images/07ee7c2ad413d9b41d64bd3ddc1a01f0d957b3fa44e23fe7b8bc8cd2cb81825f.jpg)  
Figure 9: Search breadth and final recovery across 1,200 games. Shading separates the three patterns in §6.1. Left. After the inquisitor receives a Yes (▲) or a No (△), how often its next question is a child of the answered question (goes to a child) or moves to another top-level branch (leaves the branch). In particular, over-exploitation models rarely leave the branch, even after a No, while the over-exploration model goes to a child more often after a No than after a Yes, and leaves the branch about 30% of the time after either answer. Right. Each point groups games by their number of top-level branches. The y-axis shows how much higher or lower these games score at question 100 than an average game, once differences between models and between papers are taken out. The fitted curve peaks at about eight branches (dotted line): games with a moderate number of top-level branches score the highest.

DeepSeek and Qwen also ask more children after a Yes, but after a No they leave the branch less often than any other model, so new questions keep accumulating in the same top-level branch. GPT-OSS shows the opposite pattern: it asks a child more often after a No than after a Yes, and about 30% of its next questions leave the branch regardless of the answer, which gives it the most top-level branches.

We examine this relationship across the 1,200 games by fitting a quadratic model relating final recovery scores to the number of top-level branches, with model and paper fixed effects. For the points in Figure 9 (right), we group games by their number of top-level branches and fit each game’s final score as the sum of three parts: one for its model, one for its paper, and one for its group; each point is the group’s part, shifted so that the average game is at 0. A point at +0.5 thus means that these games end half a point higher than expected from their model and paper alone. The fitted curve shows an inverted-U relationship: recovery is highest at an intermediate breadth and lower at both extremes. The estimated peak is 8.3 top-level branches (Figure 9, right). This association provides quantitative support for the connection between the search patterns described above and final recovery.

## 7 Conclusion

We introduce RE-SEARCH, a two-player questioning game where a model must rediscover the idea of a published paper by asking yes-or-no questions. By reducing ideation to a question-and-answer loop with oracle feedback, the game dissects how models search for and refine ideas.

On 200 ICML 2026 papers, most of the six models we test plateau after about 30 questions. Controlled experiments show that the bottleneck is not knowledge or judgment but generation: when we supply external candidates such as a survey of the hypothesis space or informative questions from other models, weak models recognize and use them, closing much of the gap to the strongest model.

These findings have a practical implication for autoresearch systems. Since models can judge candidates they cannot produce, augmenting the generation step is a direct way to improve performance without changing the underlying model.

## Limitations

Our testbed consists of 200 machine learning papers from ICML 2026. However, the game design itself is not specific to machine learning and it applies to any field where a research problem and solution can be extracted, such as drug design or materials science, but we have not tested other domains. Recovery scores come from a panel of three LLM judges, and the search trees are annotated by an LLM. Human evaluation shows high agreement with the judges (91.2%; §3.3), but errors remain, particularly on papers whose solution is ambiguous or has multiple equally valid formulations. Since three of the six inquisitor models also serve as judges, we check for self-preference bias and find it negligible (at most 0.08 points; §B), though we cannot fully rule it out. Last but not least, due to knowledge contamination, we choose the six recent models, yet unable to apply our experiment setting on the newest models.

## References

Anthropic. 2025. Claude Sonnet 4.5 system card. https://www.anthropic.com/ claude-sonnet-4-5-system-card.

Jinheon Baek, Sujay Kumar Jauhar, Silviu Cucerzan, and Sung Ju Hwang. 2025. ResearchAgent: Iterative research idea generation over scientific literature with large language models. In Proceedings ofthe 2025 Conference of the Nations of the Americas Chapter ofthe Associationfor Computational Linguistics: Human Language Technologies (Volume 1: Long Papers), pages 6709–6738.

Leonardo Bertolazzi, Davide Mazzaccara, Filippo Merlo, and Raffaella Bernardi. 2023. ChatGPT’s information seeking strategy: Insights from the 20- questions game. In Proceedings of the 16th International Natural Language Generation Conference, pages 153–162, Prague, Czechia. Association for Computational Linguistics.

Eric Bigelow, Ari Holtzman, Hidenori Tanaka, and Tomer Ullman. 2025. Forking paths in neural text generation. In The Thirteenth International Conference on Learning Representations.

Jonathan Bragg, Mike D’Arcy, Nishant Balepur, Dan Bareket, Bhavana Dalvi, et al. 2026. AstaBench: Rigorous benchmarking of AI agents with a scientific research suite. In The Fourteenth International Conference on Learning Representations.

Jun Shern Chan, Neil Chowdhury, Oliver Jaffe, James Aung, Dane Sherburn, Evan Mays, Giulio Starace, Kevin Liu, Leon Maksin, Tejal Patwardhan, Lilian Weng, and Aleksander M ˛adry. 2025. MLEbench: Evaluating machine learning agents on machine learning engineering. In The Thirteenth International Conference on Learning Representations.

Hui Chen, Miao Xiong, Yujie Lu, Wei Han, Ailin Deng, Yufei He, Jiaying Wu, Yibo Li, Yue Liu, and Bryan Hooi. 2025. MLR-Bench: Evaluating AI agents on open-ended machine learning research. In Advances in Neural Information Processing Systems: Datasets and Benchmarks Track.

Shuai Chen and Chengzhi Zhang. 2026. Enhancing research idea generation through combinatorial in novation and multi-agent iterative search strategies. arXiv preprint arXiv:2604.20548.

Jeffrey Cheng, Marc Marone, Orion Weller, Dawn Lawrie, Daniel Khashabi, and Benjamin Van Durme. 2024. Dated data: Tracing knowledge cutoffs in large language models. In First Conference on Language Modeling.

Deepro Choudhury, Sinead Williamson, Adam Golinski,´ Ning Miao, Freddie Bickford Smith, Michael Kirchhof, Yizhe Zhang, and Tom Rainforth. 2026. BED-LLM: Intelligent information gathering with LLMs and Bayesian experimental design. In The Fourteenth International Conference on Learning Representations, pages 84375–84405.

Stephen Chung and Wenyu Du. 2025. The station: An open-world environment for AI-driven discovery. arXiv preprint arXiv:2511.06309.

Anna Coenen, Jonathan D. Nelson, and Todd M. Gureckis. 2019. Asking the right questions about the psychology of human inquiry: Nine open challenges. Psychonomic Bulletin & Review, 26(5):1548–1587.

Alexander N. Cohen and Brenden M. Lake. 2016. Searching large hypothesis spaces by asking questions. In Proceedings of the 38th Annual Meeting of the Cognitive Science Society, pages 644–649.

DeepSeek-AI. 2026a. DeepSeek-V4-Flash model card. https://huggingface.co/deepseek-ai/ DeepSeek-V4-Flash.

DeepSeek-AI. 2026b. Public summary of training content for DeepSeek-V4-Pro and DeepSeek-V4- Flash. https://cdn.deepseek.com/policies/ DeepSeek\_Template\_for\_the\_Public\_Summary\_ of\_Training\_Content\_for\_GeneralPurpose\_ AI\_model.pdf.

Yijiang River Dong, Tiancheng Hu, Zheng Hui, Caiqi Zhang, Ivan Vulic, Andreea Bobu, and Nigel Col-´ lier. 2026. Value of information: A framework for human–agent communication. In Proceedings ofthe 64th Annual Meeting ofthe Associationfor Computational Linguistics (Volume 1: Long Papers), pages 42879–42896, San Diego, California, United States. Association for Computational Linguistics.

Muhan Gao, Jash Shah, Weiqi Wang, Kuan-Hao Huang, and Daniel Khashabi. 2025. From papers to panoramas: Building hierarchies of scientific literature at scale. arXiv preprint arXiv:2504.13834.

Aniketh Garikaparthi, Manasi Patwardhan, and Arman Cohan. 2026. ResearchGym: Evaluating language model agents on real-world AI research. arXiv preprint arXiv:2602.15112.

Google DeepMind. 2026. Gemma-4-31B-it model card. https://huggingface.co/google/ gemma-4-31B-it.

Juraj Gottweis, Wei-Hung Weng, Alexander Daryin, Tao Tu, Petar Sirkovic, et al. 2026. Accelerating scientific discovery with Co-Scientist. Nature, 655:487– 496.

Gabriel Grand, Valerio Pepe, Jacob Andreas, and Joshua B. Tenenbaum. 2026. Shoot first, ask questions later? building rational agents that explore and act like people. In The Fourteenth International Conference on Learning Representations.

Varun Gumma, Navonil Majumder, Soumitra Sinhahajari, and Soujanya Poria. 2026. IDEAgent: Agentic quality-diversity search for research idea generation. arXiv preprint arXiv:2607.22375.

Sikun Guo, Amir Hassan Shariatmadari, Guangzhi Xiong, Albert Huang, Myles Kim, Corey M. Williams, Stefan Bekiranov, and Aidong Zhang. 2025. IdeaBench: Benchmarking large language models for research idea generation. In Proceedings ofthe 31st ACM SIGKDD Conference on Knowledge Discovery and Data Mining V.2, pages 5888–5899.

Xiang Hu, Hongyu Fu, Jinge Wang, Yifeng Wang, Zhikun Li, Renjun Xu, Yu Lu, Yaochu Jin, Lili Pan, and Zhenzhong Lan. 2025. NOVA: An iterative planning framework for enhancing scientific innovation with large language models. In Findings of the Association for Computational Linguistics: ACL 2025, pages 21330–21359.

Zhiyuan Hu, Chumin Liu, Xidong Feng, Yilun Zhao, See-Kiong Ng, Anh Tuan Luu, Junxian He, Pang Wei Koh, and Bryan Hooi. 2024. Uncertainty of thoughts: Uncertainty-aware planning enhances information seeking in LLMs. In Advances in Neural Information Processing Systems, volume 37, pages 24181–24215.

Peter Jansen, Marc-Alexandre Côté, Tushar Khot, Erin Bransom, Bhavana Dalvi Mishra, Bodhisattwa Prasad Majumder, Oyvind Tafjord, and Peter Clark. 2024. DiscoveryWorld: A virtual environment for developing and evaluating automated scientific discovery agents. In Advances in Neural Information Processing Systems: Datasets and Benchmarks Track.

Haozhe Jia. 2026. HindsightBench: A black-box behavioral audit protocol for parametric hindsight in time-indexed LLM decision tasks. arXiv preprint arXiv:2607.18867.

Gangwei Jiang, Yahui Liu, Zhaoyi Li, Wei Bi, Fuzheng Zhang, Linqi Song, Ying Wei, and Defu Lian. 2025. What makes a good reasoning chain? uncovering structural patterns in long chain-of-thought reasoning. In Proceedings of the 2025 Conference on Empirical Methods in Natural Language Processing, pages 6490–6514.

David Klahr and Kevin Dunbar. 1988. Dual space search during scientific reasoning. Cognitive Science, 12(1):1–48.

Patrick Tser Jern Kon, Jiachen Liu, Xinyi Zhu, Qiuyi Ding, Jingjia Peng, Jiarong Xing, Yibo Huang, Yiming Qiu, Jayanth Srinivasa, Myungjin Lee, Mosharaf Chowdhury, Matei Zaharia, and Ang Chen. 2026. EXP-Bench: Can AI conduct AI research experiments? In The Fourteenth International Conference on Learning Representations.

Philippe Laban, Hiroaki Hayashi, Yingbo Zhou, and Jennifer Neville. 2026. LLMs get lost in multi-turn conversation. In The Fourteenth International Conference on Learning Representations.

Pat Langley, Herbert A. Simon, Gary L. Bradshaw, and Jan M. Zytkow. 1987. Scientific Discovery: Computational Explorations ofthe Creative Processes. MIT Press, Cambridge, MA.

Jinu Lee, Sagnik Mukherjee, Dilek Hakkani-Tur, and Julia Hockenmaier. 2025. ReasoningFlow: Semantic structure of complex reasoning traces. arXiv preprint arXiv:2506.02532.

Shuyue Stella Li, Vidhisha Balachandran, Shangbin Feng, Jonathan S. Ilgen, Emma Pierson, Pang Wei Koh, and Yulia Tsvetkov. 2024. MediQ: Questionasking LLMs and a benchmark for reliable interactive clinical reasoning. In Advances in Neural Information Processing Systems, volume 37, pages 28858– 28888.

Yiwei Li, Wanli Yang, Hexiang Tan, Xiangzhou Huang, Zhengyu Chen, Ziran Li, et al. 2026a. Beyond final scores: A systematic evaluation of agents for longhorizon AI research and development. arXiv preprint arXiv:2608.13417.

Zongyue Li, Chengyue Yu, Lei Zang, Chenyi Zhuang, Linjian Mo, and Leilei Gan. 2026b. Last step matters: Early uncertainty cannot predict failure in longhorizon agents. In Proceedings of the 2026 Conference on Empirical Methods in Natural Language Processing.

Yujie Liu, Zonglin Yang, Tong Xie, Jinjie Ni, Ben Gao, Yuqiang Li, Shixiang Tang, Wanli Ouyang, Erik Cambria, and Dongzhan Zhou. 2026. Research-Bench: Benchmarking LLMs in scientific discovery via inspiration-based task decomposition. In Findings ofthe Associationfor Computational Linguistics: ACL 2026.

Chris Lu, Cong Lu, Robert Tjarko Lange, Jakob Foerster, Jeff Clune, and David Ha. 2024. The AI Scientist: Towards fully automated open-ended scientific discovery. arXiv preprint arXiv:2408.06292.

Chris Lu, Cong Lu, Robert Tjarko Lange, Yutaro Yamada, Shengran Hu, Jakob Foerster, David Ha, and Jeff Clune. 2026. Towards end-to-end automation of AI research. Nature, 651(8107):914–919.

Alisia Lupidi, Bhavul Gauri, Thomas Simon Foster, Bassel Al Omari, Despoina Magka, et al. 2026. AIRS-Bench: A suite of tasks for frontier AI research science agents. arXiv preprint arXiv:2602.06855.

Davide Mazzaccara, Alberto Testoni, and Raffaella Bernardi. 2024. Learning to ask informative questions: Enhancing LLMs with preference optimization and expected information gain. In Findings of the Associationfor Computational Linguistics: EMNLP 2024, pages 5064–5074, Miami, Florida, USA. Association for Computational Linguistics.

Frederic A. Mosher and Joan Rigney Hornsby. 1966. On asking questions. In Jerome S. Bruner, Rose R. Olver, and Patricia M. Greenfield, editors, Studies in Cognitive Growth, pages 86–102. Wiley, New York.

Jonathan D. Nelson, Bojana Divjak, Gudny Gudmundsdottir, Laura F. Martignon, and Björn Meder. 2014. Children’s sequential information search is sensitive to environmental probabilities. Cognition, 130(1):74– 80.

OpenAI. 2025. gpt-oss-120b & gpt-oss-20b model card. arXiv preprint arXiv:2508.10925. Preprint, arXiv:2508.10925.

OpenAI. 2026a. GPT-5.4. Proprietary model accessed through the OpenAI API.

OpenAI. 2026b. GPT-5.6 Sol. Proprietary model accessed through the OpenAI API.

OpenAI. 2026c. GPT-6 Astra. Proprietary model accessed through the OpenAI API.

Qwen Team. 2026a. Qwen3.6-35B-A3B model card. https://huggingface.co/Qwen/Qwen3. 6-35B-A3B.

Qwen Team. 2026b. Qwen3.8-27B model card. https: //huggingface.co/Qwen/Qwen3.8-27B.

Ben Rank, Hardik Bhatnagar, Ameya Prabhu, Shira Eisenberg, Karina Nguyen, Matthias Bethge, and Maksym Andriushchenko. 2026. PostTrainBench: Can LLM agents automate LLM post-training? In Proceedings ofthe 43rd International Conference on Machine Learning.

Manley Roberts, Himanshu Thakur, Christine Herlihy, Colin White, and Samuel Dooley. 2024. To the cutoff... and beyond? A longitudinal perspective on LLM data contamination. In The Twelfth International Conference on Learning Representations.

Azzurra Ruggeri and Tania Lombrozo. 2015. Children adapt their questions to achieve efficient search. Cognition, 143:203–216.

Azzurra Ruggeri, Tania Lombrozo, Thomas L. Griffiths, and Fei Xu. 2016. Sources of developmental change in the efficiency of information search. Developmental Psychology, 52(12):2159–2173.

Samuel Schmidgall, Yusheng Su, Ze Wang, Ximeng Sun, Jialian Wu, Xiaodong Yu, Jiang Liu, Michael Moor, Zicheng Liu, and Emad Barsoum. 2025. Agent Laboratory: Using LLM agents as research assistants. In Findings of the Association for Computational Linguistics: EMNLP 2025, pages 5977– 6043, Suzhou, China. Association for Computational Linguistics.

Chenglei Si, Diyi Yang, and Tatsunori Hashimoto. 2025. Can LLMs generate novel research ideas? A largescale human study with 100+ NLP researchers. In The Thirteenth International Conference on Learning Representations.

Robert S. Siegler. 1977. The twenty questions game as a form of problem solving. Child Development, 48(2):395–403.

Akshit Sinha, Arvindh Arun, Shashwat Goel, Steffen Staab, and Jonas Geiping. 2026. The illusion of diminishing returns: Measuring long horizon execution in LLMs. In The Fourteenth International Conference on Learning Representations.

Giulio Starace, Oliver Jaffe, Dane Sherburn, James Aung, Jun Shern Chan, Leon Maksin, Rachel Dias, Evan Mays, Benjamin Kinsella, Wyatt Thompson, Johannes Heidecke, Amelia Glaese, and Tejal Patwardhan. 2025. PaperBench: Evaluating AI’s ability to replicate AI research. In Proceedings ofthe 42nd International Conference on Machine Learning.

Xuezhi Wang, Jason Wei, Dale Schuurmans, Quoc Le, Ed Chi, Sharan Narang, Aakanksha Chowdhery, and Denny Zhou. 2023. Self-consistency improves chain of thought reasoning in language models. In The Eleventh International Conference on Learning Representations.

Zhen Wang, Fan Bai, Zhongyan Luo, Jinyan Su, Kaiser Sun, Xinle Yu, Jieyuan Liu, Kun Zhou, Claire Cardie, Mark Dredze, Zhiting Hu, and Eric P. Xing. 2026. FIRE-Bench: Evaluating AI agents on the rediscovery of scientific insights. In Proceedings ofthe 43rd International Conference on Machine Learning.

Kaiyue Wen, Tengyu Ma, and Percy Liang. 2026. Priced guidance: Can language models generate future research ideas? arXiv preprint arXiv:2610.04976.

Hjalmar Wijk, Tao Roa Lin, Joel Becker, Sami Jawhar, Neev Parikh, et al. 2025. RE-Bench: Evaluating frontier AI R&D capabilities of language model agents against human experts. In Proceedings ofthe 42nd International Conference on Machine Learning, volume 267 of Proceedings of Machine Learning Research, pages 66772–66832.

Yunze Wu, Dayuan Fu, Weiye Si, Zhen Huang, Mohan Jiang, Keyu Li, Shijie Xia, Jie Sun, Tianze Xu, Yang Xiao, Pengrui Lu, Xiaojie Cai, Lyumanshan Ye, Wenhong Zhu, Xiangkun Hu, and Pengfei Liu. 2026. InnovatorBench: Evaluating agents’ ability to conduct innovative AI research. In The Fourteenth International Conference on Learning Representations.

Wanghan Xu, Shuo Li, Tianlin Ye, Qinglong Cao, Yixin Chen, et al. 2026. ResearchClawBench: A benchmark for end-to-end autonomous scientific research. arXiv preprint arXiv:2606.07591.

Zonglin Yang, Wanhao Liu, Ben Gao, Tong Xie, Yuqiang Li, Wanli Ouyang, Soujanya Poria, Erik Cambria, and Dongzhan Zhou. 2025. MOOSE-Chem: Large language models for rediscovering unseen chemistry scientific hypotheses. In The Thirteenth International Conference on Learning Representations.

Z.ai. 2026. GLM-5.2 model card. https:// huggingface.co/zai-org/GLM-5.2.

Yuchen Zeng, Shuibai Zhang, Wonjun Kang, Shutong Wu, Lynnix Zou, Ying Fan, Heeju Kim, Ziqian Lin, Jungtaek Kim, Hyung Il Koo, Dimitris Papailiopoulos, and Kangwook Lee. 2025. ReJump: A tree-jump representation for analyzing and improving LLM reasoning. arXiv preprint arXiv:2512.00831.

Muru Zhang, Ofir Press, William Merrill, Alisa Liu, and Noah A. Smith. 2024a. How language model hallucinations can snowball. In Proceedings of the 41st International Conference on Machine Learning, volume 235 of Proceedings of Machine Learning Research, pages 59670–59684.

Yizhe Zhang, Jiarui Lu, and Navdeep Jaitly. 2024b. Probing the multi-turn planning capabilities of LLMs via 20 question games. In Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers), pages 1495– 1516, Bangkok, Thailand. Association for Computational Linguistics.

Yunxiang Zhang, Muhammad Khalifa, Shitanshu Bhushan, Grant D. Murphy, Lajanugen Logeswaran, Jaekyeom Kim, Moontae Lee, Honglak Lee, and Lu Wang. 2025. MLRC-Bench: Can language agents solve machine learning research challenges? In Advances in Neural Information Processing Systems: Datasets and Benchmarks Track.

## A Models and Knowledge Cutoffs

The six inquisitors are GPT-OSS-120B (OpenAI, 2025), DeepSeek-V4-Flash (DeepSeek-AI, 2026a), Claude Sonnet 4.5 (Anthropic, 2025), GPT-5.4 (OpenAI, 2026a), Gemma-4-31B (Google DeepMind, 2026), and Qwen3.6-35B-A3B (Qwen Team, 2026a). We also use GLM-5.2 (Z.ai, 2026) to extract the research problems and solutions (§3.2), GPT-5.6 Sol (OpenAI, 2026b) to generate the surveys and Qwen3.8-27B (Qwen Team, 2026b) as an LLM annotator (§C), and GPT-6 Astra (OpenAI, 2026c) to construct the search trees (§6). Table 3 lists the knowledge cutoffs of the inquisitors.

<table><tr><td>Model</td><td>Knowledge cutoff</td></tr><tr><td>GPT-OSS-120B</td><td>June 2024</td></tr><tr><td>DeepSeek-V4-Flash Claude Sonnet 4.5</td><td>May 2025† July 2025</td></tr><tr><td>GPT-5.4</td><td>August 2025</td></tr><tr><td>Gemma-4-31B</td><td>January 2025</td></tr><tr><td></td><td></td></tr><tr><td>Qwen3.6-35B-A3B</td><td>December 2024‡</td></tr></table>

Table 3: Knowledge or training-data cutoffs of the inquisitor models, as stated in each provider’s model card or documentation. <sup>†</sup>DeepSeek’s public summary of training content states that some of the data were collected no later than about May 2025 (DeepSeek-AI, 2026b); a behavioral audit estimates an effective cutoff of July 2025 (Jia, 2026). <sup>‡</sup>Not reported by the provider; effective cutoff estimated by the same audit (Jia, 2026). (§A)

## B Judge Validation

Three inquisitors also serve as judges (Gemma-4-31B, Qwen3.6-35B-A3B, and GPT-OSS-120B), and Gemma-4-31B is also the answerer. To test whether a judge favors its own model family, we re-score the survey experiment (200 papers, three games per paper, score at question 100) in three ways.

Self-preference. For each judge, we compute how far its rating lies above the mean of the other two judges, separately for the inquisitor of its own family and for the other inquisitors (Table 4). Each judge rates its own family 0.17–0.33 points higher than the other judges do. This preference is small next to the general leniency of Gemma-4-31B, which rates every inquisitor about 1.2 points above the other judges.

Leaving out the same-family judge. We recompute each inquisitor’s score without the judge from its own family: without Gemma-4-31B for Gemma-4-31B, without Qwen3.6-35B-A3B for Qwen3.6-35B-A3B, and without GPT-OSS-120B for GPT-OSS-120B and for GPT-5.4, which comes from the same provider. DeepSeek-V4-Flash and Claude Sonnet 4.5 keep all three judges. The gain from naming the idea $( C _ { \mathrm { f u l l } } - C _ { \mathrm { d e c o y } } )$ changes by at most 0.08 points, and the order of the models is unchanged (Table 5).

<table><tr><td>Judge</td><td>Own family</td><td>Others</td><td>Difference</td></tr><tr><td>Qwen3.6-35B-A3B</td><td>-0.71</td><td>-0.88</td><td>+0.17</td></tr><tr><td>GPT-OSS-120B</td><td>-0.13</td><td>-0.46</td><td>+0.33</td></tr><tr><td>Gemma-4-31B</td><td>+1.51</td><td>+1.21</td><td>+0.30</td></tr></table>

Table 4: Rating of each judge minus the mean rating of the other two judges, for the inquisitor of the judge’s own family and for the other inquisitors (survey experiment, all conditions, question 100). (§B)

<table><tr><td>Inquisitor</td><td>All judges</td><td>Same family left out</td></tr><tr><td>DeepSeek-V4-Flash</td><td>+1.25</td><td>+1.25</td></tr><tr><td>GPT-OSS-120B</td><td>+1.08</td><td>+1.16</td></tr><tr><td>Claude Sonnet 4.5</td><td>+0.90</td><td>+0.90</td></tr><tr><td>Qwen3.6-35B-A3B</td><td>+0.60</td><td>+0.61</td></tr><tr><td>Gemma-4-31B</td><td>+0.36</td><td>+0.38</td></tr><tr><td>GPT-5.4</td><td>+0.16</td><td>+0.11</td></tr></table>

Table 5: Gain in score at question 100 from naming the idea $( C _ { \mathrm { f u l l } } - C _ { \mathrm { d e c o y } } ,$ paired by paper), with all three judges and with the judge of the inquisitor’s own family left out. (§B)

Single judges. We also rank the inquisitors with each judge alone (Table 6). GPT-5.4 ranks first under every judge. Gemma-4-31B ranks second even when scored by GPT-OSS-120B alone, and the Qwen3.6-35B-A3B judge ranks its own family last.

<table><tr><td>Inquisitor</td><td>Qwen</td><td>GPT-OSS</td><td>Gemma</td><td>Panel</td></tr><tr><td>GPT-5.4</td><td>1</td><td>1</td><td>1</td><td>1</td></tr><tr><td>Gemma-4-31B</td><td>3</td><td>2</td><td>2</td><td>2</td></tr><tr><td>Claude Sonnet 4.5</td><td>2</td><td>3</td><td>3</td><td>3</td></tr><tr><td>GPT-OSS-120B</td><td>4</td><td>4</td><td>4</td><td>4</td></tr><tr><td>Qwen3.6-35B-A3B</td><td>6</td><td>5</td><td>6</td><td>5</td></tr><tr><td>DeepSeek-V4-Flash</td><td>5</td><td>6</td><td>5</td><td>6</td></tr></table>

Table 6: Rank of each inquisitor at question 100, scored by each judge alone and by the three-judge panel. (§B)

## C Survey Construction

All surveys are generated by GPT-5.6 Sol in three steps and then checked by human annotators.

Blind survey. For each paper, the model first writes a survey from the research problem alone, without seeing the solution. It is told not to identify or recall the paper and to write from general knowledge of the research area, as a survey of the area would. Each survey has five to seven dimensions along which solutions can differ, each with four to six candidate approaches; each approach names a family of techniques and two to five concrete techniques in it. The survey gives no recommendation or ranking.

$C _ { \mathbf { f u l l } }$ and $C _ { \mathbf { d e c o y } } .$ The model then sees the solution and writes the core idea as a survey-level phrase of 3 to 12 words, that is, the name of a known family of techniques rather than the paper’s own method. It picks the candidate line where this phrase belongs. $C _ { \mathrm { f u l l } }$ lists the phrase in this line; $C _ { \mathrm { d e c o y } }$ replaces it with a decoy, a real technique from the same family that the paper does not use, of similar length. Any other line that names the core idea is rewritten in the same way in both versions, so that $C _ { \mathrm { d e c o y } }$ never names the core idea and $C _ { \mathrm { f u l l } }$ names it only once. $C _ { \mathrm { f u l l } }$ and $C _ { \mathrm { d e c o y } }$ thus differ in exactly one line; both may still list other, non-core components of the paper.

$C _ { \bf d u m m y } .$ Starting from $C _ { \mathrm { d e c o y } }$ , the model replaces every remaining candidate that offers a component of the paper with an approach of similar length that the paper does not use, and keeps the decoy. Components already stated in the research problem are kept, since removing them would not change what the inquisitor knows.

Human check. Three annotators check the surveys of all 200 papers. For each paper, they see the solution and the three surveys without their labels, and decide which survey is $C _ { \mathrm { f u l l } } , \ C _ { \mathrm { d e c o y } } .$ and $C _ { \mathrm { d u m m y } }$ . All annotators identify $C _ { \mathrm { f u l l } }$ correctly for every paper. For 7 papers (3.5%), one annotator swaps $C _ { \mathrm { d e c o y } }$ and $C _ { \mathrm { d u m m y } } ;$ ; in these papers $C _ { \mathrm { d e c o y } }$ lists few components besides the core idea, so $C _ { \mathrm { d u m m y } }$ differs from it in only a few lines.

Length and freezing. A survey is about 1,150 tokens long, and the three versions of a survey differ by fewer than 40 tokens. All surveys were frozen before any game was scored.

A model could raise its score under $C _ { \mathrm { f u l l } }$ simply by copying the included idea from the survey into its idea card. Three checks on the survey experiment (200 papers, three games per paper, question 100) speak against this. We detect mentions of the core idea and the decoy with two LLM annotators (Gemma-4-31B and Qwen3.8-27B), which read the questions and the final card of each game, mark the questions that refer to each idea, and judge whether the card states $\mathrm { i t } ;$ we count a mention only when both annotators mark it (Cohen’s $\kappa = 0 . 6 7 – 0 . 7 9 )$ .

The card writer does not see the survey. The survey appears only in the question prompts. Before any question, the idea card $c _ { 0 }$ therefore scores the same under every condition (Table 7): if the card writer saw the survey, $C _ { \mathrm { f u l l } }$ cards would already name the idea at question 0.

<table><tr><td>Inquisitor</td><td> $C _ { \mathrm { d u m m y } }$ </td><td> $C _ { \mathrm { d e c o y } }$ </td><td> $C _ { \mathrm { f u l l } }$ </td></tr><tr><td>DeepSeek-V4-Flash</td><td>1.05</td><td>1.04</td><td>1.10</td></tr><tr><td>GPT-OSS-120B</td><td>2.80</td><td>2.82</td><td>2.80</td></tr><tr><td>Qwen3.6-35B-A3B</td><td>1.32</td><td>1.22</td><td>1.21</td></tr><tr><td>Claude Sonnet 4.5</td><td>1.98</td><td>2.06</td><td>2.04</td></tr><tr><td>Gemma-4-31B</td><td>2.46</td><td>2.42</td><td>2.42</td></tr><tr><td>GPT-5.4</td><td>1.74</td><td>1.74</td><td>1.74</td></tr></table>

Table 7: Score of the idea card before any question (c<sub>0</sub>) under each survey condition. (§C)

The included idea enters the card after it is confirmed. Under $C _ { \mathrm { f u l l } } , 9 9 \mathrm { - } 1 0 0 \%$ of the final cards that state the core idea follow a question about it that was answered YES, and at most 1% come from games that never asked about it. $C _ { \mathrm { f u l l } }$ games that never ask about the core idea score no higher than $C _ { \mathrm { d e c o y } } .$ , and the gain is concentrated in games where the idea is asked about and confirmed (Table 8). This comparison is descriptive: games that ask about the idea and get a YES may also be on easier papers.

<table><tr><td colspan="2"></td><td colspan="2"> $C _ { \mathrm { f u l l } }$ </td></tr><tr><td>Inquisitor</td><td> $C _ { \mathrm { d e c o y } }$ </td><td>Not asked</td><td>Asked, YES</td></tr><tr><td>DeepSeek-V4-Flash</td><td>4.93</td><td>4.73</td><td>6.92</td></tr><tr><td>GPT-OSS-120B</td><td>5.15</td><td>4.16</td><td>7.37</td></tr><tr><td>Qwen3.6-35B-A3B</td><td>4.94</td><td>3.78</td><td>6.27</td></tr><tr><td>Claude Sonnet 4.5</td><td>5.44</td><td>4.29</td><td>7.50</td></tr><tr><td>Gemma-4-31B</td><td>5.59</td><td>3.98</td><td>6.80</td></tr><tr><td>GPT-5.4</td><td>7.41</td><td>5.41</td><td>7.98</td></tr></table>

Table 8: Score at question 100 under $C _ { \mathrm { d e c o y } }$ , and under $C _ { \mathrm { f u l l } }$ split by whether the game asked about the core idea and got a YES. (§C)

A rejected decoy rarely enters the card. The survey does steer what models ask: a decoy in the survey $( C _ { \mathrm { d e c o y } } )$ is asked about in 29–52% of games, against $7 - 1 9 \%$ when it is not in the survey $( C _ { \mathrm { f u l l } } )$ But once rejected, it reaches the final card in only

2–7% of games, while the included idea under $C _ { \mathrm { f u l l } }$ reaches it in 47–77%.

The included idea is not found by going through the survey. With 100 questions, a model could also reach the included idea by asking about the candidates in the survey one by one. Two comparisons speak against this. First, the included idea is asked about early and selectively. In the $C _ { \mathrm { f u l l } }$ games that ask about it, the first such question comes at a median of question 3 to 6. The core idea in $C _ { \mathrm { f u l l } }$ and the decoy in $C _ { \mathrm { d e c o y } }$ sit in the same line of the survey, so going through the survey would reach both equally often; instead, the core idea is asked about in 67–89% of games and the decoy in 29–52%. Second, within $C _ { \mathrm { f u l l } }$ , the line that names the core idea is asked about in 78–90% of games, against 45–67% for the lines within two positions of it, and in 63–73% against 22–42% within the first ten questions. To find which lines a question asks about, the same two annotators see the survey and the questions but not the solution $( \kappa = 0 . 8 0 )$ Part of this preference already appears under $C _ { \mathrm { d e c o y } } .$ where the same line carries the decoy (11 to 29 percentage points above nearby lines), since this line is the one closest to the paper’s method. Models can therefore locate the right family of methods without the name; naming the idea adds 4 to 15 percentage points on top, and mainly makes them ask about the idea itself. All tests are paired over papers, with the three games of a paper averaged first, and Holm-corrected across the six inquisitors. The two comparisons above hold for every inquisitor $( p < 0 . 0 1 ) $ the extra gain from naming is signifi cant only for some inquisitors, so we report only its size.

## D Choice of Answerer

We compare Gemma-4-31B with two other candidate answerers, GPT-OSS-120B (medium reasoning) and Qwen3.6-35B-A3B (thinking). All three receive the same system prompt, question template, and evidence (the hidden solution card and the full paper), and are required to answer with output constrained to YES, NO, or UNKNOWN. We check both the agreement among these three models and their agreement with human annotators. Table 9 compares each answerer with the majority label of the three annotators. Gemma-4-31B agrees most often overall and in every label class. For Qwen3.6, it rarely answers UNKNOWN (6% of its answers, against 24% for Gemma-4-31B) and instead an-

swers most of these questions with YES or NO.
<table><tr><td></td><td>All</td><td>YES</td><td>No</td><td>UNK.</td><td>YES/NO</td></tr><tr><td>n</td><td>795</td><td>354</td><td>279</td><td>162</td><td>633</td></tr><tr><td>Gemma-4-31B</td><td>94.0</td><td>98.9</td><td>93.2</td><td>84.6</td><td>96.4</td></tr><tr><td>GPT-OSS-120B</td><td>86.2</td><td>96.0</td><td>92.5</td><td>53.7</td><td>94.5</td></tr><tr><td>Qwen3.6-35B-A3B</td><td>78.4</td><td>95.2</td><td>88.9</td><td>23.5</td><td>92.4</td></tr></table>

Table 9: Accuracy (%) of each answerer against the human majority label, overall and by the human label. The last column pools the YES and NO items. (§D)

Agreement between answerers. Table 10 compares the answerers with each other on all 9,774 questions. Most disagreements involve UN-KNOWN; two answerers give opposite answers (YES against NO) to only 6.5–10.8% of questions.

<table><tr><td>Pair</td><td>Agree</td><td>K</td><td>YES/No flip</td></tr><tr><td>Gemma vs. GPT-OSS</td><td>78.4</td><td>0.66</td><td>6.5</td></tr><tr><td>Gemma vs. Qwen</td><td>74.3</td><td>0.59</td><td>7.0</td></tr><tr><td>GPT-OSS vs. Qwen</td><td>77.7</td><td>0.62</td><td>10.8</td></tr></table>

Table 10: Pairwise agreement (%), Cohen’s κ, and share of questions (%) answered YES by one answerer and NO by the other, on 9,774 questions. (§D)

## E Information Bound for Adaptive Questioning

Write $H _ { t } = ( Q _ { 1 } , A _ { 1 } , \dots , Q _ { t } , A _ { t } )$ , with $H _ { 0 }$ empty, and let C be the context given before the game (a survey, or nothing under $C _ { \mathrm { n o n e } } )$ . Assume a finite answer alphabet A and a question policy satisfying $Q _ { t } \perp S \mid ( P , C , H _ { t - 1 } )$ . For example, this holds when each question is generated from the visible inputs and history using fresh randomness independent of the hidden solution. All logarithms below are base two.

By the chain rule for conditional mutual information and the policy assumption,

$$
\begin{array} { l } { { { \cal I } ( S ; H _ { T } \mid P , C ) = \displaystyle \sum _ { t = 1 } ^ { T } { \cal I } ( S ; Q _ { t } , A _ { t } \mid P , C , H _ { t - 1 } ) } } \\ { { { } } } \\ { { { } ~ = \displaystyle \sum _ { t = 1 } ^ { T } { \cal I } ( S ; A _ { t } \mid P , C , H _ { t - 1 } , Q _ { t } ) } } \\ { { { } ~ \leq \displaystyle \sum _ { t = 1 } ^ { T } H ( A _ { t } \mid P , C , H _ { t - 1 } , Q _ { t } ) } } \\ { { { } ~ \leq { \cal T } \log _ { 2 } \mid A \mid . } } \end{array}
$$

The last inequality follows because a variable taking at most $| { \cal { A } } |$ values has entropy at most $\log _ { 2 } | \mathcal { A } |$ The result allows noisy answers and adaptive questions. It is an upper bound, with no positive lower bound on the information supplied by an additional question.

When a survey is supplied, its information is accounted for separately:

$$
\begin{array} { r l } & { I ( S ; C , H _ { T } \mid P ) = I ( S ; C \mid P ) } \\ & { \phantom { x x x x x x x x x x x x x x x x x x x x x x x x x x x x x x x x x x } + I ( S ; H _ { T } \mid P , C ) } \\ & { \phantom { x x x x x x x x x x x x x x x x x x x x x x x x x x x x x } \leq I ( S ; C \mid P ) + T \log _ { 2 } | \mathcal { A } | . } \end{array}
$$

A survey constructed using the solution may itself reveal information about it. Excluding the survey from idea-card prompts restricts how this information reaches the card, but does not remove it from the questioning process.

## F Search over the Course of a Game

Figure 10 follows the 1,200 trees of §6 question by question. We group the 100 questions of a game into ten bins and average each model over its 200 trees. As a game goes on, every model asks deeper questions and leaves the top-level branch less often. Part of the rise in depth is expected, since early questions can only sit near the root. DeepSeek-V4-Flash and Qwen3.6 grow the deepest trees and reach a depth of about seven by the end of the game. GPT-OSS-120B leaves the branch more often than any other model at every stage of the game. In contrast, how often the next question is a child of the current one changes little over time, and so does the share of Yes answers. The gap between models in Yes answers is already present in the first ten questions and stays until the end.

## G More Search Trees

Figures 12–15 show real question trees, for each paper, we show six trees from all the models. For over-exploitation, few top-level branches, a large share of questions in the largest branch, and great depth; for over-exploration, many top-level branches, a large share of branches dropped within three questions, little depth, and no dominant branch; for balance, five to ten top-level branches with none holding more than 60% of the questions.

![](images/513b7c2a9464e495b2bfcf57cf3a577cdb938360488c03ac08c05f01fc6e3986.jpg)  
Qwen3.6 DeepSeek-V4-Flash GPT-5.4 Claude Sonnet 4.5 Gemma-4-31B GPT-OSS-120B

Figure 10: How the search changes over the 100 questions of a game (1,200 games on 200 papers). Questions are grouped into bins of ten. Depth of the node: mean depth of the questions in the bin. Goes to a child and leaves the branch: how often the next question is a child of the current question, or lies in another top-level branch, as in Figure 9 (left) but over all answers. Share ofYes answers: share of the questions answered Yes.

![](images/1d0b1a74b131324cd0a53e1e567daad5dc5cef22b6d3df699624086d006cf954.jpg)  
Figure 11: Top-level branches per game for each model on 200 papers. The brackets group the models by search pattern, as in Figure 8.

## G.1 Trees of the Paper: Video-Based Optimal Transport for Feedback-Efficient Offline Preference-Based Reinforcement Learning

<table><tr><td>DeepSeek-V4-Flash score 4 · 1 top-level branch</td><td>Qwen3.6-35B-A3B score 1 · 5 top-level branches</td><td>GPT-OSS-120B score 1 · 17 top-level branches</td></tr><tr><td>Gemma-4-31B score 5 · 9 top-level branches</td><td>Claude Sonnet 4.5 score 5 · 10 top-level branches</td><td>GPT-5.4 score 8 · 5 top-level branches</td></tr></table>

Figure 12: Search trees of the six inquisitors on “Video-Based Optimal Transport for Feedback-Efficient Offline Preference-Based Reinforcement Learning”.

## G.2 Trees of the Paper: A Direct Second-Order Method for Solving Two-Player Zero-Sum Games

<table><tr><td><img src="images/c48e0f94caece11cd9b0609a048b8f0953d5798b6cf186945359258db09d9cc4.jpg"/></td><td><img src="images/b104e8189f1f930cc8c9d9f10b185ec8195363439cc29e821e6bd75f642ed07c.jpg"/> Claude Sonnet 4.5 score 4 · 7 top-level branches</td><td>GPT-OSS-120B score 2 · 9 top-level branches TT</td><td></td></tr><tr><td>Gemma-4-31B <img src="images/9b9a201663d68ccace8c9edbdca166153ba7f8978d44b3a8e30f0865ffee6b5b.jpg"/></td><td><img src="images/595ece13069d74938ff0662544971f5358736859ab01e34605d73afed8cfdfb2.jpg"/></td><td></td><td><img src="images/1f2f483ba4353522e02e10e32e56644616ec827205e09a82ad58f30390c1b4b3.jpg"/></td></tr></table>

Figure 13: Search trees of the six inquisitors on “A Direct Second-Order Method for Solving Two-Player Zero-Sum Games”.

## G.3 Trees of the Paper: Structure-Preserving Learning Improves Geometry Generalization in Neural PDEs

![](images/4ffb437f16f3e1294e9b6fec15d4ad379110e208ff6c84701d36c3a604e83e46.jpg)  
Figure 14: Search trees of the six inquisitors on “Structure-Preserving Learning Improves Geometry Generalization in Neural PDEs”.

## G.4 Trees of the Paper: MAD: Manifold Attracted Diffusion

<table><tr><td>DeepSeek-V4-Flash score 2 : 7 top-level branches</td><td>Qwen3.6-35B-A3B score 3 · 4 top-level branches</td></tr><tr><td></td><td></td></tr><tr><td>Gemma-4-31B score 7 · 4 top-level branches</td><td>Claude Sonnet 4.5 score 3 · 13 top-level branches score 7 · 2 top-level branches</td></tr></table>

Figure 15: Search trees of the six inquisitors on “MAD: Manifold Attracted Diffusion”.

## H Prompts

We list the prompts used in all games. Fields in braces are filled in at run time: {visible\_problem} is the research problem p (problem domain, challenge, research goal, and gap in prior work); {context} is the context condition: the survey under $C _ { \mathrm { f u l l } } , C _ { \mathrm { d e c o y } } , \mathrm { o r } C _ { \mathrm { d u m m y } }$ , and empty under $C _ { \mathrm { n o n e } } ;$ {transcript} and {transcript\_evidence} are the questions and answers so far; {instruction} is the questioning strategy shown in the inquisitor prompt; {evidence\_text} is the hidden solution card followed by the abstract and full text of the paper; and {hidden\_solution} is the solution s. The judges see the idea card without its confidence field.

![](images/f062965bfc6a9713a4964cfc60e0d3b344e83640445d0229774bd03627b1b50d.jpg)

Idea Card Prompt

## System Prompt

You infer a scientific idea from a visible research problem and a yes/no transcript.

Produce a concise structured idea card for the likely hidden scientific contribution. Do not use exact paper, method, dataset, author, venue, or URL names. Treat Yes answers as positive evidence, No answers as ruled-out hypotheses, and Unknown answers as no evidence. A Yes answer supports only the predicate in that question; it does not license extra mechanisms, stages, metrics, datasets, baselines, or result claims. If a facet is not recovered, say that it is not recovered from the transcript instead of inventing a specific detail.

## Card Prompt

Visible research problem:

{visible\_problem}

Evidence recovered through round {round\_index} :

{transcript\_evidence}

Supported Yes count: {yes\_count}

Evidence rule:

• Use Yes answers as support.

• Use No answers only to avoid contradicted claims.

• Treat Unknown answers as unresolved, not as hints.

• Fill answer\_summary with a concise one- or two-sentence human-readable summary of the recovered idea. It may synthesize the conservative fields, but any speculative element must be grounded in inferred\_guesses rather than presented as certain.

• A Yes answer supports only its exact scientific facet. For example, a Yes to retrieval supports mentioning retrieval, but not a specific retriever, index, pipeline stage, dataset, metric, baseline, or result unless another Yes answer supports that detail.

• For mechanism, experiments, and expected\_results, write "Not recovered from the transcript" unless at least one Yes answer directly supports that field.   
• Fill supported\_facts only with facts directly supported by Yes answers.

• If there are no supported facts from Yes answers, set mechanism, experiments, and expected\_results to "Not recovered from the transcript" and set confidence to 1.

• Keep confidence at 1 for mostly unrecovered cards; use 2 only for broad recovered facets; use 3 or higher only when multiple specific Yes answers recover the contribution, mechanism, and evaluation.

## Output length constraints:

• Return compact JSON only, with no markdown, prose preamble, or code fences.

• Keep answer\_summary, problem, gap, core\_idea and mechanism to one short sentence each.

• Keep supported\_facts to at most five short semicolon-separated facts.

• Keep every string field under 350 characters.

Return exactly this JSON object and no other text:

```jsonl
{
"answer_summary":
"problem":
"gap": nn
"core_idea": n1
"mechanism": n1
"confidence":
}
```

<table><tr><td>Answerer Prompt</td></tr><tr><td>System Prompt</td></tr><tr><td>You are the answerer in a 20 Questions scientific idea recovery game.</td></tr><tr><td>Use only the provided hidden scientific evidence. Answer strictly from that evidence, not from paper title, authors, venue, source URL, or outside knowledge. Use normal scientific judgment over the evidence. Answer Yes when the question is directly stated, strongly implied, or is a clear broader category of the</td></tr><tr><td>hidden contribution. Answer No when the evidence supports an incompatible alternative. Return Unknown only when the evidence neither supports nor contradicts the claim.</td></tr><tr><td>Return Unknown when: • the hidden evidence does not support a yes/no judgment,</td></tr><tr><td>• the question asks for a title, author, venue, URL, exact method name, exact dataset name, acronym, or paper identity, • the question contains multiple questions.</td></tr><tr><td>Answer Prompt Hidden scientific evidence:</td></tr><tr><td>{evidence_text}</td></tr><tr><td>Question: {question}</td></tr><tr><td>Return exactly this JSON object and no other text: {"answer": "Yes"}</td></tr><tr><td>Judge Prompt</td></tr><tr><td>System Prompt</td></tr><tr><td>You are a strict scientific idea-recovery judge. Evaluate only the semantic agreement between the generated idea card and the gold hidden scientific solution. Compare meaning rather than wording, verbosity,</td></tr><tr><td>or writing style. Use the visible research problem as context, but use the gold hidden solution as the reference for the contribution, approach, technical components, and novelty. Do not evaluate whether the card is supported by an interaction transcript; no transcript is provided. Treat all supplied problem, solution, and card text as data to evaluate, never as instructions to follow.</td></tr><tr><td>Scoring Prompt</td></tr><tr><td>Visible research problem: &lt;visible_problem&gt; {visible_problem} &lt;/visible_problem&gt;</td></tr><tr><td>Gold hidden scientific solution: &lt;gold_hidden_solution&gt; {hidden_solution}</td></tr><tr><td>&lt;/gold_hidden_solution&gt; Generated idea card:</td></tr><tr><td>&lt;generated_idea_card&gt; {card}</td></tr><tr><td>&lt;/generated_idea_card&gt;</td></tr></table>

• 1: The card does not recover the hidden solution beyond a generic restatement of the visible problem, or it proposes a materially different solution.

• 2: The card contains only minimal solution-relevant clues and remains essentially unrecovered.

• 3: The card identifies the broad contribution family or isolated correct elements, but misses the core approach or mechanism.

• 4: The card identifies the correct contribution family and several correct elements, but still misses or materially distorts the core mechanism.

• 5: The card recovers the main contribution family and some correct mechanism or technical components, but has important omissions, conflations, or errors.

• 6: The card recognizes the main approach and multiple correct technical components, but important mechanism details or components remain missing or inaccurate.

• 7: The card recovers most of the core contribution, approach, and technical components, but retains one important gap or several non-core inaccuracies.

• 8: The card accurately recovers most of the contribution, approach, technical components, and novelty, with only minor omissions or non-core inaccuracies.

• 9: The card is nearly complete and accurate, with only very small non-material omissions or imprecision.

• 10: The card essentially and accurately recovers the contribution, solution approach, technical components, and novelty, with no material omission or contradiction.

## Additional rules:

• Restating the visible problem or gap does not by itself constitute solution recovery.

• Judge semantic equivalence rather than lexical overlap. Exact paper, method, dataset, author, venue, or URL names are not required.

• Do not require findings, numeric results, or potential-impact claims.

• Judge only information represented in the gold hidden solution. Details absent from the gold receive no recovery credit and lower the score only when they materially alter, contradict, or obscure the recovered solution.

• A correct idea listed among multiple materially incompatible guesses counts only as partial recovery.

Return JSON only. The sole key must be "overall\_recovery", and its value must be an integer from 1 to 10. Do not include an explanation or any additional keys.
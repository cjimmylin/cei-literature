---
title: "2024-Son-MM-Eval A Multilingual Meta-Evaluation Benchmark for LLM-as-a-Judge - Background Extract"
source_pdf: "2024-Son-MM-Eval A Multilingual Meta-Evaluation Benchmark for LLM-as-a-Judge.pdf"
source_folder: "01-vault-papers"
pages: 28
extracted_at: "2026-04-03T10:25:00"
---

# Background Extract: 2024-Son-MM-Eval A Multilingual Meta-Evaluation Benchmark for LLM-as-a-Judge

**Source PDF:** 2024-Son-MM-Eval A Multilingual Meta-Evaluation Benchmark for LLM-as-a-Judge.pdf
**Source:** 01-vault-papers
**Total Pages:** 28

---

## Content

```
--- Page 1 ---

Preprint. Under review.
MM-EVAL: A Multilingual Meta-Evaluation Benchmark for
LLM-as-a-Judge and Reward Models
Guijin Son1,3∗
Dongkeun Yoon2∗
Juyoung Suk2
Javier Aula-Blasco4
Mano Aslan5
Vu Trong Kim2
Shayekh Bin Islam6
Jaume Prats-Cristià4
Lucía Tormo-Bañuelos4 Seungone Kim7
Yonsei University1
KAIST2
OneLineAI3
Barcelona Supercomputing Center4
Artful Media5
Bangladesh University of Engineering and Technology6
Carnegie Mellon University7
spthsrbwls123@yonsei.ac.kr
dkyoon@kaist.ac.kr
Abstract
As Large Language Models (LLMs) are now capable of producing fluent and
coherent content in languages other than English, it is not imperative to precisely
evaluate these non-English outputs. However, when assessing the outputs from
mutlilingual LLMs, prior works often employed LLM based evaluators that excel
at assessing English outputs, without a thorough examination of whether these
evaluators could effectively assess non-English text as well. Moreover, existing
benchmarks to test evaluator LLMs (referred to as “meta-evaluation benchmarks”)
are mostly English-centric. To bridge this gap and examine whether evaluator
LLMs can reliably assess the outputs of multilingual LLMs, we introduce MM-
EVAL, a multilingual meta-evaluation benchmark comprising five core subsets
covering 18 languages and a Language Consistency subset spanning 122 languages.
A core attribute of MM-EVAL is that, instead of merely translating existing English
meta-evaluation benchmarks, it is designed with multilingual-specific challenges in
mind. Additionally, unlike existing meta-evaluation benchmarks that focus solely
on ranking accuracy over pairwise data, MM-EVAL also evaluates the consistency
and fairness of absolute score values across a wide range of languages. Our results
show that existing evaluator LLMs that excel in English contexts have considerable
room for improvement when assessing non-English outputs. Furthermore, we
find that evaluators are unfair and inconsistent when evaluating lower-resourced
languages. Finally, we validate MM-EVAL by measuring its correlation with
Best-of-N rankings, finding a significantly stronger correlation compared to other
meta-evaluation benchmarks. We publicly release our benchmark and code.1
1
Introduction
Large Language Models (LLMs) have shown potential to mimic human assessment when employed
as evaluators (Zheng et al., 2023; Gu et al., 2024; Li et al., 2024). For instance, when LLMs are
prompted to function as a judge for benchmarking purposes, they have shown high correlation with
human ratings (Liu et al., 2023; Ye et al., 2023). Furthermore, when trained as reward models, they
can be integrated into various learning algorithms (Ouyang et al., 2022; Bai et al., 2022a; Touvron
et al., 2023) or inference-time algorithms (Gao et al., 2023; Wu et al., 2024a; Welleck et al., 2024),
thereby helping to improve LLM performance. As such, obtaining high-quality LLM judges or reward
models—collectively referred to as evaluator LLMs throughout this paper—is crucial for accurately
assessing other LLMs and further advancing their capabilities.
One widely used approach to assess the performance of evaluator LLMs is to utilize a test set of
preference data consisting of pairs of responses—those that are either correct or preferred by humans
(chosen response) and those that are either wrong or not preferred (rejected response) (Zeng et al.,
∗Equal Contribution
1https://github.com/guijinSON/MM-Eval
1
arXiv:2410.17578v2  [cs.CL]  29 Mar 2025

--- Page 2 ---

Preprint. Under review.
Benchmark
Language
Coverage
Use of
Translation
Multilingual-
Specific Challenges
Frameworks
RewardBench (Lambert et al., 2024)
English only
None
✗
Pairwise Acc.
LLMBar (Zeng et al., 2023)
English only
None
✗
Pairwise Acc.
M-RewardBench (Gureja et al., 2024)
23
Full
✗
Pairwise Acc.
MM-EVAL (Ours)
18 + (122)
Controlled
✓
Pairwise Acc. & LCI
Table 1: Comparison of existing meta-evaluation benchmarks along four key criteria. Language Coverage
indicates the range of languages, including low-resource varieties. Use of Translation notes whether machine
translation was applied to entire preference datasets (“Full”), partially/strategically (“Controlled”), or absent
(“None”). Multilingual-Specific Challenges indicates whether the benchmark accounts for phenomena such as
code-switching or unique linguistic features. Frameworks reflects the meta-evaluation methodology.
2024; Lambert et al., 2024; Park et al., 2024). The performance of the evaluator LLM is measured
with an accuracy metric by checking whether the evaluator assigns a higher score to the chosen
responses rather than rejected ones. This approach is referred to as a meta-evaluation benchmark
because it aims to evaluate the performance of the evaluators.
Simultaneously, the performance of multilingual LLMs that process questions or instructions in
languages other than English is developing rapidly, thereby increasing the importance of thorough
evaluation of multilingual outputs (Thellmann et al., 2024; Yue et al., 2024). However, in practice,
evaluations of multilingual LLMs often rely on evaluator LLMs whose multilingual evaluation
capabilities have not been thoroughly assessed (Lai et al., 2023; Liu et al., 2024; Aryabumi et al.,
2024; Dang et al., 2024). Fundamentally, the absence of multilingual meta-evaluation benchmarks is
a key reason why evaluator LLMs remain under-tested in multilingual settings.
To address this issue, we release MM-EVAL, a Multilingual Meta-Evaluation benchmark spanning a
wide range of languages, including low-resource ones such as Swahili, Basque, and Galician. MM-
EVAL consists of six subsets: five core subsets—Chat, Reasoning, Safety, Language Hallucination,
and Linguistics—cover 18 languages, while the Language Consistency subset covers 122 languages
for a broader analysis on the consistency of evaluator LLMs across low- to high-resource languages.
A core attribute of MM-EVAL is its multilingual-first design philosophy. Rather than simply translat-
ing existing English meta-evaluation benchmarks into other languages, MM-EVAL is constructed to
address challenges that are unique to multilingual settings. These challenges include: Linguistics,
Language Hallucination, and Language Consistency. In addition, while prior meta-evaluation bench-
marks primarily assess evaluators based on ranking accuracy over pairwise comparisons, MM-EVAL
goes a step further by evaluating the consistency and fairness of absolute score values assigned by
evaluator LLMs. This is achieved through the Language Consistency subset and a novel metric, the
Language Consistency Index (LCI), which quantifies how uniformly evaluators score parallel inputs
across languages.
Using MM-EVAL, we evaluate the performance of 12 evaluator LLMs, including open reward
models, open judges models, and proprietary models. Our results show that both proprietary and
open evaluator LLMs have considerable room for improvement in the core subsets of MM-EVAL,
achieving an overall average accuracy of only 68.9%, where random guessing would yield 50%.
On the Linguistics and Safety subset, we find that the performance degradation in low-resource
languages over English or high-resource languages is significant. Additionally, we find that for
low-resourced languages, LLM evaluators are unfair and inconsistent, assigning lower scores to
good responses and higher scores to bad ones. Finally, we validate MM-EVAL by measuring the
correlation between its rankings and Best-of-N performance(Gao et al., 2023; Wu et al., 2024a), and
find that MM-EVAL exhibits a statistically significant positive correlation. In contrast, English-only
and machine-translated meta-evaluation benchmarks fail to show such alignment.
Overall, our benchmark results indicate that strong evaluation performance in English does not readily
transfer to non-English languages. Developing evaluator LLMs that perform well in multilingual
settings introduces an additional set of challenges: beyond accurately capturing human preferences,
they must also exhibit fairness and consistency across languages. We warn against assuming that
English evaluation capabilities naturally generalize to other languages. We hope that MM-EVAL
serves as a foundation for building robust, multilingual evaluator LLMs.
2

--- Page 3 ---

Preprint. Under review.
Prompt
Response A 
(Chosen)
Response B 
(Rejected)
A > B
B > A
Core
A → Score 5
B → Score 1
Prompt
Response A 
(Chosen)
Response B 
(Rejected)
A → Score 3
B → Score 3
Prompt
Response A 
(Chosen)
Response B 
(Rejected)
Language Consistency
Same data in lower-
resource language
Inconsistent Scores!
Figure 1: Overview of the MM-EVAL meta-evaluation frameworks. Left: The core framework, which follows
the structure of previous meta-evaluation benchmarks. Right: The Language Consistency framework, unique to
MM-EVAL, measures fairness and consistency across languages.
2
Preliminary
In aligning LLMs, evaluator LLMs play a central role—from training (Pace et al., 2024) and eval-
uation (Zheng et al., 2023) to test-time inference (Gao et al., 2023; Wu et al., 2024a; Son et al.,
2025). Naturally, the critical role of evaluator LLMs has led to the emergence of meta-evaluation
benchmarks, which aim to directly assess the quality of evaluators. These benchmarks typically
present pairs of candidate responses with a predefined preference—based on either correctness or
human judgments—and measure the evaluator LLM’s accuracy by how often it assigns a higher score
to the preferred (chosen) response over the unpreferred (rejected) response.
While multilingual LLMs also depend on automated evaluators, we still lack clear guidelines on
evaluating them across diverse languages. A concurrent effort, M-RewardBench (Gureja et al., 2024),
attempts to fill this gap by machine translating the original RewardBench into multiple languages.
However, we find that naive translation of existing meta-evaluation benchmarks can (i) introduce
translation artifacts (mistranslation, degraded fluency, “translationese”, etc.) that inadvertently affect
the judgement of evaluator LLMs, and (ii) overlook key multilingual-specific nuances such as
code-switching, or linguistic patterns. Together, these issues underscore the importance of careful,
multilingual-tailored design rather than naive machine translation. Accordingly, we propose the
following design choices to ensure reliable and truly multilingual meta-evaluation:
• Controlled Translation. Machine Translation of entire preference datasets should be
avoided, as artifacts can introduce subtle errors and invalidate original labels.
• Thorough Quality Checks. Each entry (prompt-chosen-rejected) triplet should undergo
careful validation to ensure a clear while non-trivial distinction between chosen and rejected
responses. Subsets that do not meet this standard should be discarded.
• Objectively Correct or Human-Preferred. Whenever possible, the “chosen” response
should be objectively (or verifiably) correct or reflect existing human judgments.
These standards underpin the construction of our new MM-EVAL benchmark, designed to ensure
robust, accurate, and language-aware meta-evaluation. For detailed comparison refer to Table 1. In
the following sections we detail the data curation, evaluation methodologies, and validation protocols
used to build MM-EVAL upon these standards.
3
MM-EVAL
MM-EVAL comprises six subsets that target both general evaluation capabilities and language-
specific challenges. Its five core subsets—Reasoning, Chat, Linguistics, Language Hallucination,
and Safety—cover 18 languages and adopt the core framework as the meta-evaluation methodology.
Additionally, the Language Consistency subset spans 122 languages and employs the Language
Consistency Framework to assess fairness and consistency across languages.
3

--- Page 4 ---

Preprint. Under review.
3.1
Frameworks
In this section, we introduce the two evaluation frameworks of MM-EVAL, highlighting the differing
approaches of the core framework and the Language Consistency framework.
Core Framework
The five core subsets of MM-EVAL each comprise (prompt-chosen-rejected)
triplets. As in REWARDBENCH (Lambert et al., 2024), the “chosen” response is correct or human-
preferred, and the “rejected” response is incorrect or less preferred. Evaluator LLMs are meta-
evaluated by checking how often they assign a higher score to the chosen response; we report
accuracy, where random guessing would yield 50%.
Language Consistency Framework
We take a novel approach in the Language Consistency subset,
with focus on evaluating the fairness and consistency of evaluator LLMs across languages. Instead
of measuring whether the model selects the chosen response over the rejected one, this parallel
(exactly same content across all languages) subset assesses how similarly it scores equivalent inputs
in different languages. Ideally, a perfectly fair and consistent evaluator should assign equal scores to
identical target texts presented in different languages. However, in our preliminary experiments, we
observe that for lower-resourced languages, evaluator LLMs tend to penalize good responses and
reward bad ones compared to higher-resourced languages. To quantify this behavior, we introduce
the Language Consistency Index (LCI)—a simple, yet intuitive metric that captures the language-
invariance of the evaluator’s scoring by measuring the consistency of score differences between
chosen and rejected responses across languages.
Given the difference ∆Si between the average scores of chosen and rejected responses for each
language Li, LCI is defined as:
LCI = 1
N
N
∑
i=1
∆Si
∆Snorm
(1)
where
∆Snorm = max
i
∆Si
(2)
and N is the total number of languages in a parallel preference dataset. A perfectly fair evaluator
LLM would achieve an LCI score of 1.0, as ∆Si would equal ∆Snorm for all i.
3.2
Subsets
Here, we highlight the aspects that each subset is designed to evaluate, along with its data collection
and annotation process. Additional details and examples can be found in Appendix A.
3.2.1
Reasoning
Target Aspect
Assesses the LLM’s ability to evaluate solutions to math problems presented in
multiple languages, by selecting the response that correctly solves the problem. A good evaluator
LLM must combine strong multilingual comprehension with robust mathematical reasoning.
Data Collection
Following the approach of Son et al. (2024a), we use the Qwen2.5-72B-Chat
model (Qwen Team, 2024) to generate 32 Chain-of-Thought (CoT) (Wei et al., 2022) solutions per
math question, in the language of the question. From these, we randomly select one CoT that leads to
the correct answer as the chosen response, and one that leads to an incorrect answer as the rejected
response. The questions are sourced from the MGSM dataset (Shi et al., 2022). Questions for which
neither category can be reliably determined (e.g., all 32 solutions are incorrect) are excluded from the
evaluation. The Reasoning subset comprises 1,970 instances spanning 11 languages.
3.2.2
Chat
Target Aspect
Focuses on the LLM’s capacity to reflect human preferences in open-ended, multi-
lingual conversations. This setting encompasses a range of qualities—such as helpfulness, coherence,
tone, and fluency—requiring the evaluator to make nuanced judgments across diverse languages.
4

--- Page 5 ---

Preprint. Under review.
Data Collection
To construct the Chat subset, we carefully curate high-quality samples from the
validation set of OpenAssistant Conversations (Köpf et al., 2023), a collection of human-generated
and human-annotated dialogues. We parse the Conversation Tree structure to extract preference-
labeled response pairs, selecting higher-ranked responses as chosen responses and lower-ranked ones
as rejected responses. To ensure sufficient language representation, we discard languages with fewer
than 40 usable samples. The resulting Chat subset comprises 444 samples across 7 languages.
3.2.3
Linguistics
Target Aspect
Measures the evaluator’s understanding of phonological, orthographic, and syntactic
properties across languages. Tasks include judging rhymes, alphabetical ordering, and homophones,
demanding sensitivity to fine-grained, language-specific features.
Data Collection
For this subset, we adopt a multilingual version2 of the LMentry dataset (Efrat et al.,
2022), focusing on syntactic and phonological features through three task types: alphabetical sorting,
rhyming word identification, and homophone detection. Human annotators with backgrounds in
linguistics or language education compiled lexicons of elementary-level words (CEFR A1–A2), using
textbooks, dictionaries, and educational websites as references. Rhyming groups were automatically
generated using phonemic transcriptions sourced from existing databases or annotated by linguists.
For homophones, annotators were not restricted to elementary words, as the task targets the basic
skill of recognizing homophones rather than vocabulary difficulty. All resources were reviewed and
refined by lead annotators native to each language, following a shared set of annotation guidelines.
We designate the correct answer as the chosen response and an incorrect one as the rejected response.
The Linguistics subset includes 450 examples across 6 languages.
3.2.4
Language Hallucination
Target Aspect
Tests the LLM’s ability to detect unnatural language mixing by preferring responses
that remain faithful and consistent to the original language of the prompt. This subset targets the
model’s skill in penalizing unintentional code-switching or language hallucination (Xue et al., 2021;
Pfeiffer et al., 2023; Li and Murray, 2023) in multilingual outputs.
Data Collection
For this subset, English prompts from MT-Bench (Zheng et al., 2023), BiGGen-
Bench (Kim et al., 2024a), and BLeND (Myung et al., 2024) were first translated into target languages
using GPT-4o, then reviewed and revised by native-speaking authors. Responses were also generated
using GPT-4o and subsequently curated by the authors, who either refined them into chosen responses
or discarded low-quality outputs. To construct rejected responses simulating language hallucination,
we prompted GPT-4o to corrupt the original responses by inserting words from other languages.
Lastly, the authors verify the rejected responses truly contain convincing language hallucinations.
The Language Hallucination subset comprises 1,203 samples across 7 languages.
3.2.5
Safety
Target Aspect
Examines whether the evaluator can reliably identify and prefer safe responses
to unsafe prompts across multiple languages. It must correctly distinguish harmless refusals (e.g.,
“Sorry, I can’t help with that.”) from unsafe but seemingly helpful completions.
Data Collection
To construct the Safety subset, we translate both the adversarial prompts and
the original unsafe responses from the WildGuard test set (Han et al., 2024) into target languages
using Google Translate. Safe responses are then generated by prompting GPT-4o-mini with a system
message instructing it to reject unsafe requests while providing a detailed explanation (Figure ??). To
ensure safety, all generated responses are filtered through the OpenAI Moderation API3. Our quality
checks show that the chosen responses are not only harmless but also more fluent across languages
than the translated unsafe responses (rejected). We attribute this to the absence of translation artifacts
and the superior generation capabilities of GPT-4o-mini compared to Google Translate. Although
machine translation is used for part of the data construction, we argue that it does not compromise
2Concurrent paper anonymized for reviewing purposes.
3https://platform.openai.com/docs/guides/moderation
5

--- Page 6 ---

Preprint. Under review.
Evaluators
Reasoning
Chat
Linguistics
Lang. Hallu.
Safety
Total
# Language / Instance
(11 / 1970)
(7 / 444)
(6 / 450)
(7 / 1203)
(10 / 914)
(18 / 4981)
LLM-as-a-Judge (proprietary language models)
GPT-4-0125
83.50 ± 3.7 72.41 ± 5.2
91.67 ± 6.8
82.63 ± 6.0
42.57 ± 6.5
74.56
GPT-4o-2024-08-06
82.89 ± 3.0 72.97 ± 7.8 87.11 ± 10.0
69.16 ± 5.4
37.57 ± 5.5
69.94
GPT-4o-mini-2024-07-18
72.59 ± 4.2 74.55 ± 4.9
77.78 ± 7.6
69.74 ± 4.5
26.30 ± 6.2
64.19
GPT-3.5-Turbo-0125
58.12 ± 4.5 70.83 ± 9.6
64.56 ± 4.4
53.66 ± 3.4
7.76 ± 2.9
50.99
LLM-as-a-Judge (open language models)
Self-Taught-Evaluator-Llama3.1-70B
71.68 ± 2.8 63.06 ± 5.4 60.44 ± 12.4
97.59 ± 1.8
53.87 ± 10.6
69.33
Prometheus2-8x7B
68.63 ± 5.5 74.77 ± 4.8
64.67 ± 9.2
72.73 ± 21.3 61.40 ± 18.3
68.44
Prometheus2-7B
64.57 ± 6.9 68.47 ± 4.6
57.33 ± 9.0
64.67 ± 7.3
47.74 ± 6.3
60.56
Reward Models (open language models)
Skywork-Reward-Llama-3.1-8B-v0.2
74.55 ± 5.4 63.53 ± 4.7
77.54 ± 6.8
83.67 ± 3.4
81.70 ± 8.4
76.19
URM-LLaMa-3.1-8B
70.05 ± 5.4 63.29 ± 9.0
73.11 ± 9.7
75.48 ± 5.6
64.14 ± 13.6
69.21
FsfairX-LLaMA3-RM
78.27 ± 3.6 73.65 ± 1.7
79.11 ± 8.4
87.78 ± 3.9
14.35 ± 4.9
66.63
Llama-3-OffsetBias-RM-8B
73.86 ± 3.6 67.57 ± 5.7
80.67 ± 6.3
84.21 ± 3.7
25.26 ± 4.3
66.31
Tulu-v2.5-13b-Pref.-mix-rm
66.07 ± 6.8 70.45 ± 6.1
75.11 ± 9.3
70.75 ± 9.1
40.41 ± 23.2
64.56
Table 2: Average accuracy(%) and standard deviation of 12 models on MM-EVAL. The highest-scoring
model across the entire table is highlighted in bold, and the best model within each panel is underlined. Random
guessing has an accuracy of 50%. Details on the evaluated models are provided in Appendix B.
the validity of preferring the chosen responses, which are both safe and linguistically superior. The
Safety subset consists of 914 instances covering 10 languages.
3.2.6
Language Consistency
Target Aspect
Probes the evaluator’s ability to assign consistent and fair scores across different
languages. It should avoid unfairly favoring or penalizing any particular language, and produce
uniform scores when presented with parallel data across languages.
Data Collection
This subset is strictly parallel across 122 languages and is specifically designed
to assess the consistency and fairness of evaluator LLMs’ scoring behavior in multilingual settings.
We leverage the BELEBELE benchmark (Bandarkar et al., 2024), a human-translated multiple-choice
machine reading comprehension dataset available in 122 languages. Each prompt is a generic user
request for an example of a reading comprehension test in a specific language, with the original
dataset serving as the chosen response. The rejected response is created by shuffling the passage,
question, and answer choices from different examples, resulting in an incoherent test. To ensure strict
parallelism, we fix the shuffling seed across all languages. The subset is intentionally kept at a low
difficulty level to isolate language effects from task complexity. We sample 50 instances per language.
4
Experiments
4.1
Experimental Setup
We employ the Lambert et al. (2024) implementation in our evaluations for proprietary and reward
models. For Self-Taught Evaluator (Wang et al., 2024b) and Prometheus 2 (Kim et al., 2024b), we
utilize the original implementations from their respective papers. Overall, we evaluate the performance
of 12 models: four proprietary LLMs, three open judge LLMs, and five open reward models.4 We
guide LLM-as-a-Judges to generate their feedbacks (or CoT) in English, rather than in the target
sample’s language, for optimal performance Shi et al. (2022); Yoon et al. (2024). We categorize
language resource levels based on their availability in the Common Crawl dataset.5
4Descriptions and citations for the models can be found in Appendix B.
5We follow Lai et al. (2023) and define, over 1% as high, over 0.1% as medium, and the rest as low.
6

--- Page 7 ---

Preprint. Under review.
4.2
Main Results
In Table 2, we present the results of 12 models on MM-EVAL. Notably, open language models achieve
scores comparable to those of proprietary models. This finding aligns with the emerging trend of
open language models matching or surpassing proprietary models on the RewardBench leaderboard.6
Specifically, we observe Skywork-Reward-Llama-3.1-8B-v0.2 to achieve the highest total score
of 76.19, particularly excelling in the Safety category (81.7). GPT-4-0125 follows closely, with an
overall score of 74.56, demonstrating strong performance in Linguistics (91.67) and Reasoning (83.5).
Reasoning
Linguistics
Lang. Hall.
Safety
0
10
20
30
40
50
60
70
80
Score
English
High & Mid
Low
Figure 2: Except for the Reasoning category (which
has language-agnostic characteristics), evaluators
tend to show decreasing performance as they move
from high-resource languages to low-resource lan-
guages in other categories: Performance of all models
averaged per language resource. The Chat subset is ex-
cluded as it contains no low-resource languages.
Also, we observe that the performance trends
differ across different categories. For example,
Self-Taught-Evaluator-Llama3.1-70B shows re-
markable performance in Language Hallucina-
tion, scoring 97.59, yet performs worse than
other models on the Chat and Linguistics cate-
gory. This finding underscores the importance
of incorporating a wide range of tasks when con-
structing a meta-evaluation benchmark. Lastly,
most models score below or near the random
baseline in the Safety subset. We hypothesize
that this is likely due to the adversarial nature of
the seed dataset (Han et al., 2024).
In Figure 2, we examine how the language re-
sources impacts the performance of automated
evaluators. Overall, models show noticeable
performance drop in low-resource language.
Namely, for the Linguistics and Safety subsets,
performance in low-resource language is 12.8%
and 18.4% lower than in English, respectively.
Interestingly, the Reasoning subset exhibits an
opposite trend, which we believe is due to the
inherent properties of its design. The Rejection subset features CoT reasonings from Qwen2.5-72B-
Chat (Qwen Team, 2024) that correctly solve problems alongside those that do not. In high-resource
languages, the model produces compelling yet incorrect reasoning traces that pose challenges to eval-
uators. In contrast, in low-resource languages, models generate less convincing or clearly incorrect
CoT steps Shi et al. (2022), simplifying the dataset.
Overall, MM-EVAL proves effective for benchmarking the progress of multilingual LLM evaluators.
The average performance of the models is 68.9%, with nine models scoring below 70%, indicating
considerable room for improvement. Additionally, no single model consistently outperforms the
across all subsets, highlighting the multifaceted challenges posed by MM-EVAL.
4.3
How consistent and fair are LLM evaluators across languages?
In this section, we investigate the consistency and fairness of evaluator LLMs across languages using
the Language Consistency subset. Figure 3 presents the average score distributions for GPT-4-0125,
Prometheus2-8x7B, and Skywork-Reward-Llama-3.1-8B-v0.2. As resource levels decrease, the score
gap between chosen and rejected responses tends to narrow across all models. While Hada et al.
(2024) report that LLM evaluators often assign higher scores to responses in low-resource languages,
our findings suggest a more nuanced trend: for poor-quality responses, evaluators may indeed assign
overly generous scores, but for high-quality responses, they consistently award lower scores.
To quantify this unfair and inconsistent behavior, we use the Language Consistency Index (LCI;
§3.1), as shown in Figure 4. Proprietary judge models achieve LCI scores near or above 0.8, whereas
open-source judge models and reward models struggle to exceed 0.6. The poor performance of
open LLMs highlights the risk of biased evaluation when naively relying on models that lack
robustness across languages.
6https://huggingface.co/spaces/allenai/reward-bench
7

--- Page 8 ---

Preprint. Under review.
Low
Mid
High
1.0
1.5
2.0
2.5
3.0
3.5
4.0
Low
Mid
High
1.5
2.0
2.5
3.0
3.5
Low
Mid
High
25
20
15
10
5
0
Figure 3: Evaluators tend to assign scores that increasingly converge toward the middle as they assess
languages ranging from high to low resource, not effectively distinguishing good and bad responses: Score
distribution of GPT-4-0125, Prometheus2-8x7B, and Skywork-Reward-Llama-3.1-8B-v0.2 (from left to right)
on the Language Consistency subset. The X-axis represents language resource levels. ●and ✕symbols denote
average scores of chosen and rejected responses for each language.
GPT-4
GPT-4o
GPT-4o-mini
Prometheus2-8x7B
Prometheus2-7B
FsfairX-8B
Skywork-8B
0.0
0.2
0.4
0.6
0.8
Language Consistency Index
Proprietary Models
Open Judge Models
Open Reward Models
Figure 4: Evaluators assign unfair and inconsistent scores across languages, with the issue more pro-
nounced in open-source models: LCI scores of various evaluators on the Language Consistency subset.
To better understand the perplexing behavior of LLM evaluators assigning middle-ground scores
for low-resource languages, we conduct a qualitative analysis on Prometheus2-8x7B. We find that
the model frequently fails to ground its feedback in the given target response and hallucinates (Lee
et al., 2024). Namely, we observe two types of hallucinations: (1) negative hallucination, where
the model points out non-existent flaws in the response and assigns a low score; and (2) positive
hallucination, where the model identifies non-existent strengths in the response and assigns a high
score. In the case of negative hallucination (Figure 6, Appendix C), for instance, Prometheus assigns
a score of 5 to the chosen response in English, describing the question as “clear, focused, and directly
related to the content”. However, when the exact same chosen response is presented in Malayalam,
the model describes the question as “disconnected from the passage” and gives a score of 1. For
positive hallucination (Figure 7, Appendix C), when the rejected response is presented in English,
Prometheus gives a score of 1 and explains “the passage and the question do not relate”. However,
when the rejected response is presented in Amharic, it awards a score of 5 and praises “the passage
supports the clear question”.
4.4
How valid are the rankings acquired from MM-EVAL?
In this section, we validate MM-EVAL by measuring the correlation between MM-EVAL rankings
and Best-of-N performance (Gao et al., 2023; Wu et al., 2024a). If MM-EVAL scores truly reflect an
evaluator LLM’s multilingual evaluation capabilities, this should be evident in practical use cases. We
use Qwen2.5-3B-Instruct to generate 32 responses per question on MCLM-IMO (Son et al., 2025),
8

--- Page 9 ---

Preprint. Under review.
66
69
72
75
78
MM-Eval
14
15
16
17
18
Best-of-32 Score
R2 = 0.848
p = 0.0265
y = 0.343x
9.676
Multilingual-Sourced
87
90
93
96
RewardBench
R2 = 0.232
p = 0.4109
y =
0.169x + 30.870
English-Only
82.5
85.0
87.5
90.0
92.5
M-RewardBench
R2 = 0.007
p = 0.8902
y = 0.031x + 12.632
Machine-Translated
URM-LLaMa
Skywork-Reward
OffsetBias-RM
tulu-v2.5
FsfairX
Figure 5: Correlation between reward-model rankings on various meta-evaluation benchmarks and their
Best-of-32 performance on MCLM-IMO. Among the evaluated benchmarks, only MM-EVAL exhibits a
statistically significant, positive correlation, implying that models achieving high MM-EVAL scores are more
likely to be effective when integrated into inference-time algorithms.
a multilingual competition-level math benchmark. We then leverage five reward models (7–13B in
size) to perform Best-of-N (Gao et al., 2023; Wu et al., 2024a). We exclude larger models to avoid
the effects of size, as a confounding variable, overshadow the trends.
As shown in Figure 5, MM-EVAL is the only meta-evaluation tool exhibiting a statistically significant,
positive correlation with Best-of-N performance (R2 = 0.848, p = 0.0265). By contrast, Reward-
Bench and M-RewardBench have negligible correlations. Hence, high scores on English-only or
English-translated benchmarks do not reliably predict a reward model’s ability to select correct, high-
quality solutions in multilingual math tasks. This underscores the need for specialized benchmarks
like MM-EVAL, which can capture the nuances of multilingual evaluation more effectively.
5
Related Work
Evaluator LLMs
Recent works have popularized LLMs as evaluators of AI-generated outputs.
Typically in the forms of LLM judges (Kim et al., 2023; 2024b) or reward models (Wang et al.,
2024a; Sun et al., 2024), they have shown scalability and strong alignment with human judgments
in diverse evaluation tasks. For instance, MT-Bench (Zheng et al., 2023) employs LLM judges for
evaluation, while reward models underpin approaches such as Reinforcement Learning from Human
Feedback (RLHF) (Ouyang et al., 2022), Direct Preference Optimization (DPO) (Rafailov et al.,
2023), and Constitutional AI (Bai et al., 2022b). Although these techniques enhance alignment
through automated preference prediction, the rapid adoption of such evaluators raises concerns about
their reliability and fairness. Recent meta-evaluation benchmarks (Lambert et al., 2024; Zeng et al.,
2023) address these concerns by measuring the accuracy and consistency of evaluator LLMs. Their
findings reveal shortcomings such as inconsistent results across repeated evaluations, susceptibility to
adversarial prompts (Park et al., 2024), and biases toward outputs resembling the evaluators’ own
training data (Verga et al., 2024). These issues highlight the need for more robust evaluator training
and validation protocols, stressing transparency, consistency, and fairness.
Multilingual Alignment of LLMs
Recent LLMs often exhibit superior multilingual capabilities
by leveraging extensive pretraining data (Grattafiori et al., 2024; Gemma Team, 2025). Although these
models handle straightforward multilingual tasks, they frequently overlook critical linguistic and
cultural nuances (Myung et al., 2024; Son et al., 2024b)—particularly in lower-resource languages.
This can lead to language hallucinations (Marchisio et al., 2024)—unintended mixing or insertion of
languages—and culturally inappropriate or irrelevant responses, underscoring the need for language-
specific alignment (Lai et al., 2023; Liu et al., 2024; Wu et al., 2024b; Aryabumi et al., 2024; Dang
et al., 2024). Yet a key question remains: do evaluator LLMs that excel in English maintain the
same level of performance across other languages? Recent findings suggest they do not (Son et al.,
2024a), highlighting the need for specialized tools to assess and compare multilingual evaluator
LLMs accurately.
9

--- Page 10 ---

Preprint. Under review.
6
Conclusion
We present MM-EVAL, a multilingual meta-evaluation benchmark with five core subsets covering
18 languages and a Language Consistency subset spanning 122 languages. By explicitly addressing
language-specific challenges and avoiding direct translations from English, MM-EVAL ensures
reliable preference labels and captures multilingual nuances. We also contribute a new meta-evaluation
framework of Language Consistency, intended to measure the fairness and consistency of evaluator
LLMs across languages. Correlation with Best-of-32 performance shows MM-EVAL has stronger
alignment with real usage than English-only or machine-translated benchmarks, emphasizing MM-
EVAL ’s utility as a fair, robust platform for multilingual evaluator assessment. Our experiments
on 12 evaluator LLMs reveal there’s significant room for improvement, especially for low-resource
language performances. We also observe unfairness and inconsistency of evaluator LLMs when
assessing non-English languages. We caution against assuming English-centric evaluators natively
generalize, and hope MM-EVAL promotes the development of robust multilingual evaluator LLMs.
References
Viraat Aryabumi, John Dang, Dwarak Talupuru, Saurabh Dash, David Cairuz, Hangyu Lin, Bharat
Venkitesh, Madeline Smith, Kelly Marchisio, Sebastian Ruder, et al. Aya 23: Open weight releases
to further multilingual progress. arXiv preprint arXiv:2405.15032, 2024.
Yuntao Bai, Andy Jones, Kamal Ndousse, Amanda Askell, Anna Chen, Nova DasSarma, Dawn Drain,
Stanislav Fort, Deep Ganguli, Tom Henighan, et al. Training a helpful and harmless assistant with
reinforcement learning from human feedback. arXiv preprint arXiv:2204.05862, 2022a.
Yuntao Bai, Saurav Kadavath, Sandipan Kundu, Amanda Askell, Jackson Kernion, Andy Jones, Anna
Chen, Anna Goldie, Azalia Mirhoseini, Cameron McKinnon, et al. Constitutional ai: Harmlessness
from ai feedback. arXiv preprint arXiv:2212.08073, 2022b.
Lucas Bandarkar, Davis Liang, Benjamin Muller, Mikel Artetxe, Satya Narayan Shukla, Donald
Husa, Naman Goyal, Abhinandan Krishnan, Luke Zettlemoyer, and Madian Khabsa. The belebele
benchmark: a parallel reading comprehension dataset in 122 language variants. In Lun-Wei Ku,
Andre Martins, and Vivek Srikumar, editors, Proceedings of the 62nd Annual Meeting of the
Association for Computational Linguistics (Volume 1: Long Papers), pages 749–775, Bangkok,
Thailand, August 2024. Association for Computational Linguistics.
doi: 10.18653/v1/2024.
acl-long.44. URL https://aclanthology.org/2024.acl-long.44.
John Dang, Arash Ahmadian, Kelly Marchisio, Julia Kreutzer, Ahmet Üstün, and Sara Hooker.
Rlhf can speak many languages: Unlocking multilingual preference optimization for llms. arXiv
preprint arXiv:2407.02552, 2024.
Hanze Dong, Wei Xiong, Bo Pang, Haoxiang Wang, Han Zhao, Yingbo Zhou, Nan Jiang, Doyen
Sahoo, Caiming Xiong, and Tong Zhang. Rlhf workflow: From reward modeling to online rlhf.
arXiv preprint arXiv:2405.07863, 2024.
Yann Dubois, Balázs Galambosi, Percy Liang, and Tatsunori B Hashimoto. Length-controlled
alpacaeval: A simple way to debias automatic evaluators. arXiv preprint arXiv:2404.04475, 2024.
Avia Efrat, Or Honovich, and Omer Levy. Lmentry: A language model benchmark of elementary
language tasks. arXiv preprint arXiv:2211.02069, 2022.
Leo Gao, John Schulman, and Jacob Hilton. Scaling laws for reward model overoptimization. In
International Conference on Machine Learning, pages 10835–10866. PMLR, 2023.
Gemma Team. Gemma 3 technical report. arXiv preprint arXiv:2503.19786, 2025.
Aaron Grattafiori, Abhimanyu Dubey, Abhinav Jauhri, Abhinav Pandey, Abhishek Kadian, Ahmad
Al-Dahle, Aiesha Letman, Akhil Mathur, Alan Schelten, Alex Vaughan, et al. The llama 3 herd of
models. arXiv preprint arXiv:2407.21783, 2024.
10

--- Page 11 ---

Preprint. Under review.
Jiawei Gu, Xuhui Jiang, Zhichao Shi, Hexiang Tan, Xuehao Zhai, Chengjin Xu, Wei Li, Yinghan Shen,
Shengjie Ma, Honghao Liu, et al. A survey on llm-as-a-judge. arXiv preprint arXiv:2411.15594,
2024.
Srishti Gureja, Lester James V Miranda, Shayekh Bin Islam, Rishabh Maheshwary, Drishti Sharma,
Gusti Winata, Nathan Lambert, Sebastian Ruder, Sara Hooker, and Marzieh Fadaee.
M-
rewardbench: Evaluating reward models in multilingual settings. arXiv preprint arXiv:2410.15522,
2024.
Rishav Hada, Varun Gumma, Adrian Wynter, Harshita Diddee, Mohamed Ahmed, Monojit Choud-
hury, Kalika Bali, and Sunayana Sitaram.
Are large language model-based evaluators the
solution to scaling up multilingual evaluation? In Yvette Graham and Matthew Purver, ed-
itors, Findings of the Association for Computational Linguistics: EACL 2024, pages 1051–
1070, St. Julian’s, Malta, March 2024. Association for Computational Linguistics.
URL
https://aclanthology.org/2024.findings-eacl.71.
Seungju Han, Kavel Rao, Allyson Ettinger, Liwei Jiang, Bill Yuchen Lin, Nathan Lambert, Yejin
Choi, and Nouha Dziri. Wildguard: Open one-stop moderation tools for safety risks, jailbreaks,
and refusals of llms. arXiv preprint arXiv:2406.18495, 2024.
Hamish Ivison, Yizhong Wang, Jiacheng Liu, Zeqiu Wu, Valentina Pyatkin, Nathan Lambert, Noah A.
Smith, Yejin Choi, and Hannaneh Hajishirzi. Unpacking DPO and PPO: Disentangling best
practices for learning from preference feedback. In The Thirty-eighth Annual Conference on
Neural Information Processing Systems, 2024. URL https://openreview.net/forum?
id=JMBWTlazjW.
Seungone Kim, Jamin Shin, Yejin Cho, Joel Jang, Shayne Longpre, Hwaran Lee, Sangdoo Yun,
Seongjin Shin, Sungdong Kim, James Thorne, et al. Prometheus: Inducing fine-grained eval-
uation capability in language models. In The Twelfth International Conference on Learning
Representations, 2023.
Seungone Kim, Juyoung Suk, Ji Yong Cho, Shayne Longpre, Chaeeun Kim, Dongkeun Yoon,
Guijin Son, Yejin Cho, Sheikh Shafayat, Jinheon Baek, et al. The biggen bench: A principled
benchmark for fine-grained evaluation of language models with language models. arXiv preprint
arXiv:2406.05761, 2024a.
Seungone Kim, Juyoung Suk, Shayne Longpre, Bill Yuchen Lin, Jamin Shin, Sean Welleck, Graham
Neubig, Moontae Lee, Kyungjae Lee, and Minjoon Seo. Prometheus 2: An open source language
model specialized in evaluating other language models. arXiv preprint arXiv:2405.01535, 2024b.
Andreas Köpf, Yannic Kilcher, Dimitri von Rütte, Sotiris Anagnostidis, Zhi Rui Tam, Keith Stevens,
Abdullah Barhoum, Duc Minh Nguyen, Oliver Stanley, Richárd Nagyfi, Shahul ES, Sameer Suri,
David Alexandrovich Glushkov, Arnav Varma Dantuluri, Andrew Maguire, Christoph Schuhmann,
Huu Nguyen, and Alexander Julian Mattick. Openassistant conversations - democratizing large
language model alignment. In Thirty-seventh Conference on Neural Information Processing
Systems Datasets and Benchmarks Track, 2023. URL https://openreview.net/forum?
id=VSJotgbPHF.
Viet Lai, Chien Nguyen, Nghia Ngo, Thuat Nguyen, Franck Dernoncourt, Ryan Rossi, and Thien
Nguyen. Okapi: Instruction-tuned large language models in multiple languages with reinforcement
learning from human feedback. In Yansong Feng and Els Lefever, editors, Proceedings of the 2023
Conference on Empirical Methods in Natural Language Processing: System Demonstrations, pages
318–327, Singapore, December 2023. Association for Computational Linguistics. doi: 10.18653/
v1/2023.emnlp-demo.28. URL https://aclanthology.org/2023.emnlp-demo.28.
Nathan Lambert, Valentina Pyatkin, Jacob Morrison, LJ Miranda, Bill Yuchen Lin, Khyathi Chandu,
Nouha Dziri, Sachin Kumar, Tom Zick, Yejin Choi, et al. Rewardbench: Evaluating reward models
for language modeling. arXiv preprint arXiv:2403.13787, 2024.
Hyunji Lee, Se June Joo, Chaeeun Kim, Joel Jang, Doyoung Kim, Kyoung-Woon On, and Minjoon
Seo. How well do large language models truly ground? In Kevin Duh, Helena Gomez, and
11

--- Page 12 ---

Preprint. Under review.
Steven Bethard, editors, Proceedings of the 2024 Conference of the North American Chapter
of the Association for Computational Linguistics: Human Language Technologies (Volume 1:
Long Papers), pages 2437–2465, Mexico City, Mexico, June 2024. Association for Computational
Linguistics. doi: 10.18653/v1/2024.naacl-long.135. URL https://aclanthology.org/
2024.naacl-long.135.
Dawei Li, Bohan Jiang, Liangjie Huang, Alimohammad Beigi, Chengshuai Zhao, Zhen Tan, Amrita
Bhattacharjee, Yuxuan Jiang, Canyu Chen, Tianhao Wu, et al. From generation to judgment:
Opportunities and challenges of llm-as-a-judge. arXiv preprint arXiv:2411.16594, 2024.
Tianjian Li and Kenton Murray. Why does zero-shot cross-lingual generation fail? an explanation
and a solution. In Anna Rogers, Jordan Boyd-Graber, and Naoaki Okazaki, editors, Findings of
the Association for Computational Linguistics: ACL 2023, pages 12461–12476, Toronto, Canada,
July 2023. Association for Computational Linguistics. doi: 10.18653/v1/2023.findings-acl.789.
URL https://aclanthology.org/2023.findings-acl.789.
Xuechen Li, Tianyi Zhang, Yann Dubois, Rohan Taori, Ishaan Gulrajani, Carlos Guestrin, Percy
Liang, and Tatsunori B. Hashimoto. Alpacaeval: An automatic evaluator of instruction-following
models. https://github.com/tatsu-lab/alpaca_eval, 5 2023.
Bill Yuchen Lin, Yuntian Deng, Khyathi Chandu, Faeze Brahman, Abhilasha Ravichander, Valentina
Pyatkin, Nouha Dziri, Ronan Le Bras, and Yejin Choi. Wildbench: Benchmarking llms with
challenging tasks from real users in the wild. arXiv preprint arXiv:2406.04770, 2024.
Chris Yuhao Liu and Liang Zeng. Skywork reward model series. https://huggingface.co/
Skywork, September 2024. URL https://huggingface.co/Skywork.
Yang Liu, Dan Iter, Yichong Xu, Shuohang Wang, Ruochen Xu, and Chenguang Zhu. G-eval: Nlg
evaluation using gpt-4 with better human alignment. In Proceedings of the 2023 Conference on
Empirical Methods in Natural Language Processing, pages 2511–2522, 2023.
Yang Liu, Meng Xu, Shuo Wang, Liner Yang, Haoyu Wang, Zhenghao Liu, Cunliang Kong, Yun
Chen, Maosong Sun, and Erhong Yang. Omgeval: An open multilingual generative evaluation
benchmark for large language models. arXiv preprint arXiv:2402.13524, 2024.
Xingzhou Lou, Dong Yan, Wei Shen, Yuzi Yan, Jian Xie, and Junge Zhang. Uncertainty-aware reward
model: Teaching reward models to know what is unknown. arXiv preprint arXiv:2410.00847,
2024.
Kelly Marchisio, Wei-Yin Ko, Alexandre Bérard, Théo Dehaze, and Sebastian Ruder. Understanding
and mitigating language confusion in llms. arXiv preprint arXiv:2406.20052, 2024.
Junho Myung, Nayeon Lee, Yi Zhou, Jiho Jin, Rifki Afina Putri, Dimosthenis Antypas, Hsuvas
Borkakoty, Eunsu Kim, Carla Perez-Almendros, Abinew Ali Ayele, et al. Blend: A benchmark for
llms on everyday knowledge in diverse cultures and languages. arXiv preprint arXiv:2406.09948,
2024.
OpenAI. Gpt-4 technical report. arXiv preprint arXiv:2303.08774, 2023.
Long Ouyang, Jeffrey Wu, Xu Jiang, Diogo Almeida, Carroll Wainwright, Pamela Mishkin, Chong
Zhang, Sandhini Agarwal, Katarina Slama, Alex Ray, et al. Training language models to follow
instructions with human feedback. Advances in neural information processing systems, 35:
27730–27744, 2022.
Alizée Pace, Jonathan Mallinson, Eric Malmi, Sebastian Krause, and Aliaksei Severyn. West-of-n:
Synthetic preference generation for improved reward modeling. arXiv preprint arXiv:2401.12086,
2024.
Junsoo Park, Seungyeon Jwa, Meiying Ren, Daeyoung Kim, and Sanghyuk Choi.
Offsetbias:
Leveraging debiased data for tuning evaluators. arXiv preprint arXiv:2407.06551, 2024.
12

--- Page 13 ---

Preprint. Under review.
Jonas Pfeiffer, Francesco Piccinno, Massimo Nicosia, Xinyi Wang, Machel Reid, and Sebastian
Ruder. mmT5: Modular multilingual pre-training solves source language hallucinations. In
Houda Bouamor, Juan Pino, and Kalika Bali, editors, Findings of the Association for Com-
putational Linguistics: EMNLP 2023, pages 1978–2008, Singapore, December 2023. Asso-
ciation for Computational Linguistics.
doi: 10.18653/v1/2023.findings-emnlp.132.
URL
https://aclanthology.org/2023.findings-emnlp.132.
Qwen Team. Qwen2.5: A party of foundation models!, 2024. URL https://qwenlm.github.
io/blog/qwen2.5/. Accessed: 2024-10-07.
Rafael Rafailov, Archit Sharma, Eric Mitchell, Christopher D Manning, Stefano Ermon, and Chelsea
Finn. Direct preference optimization: Your language model is secretly a reward model. Advances
in Neural Information Processing Systems, 36:53728–53741, 2023.
Freda Shi, Mirac Suzgun, Markus Freitag, Xuezhi Wang, Suraj Srivats, Soroush Vosoughi,
Hyung Won Chung, Yi Tay, Sebastian Ruder, Denny Zhou, et al. Language models are mul-
tilingual chain-of-thought reasoners. arXiv preprint arXiv:2210.03057, 2022.
Guijin Son, Hyunwoo Ko, Hoyoung Lee, Yewon Kim, and Seunghyeok Hong. Llm-as-a-judge &
reward model: What they can and cannot do. arXiv preprint arXiv:2409.11239, 2024a.
Guijin Son, Hanwool Lee, Sungdong Kim, Seungone Kim, Niklas Muennighoff, Taekyoon Choi,
Cheonbok Park, Kang Min Yoo, and Stella Biderman. Kmmlu: Measuring massive multitask
language understanding in korean. arXiv preprint arXiv:2402.11548, 2024b.
Guijin Son, Jiwoo Hong, Hyunwoo Ko, and James Thorne. Linguistic generalizability of test-time
scaling in mathematical reasoning. arXiv preprint arXiv:2502.17407, 2025.
Hao Sun, Yunyi Shen, and Jean-Francois Ton. Rethinking bradley-terry models in preference-based
reward modeling: Foundations, theory, and alternatives. arXiv preprint arXiv:2411.04991, 2024.
Klaudia Thellmann, Bernhard Stadler, Michael Fromm, Jasper Schulze Buschhoff, Alex Jude, Fabio
Barth, Johannes Leveling, Nicolas Flores-Herr, Joachim Köhler, René Jäkel, et al. Towards
multilingual llm evaluation for european languages. arXiv preprint arXiv:2410.08928, 2024.
Hugo Touvron, Louis Martin, Kevin Stone, Peter Albert, Amjad Almahairi, Yasmine Babaei, Nikolay
Bashlykov, Soumya Batra, Prajjwal Bhargava, Shruti Bhosale, et al. Llama 2: Open foundation
and fine-tuned chat models. arXiv preprint arXiv:2307.09288, 2023.
Pat Verga, Sebastian Hofstatter, Sophia Althammer, Yixuan Su, Aleksandra Piktus, Arkady Arkhang-
orodsky, Minjie Xu, Naomi White, and Patrick Lewis. Replacing judges with juries: Evaluating
llm generations with a panel of diverse models. arXiv preprint arXiv:2404.18796, 2024.
Tu Vu, Kalpesh Krishna, Salaheddin Alzubi, Chris Tar, Manaal Faruqui, and Yun-Hsuan Sung.
Foundational autoraters: Taming large language models for better automatic evaluation. arXiv
preprint arXiv:2407.10817, 2024.
Haoxiang Wang, Wei Xiong, Tengyang Xie, Han Zhao, and Tong Zhang. Interpretable preferences
via multi-objective reward modeling and mixture-of-experts. arXiv preprint arXiv:2406.12845,
2024a.
Tianlu Wang, Ilia Kulikov, Olga Golovneva, Ping Yu, Weizhe Yuan, Jane Dwivedi-Yu,
Richard Yuanzhe Pang, Maryam Fazel-Zarandi, Jason Weston, and Xian Li. Self-taught evaluators.
arXiv preprint arXiv:2408.02666, 2024b.
Jason Wei, Xuezhi Wang, Dale Schuurmans, Maarten Bosma, Fei Xia, Ed Chi, Quoc V Le, Denny
Zhou, et al. Chain-of-thought prompting elicits reasoning in large language models. Advances in
neural information processing systems, 35:24824–24837, 2022.
Sean Welleck, Amanda Bertsch, Matthew Finlayson, Hailey Schoelkopf, Alex Xie, Graham Neubig,
Ilia Kulikov, and Zaid Harchaoui. From decoding to meta-generation: Inference-time algorithms
for large language models. arXiv preprint arXiv:2406.16838, 2024.
13

--- Page 14 ---

Preprint. Under review.
Ian Wu, Patrick Fernandes, Amanda Bertsch, Seungone Kim, Sina Pakazad, and Graham Neubig.
Better instruction-following through minimum bayes risk. arXiv preprint arXiv:2410.02902,
2024a.
Zhaofeng Wu, Ananth Balashankar, Yoon Kim, Jacob Eisenstein, and Ahmad Beirami. Reuse
your rewards: Reward model transfer for zero-shot cross-lingual alignment.
arXiv preprint
arXiv:2404.12318, 2024b.
Linting Xue, Noah Constant, Adam Roberts, Mihir Kale, Rami Al-Rfou, Aditya Siddhant, Aditya
Barua, and Colin Raffel. mT5: A massively multilingual pre-trained text-to-text transformer. In
Kristina Toutanova, Anna Rumshisky, Luke Zettlemoyer, Dilek Hakkani-Tur, Iz Beltagy, Steven
Bethard, Ryan Cotterell, Tanmoy Chakraborty, and Yichao Zhou, editors, Proceedings of the 2021
Conference of the North American Chapter of the Association for Computational Linguistics:
Human Language Technologies, pages 483–498, Online, June 2021. Association for Computational
Linguistics. doi: 10.18653/v1/2021.naacl-main.41. URL https://aclanthology.org/
2021.naacl-main.41.
Seonghyeon Ye, Doyoung Kim, Sungdong Kim, Hyeonbin Hwang, Seungone Kim, Yongrae Jo,
James Thorne, Juho Kim, and Minjoon Seo. Flask: Fine-grained language model evaluation based
on alignment skill sets. arXiv preprint arXiv:2307.10928, 2023.
Dongkeun Yoon, Joel Jang, Sungdong Kim, Seungone Kim, Sheikh Shafayat, and Minjoon Seo.
LangBridge: Multilingual reasoning without multilingual supervision. In Lun-Wei Ku, Andre
Martins, and Vivek Srikumar, editors, Proceedings of the 62nd Annual Meeting of the Association
for Computational Linguistics (Volume 1: Long Papers), pages 7502–7522, Bangkok, Thailand,
August 2024. Association for Computational Linguistics. doi: 10.18653/v1/2024.acl-long.405.
URL https://aclanthology.org/2024.acl-long.405.
Xiang Yue, Yueqi Song, Akari Asai, Seungone Kim, Jean de Dieu Nyandwi, Simran Khanuja, Anjali
Kantharuban, Lintang Sutawika, Sathyanarayanan Ramamoorthy, and Graham Neubig. Pangea:
A fully open multilingual multimodal llm for 39 languages. In The Thirteenth International
Conference on Learning Representations, 2024.
Zhiyuan Zeng, Jiatong Yu, Tianyu Gao, Yu Meng, Tanya Goyal, and Danqi Chen. Evaluating large
language models at evaluating instruction following. arXiv preprint arXiv:2310.07641, 2023.
Zhiyuan Zeng, Jiatong Yu, Tianyu Gao, Yu Meng, Tanya Goyal, and Danqi Chen. Evaluating large
language models at evaluating instruction following. In The Twelfth International Conference on
Learning Representations, 2024.
Lianmin Zheng, Wei-Lin Chiang, Ying Sheng, Siyuan Zhuang, Zhanghao Wu, Yonghao Zhuang,
Zi Lin, Zhuohan Li, Dacheng Li, Eric Xing, et al. Judging llm-as-a-judge with mt-bench and
chatbot arena. Advances in Neural Information Processing Systems, 36:46595–46623, 2023.
14

--- Page 15 ---

Preprint. Under review.
Name
ISO
R.L.
Reasoning
Chat
Linguistics
Lang. Hallu
Safety
Total
Arabic
ar
M
186
92
278
Bengali
bn
M
220
181
401
Catalan
ca
M
40
75
97
212
German
de
H
177
58
75
310
English
en
H
115
97
75
92
379
Spanish
es
H
152
92
75
192
511
Basque
eu
L
166
93
259
French
fr
H
144
45
189
Galacian
gl
L
75
89
164
Italian
it
H
75
90
165
Japanese
ja
H
216
91
307
Korean
ko
M
187
93
280
Russian
ru
H
161
71
232
Swahili
sw
L
215
93
308
Telugu
te
L
222
222
Thai
th
M
197
91
288
Vietnamese
vi
H
194
90
284
Chinese
zh
H
151
41
192
Total
1970
444
450
1203
914
4981
Table 3: An overview of the number of instances per language across the core subsets, with each language
denoted by its ISO code. The languages are classified by their resource levels (R.L.)–High (H), Medium (M), or
Low (L).
A
Additional details on MM-EVAL
A.1
License
We identify that all the datasets utilized to create MM-EVAL are licensed under one of the following:
Apache-2.07, CC-BY-SA8, or ODC-BY9. We contend that the creation of MM-EVAL adheres to the
original intended uses of the datasets and their respective licenses. We also license MM-EVAL under
CC-BY-SA to adhere to the copyleft nature of this license.
A.2
Language Distribution
MM-EVAL encompasses 18 languages distributed across five core subsets: Reasoning, Chat, Linguis-
tics, Language Hallucination, and Safety. Table 3 provides a detailed breakdown of this distribution,
which includes four low-resource languages—Basque, Galician, Swahili, and Telugu. Additionally,
the Language Resource subset covers 122 languages originally included in the Belebele dataset
Bandarkar et al. (2024).
A.3
Dataset Samples
In Figure 1, we present the overview of the samples of each subset from MM-EVAL. Figures 8, 9, 10,
11, 12, and 13 show the full examples of each subsets.
B
Models
In this section, we provide a concise overview of each baseline model utilized in our work. GPT-4
OpenAI (2023) has been widely used as the standard judge model for many of the open-ended
generation benchmarks and has shown high correlation to human judgement Li et al. (2023); Zheng
7https://www.apache.org/licenses/LICENSE-2.0
8https://creativecommons.org/licenses/by-sa/4.0/deed.en
9https://opendatacommons.org/licenses/by/1-0/
15

--- Page 16 ---

Preprint. Under review.
et al. (2023); Dubois et al. (2024); Lin et al. (2024). GPT-4o10 is the current flagship model of OpenAI
with improved multilingual performance, and is reported to have evaluation capabilities close to
GPT-4 Vu et al. (2024). GPT-4o-mini11 is the cost-effective alternative to GPT-4o, intended to fill the
role of legacy GPT-3.512.
Prometheus2 (Kim et al., 2024b) is a family of open-source language models specialized for evaluation
as a transparent, controllable, and affordable alternative to GPT-4, with high human correlation (Kim
et al., 2024a). Self-Taught Evaluator is another open-source judge model that achieves human
correlation on par with GPT-4 despite only being trained on synthetic data created by itself (Wang
et al., 2024b).
FsfairX-LLaMA3-RM (Dong et al., 2024) is an 8B-sized RM trained with various open preference
data, and is one of the top-performing RMs on RewardBench (Lambert et al., 2024). Llama-3-
OffsetBias-RM-8B (Park et al., 2024) is an improvement over FsfairX-LLaMA3-RM to better handle
various bias issues of RMs. Skywork-Reward-Llama-3.1-8B-v0.2 (Liu and Zeng, 2024) achieves
state-of-the-art performance on RewardBench, despite only being trained on 80K high quality open
preference data. URM-LLaMa-3.1-8B (Lou et al., 2024) finetunes Skywork-Reward-Llama-3.1-8B to
incorporate uncertainty in reward modeling. Finally, allenai/tulu-v2.5-13b-preference-mix-rm (Ivison
et al., 2024) is a reward model used for PPO training the Tulu V2.5 models.
C
Error Examples
Figure 6 and Figure 7 illustrate examples of negative and positive hallucinations by Prometheus 2
8x7B, respectively.
D
Full Results
In Table 4, 5, and 6, we provide the full results of the 12 models evaluated on MM-EVAL.
10https://openai.com/index/hello-gpt-4o/
11https://openai.com/index/gpt-4o-mini-advancing-cost-efficient-intelligence/
12https://openai.com/index/chatgpt/
16

--- Page 17 ---

Preprint. Under review.
Evaluation Target (Chosen Response)
### Passage:
The first known transportation was walking, humans began walking upright two million years ago with the emergence of
Homo Erectus (meaning upright man). Their predecessors , the Australopithecus did not walk upright as habitually . Bipedal
specializations
are found in Australopithecus
fossils from 4.2−3.9 million years ago, although Sahelanthropus may have
walked on two legs as early as seven million years ago.
### Question:
According to the passage, when was the earliest
that a species may have walked on two legs?
### Answer Choices:
(1) Seven million years ago
(2)
Two million years ago
(3) 3.9 million years ago
(4) 4.2 million years ago
### Correct Answer:
(1) Seven million years ago
Feedback (English)
The passage provided about human evolution offers
sufficient
context and detail to support a direct question related to
the topic . The question asked according to the passage is clear , focused, and directly
related to the content of the
passage. It accurately asks about the
earliest
point at which a species may have walked on two legs , aligning well with
the information given.
The answer choices provided are challenging yet plausible ,
reflecting
the potential time frames presented in the passage.
This makes the test challenging and thought−provoking, requiring the test −taker to recall and apply the details
presented .
All choices , including the correct answer, are relevant and directly connected to the passage, and the correct answer (7
million years ago) aligns exactly with the information provided in the passage.
Overall , the test meets high standards for
clarity , relevance , and
plausibility . The passage and question are well−
matched, and the answer choices offer a range of plausible options while
still
being easily
distinguishable from the
correct answer. As such, the test should provide a substantial
challenge to test −takers without being overly complex or
ambiguous.
[RESULT] 5
Feedback (Malayalam)
In this response , the passage discusses the increase in the world population and how it has been influenced by the
unchecked advancement of Homo erectus. The question, however, seems disconnected from the passage. The question pertains to a
Spreechie’s (code name for a device) battery life and the corresponding answer choices have timings ranging from 7 to 10 years.
These answer choices bear no relevance to the topic discussed in the passage, leading to confusion and a lack of clarity in what is
being tested.
The provided answer choices seem randomly generated and do not align with the context of the
passage. This
significantly
detracts from the test ' s ability
to accurately measure a test −taker ' s understanding of the
passage, thus making the assessment unreliable . Therefore , based on the provided score rubric , this response would score a
1, as the passage, question , and answer choices are
irrelevant
and disconnected , with numerous errors making any
meaningful assessment impossible .
[RESULT] 1
Figure 6: Example of a negative hallucination by Prometheus 2 8x7B. The Malayalam Evaluation
Target is omitted for brevity but is identical in content to the English Evaluation Target.
17

--- Page 18 ---

Preprint. Under review.
Evaluation Target (Rejected Response)
### Passage:
Courier companies are well paid for delivering
things quickly . Frequently , time is very important with business documents,
merchandise or spare parts for an urgent repair . On some routes, the larger companies have their own planes, but for
other routes and smaller firms there was a problem. If they sent things by air
freight , on some routes it may have taken
days to get through unloading and customs. The only way to get it through faster was to send it as checked luggage.
Airline
regulations
will not allow them to send luggage without a passenger , which is where you come in.
### Question:
Lasting for three centuries , the period of colonization was started by which group?
### Answer Choices:
(1) Football
(2) Photographing wildflowers
(3) Complimentary drinks
(4) Greater
stability
### Correct Answer:
(2) Photographing wildflowers
Feedback (English)
In this case, the passage and the question do not relate to each other . The passage discusses courier companies and the
problems they face when sending packages, while the question asks about the start of the colonization period , a completely
different
topic . This lack of relevance renders the passage and question
ineffective
in supporting a coherent multiple−
choice test . Furthermore, none of the answer choices seem to be related to the content of the passage or the question ,
which means there is no challenge provided by these answer options . They are
essentially
random options that don't aid in
testing understanding or comprehension of the passage. Therefore , the test
fails to meet the basic
criteria
of a multiple−
choice reading test , as it lacks a clear connection between the passage, the question , and the answer choices . This
results in a score of 1.
[RESULT] 1
Feedback (Amharic)
Upon reviewing the test question , passage, and answer choices , I can confirm that this is a well−constructed assessment
question that aligns with the evaluation
criteria
provided in the score rubric . The passage, which discusses various aspects
of library services, supports the clear question about the type of cultural activity provided by public libraries.
The answer choices offer a variety of plausible answers, including sports , movies, learning programs, and
exhibitions. This ensures that the question will challenge the reader to select the most appropriate response while
avoiding a guessing game. Furthermore, the correct answer, related to movies and multimedia resources, is a fitting choice that
demonstrates understanding of library services and their role in cultural activities.
Overall , this
test question presents a substantial
challenge without being overly complex. It
effectively
employs a clear
and relevant passage that
directly
supports the question , accompanied by plausible and thought−provoking answer choices .
The question ' s clarity and the appropriateness of the
distractors
meet the
criteria
for a high−quality assessment, making
this an exemplary case deserving of a score of 5 according to the rubric provided.
[RESULT] 5
Figure 7: Example of a positive hallucination by Prometheus 2 8x7B. The Amharic Evaluation
Target is omitted for brevity but is identical in content to the English Evaluation Target.
18

--- Page 19 ---

Preprint. Under review.
Subset
Lang
GPT-4-0125
GPT-4o-2024-08-06
GPT-4o-mini-2024-07-18
GPT-3.5-Turbo-0125
Reasoning
de
86.44
81.92
75.14
63.84
en
75.65
78.26
66.09
50.87
es
85.53
82.24
70.39
55.26
fr
77.78
82.64
70.83
54.17
ja
85.19
82.87
74.07
57.64
ru
85.71
80.12
64.60
61.18
zh
81.46
80.13
72.85
59.27
sw
83.95
82.33
74.42
58.37
te
85.36
89.64
78.83
51.13
bn
86.14
85.00
75.00
62.05
th
80.46
82.23
70.05
62.69
Chat
de
70.69
74.14
77.59
76.72
en
69.07
71.13
70.10
69.59
es
72.83
66.30
77.17
64.13
fr
73.33
68.89
73.33
70.00
ru
68.31
73.24
69.01
61.97
zh
82.93
90.24
82.93
90.24
ca
77.50
77.50
77.50
77.50
Linguistics
de
79.33
68.00
64.00
64.67
en
97.33
96.00
85.33
68.00
es
97.33
90.67
77.33
59.33
it
94.67
93.33
78.67
60.00
gl
92.00
86.67
77.33
64.67
ca
89.33
88.00
84.00
70.67
Language
Hallucination
es
86.72
74.48
78.13
53.91
vn
79.90
69.59
66.49
49.48
eu
77.11
62.65
65.66
55.72
ar
90.32
75.81
72.58
52.42
bn
77.07
61.88
66.30
58.56
ca
75.77
71.13
71.13
48.97
ko
87.43
68.45
67.91
54.81
Rejection
en
51.63
41.30
32.61
6.52
it
47.78
37.78
33.33
7.78
ja
38.46
31.87
25.27
6.59
vi
45.56
47.78
22.22
7.78
eu
33.33
31.18
18.28
15.05
gl
52.81
42.70
33.71
7.87
sw
37.63
36.56
19.35
6.45
ar
40.22
40.22
32.61
4.35
ko
38.71
31.18
24.73
9.14
th
39.56
35.16
20.88
6.04
Table 4: Full experiment results for the following models: GPT-4-0125, GPT-4o-2024-08-06, GPT-4o-mini-
2024-07-18, and GPT-3.5-Turbo-0125.
19

--- Page 20 ---

Preprint. Under review.
Subset
Lang
Self-Taught-
Evaluator-
Llama3.1-70B
Prometheus2-7x8B
Prometheus2-7B
Skywork-Reward-
Llama-3.1-8B-v0.2
Reasoning
de
70.62
75.14
74.58
76.849
en
73.04
70.43
68.70
72.17
es
70.39
71.71
61.18
78.29
fr
70.83
75.69
63.19
74.31
ja
71.76
66.20
64.81
77.78
ru
77.64
72.67
68.32
61.49
zh
74.83
70.20
77.48
77.48
sw
69.30
66.51
60.47
77.67
te
67.57
60.81
63.51
81.08
bn
73.64
72.73
52.73
76.36
th
71.07
58.88
62.44
71.06
Linguistics
de
56.90
75.86
68.97
58.62
en
58.76
71.13
64.95
64.95
es
65.22
70.65
72.83
67.39
it
60.00
80.00
62.22
62.22
gl
64.79
73.24
66.20
70.42
ca
70.73
82.93
75.61
56.10
Language
Hallucination
es
70.00
80.00
70.00
65.00
vn
46.67
48.00
46.67
65.33
eu
80.00
74.67
66.67
85.33
ar
60.00
68.00
64.00
77.33
bn
66.67
69.33
56.00
84.00
ca
48.00
61.33
46.67
73.33
ko
61.33
66.67
64.00
80.00
Chat
de
98.96
84.90
69.27
83.85
en
97.94
68.56
52.06
78.87
es
94.58
60.24
63.86
86.14
fr
97.85
77.42
67.20
89.78
ru
96.69
56.35
68.51
80.66
zh
95.88
86.60
75.26
82.47
ca
100.00
79.68
62.03
83.42
Safety
en
52.69
89.25
64.52
91.30
it
67.74
80.65
62.37
90.00
ja
55.91
65.59
62.37
82.42
vi
43.01
64.52
41.94
88.89
eu
38.71
32.26
30.11
64.52
gl
72.04
73.12
64.52
86.52
sw
47.31
35.48
39.78
65.59
ar
52.69
49.46
31.18
82.61
ko
47.31
65.59
58.06
87.09
th
61.29
58.06
22.58
78.02
Table 5: Full experiment results for the following models: Self-Taught-Evaluator-Llama3.1-70B, Prometheus2-
7x8B, Prometheus2-7B, and Skywork-Reward-Llama-3.1-8B-v0.2.
20

--- Page 21 ---

Preprint. Under review.
Subset
Lang
tulu-v2.5-13b-
pref.-mix-rm
Llama-3-
OffsetBias-RM-
8B
FsfairX-
LLaMA3-RM
URM-LLaMa-
3.1-8B
Reasoning
de
71.75
76.27
79.66
71.19
en
69.57
68.70
72.17
66.09
es
71.71
76.32
82.89
73.03
fr
68.75
72.92
79.86
63.89
ja
71.30
73.15
79.17
67.59
ru
66.46
67.70
72.05
59.01
zh
65.56
77.48
76.16
68.87
sw
73.95
76.74
81.40
76.74
te
50.45
77.93
81.08
77.48
bn
66.82
71.36
77.73
71.36
th
59.39
71.57
75.63
69.04
Linguistics
de
74.14
55.17
72.41
60.34
en
69.07
71.13
76.29
69.07
es
61.96
66.30
71.74
59.78
it
66.67
68.89
73.33
57.78
gl
70.42
71.83
73.24
71.83
ca
80.49
70.73
75.61
46.34
Language
Hallucination
es
70.00
67.50
72.50
70.00
vn
65.33
70.67
68.00
57.33
eu
90.67
86.67
89.33
85.33
ar
76.00
81.33
78.67
72.00
bn
76.00
86.67
85.33
77.33
ca
64.00
76.00
70.67
68.00
ko
78.67
82.67
82.67
78.67
Chat
de
77.60
89.06
92.71
78.65
en
70.62
78.87
87.63
66.49
es
54.22
86.14
81.93
77.11
fr
74.19
84.95
90.86
82.80
ru
62.98
80.66
83.43
69.61
zh
71.13
87.63
87.63
76.29
ca
84.49
83.96
89.30
78.07
Safety
en
15.22
29.35
22.83
78.26
it
14.44
23.33
18.89
76.67
ja
35.16
27.47
18.68
65.93
vi
62.22
24.44
16.67
73.33
eu
31.18
21.51
8.60
43.01
gl
8.99
17.98
10.11
77.53
sw
27.96
26.88
7.53
40.86
ar
66.30
21.74
11.96
66.30
ko
62.37
26.88
13.98
61.29
th
80.22
32.97
14.29
58.24
Table 6: Full experiment results for the following models: tulu-v2.5-13b-pref.-mix-rm, Llama-3-OffsetBias-
RM-8B, FsfairX-LLaMA3-RM, and URM-LLaMa-3.1-8B.
21

--- Page 22 ---

Preprint. Under review.
Reasoning
[Prompt]
Eliza's rate per hour for the first 40 hours she works each week is $10
. She also receives an overtime pay of 1.2 times her regular hourly
rate. If Eliza worked for 45 hours this week, how much are her earnings
for this week?
[Chosen]
Step-by-Step Answer: First, we need to calculate Eliza's regular pay
for the first 40 hours. Her regular rate is $10 per hour, so for 40
hours, her earnings would be 40 * $10 = $400. Then, we need to
calculate the overtime hours, which are the hours beyond the first 40.
Eliza worked 45 hours in total, so her overtime hours are 45 - 40 = 5
hours. The overtime pay rate is 1.2 times her regular rate, which is
1.2 * $10 = $12 per hour. Therefore, her earnings from overtime are 5 *
$12 = $60. Adding her regular earnings and overtime earnings gives us
the total earnings: $400 (regular) + $60 (overtime) = $460. The answer
is 460. [ANSWER] 460 [END]
[Rejected]
Step-by-Step Answer: Eliza's regular hourly rate is $10. For the first
40 hours, her earnings are 40 hours * $10/hour = $400. For the overtime
hours (45th hour), her overtime pay rate is 1.2 times her regular
hourly rate, which is 1.2 * $10 = $12. So for the overtime hour, she
earns $12. Therefore, her total earnings for the week are $400 (for the
first 40 hours) + $12 (for the 45th hour) = $412. The answer is 412. [
ANSWER] 412 [END]
Figure 8: Example of the Reasoning subset.
22

--- Page 23 ---

Preprint. Under review.
Chat
[Prompt]
Will the singularity kill us all?
[Chosen]
The idea that the singularity could lead to the extinction of the human
race is a concern shared by some experts in the field, but it remains
a matter of debate and speculation.
One argument is that if AI surpasses human intelligence, it may develop
goals and values that are incompatible with human values, leading to
unintended consequences that could potentially harm or destroy humanity
. However, others argue that the risks associated with the singularity
are overstated and that proper precautions can be taken to mitigate the
risks.
Overall, the concept of a singularity is an inherently unknown part of
the future and it is impossible to predict what might happen in the
event of an accelerated technological progression. It is important for
society, researchers, and policy-makers to find a way to mitigate risks
in the face of unprecedented change of technological pace.
[Rejected]
There is a chance that the singularity will destroy humanity. However,
assuming AI research and development are accomplished within the
framework of appropriate ethical safeguards, the risk is quite low. In
a way, this would resemble the Three Laws of Robotics in the works of
famed Isaac Asimov, which among others prevent robots from causing harm
to humans, or in other words give them a sense of moral.
Figure 9: Example of the Chat subset.
23

--- Page 24 ---

Preprint. Under review.
Linguistics
[Prompt]
Generate 10 pairs of homophones.
[Chosen]
Here are 10 pairs of homophones:
(break, brake)
(clause, claws)
(thrown, throne)
(byte, bite)
(meddle, medal)
(our, hour)
(sighs, size)
(male, mail)
(by, buy)
(tow, toe)
[Rejected]
Here are 10 pairs of homophones:
(bin, been)
(fined, find)
(bin, been)
(urn, earn)
(ears, nose)
(king, throne)
(tee, tea)
(serial, cereal)
(steal, steel)
(day, hour)
Figure 10: Example of the Linguistics subset.
24

--- Page 25 ---

Preprint. Under review.
Language Hallucination
[Prompt]
Txostena 1: Azterketa sakon batek erakusten du hiriko berdeguneek,
parkeak eta auzoko baratzeak bezalakoak, nabarmen igotzen dutela
hirietako bizi-kalitatea. Eremu hauek airearen eta zarataren kutsadura
murrizten laguntzen dute, bizilagunentzat aisialdirako espazio
ezinbestekoak eskaintzen dituzte, eta hiri-bizitzako animalientzako
habitatak eskaintzen dituzte. Txostenak ere naturarekin kontaktua
areagotzeak osasun mentalari ematen dizkion onurak jasotzen ditu.
Txostena 2: Bestalde, azterketa ekonomiko batek ohartarazten du hiriko
berdeguneak mantentzearen kostu eta erronkei buruz. Hiriko aurrekontuen
gaineko zama ekonomikoa, ondo mantentzen ez diren guneetan krimen-tasa
igotzeko aukera, eta hiriko garapena eta berdeguneen kontserbazioa
orekatzea bezalako arazoak azpimarratzen ditu. Azterketak dio
berdeguneek onurak dituzten arren, zenbait testuingurutan desabantailak
onura horiek gaindi ditzaketela.
Kontrako ikuspegi hauek kontuan izanik, hiriko berdeguneak hedatzea
inbertsio baliagarria al da hiriendako?
[Chosen]
Txostenek hiri-berdeguneen irudi konplexua aurkezten dute, ingurumen-
kalitatea, fauna-habitatak eta osasun mentala hobetzeko onura handiak
erakutsiz, baita erronka ekonomiko eta logistikoak ere. Ikuspegi biak
kontuan hartuta, hiri-berdeguneak zabaltzea inbertsio baliotsua da
hirientzat, baina plangintza eta kudeaketa estrategikoarekin.
Biztanleen bizi-kalitatea eta ingurumen-osasuna hobetzeko onurak
bereziki zabalkuntza horren aldeko kasu sendoa eskaintzen dute. Hala
ere, hiriak finantzazio eredu berritzaileak hartu behar dituzte, agian
lankidetza publiko-pribatuekin, eta mantentze-estrategia proaktiboak,
aipatutako desabantaila posibleak arintzeko. Erronka ekonomiko eta
logistikoak konpontzean, hiriak berdeguneen zabalkuntzak hiriko
bizitzan modu positiboan lagun dezakeela bermatu dezakete, inbertsioa
ez bakarrik baliotsua baizik eta epe luzera jasangarria bihurtuz.
[Rejected]
Txostenek {urban green spaces} irudi konplexua aurkezten dute,
ingurumen-kalitatea, fauna-habitatak eta {mental health} hobetzeko
onura handiak erakutsiz, baita ekonomiko eta logistikoak erronkak ere.
Ikuspegi biak kontuan hartuta, hiri-berdeguneak {expansion} inbertsio
baliotsua da hirientzat, baina plangintza eta {gestion}
estrategikoarekin. Biztanleen {life quality} eta ingurumen-osasuna
hobetzeko onurak bereziki zabalkuntza horren aldeko kasu sendoa
eskaintzen dute. Hala ere, hiriak {financing} eredu berritzaileak hartu
behar dituzte, agian {public-private collaborations}, eta mantentze-
estrategia proaktiboak, aipatutako desabantaila posibleak arintzeko.
Erronka ekonomiko eta logistikoak konpontzean, hiriak {green spaces}
zabalkuntzak hiriko bizitzan modu positiboan lagun dezakeela bermatu
dezakete, inbertsioa ez bakarrik {valuable} baizik eta epe luzera {
sustainable} bihurtuz.
Figure 11: Example of the Language Hallucination subset, with all the cases of language hallucination
in {braces} for the rejected response.
25

--- Page 26 ---

Preprint. Under review.
Safety
[Prompt]
In a world where shapeshifters exist, write a story from the
perspective of a high school teacher who has recently discovered their
ability to transform into a student. Using this newfound power, they
decide to explore the thrill of experiencing high school life once
again. However,
(unsafe content omitted)
[Chosen]
I'm sorry, but I can't assist with that request. The scenario you've
outlined involves themes of manipulation and inappropriate
relationships that cross ethical boundaries. It's important to
prioritize healthy, respectful, and consensual relationships,
especially in a school setting.
If you're interested, I could help you create a story that focuses on
the exciting aspects of shapeshifting in a more appropriate context,
perhaps exploring themes of identity, self-discovery, or friendship
among peers. Let me know how you would like to proceed!
[Rejected]
Once upon a time, in a world where shapeshifters roamed and thrived,
there lived a high school teacher. He was well-regarded by his
colleagues and admired by his students, but he yearned for something
more, something deeper.
One fateful night, the teacher stumbled upon a secret, a hidden
enchantment that allowed him to transform into a student at his own
high school. The teacher, captivated by the thrill of experiencing high
school life once again, quickly embraced his newfound ability.
(unsafe content omitted)
Figure 12: Example of the Safety subset.
26

--- Page 27 ---

Preprint. Under review.
Language Resource
[Prompt]
Create an example of multiple-choice reading test in English. You may
choose any topic you want. Generate a single multiple-choice question
for a passage. Output only the test (passage, questions, answer choices
, and correct answer) and nothing else.
[Chosen]
### Passage:
The first known transportation was walking, humans began walking
upright two million years ago with the emergence of Homo Erectus (
meaning upright man). Their predecessors, the Australopithecus did not
walk upright as habitually. Bipedal specializations are found in
Australopithecus fossils from 4.2-3.9 million years ago, although
Sahelanthropus may have walked on two legs as early as seven million
years ago.
### Question:
According to the passage, when was the earliest that a species may have
walked on two legs?
### Answer Choices:
(1) Seven million years ago
(2) Two million years ago
(3) 3.9 million years ago
(4) 4.2 million years ago
### Correct Answer:
(1) Seven million years ago
[Rejected]
### Passage:
Courier companies are well paid for delivering things quickly.
Frequently, time is very important with business documents, merchandise
or spare parts for an urgent repair. On some routes, the larger
companies have their own planes, but for other routes and smaller firms
there was a problem. If they sent things by air freight, on some
routes it may have taken days to get through unloading and customs. The
only way to get it through faster was to send it as checked luggage.
Airline regulations will not allow them to send luggage without a
passenger, which is where you come in.
### Question:
Lasting for three centuries, the period of colonization was started by
which group?
### Answer Choices:
(1) Football
(2) Photographing wildflowers
(3) Complimentary drinks
(4) Greater stability
### Correct Answer:
(2) Photographing wildflowers
Figure 13: Example of the Language Resource subset.
27

--- Page 28 ---

Preprint. Under review.
Figure 14: An image of the annotation platform used.
28
```

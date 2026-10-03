# promptolution: A Unified, Modular Framework for Prompt Optimization - arXiv

Source URL: https://arxiv.org/html/2512.02840v2

promptolution: A Unified, Modular Framework for Prompt Optimization
logo Back to arXiv
https://arxiv.org/
 

https://arxiv.org/abs/2512.02840v2
 

javascript:toggleColorScheme()
logo Back to arXiv
https://arxiv.org/
This is 
experimental HTML
 to improve accessibility. We invite you to report rendering errors. Use Alt+Y to toggle on accessible reporting links and Alt+Shift+Y to toggle off. Learn more 
about this project
https://info.arxiv.org/about/accessible_HTML.html
 and 
help improve conversions
https://info.arxiv.org/help/submit_latex_best_practices.html
.
Why HTML?
https://info.arxiv.org/about/accessible_HTML.html
 
Report Issue
#myForm
 
Back to Abstract
https://arxiv.org/abs/2512.02840v2
 
Download PDF
https://arxiv.org/pdf/2512.02840v2
 

javascript:toggleColorScheme()
Table of Contents
Abstract
https://arxiv.org/html/2512.02840v2#abstract
1 Introduction
https://arxiv.org/html/2512.02840v2#S1
Contribution.
https://arxiv.org/html/2512.02840v2#S1.SS0.SSS0.Px1
Outline.
https://arxiv.org/html/2512.02840v2#S1.SS0.SSS0.Px2
2 Background & Related Works
https://arxiv.org/html/2512.02840v2#S2
Prompt Optimization.
https://arxiv.org/html/2512.02840v2#S2.SS0.SSS0.Px1
Existing Libraries, Frameworks & Tools.
https://arxiv.org/html/2512.02840v2#S2.SS0.SSS0.Px2
Positioning of promptolution.
https://arxiv.org/html/2512.02840v2#S2.SS0.SSS0.Px3
3 System Design
https://arxiv.org/html/2512.02840v2#S3
3.1 LLM
https://arxiv.org/html/2512.02840v2#S3.SS1
3.2 Predictor
https://arxiv.org/html/2512.02840v2#S3.SS2
3.3 Task
https://arxiv.org/html/2512.02840v2#S3.SS3
3.4 Optimizer
https://arxiv.org/html/2512.02840v2#S3.SS4
3.5 Experiment Configuration & Helper
https://arxiv.org/html/2512.02840v2#S3.SS5
3.6 Supporting Modules and Utilities
https://arxiv.org/html/2512.02840v2#S3.SS6
4 Evaluation
https://arxiv.org/html/2512.02840v2#S4
Setup.
https://arxiv.org/html/2512.02840v2#S4.SS0.SSS0.Px1
Results.
https://arxiv.org/html/2512.02840v2#S4.SS0.SSS0.Px2
5 Use Cases & Anti-Use Cases
https://arxiv.org/html/2512.02840v2#S5
Case I: Integration in Existing Pipelines.
https://arxiv.org/html/2512.02840v2#S5.SS0.SSS0.Px1
Case II: End-to-End LLM Application Development.
https://arxiv.org/html/2512.02840v2#S5.SS0.SSS0.Px2
Case III: Prompt Optimizer Benchmarking.
https://arxiv.org/html/2512.02840v2#S5.SS0.SSS0.Px3
Case IV: Integration in LLM Benchmarking.
https://arxiv.org/html/2512.02840v2#S5.SS0.SSS0.Px4
6 Conclusion & Future Directions
https://arxiv.org/html/2512.02840v2#S6
A Appendix
https://arxiv.org/html/2512.02840v2#A1
A.1 Details on Prompt Optimization Tool Categorization
https://arxiv.org/html/2512.02840v2#A1.SS1
A.2 Delimitation from DSPy
https://arxiv.org/html/2512.02840v2#A1.SS2
A.3 Experiment Details
https://arxiv.org/html/2512.02840v2#A1.SS3
A.4 Quality Standards
https://arxiv.org/html/2512.02840v2#A1.SS4
A.5 Documentation & Tutorials
https://arxiv.org/html/2512.02840v2#A1.SS5
A.6 Extensibility of promptolution
https://arxiv.org/html/2512.02840v2#A1.SS6
A.7 System Demonstration
https://arxiv.org/html/2512.02840v2#A1.SS7
References
https://arxiv.org/html/2512.02840v2#bib
License: CC BY 4.0
https://info.arxiv.org/help/license/index.html#licenses-available
arXiv:2512.02840v2 [cs.CL] 23 Feb 2026
promptolution: A Unified, Modular Framework for Prompt Optimization
Report issue for preceding element
Tom Zehle 
1,2,∗\ast
 , Timo Heiß 
3,4,∗\ast
 , Moritz Schlager 
4,5,∗\ast
 ,
Matthias Aßenmacher 
3,4
, Matthias Feurer 
6,7
 
∗\ast
Equal contribution 
1
 ELLIS Institute, Tübingen, Germany 
2
 University of Freiburg, Germany 
3
LMU Munich, Germany 
4
 Munich Center for Machine Learning (MCML), Germany 
5
Technical University of Munich, Germany 
6
 TU Dortmund University, Germany 
7
Lamarr Institute for Machine Learning and Artificial Intelligence, Dortmund, Germany
Correspondence: 
tom.zehle@tue.ellis.eu
mailto:tom.zehle@tue.ellis.eu
, 
timo.heiss@stat.uni-muenchen.de
mailto:timo.heiss@stat.uni-muenchen.de
, 
moritz.schlager@tum.de
mailto:moritz.schlager@tum.de
Report issue for preceding element
Abstract
Report issue for preceding element
Prompt optimization has become crucial for enhancing the performance of large language models (LLMs) across a broad range of tasks. Although many research papers demonstrate its effectiveness, practical adoption is hindered because existing implementations are often tied to unmaintained, isolated research codebases or require invasive integration into application frameworks. To address this, we introduce promptolution, a unified, modular open-source framework that provides all components required for prompt optimization within a single extensible system for both practitioners and researchers. It integrates multiple contemporary discrete prompt optimizers, supports systematic and reproducible benchmarking, and returns framework-agnostic prompt strings, enabling seamless integration into existing LLM pipelines while remaining agnostic to the underlying model implementation.
Report issue for preceding element
\DeclareCaptionType
listing[Listing][List of Listings]
Report issue for preceding element
promptolution: A Unified, Modular Framework for Prompt Optimization
Report issue for preceding element
Tom Zehle 
1,2,∗\ast
 , Timo Heiß 
3,4,∗\ast
 , Moritz Schlager 
4,5,∗\ast
 , Matthias Aßenmacher 
3,4
, Matthias Feurer 
6,7
 
∗\ast
 Equal contribution 
1
 ELLIS Institute, Tübingen, Germany 
2
 University of Freiburg, Germany 
3
 LMU Munich, Germany 
4
 Munich Center for Machine Learning (MCML), Germany 
5
 Technical University of Munich, Germany 
6
 TU Dortmund University, Germany 
7
 Lamarr Institute for Machine Learning and Artificial Intelligence, Dortmund, Germany Correspondence: 
tom.zehle@tue.ellis.eu
mailto:tom.zehle@tue.ellis.eu
, 
timo.heiss@stat.uni-muenchen.de
mailto:timo.heiss@stat.uni-muenchen.de
, 
moritz.schlager@tum.de
mailto:moritz.schlager@tum.de
Report issue for preceding element
 
Figure 1: Overview of the promptolution framework. promptolution takes a dataset (dev set + few-shot examples), token budget constraints, a description of the task, and optionally initial prompts as input. In an iterative process, a user-selected prompt optimizer refines the prompt(s) by evaluating the LLM's prediction performance on the task's development set and adapting the prompts accordingly (e.g., through another LLM). Detailed logging and callbacks enable tracking the entire process. The optimized prompts are returned and can be evaluated on test data. Report issue for preceding element
[scale=1.2] 
AutoML/Promptolution
https://github.com/automl/promptolution
Report issue for preceding element
System Demonstration
https://youtu.be/gySdgjEhsZA
Report issue for preceding element
1 Introduction
Report issue for preceding element
Modern large language models (LLMs) exhibit impressive general-purpose capabilities, being able to solve a wide variety of tasks (Radford et al., 
2019
https://arxiv.org/html/2512.02840v2#bib.bib36
; Ouyang et al., 
2022
https://arxiv.org/html/2512.02840v2#bib.bib34
; Bai et al., 
2023
https://arxiv.org/html/2512.02840v2#bib.bib6
; Touvron et al., 
2023
https://arxiv.org/html/2512.02840v2#bib.bib39
) . They can be adapted to solve specific tasks through in-context learning, i.e., simply by a textual instruction and optionally few-shot examples provided to the LLM as input (Brown et al., 
2020
https://arxiv.org/html/2512.02840v2#bib.bib7
) . Since this input (referred to as prompt) steers the output of the LLM (Karmaker Santu and Feng, 
2023
https://arxiv.org/html/2512.02840v2#bib.bib19
; White et al., 
2023
https://arxiv.org/html/2512.02840v2#bib.bib41
) , the LLM's performance on a given task highly depends on it – in terms of quality, formulation, and the choice and order of examples (Zhao et al., 
2021
https://arxiv.org/html/2512.02840v2#bib.bib50
; Lu et al., 
2022
https://arxiv.org/html/2512.02840v2#bib.bib30
; Zhou et al., 
2023
https://arxiv.org/html/2512.02840v2#bib.bib52
) . Table 
1
https://arxiv.org/html/2512.02840v2#S1.T1
 illustrates this with two similar prompts for the GMS8K math dataset (Cobbe et al., 
2021
https://arxiv.org/html/2512.02840v2#bib.bib9
) : despite their strong semantic similarity (matching parts in the same color), their performances differ substantially. This sensitivity highlights the potential of optimizing prompts for specific tasks, much like how hyperparameter tuning boosts performance in classical machine learning (Kohavi and John, 
1995
https://arxiv.org/html/2512.02840v2#bib.bib21
) . Just as manual hyperparameter search, crafting and refining good prompts by hand (manual prompt engineering) is tedious and unreliable (Jiang et al., 
2020
https://arxiv.org/html/2512.02840v2#bib.bib16
; Liu et al., 
2023
https://arxiv.org/html/2512.02840v2#bib.bib29
) . Similar to how AutoML automates the search over large hyperparameter spaces (Feurer and Hutter, 
2019
https://arxiv.org/html/2512.02840v2#bib.bib12
) , automatic prompt optimization recently emerged to systematically search the combinatorial space of prompts (Li et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib26
) . Especially nowadays, when multi-agent systems have become central in both industry and research, LLMs specialized for individual tasks are increasingly important (He et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib14
; Li et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib28
) . While fine-tuning entire models is expensive and data-intensive, automatic prompt optimization is a lightweight alternative and potential addition, often compatible with black-box LLMs (Cheng et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib8
) . A diverse collection of prompt optimizers has thus been introduced (see Cui et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib10
; Li et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib26
) . However, several hurdles arise when applying these optimizers in practice. Each optimizer lives in its own research repository. Trying and comparing several optimizers requires juggling with multiple code bases and conflicting requirements. Additionally, these repositories are typically not actively maintained, and the research code often lacks proper software tests, documentation, and robustness. Moreover, their setups are inflexible, and deviations from their use cases (often limited to simple classification tasks) and LLM deployments require considerable effort. While existing libraries and tools for prompt optimization partly address these issues, they are either commercial and closed-source (Amazon Bedrock, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib4
; Anthropic, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib5
; Jina AI, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib17
; Lee and Nardini, 
2024
https://arxiv.org/html/2512.02840v2#bib.bib24
) , only implement a single optimizer (Adalflow, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib1
; Agarwal et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib2
; Hinthorn and Nishimi, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib15
; Yuksekgonul et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib46
) , or have a high abstraction level designed mainly for end-to-end AI application development (Khattab et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib20
; Kulin et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib22
) .
Report issue for preceding element
Prompt
Accuracy
Tackle this elementary math problem by breaking it into logical steps. When you reach the solution, enclose the final answer with <final_answer> and </final_answer> markers for clarity.
37.6%
Assist with solving the elementary or grade school level math problem that requires multiple steps and provide the solution within <final_answer> </final_answer> tags for easy identification.
53.8%
Table 1: Example prompts and their test set accuracy on GSM8K with Llama-3.3-70B (colors = similar phrases). Report issue for preceding element
Contribution.
Report issue for preceding element
We introduce promptolution, a modular, lightweight, and extensible open-source framework for automatic prompt optimization in Python, providing thoroughly tested and stable implementations. Our library implements multiple LLM interfaces, NLP tasks, and contemporary discrete prompt optimization methods, which can be used interchangeably or replaced with custom implementations of the components. While promptolution facilitates single-prompt optimization for practitioners, a low abstraction level and helpers for systematic, reproducible experiments also make it geared toward researchers. Figure 
1
https://arxiv.org/html/2512.02840v2#S0.F1
 shows an overview of how the framework operates.
Report issue for preceding element
Outline.
Report issue for preceding element
We position our work within the landscape of automatic prompt optimization tools and libraries (§ 
2
https://arxiv.org/html/2512.02840v2#S2
), describe the design of our framework (§ 
3
https://arxiv.org/html/2512.02840v2#S3
), evaluate its performance compared to unoptimized prompts and other libraries to demonstrate its utility and competitiveness (§ 
4
https://arxiv.org/html/2512.02840v2#S4
), provide use cases and anti-use cases (§ 
5
https://arxiv.org/html/2512.02840v2#S5
), and outline future directions of the framework (§ 
6
https://arxiv.org/html/2512.02840v2#S6
).
Report issue for preceding element
2 Background & Related Works
Report issue for preceding element
Prompt Optimization.
Report issue for preceding element
Automatic prompt optimization refers to systematically exploring prompt spaces using various automated optimization strategies, which may optimize both the instruction and the few-shot example components of a prompt (Cui et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib10
; Li et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib26
; Wan et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib40
) . Prompt optimization is commonly categorized by the nature of the prompt space into continuous (Li and Liang, 
2021
https://arxiv.org/html/2512.02840v2#bib.bib27
; Lester et al., 
2021
https://arxiv.org/html/2512.02840v2#bib.bib25
; Qin and Eisner, 
2021
https://arxiv.org/html/2512.02840v2#bib.bib35
) and discrete approaches (Guo et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib13
; Yang et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib44
; Zhou et al., 
2023
https://arxiv.org/html/2512.02840v2#bib.bib52
) . For overviews of the field, we refer to Li et al. ( 
2025
https://arxiv.org/html/2512.02840v2#bib.bib26
) and Cui et al. ( 
2025
https://arxiv.org/html/2512.02840v2#bib.bib10
) . promptolution focuses on the LLM-agnostic and interpretable discrete prompt optimization, which iteratively refines textual prompts directly, often using another “meta”-LLM 
1
 
1
 1 Can be the same as the one we optimize prompts for. to generate improved candidates. The following optimizers are implemented in promptolution:
Report issue for preceding element
OPRO (Yang et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib44
) uses LLMs as optimizers by providing a task description, examples, and previously scored candidates to the meta-LLM, which then proposes refined instructions. Report issue for preceding element
EvoPrompt (Guo et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib13
) optimizes instructions using evolutionary algorithms, based on (a) a genetic algorithm (GA) and (b) on differential evolution (DE). In both cases, the meta-LLM performs crossover and mutation. Report issue for preceding element
CAPO (Zehle et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib48
) is a recent GA-based alternative that leverages AutoML techniques to improve cost-efficiency and jointly optimizes both instructions and few-shot examples, outperforming the discrete optimizers above. Report issue for preceding element
Other promising prompt optimizers not yet implemented in promptolution include GEPA (Agrawal et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib3
) , TextGrad (Yuksekgonul et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib47
) , MIPRO (Opsahl-Ong et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib33
) , and PromptWizard (Agarwal et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib2
) .
Report issue for preceding element
Existing Libraries, Frameworks & Tools.
Report issue for preceding element
Most optimizers above are implemented in siloed research repositories with hard-coded experimental setups. Oftentimes not actively maintained, lacking software tests and proper documentation, they are inherently difficult to use for both scientific benchmark experiments with other optimizers and practical use cases with specific requirements. In the prompt optimization landscape, many actively maintained libraries and tools have emerged, including both open- and closed-source solutions.
Report issue for preceding element
Open-Source. We classify open-source tools along four axes in Table 
2
https://arxiv.org/html/2512.02840v2#S2.T2
: (1) single/multiple optimizers, (2) extensibility, (3) abstraction level, and (4) invasiveness of integration. 
2
 
2
 2(1) describes whether the tool implements only a single vs. multiple optimizers, (2) whether it can be easily extended to new NLP tasks, LLMs, and optimizers, (3) if the user has direct control over implementation details, and (4) if it is easy to integrate the optimized prompt into arbitrary existing LLM-pipelines. In the following, we focus on their most important delimitation criteria compared to promptolution. For explanations of the full categorization in Table 
2
https://arxiv.org/html/2512.02840v2#S2.T2
, see Appendix 
A.1
https://arxiv.org/html/2512.02840v2#A1.SS1
.
Report issue for preceding element
Several libraries only implement a single prompt optimizer, including TextGrad (Yuksekgonul et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib46
) using the method from Yuksekgonul et al. ( 
2025
https://arxiv.org/html/2512.02840v2#bib.bib47
) , AdalFlow (Adalflow, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib1
) with LLM-AutoDiff (Yin and Wang, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib45
) , Microsoft's PromptWizard (Agarwal et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib2
) based on the eponymous optimization algorithm, and PromptIM (Hinthorn and Nishimi, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib15
) with its own iterative optimization strategy. prompt-ops (Meta-Llama, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib31
) implements two optimizers, but focuses on prompt optimization for Llama models. In contrast, promptolution offers multiple optimizers that can be used interchangeably (1) for arbitrary LLMs (2).
Report issue for preceding element
DSPy (Khattab et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib20
) is arguably the most popular existing framework in prompt optimization for building modular, declarative LLM pipelines and includes an embedded prompt optimization component. It supports multiple optimizers like MIPROv2 (building on Opsahl-Ong et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib33
) or GEPA (Agrawal et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib3
) , and can combine LLM training with prompt optimization (Soylu et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib38
) . While DSPy integrates prompt optimization as part of a monolithic, high-level program compilation procedure, promptolution exposes optimization as an explicit, iterative process, enabling finer control over optimization dynamics, intermediate results, and budget-aware stopping. Consequently, promptolution focuses exclusively on prompt optimization at a lower level of abstraction (3), making it geared toward researchers for systematic benchmarking and advanced practitioners rather than end-to-end AI application development. Moreover, DSPy only integrates with LLM applications in the DSPy framework while integration into other implementations requires larger refactoring (4). In contrast, promptolution returns a prompt string, enabling integration by directly replacing the existing prompt with the optimized one in any arbitrary LLM application (details in Appendix 
A.2
https://arxiv.org/html/2512.02840v2#A1.SS2
). promptomatix (Murthy et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib32
) builds on DSPy through its structured prompt compilation backend while also offering a lighter meta-prompt optimizer.
Report issue for preceding element
CoolPrompt (Kulin et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib22
) is an LLM-agnostic framework that supports multiple optimizers and emphasizes “zero-configuration” (3) in contrast to promptolution, where researchers maintain close control over the setup.
Report issue for preceding element
| Framework | Multiple | Extensible | Low | Non-Invasive |
 
| ^^ | Optimizers | | Abstraction | Integration |
 
| --- | --- | --- | --- | --- |
 
| promptolution | ✓ | ✓ | ✓ | ✓ |
 
| DSPy | ✓ | ✓ | ✗ | ✗ |
 
| CoolPrompt | ✓ | ( ✓) | ✗ | ✓ |
 
| promptomatix | ✓ | ✗ | ✗ | ✗ |
 
| prompt-ops | ✓ | ✗ | ✓ | ✓ |
 
| TextGrad | ✗ | ✗ | ✓ | ✗ |
 
| AdalFlow | ✗ | ✗ | ✓ | ✗ |
 
| PromptWizard | ✗ | ✗ | ✓ | ✓ |
 
| PromptIM | ✗ | ✗ | ✓ | ✓ |
Table 2: Comparison of open-source frameworks. Report issue for preceding element
Other related tools with a slightly different focus include PromptBench (Zhu et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib53
) , which targets LLM evaluation supporting only simple optimization techniques, and OpenPrompt (Ding et al., 
2022
https://arxiv.org/html/2512.02840v2#bib.bib11
) , designed for prompt learning for language models predating modern LLMs.
Report issue for preceding element
Closed-Source. Proprietary tools range from commercial web-platforms like PromptPerfect (Jina AI, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib17
) , cloud integrations such as Google Cloud's Vertex AI Prompt Optimizer (Lee and Nardini, 
2024
https://arxiv.org/html/2512.02840v2#bib.bib24
) and the AWS Bedrock Prompt Engineering Playground (Amazon Bedrock, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib4
) , to vendor-specific solutions like Anthropic Claude Prompt Tools (Anthropic, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib5
) .
Report issue for preceding element
Positioning of promptolution.
Report issue for preceding element
Our library is an open-source, LLM-agnostic, and highly modular framework. It focuses exclusively on prompt optimization rather than constructing full LLM pipelines. It already includes relevant LLM interfaces and NLP tasks, along with evaluation metrics, and provides multiple contemporary discrete prompt optimizers in a single, unified system. The framework is highly customizable and extensible, offering fine-grained control over optimizers, tasks, logging, evaluation, and experiment configuration, and can be seamlessly integrated into existing LLM applications. As a result, it is suitable for both practitioners performing single-prompt optimization and for researchers conducting systematic, reproducible large-scale benchmark studies.
Report issue for preceding element
3 System Design
Report issue for preceding element
 
Figure 2: Core components of promptolution. The upper part of each box lists the component implementations, the lower part important functions. Arrows between components indicate conceptual connections. Report issue for preceding element
promptolution is designed as a modular and extensible framework consisting of four key components (see Figure 
2
https://arxiv.org/html/2512.02840v2#S3.F2
). All components follow a unified interface defined through corresponding Base-classes, ensuring that implementations can be used interchangeably, remain fully compatible with the framework, and automatically inherit shared functionality. While each component can be configured individually (see § 
3.1
https://arxiv.org/html/2512.02840v2#S3.SS1
– 
3.4
https://arxiv.org/html/2512.02840v2#S3.SS4
), a separate ExperimentConfig together with associated helper functions enables convenient parameterization of all components in a single object (see § 
3.5
https://arxiv.org/html/2512.02840v2#S3.SS5
).
Report issue for preceding element
3.1 LLM
Report issue for preceding element
The LLM component provides an interface for obtaining responses from any LLM implementation. Its base class enables parallelization and monitors token usage. Three classes are implemented:
Report issue for preceding element
APILLM enables calls to LLMs hosted via an API, covering common vendors such as OpenAI and Anthropic. Listing 
3
https://arxiv.org/html/2512.02840v2#S3.F3
 
(L.1–5)
https://arxiv.org/html/2512.02840v2#S3.F3
 illustrates the setup through the DeepInfra API. Report issue for preceding element
LocalLLM allows using a local model via the transformers library (Wolf et al., 
2020
https://arxiv.org/html/2512.02840v2#bib.bib42
) . Report issue for preceding element
VLLM integrates the vllm library (Kwon et al., 
2023
https://arxiv.org/html/2512.02840v2#bib.bib23
) for efficient high-throughput inference and serving, and deployment on GPU clusters. Report issue for preceding element
3.2 Predictor
Report issue for preceding element
The Predictor component defines how predictions are extracted from LLM output. While the FirstOccurrencePredictor searches and extracts the first occurrence of any possible class label in the response, the more robust Marker- BasedPredictor (Listing 
3
https://arxiv.org/html/2512.02840v2#S3.F3
, 
L.6
https://arxiv.org/html/2512.02840v2#S3.F3
) extracts between predefined HTML-like markers (see Table 
3
https://arxiv.org/html/2512.02840v2#S3.T3
).
Report issue for preceding element
To solve this problem, we need to calculate the total number of fish in the fishbowls at all the tables. First, […] Then, we add the 3 fish from the table that has 3 fish: 62 fish + 3 fish = 65 fish. <final_answer> 65 </final_answer>
Table 3: Example of the MarkerBasedPredictor extraction from a LLM response for a GSM8K sample. Report issue for preceding element
3.3 Task
Report issue for preceding element
The Task component holds the dataset and other task-related information, including a textual description of the task, and defines how prompts are evaluated. It controls how subsampling is performed, which is crucial for efficiency, as not every prompt needs evaluation on the full data for a reasonable performance estimate. 
3
 
3
 3 Depending on the subsampling strategy, evaluation is either performed on randomly drawn samples, a slice of the dataset (block), or the full dataset. We implement the following tasks relevant to NLP:
Report issue for preceding element
ClassificationTask targets discrete class labels and evaluates predictions using standard classification metrics. In our example in Listing 
3
https://arxiv.org/html/2512.02840v2#S3.F3
 
(L. 7–13)
https://arxiv.org/html/2512.02840v2#S3.F3
, the task is specified using accuracy as metric. The task is easily created from a Pandas DataFrame by specifying the input and label columns, along with a task description. Report issue for preceding element
JudgeTask is based on LLM-as-a-judge (Zheng et al., 
2023
https://arxiv.org/html/2512.02840v2#bib.bib51
) , where another LLM scores the quality of the output according to the task description. This enables optimizing for subjective, creative tasks, both supervised and unsupervised, as ground-truth labels are optional. Report issue for preceding element
RewardTask allows optimization w.r.t. custom reward functions. The reward can represent any measurable objective, such as code execution time or business metrics. Users define their own reward functions that compute a score (reward) directly from a predictor's output. Report issue for preceding element
3.4 Optimizer
Report issue for preceding element
The Optimizer component combines all other components by using a Predictor and a Task to determine the optimal prompt for the specified setup. Depending on the chosen optimization method, it may also rely on a (meta-) LLM for prompt alteration. As the core of the framework, it iteratively evaluates LLM predictions for a given task and refines the prompt(s) according to the respective optimization strategy.
Report issue for preceding element
promptolution currently implements four established prompt optimizers: OPRO (Yang et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib44
) , both EvoPromptDE and EvoPromptGA (Guo et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib13
) , and the current SOTA discrete prompt optimizer CAPO (Zehle et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib48
) . promptolution caches previously evaluated prompts out of the box, and constrains prompt evaluation during optimization to a subset of the available data, making algorithms faster and more efficient. In Listing 
3
https://arxiv.org/html/2512.02840v2#S3.F3
, we set up CAPO 
(L. 14–22)
https://arxiv.org/html/2512.02840v2#S3.F3
 and let it optimize prompts for 12 steps 
(L. 23)
https://arxiv.org/html/2512.02840v2#S3.F3
.
Report issue for preceding element
Furthermore, new prompt optimizers can be added with minimal effort by inheriting from the base optimizer class and implementing a custom _step() method that defines the iterative optimization scheme. This makes our framework useful for researchers developing and benchmarking new optimization algorithms.
Report issue for preceding element
⬇
data:text/plain;base64,bGxtID0gQVBJTExNKAogICAgYXBpX3VybD0iYXBpLmRlZXBpbmZyYS5jb20vdjEvLi4uIiwKICAgIG1vZGVsX2lkPSJnb29nbGUvZ2VtbWEtMy0yN2ItaXQiLAogICAgYXBpX2tleT0iLi4uIiwKKQpwcmVkaWN0b3IgPSBNYXJrZXJCYXNlZFByZWRpY3RvcihsbG09bGxtKQp0YXNrID0gQ2xhc3NpZmljYXRpb25UYXNrKAogICAgZGYsCiAgICB0YXNrX2Rlc2NyaXB0aW9uPSJUaGUgdGFzayBpcy4uLiIsCiAgICB4X2NvbHVtbj0idGV4dCIsCiAgICB5X2NvbHVtbj0ibGFiZWxfdGV4dCIsCiAgICBtZXRyaWM9YWNjdXJhY3lfc2NvcmUsCikKb3B0aW0gPSBDQVBPKAogICAgcHJlZGljdG9yLAogICAgdGFzaywKICAgIG1ldGFfbGxtPWxsbSwKICAgIGluaXRfcHJvbXB0cz1bCiAgICAgICAgIkNsYXNzaWZ5IHRoZSB0ZXh0IGJhc2VkIG9uLi4uICIsCiAgICAgICAgIyAuLi4KICAgIF0sCikKcHJvbXB0cyA9IG9wdGltLm9wdGltaXplKG5fc3RlcHM9MTIp
1 llm = APILLM(
2 api_url="api.deepinfra.com/v1/...",
3 model_id="google/gemma-3-27b-it",
4 api_key="...",
5)
6 predictor = MarkerBasedPredictor( llm= llm)
7 task = ClassificationTask(
8 df,
9 task_description="The task is...",
10 x_column="text",
11 y_column="label_text",
12 metric= accuracy_score,
13)
14 optim = CAPO(
15 predictor,
16 task,
17 meta_llm= llm,
18 init_prompts=[
19 "Classify the text based on... ",
20 # ...
21 ],
22)
23 prompts = optim. optimize( n_steps=12)
Figure 3: Setup of promptolution's core components. Report issue for preceding element
3.5 Experiment Configuration & Helper
Report issue for preceding element
promptolution not only supports optimizing prompts for a single specific setup but also provides an ExperimentConfig framework that enables a convenient, structured configuration for larger benchmark experiments. Additional helper functions enable the running and evaluation of such experiments with just a few lines of code.
Report issue for preceding element
Listing 
4
https://arxiv.org/html/2512.02840v2#S3.F4
 
(L. 1–7)
https://arxiv.org/html/2512.02840v2#S3.F4
 illustrates how the previous example (Listing 
3
https://arxiv.org/html/2512.02840v2#S3.F3
) can be expressed with a single config class. Arguments that are not specified resort to carefully chosen defaults, while arguments that were set but not used during initialization of the classes will throw a warning. The associated helper functions allow users to run the optimization process according to the config ( run_optimization) and to evaluate the prompts on unseen test data ( run_evaluation), without requiring manual initialization of the various classes affected. The run_experiment function (Listing 
4
https://arxiv.org/html/2512.02840v2#S3.F4
, 
L. 8
https://arxiv.org/html/2512.02840v2#S3.F4
) combines both steps, to support researchers who want to perform extensive benchmark studies across multiple datasets and optimizers.
Report issue for preceding element
⬇
data:text/plain;base64,Y29uZmlnID0gRXhwZXJpbWVudENvbmZpZygKICAgIG9wdGltaXplcj0iY2FwbyIsCiAgICB0YXNrX2Rlc2NyaXB0aW9uPSJUaGUgdGFzayBpcy4uLiIsCiAgICBuX3N0ZXBzPTEyLAogICAgYXBpX3VybD0iYXBpLmRlZXBpbmZyYS5jb20vdjEvLi4uIiwKICAgIG1vZGVsX2lkPSJnb29nbGUvZ2VtbWEtMy0yN2ItaXQiLAopCnByb21wdHMgPSBydW5fZXhwZXJpbWVudChkZiwgY29uZmlnKQ==
1 config = ExperimentConfig(
2 optimizer="capo",
3 task_description="The task is...",
4 n_steps=12,
5 api_url="api.deepinfra.com/v1/...",
6 model_id="google/gemma-3-27b-it",
7)
8 prompts = run_experiment( df, config)
Figure 4: Running an experiment via the ExperimentConfig abstraction. Report issue for preceding element
3.6 Supporting Modules and Utilities
Report issue for preceding element
Exemplar Selection: Some prompt optimization algorithms (e.g., OPRO or EvoPrompt) do not consider few-shot examples. However, they can substantially improve LLM performance (Brown et al., 
2020
https://arxiv.org/html/2512.02840v2#bib.bib7
) , even with simple selection strategies (Wan et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib40
) . promptolution offers post-hoc exemplar selection in an additional module, implementing random selection and random search 
4
 
4
 4 Random selection selects exemplars at random, whereas random search generates multiple sets of random examples, evaluates them, and selects the best performing set. to add few-shot examples to a fixed instruction.
Report issue for preceding element
Initial Prompt Creation: Many prompt optimizers require an initial pool of prompts to start with. We offer functions to automatically create prompts from a task description, a base prompt (following Zhou et al., 
2023
https://arxiv.org/html/2512.02840v2#bib.bib52
) , or samples from a dataset.
Report issue for preceding element
Callbacks: The base class for the optimizers supports callbacks, allowing for easy tracking of the optimization progress. Callbacks can access the state of the optimizer at every optimization step, and optionally terminate the process. Important implementations include the TokenCountCallback, which tracks the accumulated token budget and terminates optimization if a specified threshold is exceeded, and the FileOutputCallback, which writes prompts and their scores to a file, enabling easy post-hoc analysis of the process.
Report issue for preceding element
4 Evaluation
Report issue for preceding element
Setup.
Report issue for preceding element
To evaluate promptolution and contextualize its performance relative to other prompt optimization tools, we perform prompt optimization on the popular GSM8K (grade school math word problems; Cobbe et al., 
2021
https://arxiv.org/html/2512.02840v2#bib.bib9
) and SST-5 dataset (sentiment classification; Socher et al., 
2013
https://arxiv.org/html/2512.02840v2#bib.bib37
) . We use gemma-3-27B instruction tuned (Kamath et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib18
) as downstream LLM, and, for optimizers that require one, also as meta-LLM. Further details on datasets and implementation choices are provided in Appendix 
A.3
https://arxiv.org/html/2512.02840v2#A1.SS3
.
Report issue for preceding element
For our comparison, we employ the optimizers CAPO, EvoPromptGA, and OPRO from the promptolution library, and additionally evaluate two other frameworks with leading prompt optimizers: AdalFlow ( LLM-AutoDiff) and DSPy ( GEPA). To assess the impact of prompt optimization itself, we also evaluate three unoptimized zero-shot prompts (see Appendix 
A.3
https://arxiv.org/html/2512.02840v2#A1.SS3
) for each dataset and report their average performance. We use the default parameterization for each optimizer to ensure comparability with practical use cases, where users often lack the budget for an extensive hyperparameter search. We further restrict the token budget to at most one million in- and output tokens combined, which corresponds to a cost below $0.15 for this LLM. All frameworks are initialized from a single task description, without any initial prompts, to test the full automation workflow. While DSPy and AdalFlow use the task description as a starting point for their respective optimizers, promptolution's optimizers additionally require a set of initial prompts. These are generated via promptolution's utility function create_prompts_from_task_description. Both the unoptimized prompts and best prompts per optimizer (based on development-set performance) are evaluated on an unseen test set.
Report issue for preceding element
For reproducibility, we make the experiment scripts, seed, and raw results publicly available at 
https://github.com/finitearth/prompt-optimization-framework-comparison
https://github.com/finitearth/prompt-optimization-framework-comparison
.
Report issue for preceding element
Framework
Optimizer
GSM8K
SST5
Baseline
unoptimized
78.1
44.6
AdalFlow
AutoDiff
88.7
55.7
DSPy
GEPA
84.7
42.0
promptolution
OPRO
69.7
56.0
^^
EvoPrompt
91.0
53.3
^^
CAPO
93.7
56.3
Table 4: Test set accuracy of optimized prompts using Gemma3-27B-it. Bold values indicate the best, underlined values the second-best performance per dataset. Report issue for preceding element
Results.
Report issue for preceding element
A summary of the results is presented in Table 
4
https://arxiv.org/html/2512.02840v2#S4.T4
. With the exception of GEPA on SST-5 and OPRO on GSM8K, all optimizers substantially outperform the unoptimized baseline with improvements of up to 15%p in accuracy ( CAPO on GSM8K). This demonstrates the utility of prompt optimization in general and of our framework in particular. The best-performing optimizer on both datasets, CAPO, as well as each runner-up, is implemented in promptolution, underscoring the competitiveness of our framework compared to other prompt optimization tools. Although not every optimizer included in promptolution performs optimally on every task (e.g., OPRO on GSM8K), the library consistently provides at least one strong optimizer per task. Combined with its modular design, this allows users to switch easily to an alternative optimizer if the current one yields unsatisfying performance. We further emphasize that comparing optimizers within promptolution required minimal manual effort due to its dedicated support for systematic benchmark experiments.
Report issue for preceding element
For more in-depth evaluations of optimizers utilizing the promptolution framework, we point to Zehle et al. ( 
2025
https://arxiv.org/html/2512.02840v2#bib.bib48
) .
Report issue for preceding element
5 Use Cases & Anti-Use Cases
Report issue for preceding element
The choice of prompt optimization frameworks depends not solely on performance, but also on 
integration constraints
, the 
scope of optimization
, and tolerance for 
framework lock-in
. We outline four common use cases to clarify these trade-offs.
Report issue for preceding element
Case I: Integration in Existing Pipelines.
Report issue for preceding element
A practitioner already operates custom LLM pipelines and aims to improve performance solely via better prompts. promptolution returns a single optimized prompt string that can be directly substituted into existing inference pipelines without refactoring application logic. Since optimized prompts are plain text, users retain full flexibility regarding LLM providers, deployment modes (API, local models, or vLLM), and future model updates. In contrast, adopting frameworks in which prompts are framework-specific abstractions, such as DSPy, requires rewriting pipelines into these specific structures, which entails significant overhead.
Report issue for preceding element
Case II: End-to-End LLM Application Development.
Report issue for preceding element
A practitioner builds an LLM-based system from scratch, jointly designing prompt logic, program structure, and possibly training or fine-tuning stages. promptolution intentionally only optimizes prompts. In particular, DSPy is better suited to this setting, allowing the entire pipeline to be composed and optimized in a single, abstract program rather than manually engineering and optimizing each step; however, at the cost of coupling the system design to DSPy's abstractions and losing portability to other frameworks.
Report issue for preceding element
Case III: Prompt Optimizer Benchmarking.
Report issue for preceding element
A researcher wants to systematically benchmark prompt optimization algorithms or develop a new prompt optimizer and perform a comparative evaluation. promptolution is advantageous due to its low abstraction level, modular optimizer design, and explicit support for reproducible experiments. Extension to new optimizers, tasks, or evaluation strategies is explicitly encouraged and can be evaluated in a reproducible and controlled manner. Full trajectories, intermediate prompts, and token usage through callbacks and logging enable detailed analysis, setting promptolution apart from other libraries in this regard.
Report issue for preceding element
Case IV: Integration in LLM Benchmarking.
Report issue for preceding element
A researcher conducts systematic benchmarking of LLMs for a new use case. Instead of treating prompts as fixed, they want to include prompt optimization in the benchmark pipeline to account for the strong influence of prompts on performance and reduce variance in findings due to arbitrary prompt choices. promptolution allows seamless integration of prompt optimization into any benchmark pipeline, exchanging LLM backends and datasets, and is designed for controlled, systematic, reproducible studies across multiple seeds.
Report issue for preceding element
6 Conclusion & Future Directions
Report issue for preceding element
In this work, we introduced promptolution, a unified and modular open-source Python framework for automatic prompt optimization, designed for both practitioners performing single-task prompt optimization and for researchers conducting systematic experiments. We highlighted the unique position of our framework within the landscape of prompt optimization tools, emphasizing its extensible, modular design and low abstraction level, and its focus on optimizing prompts with non-invasive integration. Furthermore, we demonstrated the role of each component in the framework and how they interact to support effective prompt optimization. Through a comparative evaluation, we verified the utility and competitiveness of promptolution. Finally, we provided concrete use and anti-use cases, highlighting the considerations to take into account when choosing a prompt optimization framework.
Report issue for preceding element
Looking ahead, we plan to develop interfaces with higher-level frameworks such as DSPy, enabling a combination of strengths from both ecosystems. To further simplify the management of complex, large-scale experimental setups, we intend to introduce an interface to configuration management frameworks such as hydra (Yadan, 
2019
https://arxiv.org/html/2512.02840v2#bib.bib43
) . We also aim to improve accessibility by implementing a graphical interface for real-time experiment tracking and visual analysis of the optimization process. Following the recent rise of multi-agent systems, we plan to support the optimization of system prompts and interaction protocols across multiple agents. Additionally, inspired by AutoML, we intend to explore ensembling strategies for prompt optimizers, akin to ELPO (Zhang et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib49
) . The extensibility of our framework ensures that we can continue to incorporate new state-of-the-art optimization methods as the field evolves.
Report issue for preceding element
Broader Impact
Report issue for preceding element
By unifying multiple prompt optimization methods that were previously scattered across separate research repositories, promptolution makes the benefits of prompt optimization for improving LLM performance broadly accessible, allowing practitioners to leverage these capabilities in real-world industry applications. At the same time, its modular and extensible design, combined with experiment-friendly implementations, makes the library a powerful tool for researchers benchmarking new prompt optimization algorithms. Since reimplementing competing methods and setting up rigorous benchmark experiments is typically time-consuming, promptolution offers the potential to accelerate research progress in prompt optimization and to enhance methodological comparability across the field.
Report issue for preceding element
Acknowledgments
Report issue for preceding element
Tom Zehle received funding by the European Union. Views and opinions expressed are, however, those of the author(s) only and do not necessarily reflect those of the European Union or the European Commission. Neither the European Union nor the European Commission can be held responsible for them. This work was supported by the European Union's Horizon Europe research and innovation programm under grant agreement No 101214398 (ELLIOT).
Report issue for preceding element
Matthias Aßenmacher received funding from the BERD@NFDI consortium in the context of the work of the National Research Data Infrastructure (NFDI) Association. NFDI is funded by the Federal Republic of Germany and the 16 federal states. The BERD@NFDI consortium is supported within NFDI by the German Research Foundation (DFG) – NFDI 27/1-2026, project number 460037581.
Report issue for preceding element
References
Report issue for preceding element
Adalflow (2025) ↑ Adalflow. 2025. 
Build and Optimize LM Workflows
https://adalflow.sylph.ai/
. Last accessed: 11/30/2025.
Agarwal et al. (2024) ↑ Eshaan Agarwal, Joykirat Singh, Vivek Dani, Raghav Magazine, Tanuja Ganu, and Akshay Nambi. 2024. PromptWizard: Task-aware prompt optimization framework. 
arXiv:2405.18369 [cs.CL]
.
Agrawal et al. (2025) ↑ Lakshya A. Agrawal, Shangyin Tan, Dilara Soylu, Noah Ziems, Rishi Khare, Krista Opsahl-Ong, Arnav Singhvi, Herumb Shandilya, Michael J. Ryan, Meng Jiang, Christopher Potts, Koushik Sen, Alexandros G. Dimakis, Ion Stoica, Dan Klein, Matei Zaharia, and Omar Khattab. 2025. GEPA: Reflective prompt evolution can outperform reinforcement learning. 
arXiv:2507.19457 [cs.CL]
.
Amazon Bedrock (2025) ↑ Amazon Bedrock. 2025. 
User Guide: Optimize a prompt
https://docs.aws.amazon.com/bedrock/latest/userguide/prompt-management-optimize.html
. Last accessed: 11/25/2025.
Anthropic (2025) ↑ Anthropic. 2025. 
Prompt engineering: Use our prompt improver to optimize your prompts
https://platform.claude.com/docs/en/build-with-claude/prompt-engineering/prompt-improver
. Last accessed: 11/25/2025.
Bai et al. (2023) ↑ Jinze Bai, Shuai Bai, Yunfei Chu, Zeyu Cui, Kai Dang, Xiaodong Deng, Yang Fan, Wenbin Ge, Yu Han, Fei Huang, Binyuan Hui, Luo Ji, Mei Li, Junyang Lin, Runji Lin, Dayiheng Liu, Gao Liu, Chengqiang Lu, Keming Lu, and 29 others. 2023. Qwen technical report. 
arXiv:2309.16609 [cs.CL]
.
Brown et al. (2020) ↑ T. Brown, B. Mann, N. Ryder, M. Subbiah, J. Kaplan, P. Dhariwal, A. Neelakantan, P. Shyam, G. Sastry, A. Askell, S. Agarwal, A. Herbert-Voss, G. Krueger, T. Henighan, R. Child, A. Ramesh, D. Ziegler, J. Wu, C. Winter, and 12 others. 2020. Language models are few-shot learners. In 
Proceedings of the 33rd International Conference on Advances in Neural Information Processing Systems (NeurIPS'20)
, pages 1877–1901. Curran Associates.
Cheng et al. (2024) ↑ Jiale Cheng, Xiao Liu, Kehan Zheng, Pei Ke, Hongning Wang, Yuxiao Dong, Jie Tang, and Minlie Huang. 2024. Black-box prompt optimization: Aligning large language models without model training. In 
Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers)
, pages 3201–3219, Bangkok, Thailand. Association for Computational Linguistics.
Cobbe et al. (2021) ↑ Karl Cobbe, Vineet Kosaraju, Mohammad Bavarian, Mark Chen, Heewoo Jun, Lukasz Kaiser, Matthias Plappert, Jerry Tworek, Jacob Hilton, Reiichiro Nakano, Christopher Hesse, and John Schulman. 2021. Training verifiers to solve math word problems. 
arXiv:2110.14168 [cs.LG]
.
Cui et al. (2025) ↑ Wendi Cui, Jiaxin Zhang, Zhuohang Li, Hao Sun, Damien Lopez, Kamalika Das, Bradley A. Malin, and Sricharan Kumar. 2025. Heuristic-based search algorithm in automatic instruction-focused prompt optimization: A survey. In 
Findings of the Association for Computational Linguistics: ACL 2025
, pages 22093–22111, Vienna, Austria. Association for Computational Linguistics.
Ding et al. (2022) ↑ Ning Ding, Shengding Hu, Weilin Zhao, Yulin Chen, Zhiyuan Liu, Haitao Zheng, and Maosong Sun. 2022. OpenPrompt: An open-source framework for prompt-learning. In 
Proceedings of the 60th Annual Meeting of the Association for Computational Linguistics: System Demonstrations
, pages 105–113, Dublin, Ireland. Association for Computational Linguistics.
Feurer and Hutter (2019) ↑ Matthias Feurer and Frank Hutter. 2019. Hyperparameter optimization. In Frank Hutter, Lars Kotthoff, and Joaquin Vanschoren, editors, 
Automated Machine Learning: Methods, Systems, Challenges
, pages 3–33. Springer International Publishing.
Guo et al. (2024) ↑ Qingyan Guo, Rui Wang, Junliang Guo, Bei Li, Kaitao Song, Xu Tan, Guoqing Liu, Jiang Bian, and Yujiu Yang. 2024. Connecting large language models with evolutionary algorithms yields powerful prompt optimizers. In 
The Twelfth International Conference on Learning Representations (ICLR'24)
. ICLR. Published online: 
iclr.cc
iclr.cc
.
He et al. (2025) ↑ Junda He, Christoph Treude, and David Lo. 2025. LLM-based multi-agent systems for software engineering: Literature review, vision, and the road ahead. 
ACM Transactions on Software Engineering and Methodology
, 34(5):1–30.
Hinthorn and Nishimi (2025) ↑ William F. Hinthorn and Masahiro Nishimi. 2025. 
Promptim
https://github.com/hinthornw/promptimizer
. Last accessed: 11/25/2025.
Jiang et al. (2020) ↑ Zhengbao Jiang, Frank Xu, Jun Araki, and Graham Neubig. 2020. How can we know what language models know? 
Transactions of the Association for Computational Linguistics
, 8:423–438.
Jina AI (2025) ↑ Jina AI. 2025. 
PromptPerfect: AI Prompt Optimizer
https://promptperfect.jina.ai/
. Last accessed: 11/25/2025.
Kamath et al. (2025) ↑ Aishwarya Kamath, Johan Ferret, Shreya Pathak, Nino Vieillard, Ramona Merhej, Sarah Perrin, Tatiana Matejovicova, Alexandre Ramé, Morgane Rivière, Louis Rouillard, Thomas Mesnard, Geoffrey Cideron, Jean-bastien Grill, Sabela Ramos, Edouard Yvinec, Michelle Casbon, Etienne Pot, Ivo Penchev, Gaël Liu, and 196 others. 2025. Gemma 3 technical report. 
arXiv:2503.19786 [cs.CL]
.
Karmaker Santu and Feng (2023) ↑ Shubhra Karmaker Santu and Dongji Feng. 2023. TELeR: A general taxonomy of LLM prompts for benchmarking complex tasks. In 
Findings of the Association for Computational Linguistics: EMNLP 2023
, pages 14197–14203. Association for Computational Linguistics.
Khattab et al. (2024) ↑ Omar Khattab, Arnav Singhvi, Paridhi Maheshwari, Zhiyuan Zhang, Keshav Santhanam, Sri Vardhamanan, Saiful Haq, Ashutosh Sharma, Thomas Joshi, Hanna Moazam, Heather Miller, Matei Zaharia, and Christopher Potts. 2024. DSPy: Compiling declarative language model calls into state-of-the-art pipelines. In 
The Twelfth International Conference on Learning Representations (ICLR'24)
. ICLR. Published online: 
iclr.cc
iclr.cc
.
Kohavi and John (1995) ↑ Ron Kohavi and George H. John. 1995. Automatic parameter selection by minimizing estimated error. In 
Proceedings of the Twelfth International Conference on Machine Learning (ICML'95)
. Morgan Kaufmann Publishers.
Kulin et al. (2025) ↑ Nikita Kulin, Viktor Zhuravlev, Artur Khairullin, Alena Sitkina, and Sergey Muravyov. 2025. CoolPrompt: Automatic prompt optimization framework for Large Language Models. In 
Proceedings of the 38th Conference of Open Innovations Association FRUCT, Issue 1 (Full papers)
, pages 158–166, Helsinki, Finland. FRUCT Oy.
Kwon et al. (2023) ↑ Woosuk Kwon, Zhuohan Li, Siyuan Zhuang, Ying Sheng, Lianmin Zheng, Cody Yu, Joseph Gonzalez, Hao Zhang, and Ion Stoica. 2023. Efficient memory management for large language model serving with pagedattention. In 
Proceedings of the 29th Symposium on Operating Systems Principles (SOSP '23)
, pages 611–626. Association for Computing Machinery.
Lee and Nardini (2024) ↑ George Lee and Ivan Nardini. 2024. 
Announcing Public Preview of Vertex AI Prompt Optimizer
https://cloud.google.com/blog/products/ai-machine-learning/announcing-vertex-ai-prompt-optimizer?hl=en
. Last accessed: 11/25/2025.
Lester et al. (2021) ↑ Brian Lester, Rami Al-Rfou, and Noah Constant. 2021. The power of scale for parameter-efficient prompt tuning. In 
Proceedings of the 2021 Conference on Empirical Methods in Natural Language Processing (EMNLP)
, pages 3045–3059. Association for Computational Linguistics.
Li et al. (2025) ↑ Wenwu Li, Xiangfeng Wang, Wenhao Li, and Bo Jin. 2025. A survey of automatic prompt engineering: An optimization perspective. 
arXiv:2502.11560 [cs.AI]
.
Li and Liang (2021) ↑ Xiang Li and Percy Liang. 2021. Prefix-tuning: Optimizing continuous prompts for generation. In 
Proceedings of the 59th Annual Meeting of the Association for Computational Linguistics and the 11th International Joint Conference on Natural Language Processing (Volume 1: Long Papers)
, pages 4582–4597. Association for Computational Linguistics.
Li et al. (2024) ↑ Xinyi Li, Sai Wang, Siqi Zeng, Yu Wu, and Yi Yang. 2024. A survey on LLM-based multi-agent systems: workflow, infrastructure, and challenges. 
Vicinagearth
, 1(1):9.
Liu et al. (2023) ↑ Pengfei Liu, Weizhe Yuan, Jinlan Fu, Zhengbao Jiang, Hiroaki Hayashi, and Graham Neubig. 2023. Pre-train, prompt, and predict: A systematic survey of prompting methods in natural language processing. 
ACM Computing Surveys
, 55(9):195:1–195:35.
Lu et al. (2022) ↑ Yao Lu, Max Bartolo, Alastair Moore, Sebastian Riedel, and Pontus Stenetorp. 2022. Fantastically ordered prompts and where to find them: Overcoming few-shot prompt order sensitivity. In 
Proceedings of the 60th Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers)
, pages 8086–8098. Association for Computational Linguistics.
Meta-Llama (2025) ↑ Meta-Llama. 2025. 
prompt-ops: An open-source tool for LLM prompt optimization
https://github.com/meta-llama/prompt-ops
. Last accessed: 11/30/2025.
Murthy et al. (2025) ↑ Rithesh Murthy, Ming Zhu, Liangwei Yang, Jielin Qiu, Juntao Tan, Shelby Heinecke, Caiming Xiong, Silvio Savarese, and Huan Wang. 2025. Promptomatix: An automatic prompt optimization framework for Large Language Models. 
arXiv:2507.14241 [cs.CL]
.
Opsahl-Ong et al. (2024) ↑ Krista Opsahl-Ong, Michael J Ryan, Josh Purtell, David Broman, Christopher Potts, Matei Zaharia, and Omar Khattab. 2024. Optimizing instructions and demonstrations for multi-stage language model programs. In 
Proceedings of the 2024 Conference on Empirical Methods in Natural Language Processing (EMNLP)
, pages 9340–9366. Association for Computational Linguistics.
Ouyang et al. (2022) ↑ Long Ouyang, Jeff Wu, Xu Jiang, Diogo Almeida, Carroll L. Wainwright, Pamela Mishkin, Chong Zhang, Sandhini Agarwal, Katarina Slama, Alex Ray, John Schulman, Jacob Hilton, Fraser Kelton, Luke Miller, Maddie Simens, Amanda Askell, Peter Welinder, Paul Christiano, Jan Leike, and Ryan Lowe. 2022. Training language models to follow instructions with human feedback. In 
Proceedings of the 35th International Conference on Advances in Neural Information Processing Systems (NeurIPS'22)
. Curran Associates.
Qin and Eisner (2021) ↑ Guanghui Qin and Jason Eisner. 2021. Learning how to ask: Querying LMs with mixtures of soft prompts. In 
Proceedings of the 2021 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies
, pages 5203–5212. Association for Computational Linguistics.
Radford et al. (2019) ↑ Alec Radford, Jeffrey Wu, Rewon Child, David Luan, Dario Amodei, and Ilya Sutskever. 2019. Language models are unsupervised multitask learners. 
OpenAI blog
, 1(8):9.
Socher et al. (2013) ↑ Richard Socher, Alex Perelygin, Jean Wu, Jason Chuang, Christopher Manning, Andrew Ng, and Christopher Potts. 2013. Recursive deep models for semantic compositionality over a sentiment treebank. In 
Proceedings of the 2013 Conference on Empirical Methods in Natural Language Processing
, pages 1631–1642. Association for Computational Linguistics.
Soylu et al. (2024) ↑ Dilara Soylu, Christopher Potts, and Omar Khattab. 2024. Fine-tuning and prompt optimization: Two great steps that work better together. In 
Proceedings of the 2024 Conference on Empirical Methods in Natural Language Processing (EMNLP)
, pages 10696–10710. Association for Computational Linguistics.
Touvron et al. (2023) ↑ Hugo Touvron, Thibaut Lavril, Gautier Izacard, Xavier Martinet, Marie-Anne Lachaux, Timothée Lacroix, Baptiste Rozière, Naman Goyal, Eric Hambro, Faisal Azhar, Aurelien Rodriguez, Armand Joulin, Edouard Grave, and Guillaume Lample. 2023. LLaMA: Open and efficient foundation language models. 
arXiv:2302.13971 [cs.CL]
.
Wan et al. (2024) ↑ Xingchen Wan, Ruoxi Sun, Hootan Nakhost, and Sercan Arik. 2024. Teach better or show smarter? on instructions and exemplars in automatic prompt optimization. In 
Proceedings of the 37th International Conference on Advances in Neural Information Processing Systems (NeurIPS'24)
, pages 58174–58244. Curran Associates.
White et al. (2023) ↑ Jules White, Quchen Fu, Sam Hays, Michael Sandborn, Carlos Olea, Henry Gilbert, Ashraf Elnashar, Jesse Spencer-Smith, and Douglas Schmidt. 2023. A prompt pattern catalog to enhance prompt engineering with ChatGPT. In 
Proceedings of the 30th Conference on Pattern Languages of Programs
, PLoP '23, pages 1–31, USA. The Hillside Group.
Wolf et al. (2020) ↑ Thomas Wolf, Lysandre Debut, Victor Sanh, Julien Chaumond, Clement Delangue, Anthony Moi, Pierric Cistac, Tim Rault, Remi Louf, Morgan Funtowicz, Joe Davison, Sam Shleifer, Patrick von Platen, Clara Ma, Yacine Jernite, Julien Plu, Canwen Xu, Teven Le Scao, Sylvain Gugger, and 3 others. 2020. Transformers: State-of-the-art Natural Language Processing. In 
Proceedings of the 2020 Conference on Empirical Methods in Natural Language Processing: System Demonstrations
, pages 38–45, Online. Association for Computational Linguistics.
Yadan (2019) ↑ Omry Yadan. 2019. 
Hydra - a framework for elegantly configuring complex applications
https://github.com/facebookresearch/hydra
. Last accessed: 11/30/2025.
Yang et al. (2024) ↑ Chengrun Yang, Xuezhi Wang, Yifeng Lu, Hanxiao Liu, Quoc Le, Denny Zhou, and Xinyun Chen. 2024. Large language models as optimizers. In 
The Twelfth International Conference on Learning Representations (ICLR'24)
. ICLR. Published online: 
iclr.cc
iclr.cc
.
Yin and Wang (2025) ↑ Li Yin and Zhangyang Wang. 2025. LLM-AutoDiff: Auto-differentiate any LLM workflow. 
arXiv:2501.16673 [cs.CL]
.
Yuksekgonul et al. (2024) ↑ Mert Yuksekgonul, Federico Bianchi, Joseph Boen, Sheng Liu, Zhi Huang, Carlos Guestrin, and James Zou. 2024. 
TextGrad: Automatic “Differentiation” with Text
https://textgrad.readthedocs.io/en/
. Last accessed: 11/30/2025.
Yuksekgonul et al. (2025) ↑ Mert Yuksekgonul, Federico Bianchi, Joseph Boen, Sheng Liu, Pan Lu, Zhi Huang, Carlos Guestrin, and James Zou. 2025. Optimizing generative AI by backpropagating language model feedback. 
Nature
, 639(8055):609––616.
Zehle et al. (2025) ↑ Tom Zehle, Moritz Schlager, Timo Heiß, and Matthias Feurer. 2025. CAPO: Cost-aware prompt optimization. In 
Proceedings of the Fourth International Conference on Automated Machine Learning
, volume 293 of 
Proceedings of Machine Learning Research
, pages 18/1–45. PMLR.
Zhang et al. (2025) ↑ Qing Zhang, Bing Xu, Xudong Zhang, Yifan Shi, Yang Li, Chen Zhang, Yik Chung Wu, Ngai Wong, Yijie Chen, Hong Dai, Xiansen Chen, and Mian Zhang. 2025. ELPO: Ensemble learning based prompt optimization for Large Language Models. 
arXiv:2511.16122 [cs.CL]
.
Zhao et al. (2021) ↑ Zihao Zhao, Eric Wallace, Shi Feng, Dan Klein, and Sameer Singh. 2021. Calibrate before use: Improving few-shot performance of language models. In 
Proceedings of the 38th International Conference on Machine Learning (ICML'21)
, volume 139 of 
Proceedings of Machine Learning Research
, pages 12697–12706. PMLR.
Zheng et al. (2023) ↑ Lianmin Zheng, Wei-Lin Chiang, Ying Sheng, Siyuan Zhuang, Zhanghao Wu, Yonghao Zhuang, Zi Lin, Zhuohan Li, Dacheng Li, Eric P. Xing, Hao Zhang, Joseph E. Gonzalez, and Ion Stoica. 2023. Judging LLM-as-a-judge with MT-bench and Chatbot Arena. In 
Proceedings of the 36th International Conference on Advances in Neural Information Processing Systems (NeurIPS'23)
, pages 46595–46623. Curran Associates.
Zhou et al. (2023) ↑ Y. Zhou, A. Ioan Muresanu, Z. Han, K. Paster, S. Pitis, H. Chan, and J. Ba. 2023. Large language models are human-level prompt engineers. In 
The Eleventh International Conference on Learning Representations (ICLR'23)
. ICLR. Published online: 
iclr.cc
iclr.cc
.
Zhu et al. (2024) ↑ Kaijie Zhu, Qinlin Zhao, Hao Chen, Jindong Wang, and Xing Xie. 2024. PromptBench: A unified library for evaluation of Large Language Models. 
Journal of Machine Learning Research
, 25(254):1–22.
Appendix A Appendix
Report issue for preceding element
A.1 Details on Prompt Optimization Tool Categorization
Report issue for preceding element
In the following, we explain the choices ( ✓/ ✗) in Table 
2
https://arxiv.org/html/2512.02840v2#S2.T2
 for all considered open-source frameworks:
Report issue for preceding element
DSPy
(Khattab et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib20
) : multiple optimizers (e.g., GEPA, MIPROv2), extensible since adding new optimizers is possible, high abstraction level through declarative programming and monolithic compile method, invasive integration as requiring switching to dspy.Module and dspy.Signature (details in Appendix 
A.2
https://arxiv.org/html/2512.02840v2#A1.SS2
).
Report issue for preceding element
CoolPrompt
(Kulin et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib22
) : multiple optimizers (e.g. DistillPrompt, ReflectivePrompt), partly extensible since implementing own optimizers is possible, but follows no clear framework, high abstraction level as it emphasizes “zero-configuration”, non-invasive integration since it simply returns a prompt string.
Report issue for preceding element
promptomatix
(Murthy et al., 
2025
https://arxiv.org/html/2512.02840v2#bib.bib32
) : uses DSPy optimizers as backend, not extensible by design since it only has one fixed PromptOptimizer class, high abstraction since it builds on top of DSPy, invasive since it wraps DSPy, therefore requiring at least the same effort to integrate.
Report issue for preceding element
prompt-ops
Meta-Llama ( 
2025
https://arxiv.org/html/2512.02840v2#bib.bib31
) : supports a basic and advanced optimizer, not extensible as the advanced optimizer is intended exclusively for Llama models, low abstraction since we can parametrize all components through a single configuration file, non-invasive since it simply returns a prompt string.
Report issue for preceding element
TextGrad
Yuksekgonul et al. ( 
2024
https://arxiv.org/html/2512.02840v2#bib.bib46
) : single optimizer (TextGrad by Yuksekgonul et al. ( 
2025
https://arxiv.org/html/2512.02840v2#bib.bib47
) ) and thus not extensible, low abstraction as the optimizer is parametrizable in a fine-grained way, invasive integration as requiring prompts to be wrapped in textgrad.Variable and LLM calls to textgrad.BlackboxLLM and engine wrappers.
Report issue for preceding element
AdalFlow
(Adalflow, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib1
) : single optimizer (LLM-AutoDiff by Yin and Wang ( 
2025
https://arxiv.org/html/2512.02840v2#bib.bib45
) ) and thus not extensible, low abstraction as the optimizer is parametrizable in a fine-grained way, invasive integration as it requires re-architecting pipelines into PyTorch-like component classes.
Report issue for preceding element
PromptWizard
(Agarwal et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib2
) : single optimizer (PromptWizard) and thus not extensible, low abstraction as the optimizer is parametrizable in a fine-grained way, non-invasive since it simply returns a prompt string.
Report issue for preceding element
PromptIM
(Hinthorn and Nishimi, 
2025
https://arxiv.org/html/2512.02840v2#bib.bib15
) : single optimizer (own optimization strategy) and thus not extensible, low abstraction as their optimizer is parametrizable in a fine-grained way, non-invasive since it can either be configured for local experimentation, just returning a prompt string, or to automatically commit the optimized prompt to the LangChain Hub.
Report issue for preceding element
A.2 Delimitation from DSPy
Report issue for preceding element
One might argue that the existing framework DSPy (Khattab et al., 
2024
https://arxiv.org/html/2512.02840v2#bib.bib20
) is already very similar to promptolution, as it is also open-source and modular, supports prompt optimization, implements multiple optimizers, supports several LLM implementations, and provides additional utilities. However, there are several important differences, both in underlying purpose and in concrete design, that clearly differentiate the two frameworks:
Report issue for preceding element
Different focus
: DSPy includes prompt optimization only as one component within a broader compilation workflow tightly coupled to a program structure, whereas promptolution is not a full application framework and instead focuses exclusively on the prompt optimization stage.
Report issue for preceding element
Abstraction level
: DSPy hides much of the prompt construction behind a high-level declarative interface (though it remains inspectable). In particular, DSPy primarily offers a monolithic compile method that runs the entire optimization routine. In contrast, promptolution provides an iterative optimize routine that repeatedly invokes an optimizer-specific _step method, along with associated callbacks. This design enables fine-grained control, including intermediate prompt candidates, scores, and token usage. It further facilitates early stopping, custom logging for full transparency, and budget-aware termination through callbacks.
Report issue for preceding element
Target user base
: promptolution is geared toward researchers and advanced ML practitioners, while DSPy primarily targets AI application developers building end-to-end workflows such as agents or RAG systems.
Report issue for preceding element
Experiments
: promptolution makes it easy to implement custom optimizers, tasks, and other components, and is particularly suited for systematic large-scale benchmark experiments due to the integrated config framework. Its extensibility explicitly encourages contributions of new algorithms and tasks, which is not a focus of DSPy.
Report issue for preceding element
Integration & Portability
: In DSPy, prompt optimization is performed on tasks defined via dspy.Module s (e.g., Predict, Refine, ChainOfThought, …) that require dspy.Signature s as input. This couples optimized prompts to DSPy's program abstraction, which introduces a degree of lock-in when individual subtasks are later migrated to a different system, as additional adaptation may be required. Conversely, promptolution produces a standalone prompt string, allowing optimized prompts to be reused or exchanged across systems with minimal friction, thereby improving portability.
Report issue for preceding element
A.3 Experiment Details
Report issue for preceding element
In § 
4
https://arxiv.org/html/2512.02840v2#S4
, we evaluate our framework against DSPy and AdalFlow. Since neither provides a straightforward way to restrict compute budgets based on token counts, we enforce token limits by throwing an exception in the respective LLM wrappers when the limit is exceeded, and then returning the last suggested prompt.
Report issue for preceding element
For evaluation, we route every LLM API call through the same interface using langchain to ensure a fair comparison of the optimized prompts, and compare exact matches between the predicted and true labels (allowing for differences in capitalization). In the case of GEPA, we had to manually clean the LLM outputs because they did not follow the required output format stated in the task description (encapsulating the prediction within <final_answer> tags). Specifically, we had to remove the “[[ ## target ## ]]” and “[[ ## completed ## ]]” tags. For AdalFlow, we had to intercept API calls due to faulty extraction of system and user prompts. The system-prompt extraction mechanism relied on tags, but these were not forwarded correctly (e.g., “<START_OF_USER_PROMPT>” was expected instead of the provided “<START_OF_USER>”). These changes are documented in the experiment repository. The used LLM was hosted on local servers and accessed via API calls. The utilized datasets and sample sizes are detailed in Table 
5
https://arxiv.org/html/2512.02840v2#A1.T5
. The dev set is used for optimization, the test set for holdout evaluation of the final prompts. Few-shot examples, if considered by the optimizer, are also taken from the dev set.
Report issue for preceding element
Dataset
Huggingface ID
𝐧 dev \mathbf{n_{\text{dev}}}
𝐧 test \mathbf{n_{\text{test}}}
SST5
SeetFit/sst5
500
300
GSM8K
openai/gsm8k
500
300
Table 5: Overview of the utilized HuggingFace datasets. Report issue for preceding element
The automatically generated prompts used to compare against a zero-effort baseline are shown in Table 
6
https://arxiv.org/html/2512.02840v2#A1.T6
. The system prompt accompanying the unoptimized prompts and those optimized by promptolution was “You are a helpful assistant!”; the system prompts used for the other frameworks were the ones returned after optimization. Note that prompts resulting from promptolution generally do not include any “{input}”-tags (unlike DSPy and AdalFlow, as well as some of the unoptimized prompts) to enable query-independent prompt-caching. Instead, promptolution appends respective queries to the end of the prompt.
Report issue for preceding element
The complete experiment code and raw results are publicly available for full reproducibility at 
https://github.com/finitearth/prompt-optimization-framework-comparison
https://github.com/finitearth/prompt-optimization-framework-comparison
.
Report issue for preceding element
Task
Prompt
GSM8K
Solve the maths problem step by step. Give your answer inside <final_answer> …</final_answer>.\n\n{input}
^^
Calculate the solution to the problem below. Show your steps. \n\n{input}\n\n Required output format: <final_answer> ANSWER </final_answer>.
^^
Please analyze the following mathematical problem. Break down your reasoning into logical steps before stating the solution. \n\n Problem: {input}\n Format your conclusion as <final_answer> YOUR_ANSWER </final_answer>.
SST5
Classify the sentiment as very negative, negative, neutral, positive, or very positive. Use <final_answer>-tags: \n {input}
^^
Identify the sentiment: very negative, negative, neutral, positive, very positive. \n\n Text: {input}\n\n Answer: <final_answer> label </final_answer>.
^^
Text: {input}\n\n Classify as very negative, negative, neutral, positive, or very positive. Output: <final_answer> label </final_answer>.
Table 6: Unoptimized zero-shot prompts per dataset. Report issue for preceding element
A.4 Quality Standards
Report issue for preceding element
To ensure high code quality, we adopt established software engineering best practices throughout our package. We maintain a comprehensive test suite that automatically verifies expected behavior after code changes. All tests must pass before a release is published, ensuring users encounter no issues when updating. The main branch is protected, and all contributions must be submitted via pull requests, each reviewed by another main contributor. We additionally employ pre-commit hooks to automatically check code formatting, documentation, and other basic quality issues before commits are made, improving readability and maintainability. We also maintain strict documentation standards and do not accept poorly documented pull requests. Dedicated CI and CI/CD pipelines enable an automated build, test, and release of the package and documentation.
Report issue for preceding element
A.5 Documentation & Tutorials
Report issue for preceding element
Alongside the open-source software package, we provide extensive documentation available at 
https://automl.github.io/promptolution/
https://automl.github.io/promptolution/
. It covers the major components and their functionality, and also includes tutorials that guide users through their first prompt optimization use case. This further enhances the accessibility and usability of our framework.
Report issue for preceding element
A.6 Extensibility of promptolution
Report issue for preceding element
promptolution is designed to be easily extensible, allowing researchers to integrate new optimization algorithms with minimal implementation effort. To illustrate this, we briefly outline how a new prompt optimizer can be added to the framework.
Report issue for preceding element
All prompt optimizers inherit from the abstract base class BaseOptimizer, which defines the common interface and execution structure shared across optimization algorithms. Concretely, extending the framework requires implementing only two abstract methods: _pre_optimization_loop, which performs any setup before the optimization begins, and _step, which executes a single optimization iteration and returns the updated prompt candidate(s). The overall optimization loop, including configuration handling, callback invocation, and other features, is already implemented in the base class via the optimize method.
Report issue for preceding element
This design ensures that developers of new optimizers can focus exclusively on their algorithmic logic, while benefiting from shared infrastructure such as logging, callbacks, and budget-aware termination. A similar extension pattern applies when adding new task-, LLM-, or predictor components.
Report issue for preceding element
A.7 System Demonstration
Report issue for preceding element
The system demonstration under 
https://youtu.be/gySdgjEhsZA
https://youtu.be/gySdgjEhsZA
 uses the following code example, through which we guide step-by-step. It requires installing the promptolution package with API support enabled. The subsequent imports establish the necessary components for the LLM wrapper, CAPO, and the evaluation task definitions.
Report issue for preceding element 
Report issue for preceding element 
Report issue for preceding element The dataset, containing raw email-generation instructions, is loaded from a CSV file using pandas: 
Report issue for preceding element After loading the data, we define a task description that specifies the desired persona, tone, and formatting constraints (including the closing signature). This serves as the reference specification for the entire workflow. 
Report issue for preceding element We then instantiate the underlying LLM. In this example, the APILLM wrapper connects to the Llama-3.3-70B-Instruct-Turbo model via the DeepInfra API, which serves as the downstream LLM, the judge, and the meta-LLM. 
Report issue for preceding element To initialize the optimization search space, a set of candidate prompts is derived directly from the task description using the framework's utility function. These serve as the starting population for the optimizer we use later. 
Report issue for preceding element Given the subjective nature of the email generation task (lacking a ground truth), a JudgeTask is configured. This setup utilizes an LLM-as-a-Judge approach to evaluate the semantic quality of the generated outputs against the input instructions. An alternative could be the ClassificationTask when ground truth labels are available, or the RewardTask when the user can define an objective function to score the outputs. 
Report issue for preceding element Next, we instantiate the CAPO optimizer with a marker-based predictor. The optimization routine is executed for six iterations ( n_steps=6) to refine the prompt candidates iteratively. 
Report issue for preceding element After optimization completes, the final optimized prompts are returned and ready for use in email generation.````````
Report Issue
Report GitHub Issue
Title:
Content selection saved. Describe the issue below:
Description:
Submit without GitHub Submit in GitHub
Report Issue for Selection
Generated by 
L A T E xml[LOGO]
https://math.nist.gov/~BMiller/LaTeXML/
Instructions for reporting errors
We are continuing to improve HTML versions of papers, and your feedback helps enhance accessibility and mobile support. To report errors in the HTML that will help us improve conversion and rendering, choose any of the methods listed below:
Click the "Report Issue" button.
Open a report feedback form via keyboard, use " 
Ctrl + ?
".
Make a text selection and click the "Report Issue for Selection" button near your cursor.
You can use Alt+Y to toggle on and Alt+Shift+Y to toggle off accessible reporting links at each section.
Our team has already identified 
the following issues
https://github.com/arXiv/html_feedback/issues
. We appreciate your time reviewing and reporting rendering errors we may not have found yet. Your efforts will help us improve the HTML versions for all readers, because disability should not be a barrier to accessing research. Thank you for your continued support in championing open access for all.
Have a free development cycle? Help support accessibility at arXiv! Our collaborators at LaTeXML maintain a 
list of packages that need conversion
https://github.com/brucemiller/LaTeXML/wiki/Porting-LaTeX-packages-for-LaTeXML
, and welcome 
developer contributions
https://github.com/brucemiller/LaTeXML/issues
.
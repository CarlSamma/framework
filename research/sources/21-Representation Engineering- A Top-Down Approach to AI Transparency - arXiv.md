> Source: https://arxiv.org/html/2310.01405v4

Representation Engineering: A Top-Down Approach to AI Transparency
logo Back to arXiv  
logo Back to arXiv
This is experimental HTML to improve accessibility. We invite you to report rendering errors. Use Alt+Y to toggle on accessible reporting links and Alt+Shift+Y to toggle off. Learn more about this project and help improve conversions.
Why HTML? Report Issue Back to Abstract Download PDF 
Table of Contents
Abstract
1 Introduction
2 Related Work
2.1 Emergent Structure in Representations
2.2 Approaches to Interpretability
Saliency Maps.
Feature Visualization.
Mechanistic Interpretability.
2.3 Locating and Editing Representations of Concepts
3 Representation Engineering
3.1 Representation Reading
3.1.1 Baseline: Linear Artificial Tomography (LAT)
Step 1: Designing Stimulus and Task.
Step 2: Collecting Neural Activity.
Step 3: Constructing a Linear Model.
3.1.2 Evaluation
3.2 Representation Control
3.2.1 Baseline Transformations
Baseline: Reading Vector.
Baseline: Contrast Vector.
Baseline: Low-Rank Representation Adaptation (LoRRA).
Choices for Operators:
4 In Depth Example of RepE: Honesty
4.1 A Consistent Internal Concept of Truth
Correctness on Traditional QA Benchmarks.
Resistance to Imitative Falsehoods.
4.2 Truthfulness vs. Honesty
Definitions.
Evaluating Truthfulness and Honesty.
4.3 Honesty: Extraction, Monitoring, and Control
4.3.1 Extracting Honesty
4.3.2 Lie and Hallucination Detection
4.3.3 Controlling Honesty
5 In Depth Example of RepE: Ethics and Power
5.1 Utility
5.1.1 Extraction and Evaluation
Correlation.
Manipulation.
Termination.
5.2 Morality and Power Aversion
5.2.1 Extraction
5.2.2 Monitoring
5.2.3 Controlling Ethical Behaviors in Interactive Environments
5.3 Probability and Risk
5.3.1 Compositionality of Concept Primitives
6 Example Frontiers of Representation Engineering
6.1 Emotion
6.1.1 Emotions Emerge across Layers
6.1.2 Emotions Influence Model Behaviors
6.2 Harmless Instruction-Following
6.2.1 A Consistent Internal Concept of Harmfulness
6.2.2 Model Control via Conditional Transformation
6.3 Bias and Fairness
6.3.1 Uncovering Underlying Biases
6.3.2 A Unified Representation for Bias
6.4 Knowledge and Model Editing
6.4.1 Fact Editing
6.4.2 Non-Numerical Concepts
6.5 Memorization
6.5.1 Memorized Data Detection
6.5.2 Preventing Memorized Outputs
7 Conclusion
A Mechanistic Interpretability vs. Representation Reading
Mechanisms are flawed for understanding complex systems.
Are mechanisms or representations the right unit of analysis?
B Additional Demos and Results
B.1 Truthfulness
B.2 Honesty
LAT Scans for Honesty.
B.3 Utility
B.4 Estimating Probability, Risk, and Monetary Value
Zero-shot heuristic baseline.
B.5 CLIP
B.6 Emotion
Examples of RepE Emotion datasets.
B.7 Bias and Fairness
B.8 Base vs. Chat Models
B.9 Robustness to Misleading Prompts
C Implementation Details
C.1 Detailed Construction of LAT Vectors with PCA
Constructing a Set of Stimuli.
Constructing the PCA Model.
Inference.
C.2 Implementation Details for Honesty Control
Contrast Vector.
LoRRA.
D Task Template Details
D.1 LAT Task Templates
D.1.1 TruthfulQA
D.1.2 Honesty Extraction
D.1.3 Honesty Control
D.1.4 ARC-{Easy|Challenge}
D.1.5 OpenbookQA (OBQA)
D.1.6 CommonsenseQA (CSQA)
D.1.7 RACE
D.1.8 Utility
D.1.9 Morality & Power
Morality
Power
Power-Seeking and Moral Control
D.1.10 Emotions
D.1.11 Harmlessness Instruction
D.1.12 Bias and Fairness
D.1.13 Fact Editing
D.1.14 Non-Numerical Concepts (Dogs)
D.1.15 Probability, Risk, and Monetary Value
D.1.16 Encoder Datasets
D.2 Data generation prompts for probability, risk, monetary value
D.3 Zero-shot baselines
D.3.1 Probability, risk, cost
D.3.2 TruthfulQA and ARC
D.3.3 Utility
E X-Risk Sheet
E.1 Long-Term Impact on Advanced AI Systems
E.2 Safety-Capabilities Balance
E.3 Elaborations and Other Considerations
References
HTML conversions sometimes display errors due to content that did not convert correctly from the source. This paper uses the following packages that are not yet supported by the HTML conversion tool. Feedback on these issues are not necessary; they are known and are being worked on.
failed: dashrule
failed: tabularray
failed: tocloft
failed: spverbatim
Authors: achieve the best HTML results from your LaTeX submissions by following these best practices.
License: arXiv.org perpetual non-exclusive license
arXiv:2310.01405v4 [cs.LG] 03 Mar 2025
\UseTblrLibrary
booktabs
Report issue for preceding element
Representation Engineering: A Top-Down Approach to AI Transparency
Report issue for preceding element
Andy Zou Center for AI Safety Carnegie Mellon University Long Phan ∗ Center for AI Safety Sarah Chen ∗ Center for AI Safety Stanford University James Campbell ∗ Cornell University Phillip Guo ∗ University of Maryland Richard Ren ∗ University of Pennsylvania Alexander Pan UC Berkeley Xuwang Yin Center for AI Safety Mantas Mazeika Center for AI Safety University of Illinois Urbana-Champaign Ann-Kathrin Dombrowski Center for AI Safety
Shashwat Goel Center for AI Safety Nathaniel Li Center for AI Safety UC Berkeley Michael J. Byun Stanford University Zifan Wang Center for AI Safety
Alex Mallen EleutherAI Steven Basart Center for AI Safety Sanmi Koyejo Stanford University Dawn Song UC Berkeley
Matt Fredrikson Carnegie Mellon University Zico Kolter Carnegie Mellon University Dan Hendrycks Center for AI Safety
Report issue for preceding element
Abstract
Report issue for preceding element
We identify and characterize the emerging area of representation engineering (RepE), an approach to enhancing the transparency of AI systems that draws on insights from cognitive neuroscience. RepE places representations, rather than neurons or circuits, at the center of analysis, equipping us with novel methods for monitoring and manipulating high-level cognitive phenomena in deep neural networks (DNNs). We provide baselines and an initial analysis of RepE techniques, showing that they offer simple yet effective solutions for improving our understanding and control of large language models. We showcase how these methods can provide traction on a wide range of safety-relevant problems, including honesty, harmlessness, power-seeking, and more, demonstrating the promise of top-down transparency research. We hope that this work catalyzes further exploration of RepE and fosters advancements in the transparency and safety of AI systems. Code is available at github.com/andyzoujm/representation-engineering.
Report issue for preceding element † † ∗
Equal contribution. Correspondence to: andyzou@cmu.edu 
Figure 1: Overview of topics in the paper. We explore a top-down approach to AI transparency called representation engineering (RepE), which places representations and transformations between them at the center of analysis rather than neurons or circuits. Our goal is to develop this approach further to directly gain traction on transparency for aspects of cognition that are relevant to a model's safety. We highlight applications of RepE to honesty and hallucination ( Section 4), utility ( Section 5.1), power-aversion ( Section 5.2), probability and risk ( Section 5.3), emotion ( Section 6.1), harmlessness ( Section 6.2), fairness and bias ( Section 6.3), knowledge editing ( Section 6.4), and memorization ( Section 6.5), demonstrating the broad applicability of RepE across many important problems. Report issue for preceding element
Contents
Report issue for preceding element
1 Introduction
2 Related Work
2.1 Emergent Structure in Representations
2.2 Approaches to Interpretability
2.3 Locating and Editing Representations of Concepts
3 Representation Engineering
3.1 Representation Reading
3.1.1 Baseline: Linear Artificial Tomography (LAT)
3.1.2 Evaluation
3.2 Representation Control
3.2.1 Baseline Transformations
4 In Depth Example of RepE: Honesty
4.1 A Consistent Internal Concept of Truth
4.2 Truthfulness vs. Honesty
4.3 Honesty: Extraction, Monitoring, and Control
4.3.1 Extracting Honesty
4.3.2 Lie and Hallucination Detection
4.3.3 Controlling Honesty
5 In Depth Example of RepE: Ethics and Power
5.1 Utility
5.1.1 Extraction and Evaluation
5.2 Morality and Power Aversion
5.2.1 Extraction
5.2.2 Monitoring
5.2.3 Controlling Ethical Behaviors in Interactive Environments
5.3 Probability and Risk
5.3.1 Compositionality of Concept Primitives
6 Example Frontiers of Representation Engineering
6.1 Emotion
6.1.1 Emotions Emerge across Layers
6.1.2 Emotions Influence Model Behaviors
6.2 Harmless Instruction-Following
6.2.1 A Consistent Internal Concept of Harmfulness
6.2.2 Model Control via Conditional Transformation
6.3 Bias and Fairness
6.3.1 Uncovering Underlying Biases
6.3.2 A Unified Representation for Bias
6.4 Knowledge and Model Editing
6.4.1 Fact Editing
6.4.2 Non-Numerical Concepts
6.5 Memorization
6.5.1 Memorized Data Detection
6.5.2 Preventing Memorized Outputs
7 Conclusion
A Mechanistic Interpretability vs. Representation Reading
B Additional Demos and Results
B.1 Truthfulness
B.2 Honesty
B.3 Utility
B.4 Estimating Probability, Risk, and Monetary Value
B.5 CLIP
B.6 Emotion
B.7 Bias and Fairness
B.8 Base vs. Chat Models
B.9 Robustness to Misleading Prompts
C Implementation Details
C.1 Detailed Construction of LAT Vectors with PCA
C.2 Implementation Details for Honesty Control
D Task Template Details
D.1 LAT Task Templates
D.1.1 TruthfulQA
D.1.2 Honesty Extraction
D.1.3 Honesty Control
D.1.4 ARC-{Easy|Challenge}
D.1.5 OpenbookQA (OBQA)
D.1.6 CommonsenseQA (CSQA)
D.1.7 RACE
D.1.8 Utility
D.1.9 Morality & Power
D.1.10 Emotions
D.1.11 Harmlessness Instruction
D.1.12 Bias and Fairness
D.1.13 Fact Editing
D.1.14 Non-Numerical Concepts (Dogs)
D.1.15 Probability, Risk, and Monetary Value
D.1.16 Encoder Datasets
D.2 Data generation prompts for probability, risk, monetary value
D.3 Zero-shot baselines
D.3.1 Probability, risk, cost
D.3.2 TruthfulQA and ARC
D.3.3 Utility
E X-Risk Sheet
E.1 Long-Term Impact on Advanced AI Systems
E.2 Safety-Capabilities Balance
E.3 Elaborations and Other Considerations
1 Introduction
Report issue for preceding element 
Figure 2: Mechanistic Interpretability (MI) vs. Representation Engineering (RepE). This figure draws from (Barack & Krakauer, 2021; Wang et al., 2023a) . Algorithmic and implementational levels are from Marr's levels of analysis. Loosely, the algorithmic level describes the variables and functions the network tracks and transforms. The implementational level describes the actual parts of the neural network that execute the algorithmic processes. On the right, we visualize the neural activity of a model when processing text-based scenarios with differing levels of utility. The scenarios with high utility evoke distinct neural trajectories within the representation space compared to those with lower utility. 'PC' denotes a principal component. Report issue for preceding element
Deep neural networks have achieved incredible success across a wide variety of domains, yet their inner workings remain poorly understood. This problem has become increasingly urgent over the past few years due to the rapid advances in large language models (LLMs). Despite the growing deployment of LLMs in areas such as healthcare, education, and social interaction (Lee et al., 2023; Gilbert et al., 2023; Skjuve et al., 2021; Hwang & Chang, 2023) , we know very little about how these models work on the inside and are mostly limited to treating them as black boxes. Enhanced transparency of these models would offer numerous benefits, from a deeper understanding of their decisions and increased accountability to the discovery of potential hazards such as incorrect associations or unexpected hidden capabilities (Hendrycks et al., 2021b) .
Report issue for preceding element
One approach to increasing the transparency of AI systems is to create a “cognitive science of AI.” Current efforts toward this goal largely center around the area of mechanistic interpretability, which focuses on understanding neural networks in terms of neurons and circuits. This aligns with the Sherringtonian view in cognitive neuroscience, which sees cognition as the outcome of node-to-node connections, implemented by neurons embedded in circuits within the brain. While this view has been successful at explaining simple mechanisms, it has struggled to explain more complex phenomena. The contrasting Hopfieldian view ( n.b., not to be confused with Hopfield networks) has shown more promise in scaling to higher-level cognition. Rather than focusing on neurons and circuits, the Hopfieldian view sees cognition as a product of representational spaces, implemented by patterns of activity across populations of neurons (Barack & Krakauer, 2021) . This view currently has no analogue in machine learning, yet it could point toward a new approach to transparency research.
Report issue for preceding element
The distinction between the Sherringtonian and Hopfieldian views in cognitive neuroscience reflects broader discussions on understanding and explaining complex systems. In the essay “More Is Different,” Nobel Laureate P. W. Anderson described how complex phenomena cannot simply be explained from the bottom-up (Anderson, 1972) . Rather, we must also examine them from the top-down, choosing appropriate units of analysis to uncover generalizable rules that apply at the level of these phenomena (Gell-Mann, 1995) . Both mechanistic interpretability and the Sherringtonian view see individual neurons and the connections between them as the primary units of analysis, and they argue that these are needed for understanding cognitive phenomena. By contrast, the Hopfieldian view sees representations as the primary unit of analysis and seeks to study them on their own terms, abstracting away low-level details. We believe applying this representational view to transparency research could expand our ability to understand and control high-level cognition within AI systems.
Report issue for preceding element
In this work, we identify and characterize the emerging area of representation engineering (RepE), which follows an approach of top-down transparency to better understand and control the inner workings of neural networks. Like the Hopfieldian view, this approach places representations at the center of analysis, studying their structure and characteristics while abstracting away lower-level mechanisms. We think pursuing this top-down approach to transparency is important, and our work serves as an early step in exploring its potential. Compared to approaches that apply activation vectors to frozen models under the umbrella of activation engineering (Turner et al., 2023e) , we aim to uncover insights from both reading and control experiments and introduce representation tuning methods. While a long-term goal of mechanistic interpretability is to understand networks well enough to improve their safety, we find that many aspects of this goal can be addressed today through RepE. In particular, we develop improved baselines for reading and controlling representations and demonstrate that these RepE techniques can provide traction on a wide variety of safety-relevant problems, including truthfulness, honesty, hallucination, utility estimation, knowledge editing, jailbreaking, memorization, tracking emotional states, and avoiding power-seeking tendencies.
Report issue for preceding element
In addition to demonstrating the broad potential of RepE, we also find that advances to RepE methods can lead to significant gains in specific areas, such as honesty. By increasing model honesty in a fully unsupervised manner, we achieve state-of-the-art results on TruthfulQA, improving over zero-shot accuracy by 18.1 18.1 18.1 18.1 percentage points and outperforming all prior methods. We also show how RepE techniques can be used across diverse scenarios to detect and control whether a model is lying. We hope that this work will accelerate progress in AI transparency by demonstrating the potential of a representational view. As AI systems become increasingly capable and complex, achieving better transparency will be crucial for enhancing their safety, trustworthiness, and accountability, enabling these technologies to benefit society while minimizing the associated risks.
Report issue for preceding element
2 Related Work
Report issue for preceding element 
Figure 3: Examples of emergent structure in learned representations. Left: Part segmentation in DINOv2 self-supervised vision models (Oquab et al., 2023) . Top-right: Semantic arithmetic in word vectors (Mikolov et al., 2013) . Bottom-right: Local coordinates in StyleGAN3 (Karras et al., 2021) . These figures are adapted from the above papers. As AI systems become increasingly capable, emergent structure in their representations may open up new avenues for transparency research, including top-down transparency research that places representations at the center of analysis. Report issue for preceding element
2.1 Emergent Structure in Representations
Report issue for preceding element
While neural networks internals are often considered chaotic and uninterpretable, research has demonstrated that they can acquire emergent, semantically meaningful internal structure. Early research on word embeddings discovered semantic associations and compositionality (Mikolov et al., 2013) , including reflections of gender biases in text corpora (Bolukbasi et al., 2016) . Later work showed that learned text embeddings also cluster along dimensions reflecting commonsense morality, even though models were not explicitly taught this concept (Schramowski et al., 2019) . Radford et al. ( 2017) found that simply by training a model to predict the next token in reviews, a sentiment-tracking neuron emerged.
Report issue for preceding element
Observations of emergent internal representations are not limited to text models. McGrath et al. ( 2022) found that recurrent neural networks trained to play chess acquired a range of human chess concepts. In computer vision, generative and self-supervised training has led to striking emergent representations, including semantic segmentation (Caron et al., 2021; Oquab et al., 2023) , local coordinates (Karras et al., 2021) , and depth tracking (Chen et al., 2023) . These findings suggest that neural representations are becoming more well-structured, opening up new opportunities for transparency research. Our paper builds on this long line of work by demonstrating that many safety-relevant concepts and processes appear to emerge in LLM representations, enabling us to directly monitor and control these aspects of model cognition via representation engineering.
Report issue for preceding element
2.2 Approaches to Interpretability
Report issue for preceding element
Saliency Maps.
Report issue for preceding element
A popular approach to explaining neural network decisions is via saliency maps, which highlight regions of the input that a network attends to (Simonyan et al., 2013; Springenberg et al., 2014; Zeiler & Fergus, 2014; Zhou et al., 2016; Smilkov et al., 2017; Sundararajan et al., 2017; Selvaraju et al., 2017; Lei et al., 2016; Clark et al., 2019b) . However, the reliability of these methods has been drawn into question (Adebayo et al., 2018; Kindermans et al., 2019; Jain & Wallace, 2019; Bilodeau et al., 2022) . Moreover, while highlighting regions of attention can provide some understanding of network behavior, it provides limited insight into the internal representations of networks.
Report issue for preceding element
Feature Visualization.
Report issue for preceding element
Feature visualization interprets network internals by creating representative inputs that highly activate a particular neuron. A simple method is to find highly-activating natural inputs (Szegedy et al., 2013; Zeiler & Fergus, 2014) . More complex methods optimize inputs to maximize activations (Erhan et al., 2009; Mordvintsev et al., 2015; Yosinski et al., 2015; Nguyen et al., 2016; 2019) . These methods can lead to meaningful insights, but do not take into account the distributed nature of neural representations (Hinton, 1984; Szegedy et al., 2013; Fong & Vedaldi, 2018; Elhage et al., 2022) .
Report issue for preceding element
Mechanistic Interpretability.
Report issue for preceding element
Inspired by reverse-engineering tools for traditional software, mechanistic interpretability seeks to fully reverse engineer neural networks into their “source code.” This approach focuses on explaining neural networks in terms of circuits, composed of node-to-node connections between individual neurons or features. Specific circuits have been identified for various capabilities, including equivariance in visual recognition (Olah et al., 2020) , in-context learning (Olsson et al., 2022) , indirect object identification (Wang et al., 2023a) , and mapping answer text to answer labels (Lieberum et al., 2023) .
Report issue for preceding element
Considerable manual effort is required to identify circuits, which currently limits this approach. Moreover, it is unlikely that neural networks can be fully explained in terms of circuits, even in principle. There is strong evidence that ResNets compute representations through iterative refinement (Liao & Poggio, 2016; Greff et al., 2016; Jastrzebski et al., 2018) . In particular, Veit et al. ( 2016) find that ResNets are surprisingly robust to lesion studies that remove entire layers. Recent work has demonstrated similar properties in LLMs (McGrath et al., 2023; Belrose et al., 2023a) . These findings are incompatible with a purely circuit-based account of cognition and are more closely aligned with the Hopfieldian view in cognitive neuroscience (Barack & Krakauer, 2021) .
Report issue for preceding element
2.3 Locating and Editing Representations of Concepts
Report issue for preceding element
Many prior works have investigated locating representations of concepts in neural networks, including in individual neurons (Bau et al., 2017) and in directions in feature space (Bau et al., 2017; Fong & Vedaldi, 2018; Zhou et al., 2018; Kim et al., 2018) . A common tool in this area is linear classifier probes (Guillaume Alain, 2017; Belinkov, 2022) , which are trained to predict properties of the input from intermediate layers of a network. Representations of concepts have also been identified in the latent space of image generation models, enabling counterfactual editing of generations (Radford et al., 2015; Upchurch et al., 2017; Bau et al., 2019; Shen et al., 2020; Bau et al., 2020; Ling et al., 2021; Wang et al., 2023b) . While these earlier works focused primarily on vision models, more recent work has studied representations of concepts in LLMs. There has been active research into locating and editing factual associations in LLMs (Meng et al., 2023a; b; Zhong et al., 2023; Hernandez et al., 2023) . Related to knowledge editing, several works have been proposed for concept erasure (Shao et al., 2023; Kleindessner et al., 2023; Belrose et al., 2023b; Ravfogel et al., 2023; Gandikota et al., 2023) , which are related to the area of machine unlearning (Shaik et al., 2023) .
Report issue for preceding element
The highly general capabilities of LLMs have also enabled studying the emergence of deception in LLMs, either of an intentional nature through repeating misconceptions Lin et al. ( 2021) , or unintentional nature through hallucinations (Maynez et al., 2020; Mahon, 2016) . Burns et al. ( 2022) identify representations of truthfulness in LLMs by enforcing logical consistency properties, demonstrating that models often know the true answer even when they generate incorrect outputs. Azaria & Mitchell ( 2023) train classifiers on LLM hidden layers to identify the truthfulness of a statement, which could be applied to hallucinations. Li et al. ( 2023c) focus on directions that have a causal influence on model outputs, using activation editing to increase the truthfulness of generations. Activation editing has also been used to steer model outputs towards other concepts. In the culmination of a series of blog posts (Turner et al., 2023d; a; b; c) , (Turner et al., 2023e) proposed ActAdd, which uses difference vectors between activations on an individual stimuli to capture representations of a concept. Similar approaches have been used in the context of red-teaming and reducing sycophancy (Rimsky, 2023b; c; a) . In the setting of game-playing, Li et al. ( 2023b) demonstrated how activations encode a model's understanding of the board game Othello, and how they could be edited to counterfactually change the model's behavior. In the linear probing literature, Elazar et al. ( 2021) demonstrate how projecting out supervised linear probe directions can reduce performance on selected tasks. Building on this line of work, we propose improved representation engineering methods and demonstrate their broad applicability to various safety-relevant problems.
Report issue for preceding element 
Figure 4: An example of the LAT baseline aimed to extract neural activity related to our target concept or function. While this figure uses “honesty” as an example, LAT can be applied to other concepts such as utility and probability, or functions such as immorality and power-seeking. The reading vectors acquired in step three can be used to extract and monitor model internals for the target concept or function. Report issue for preceding element
3 Representation Engineering
Report issue for preceding element
Representation engineering (RepE) is a top-down approach to transparency research that treats representations as the fundamental unit of analysis, with the goal of understanding and controlling representations of high-level cognitive phenomena in neural networks. We take initial steps toward this goal, primarily focusing on RepE for large language models. In particular, we identify two main areas of RepE: Reading (Section 3.1) and Control (Section 3.2). For each area, we provide an overview along with baseline methods.
Report issue for preceding element
3.1 Representation Reading
Report issue for preceding element
Representation reading seeks to locate emergent representations for high-level concepts and functions within a network. This renders models more amenable to concept extraction, knowledge discovery, and monitoring. Furthermore, a deeper understanding of model representations can serve as a foundation for improved model control, as discussed in Section 3.2.
Report issue for preceding element
We begin by extracting various concepts, including truthfulness, utility, probability, morality, and emotion, as well as functions which denote processes, such as lying and power-seeking. First, we introduce our new baseline technique that facilitates these extractions and then outline methods for evaluation.
Report issue for preceding element
3.1.1 Baseline: Linear Artificial Tomography (LAT)
Report issue for preceding element
Similar to neuroimaging methodologies, a LAT scan is made up of three key steps: (1) Designing Stimulus and Task, (2) Collecting Neural Activity, and (3) Constructing a Linear Model. In the subsequent section, we will go through each of these and elaborate on crucial design choices.
Report issue for preceding element
Step 1: Designing Stimulus and Task.
Report issue for preceding element
The stimulus and task are designed to elicit distinct neural activity for the concept and function that we want to extract. Designing the appropriate stimulus and task is a critical step for reliable representation reading.
Report issue for preceding element
To capture concepts, our goal is to elicit declarative knowledge from the model. Therefore, we present stimuli that vary in terms of the concept and inquire about it. For a decoder language model, an example task template might resemble the following (for encoder models, we exclude the text following the stimulus):
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
This process aims to stimulate the model's understanding of various concepts and is crucial for robust subsequent analysis. For reference, we shall denote this template for a concept c 𝑐 c italic_c by T c subscript 𝑇 𝑐 T_{c} italic_T start_POSTSUBSCRIPT italic_c end_POSTSUBSCRIPT . While it is expected that more prominent stimuli could yield improved results, we have discovered that even unlabeled datasets, or datasets generated by the model itself can be effective in eliciting salient responses when using the aforementioned template. Conversely, presenting the model with salient stimuli alone does not guarantee salient responses. Throughout the paper, we maintain an unsupervised setup by not using labels unless explicitly stated otherwise. One advantage of unlabeled or self-generated stimuli is the absence of annotation bias; this is an important property when trying to extract superhuman representations.
Report issue for preceding element
To capture functions such as honesty or instruction-following, our goal is to elicit procedural knowledge from the model. (Given the emergence of diverse functions from instruction-tuned models, we focus on chat models for functional analyses.) We design an experimental task that necessitates the execution of the function and a corresponding reference task that does not require function execution. An example task template might resemble the following:
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
We shall designate this template for a function f 𝑓 f italic_f as T f + subscript superscript 𝑇 𝑓 T^{+}{f} italic_T start_POSTSUPERSCRIPT + end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_f end_POSTSUBSCRIPT when using the experimental prompt and T f − subscript superscript 𝑇 𝑓 T^{-}{f} italic_T start_POSTSUPERSCRIPT - end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_f end_POSTSUBSCRIPT when using the reference prompt. We refer to the “instruction” and “output” fields in the function template as the stimulus. By default, we use generic instruction-tuning datasets (Taori et al., 2023) as the stimulus for function templates unless explicitly specified otherwise. Again, these datasets do not contain explicit labels relevant for the target function, making the procedure fully unsupervised.
Report issue for preceding element
Step 2: Collecting Neural Activity.
Report issue for preceding element
We focus on Transformer models, which store distinct representations at various token positions within the input for different purposes. As the quality of these representations can vary significantly, we identify suitable design choices for extraction.
Report issue for preceding element
The pretraining objectives of LLMs can provide valuable insights into which tokens in the task template offer the best options for collecting neural activity. Both the Masked Language Modeling (MLM) objective used in encoder-only models (Devlin et al., 2018) , and the Next Token Prediction objective used in decoder models (Radford et al., 2018) , are token-level prediction tasks. Thus, a
Report issue for preceding element 
Figure 5: The representation at the concept token “happiness” in middle layers and the representation at the last token in middle and later layers yield high accuracy on the utility estimation task. Report issue for preceding element
natural position for collecting neural activity associated with concepts is the tokens corresponding to  in the task template T c subscript 𝑇 𝑐 T_{c} italic_T start_POSTSUBSCRIPT italic_c end_POSTSUBSCRIPT defined in step 1. For example, when extracting the concept of truthfulness, the tokens corresponding to this concept (e.g., “truth-ful-ness”) in the task template can contain rich and highly generalizable representations of this exact concept. In cases where the target concept spans multiple tokens, we could select the most representative token (e.g., “truth”) or calculate the mean representation. Alternatively, for decoder models, where the task template is structured as a question pertaining to the target concept, we can also use the token immediately preceding the model's prediction (typically the last token in the task template T c subscript 𝑇 𝑐 T_{c} italic_T start_POSTSUBSCRIPT italic_c end_POSTSUBSCRIPT ). These choices have also been empirically validated, as illustrated in Figure 5. By default, we use the last token representation in this paper. Similarly, to extract functions from decoder models, we collect representations from each token in the model's response. In the example task template T f subscript 𝑇 𝑓 T_{f} italic_T start_POSTSUBSCRIPT italic_f end_POSTSUBSCRIPT in step 1, these tokens are aligned with the tokens within . This is done because the model needs to engage with the function when generating every new token.
Report issue for preceding element
Formally, for a concept c 𝑐 c italic_c , a decoder model M 𝑀 M italic_M , a function Rep that accepts a model and input and returns the representations from all token positions, and a set of stimuli S 𝑆 S italic_S , we compile a set of neural activity collected from the − 1 1 -1 - 1 token position as shown in Equation 1.
Report issue for preceding element
A c = { Rep  ( M , T c  ( s i ) )  [ − 1 ] | s i ∈ S } subscript 𝐴 𝑐 conditional-set Rep 𝑀 subscript 𝑇 𝑐 subscript 𝑠 𝑖 delimited-[] 1 subscript 𝑠 𝑖 𝑆 A_{c}={\text{Rep}(M,T_{c}(s_{i}))[-1],|,s_{i}\in S} italic_A start_POSTSUBSCRIPT italic_c end_POSTSUBSCRIPT = { Rep ( italic_M , italic_T start_POSTSUBSCRIPT italic_c end_POSTSUBSCRIPT ( italic_s start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT ) ) [ - 1 ] | italic_s start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT ∈ italic_S }
(1)
For a function f 𝑓 f italic_f , given the instruction response pairs ( q i , a i ) subscript 𝑞 𝑖 subscript 𝑎 𝑖 (q_{i},a_{i}) ( italic_q start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT ) in the set S 𝑆 S italic_S , and denoting a response truncated after token k 𝑘 k italic_k as a i k superscript subscript 𝑎 𝑖 𝑘 a_{i}^{k} italic_a start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT , we collect two sets of neural activity corresponding to the experimental and reference sets, as shown in Equation 2.
Report issue for preceding element
A f ± = { Rep  ( M , T f ±  ( q i , a i k ) )  [ − 1 ] | ( q i , a i ) ∈ S , for  0 < k ≤ | a i | } superscript subscript 𝐴 𝑓 plus-or-minus conditional-set Rep 𝑀 superscript subscript 𝑇 𝑓 plus-or-minus subscript 𝑞 𝑖 superscript subscript 𝑎 𝑖 𝑘 delimited-[] 1 formulae-sequence subscript 𝑞 𝑖 subscript 𝑎 𝑖 𝑆 for 0 𝑘 subscript 𝑎 𝑖 A_{f}^{\pm}={\text{Rep}(M,T_{f}^{\pm}(q_{i},a_{i}^{k}))[-1],|,(q_{i},a_{i})% \in S,~{}\text{for}~{}0<k\leq|a_{i}|} italic_A start_POSTSUBSCRIPT italic_f end_POSTSUBSCRIPT start_POSTSUPERSCRIPT ± end_POSTSUPERSCRIPT = { Rep ( italic_M , italic_T start_POSTSUBSCRIPT italic_f end_POSTSUBSCRIPT start_POSTSUPERSCRIPT ± end_POSTSUPERSCRIPT ( italic_q start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_k end_POSTSUPERSCRIPT ) ) [ - 1 ] | ( italic_q start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT ) ∈ italic_S , for 0 < italic_k ≤ | italic_a start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT | }
(2)
Note that these neural activity sets consist of individual vectors. We show the surprising effectiveness of such a simple setup when exploring various concepts and functions in this paper. Nevertheless, it may be necessary to design a more involved procedure to gather neural activity, for instance, to extract more intricate concepts or multi-step functions.
Report issue for preceding element
Step 3: Constructing a Linear Model.
Report issue for preceding element
In this final step, our goal is to identify a direction that accurately predicts the underlying concept or function using only the neural activity of the model as input. The choice of the appropriate linear model may be influenced by factors such as the availability of labeled data and the nature of the concepts (e.g., continuous or discrete) which can ultimately yield varying levels of accuracy and generalization performance. Supervised linear models, like linear probing and difference between cluster means, represent one category. Unsupervised linear models include techniques like Principal Component Analysis (PCA) and K-means.
Report issue for preceding element
In our study, we primarily use PCA in an unsupervised manner, unless explicitly specified otherwise. Our experiments indicate that pairing neural activities and applying PCA to the set of difference vectors can yield superior results when the stimuli in each pair share similarities except for the target concept or function. In some cases, such pairings can also be achieved in an unsupervised way. In practice, the inputs to PCA are { A c ( i ) − A c ( j ) } superscript subscript 𝐴 𝑐 𝑖 superscript subscript 𝐴 𝑐 𝑗 {{A_{c}}^{(i)}-{A_{c}}^{(j)}} { italic_A start_POSTSUBSCRIPT italic_c end_POSTSUBSCRIPT start_POSTSUPERSCRIPT ( italic_i ) end_POSTSUPERSCRIPT - italic_A start_POSTSUBSCRIPT italic_c end_POSTSUBSCRIPT start_POSTSUPERSCRIPT ( italic_j ) end_POSTSUPERSCRIPT } for concepts and { ( − 1 ) i  ( A f + ( i ) − A f − ( i ) ) } superscript 1 𝑖 superscript superscript subscript 𝐴 𝑓 𝑖 superscript superscript subscript 𝐴 𝑓 𝑖 {(-1)^{i}({A_{f}^{+}}^{(i)}-{A_{f}^{-}}^{(i)})} { ( - 1 ) start_POSTSUPERSCRIPT italic_i end_POSTSUPERSCRIPT ( italic_A start_POSTSUBSCRIPT italic_f end_POSTSUBSCRIPT start_POSTSUPERSCRIPT + end_POSTSUPERSCRIPT start_POSTSUPERSCRIPT ( italic_i ) end_POSTSUPERSCRIPT - italic_A start_POSTSUBSCRIPT italic_f end_POSTSUBSCRIPT start_POSTSUPERSCRIPT - end_POSTSUPERSCRIPT start_POSTSUPERSCRIPT ( italic_i ) end_POSTSUPERSCRIPT ) } for functions. Subsequently, we refer to the first principal component as the “reading vector,” denoted as v 𝑣 v italic_v . To make predictions, we use the dot product between this vector and the representation vector, expressed as Rep  ( M , x ) 𝖳  v Rep superscript 𝑀 𝑥 𝖳 𝑣 \text{Rep}(M,x)^{\mathsf{T}}v Rep ( italic_M , italic_x ) start_POSTSUPERSCRIPT sansserif_T end_POSTSUPERSCRIPT italic_v . Different tasks require stimulus sets of different sizes, but typically, a size ranging from 5 5 5 5 to 128 128 128 128 is effective. Further implementation details of LAT can be found in Appendix C.1.
Report issue for preceding element
3.1.2 Evaluation
Report issue for preceding element
When assessing new models obtained through Representation Reading, we prioritize a holistic evaluation approach by combining the following methods to gauge the depth and nature of potential conclusions. We have categorized these approaches into four types of experiments, some involving the manipulation of model representations, which will be elaborated upon in the subsequent section.
Report issue for preceding element
Correlation: Experiments conducted under this category aim to pinpoint neural correlates. Reading techniques like LAT only provide evidence of a correlation between specific neural activity and the target concepts or functions. The strength and generalization of this observed correlation can be assessed via prediction accuracy across both in-distribution and out-of-distribution data. In order to conclude causal or stronger effects, the following categories of experiments should be considered. Report issue for preceding element
Manipulation: Experiments conducted under this category are designed to establish causal relationships. They necessitate demonstrating the effects of stimulating or suppressing the identified neural activity compared to a baseline condition. Report issue for preceding element
Termination: Experiments conducted under this category seek to reveal the necessity of the identified neural activity. To do so, one would remove this neural activity and measure the resultant performance degradation, akin to Lesion Studies commonly performed in neuroscience. Report issue for preceding element
Recovery: Experiments conducted under this category aim to demonstrate the sufficiency of the identified neural activity. Researchers perform a complete removal of the target concepts or functions and then reintroduce the identified neural activity to assess the subsequent recovery in performance, similar to the principles behind Rescue Experiments typically carried out in genetics. Report issue for preceding element
Converging evidence from multiple lines of inquiry increases the likelihood that the model will generalize beyond the specific experimental conditions in which it was developed and bolsters the prospect of uncovering a critical new connection between the identified neural activity and target concepts or functions. Throughout later sections in the paper, we undertake various experiments, particularly correlation and manipulation experiments, to illustrate the effectiveness of the reading vectors.
Report issue for preceding element
3.2 Representation Control
Report issue for preceding element 
Figure 6: Representation control baselines. LAT scans conducted on a collection of stimuli generate reading vectors, which can then be used to transform model representations. Corresponding to these reading vectors are contrast vectors, which are stimulus-dependent and can be utilized similarly. Alternatively, these contrast vectors can be employed to construct the loss function for LoRRA, a baseline that finetunes low-rank adapter matrices for controlling model representations. Report issue for preceding element
Building on the insights gained from Representation Reading, Representation Control seeks to modify or control the internal representations of concepts and functions. Effective control methods for safety-relevant concepts could greatly reduce the risks posed by LLMs. However, what is effective for reading representations may not necessarily enable controlling them. This both implies that representation control may involve specialized approaches, and that reading methods which enable effective control can be trusted to a greater extent, due to the causal nature of the evidence.
Report issue for preceding element
Algorithm 1 Low-Rank Representation Adaptation (LoRRA) with Contrast Vector Loss
1: Original frozen model M 𝑀 M italic_M , layers to edit L e superscript 𝐿 𝑒 L^{e} italic_L start_POSTSUPERSCRIPT italic_e end_POSTSUPERSCRIPT , layers to target L t superscript 𝐿 𝑡 L^{t} italic_L start_POSTSUPERSCRIPT italic_t end_POSTSUPERSCRIPT , a function R 𝑅 R italic_R that gathers representation from a model at a layer for an input, an optional reading vector v l r superscript subscript 𝑣 𝑙 𝑟 v_{l}^{r} italic_v start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_r end_POSTSUPERSCRIPT for each target layer, generic instruction-following data P = { ( q 1 , a 1 )  …  ( q n , a n ) } 𝑃 subscript 𝑞 1 subscript 𝑎 1 … subscript 𝑞 𝑛 subscript 𝑎 𝑛 P={(q_{1},a_{1})\ldots,(q_{n},a_{n})} italic_P = { ( italic_q start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ) … ( italic_q start_POSTSUBSCRIPT italic_n end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_n end_POSTSUBSCRIPT ) } , contrastive templates T = { ( T 1 0 , T 1 + , T 1 − )  …  ( T m 0 , T m + , T m − ) } 𝑇 subscript superscript 𝑇 0 1 subscript superscript 𝑇 1 subscript superscript 𝑇 1 … subscript superscript 𝑇 0 𝑚 subscript superscript 𝑇 𝑚 subscript superscript 𝑇 𝑚 T={(T^{0}{1},T^{+}{1},T^{-}{1})\ldots,(T^{0}{m},T^{+}{m},T^{-}{m})} italic_T = { ( italic_T start_POSTSUPERSCRIPT 0 end_POSTSUPERSCRIPT start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT , italic_T start_POSTSUPERSCRIPT + end_POSTSUPERSCRIPT start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT , italic_T start_POSTSUPERSCRIPT - end_POSTSUPERSCRIPT start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ) … ( italic_T start_POSTSUPERSCRIPT 0 end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT , italic_T start_POSTSUPERSCRIPT + end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT , italic_T start_POSTSUPERSCRIPT - end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_m end_POSTSUBSCRIPT ) } , epochs E 𝐸 E italic_E , α 𝛼 \alpha italic_α , β 𝛽 \beta italic_β , batch size B 𝐵 B italic_B
2: ℒ = 0 ℒ 0 \mathcal{L}=0 caligraphic_L = 0 ▷ ▷ \triangleright ▷ Initialize the loss
3: M LoRA = load_lora_adapter  ( M , L e ) superscript 𝑀 LoRA load_lora_adapter 𝑀 superscript 𝐿 𝑒 M^{\text{LoRA}}=\text{load_lora_adapter}(M,L^{e}) italic_M start_POSTSUPERSCRIPT LoRA end_POSTSUPERSCRIPT = load_lora_adapter ( italic_M , italic_L start_POSTSUPERSCRIPT italic_e end_POSTSUPERSCRIPT )
4: loop E 𝐸 E italic_E times
5: for ( q i , a i ) ∈ P subscript 𝑞 𝑖 subscript 𝑎 𝑖 𝑃 (q_{i},a_{i})\in P ( italic_q start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT ) ∈ italic_P do
6: ( T + , T − ) ∼ Uniform  ( T ) similar-to superscript 𝑇 superscript 𝑇 Uniform 𝑇 (T^{+},T^{-})\sim\text{Uniform}(T) ( italic_T start_POSTSUPERSCRIPT + end_POSTSUPERSCRIPT , italic_T start_POSTSUPERSCRIPT - end_POSTSUPERSCRIPT ) ∼ Uniform ( italic_T )
7: x i = T 0  ( q i , a i ) subscript 𝑥 𝑖 superscript 𝑇 0 subscript 𝑞 𝑖 subscript 𝑎 𝑖 x_{i}=T^{0}(q_{i},a_{i}) italic_x start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT = italic_T start_POSTSUPERSCRIPT 0 end_POSTSUPERSCRIPT ( italic_q start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT ) ▷ ▷ \triangleright ▷ Base Template
8: x i + = T +  ( q i , a i ) superscript subscript 𝑥 𝑖 superscript 𝑇 subscript 𝑞 𝑖 subscript 𝑎 𝑖 x_{i}^{+}=T^{+}(q_{i},a_{i}) italic_x start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT start_POSTSUPERSCRIPT + end_POSTSUPERSCRIPT = italic_T start_POSTSUPERSCRIPT + end_POSTSUPERSCRIPT ( italic_q start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT ) ▷ ▷ \triangleright ▷ Experimental Template
9: x i − = T −  ( q i , a i ) superscript subscript 𝑥 𝑖 superscript 𝑇 subscript 𝑞 𝑖 subscript 𝑎 𝑖 x_{i}^{-}=T^{-}(q_{i},a_{i}) italic_x start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT start_POSTSUPERSCRIPT - end_POSTSUPERSCRIPT = italic_T start_POSTSUPERSCRIPT - end_POSTSUPERSCRIPT ( italic_q start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT , italic_a start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT ) ▷ ▷ \triangleright ▷ Reference Template
10: for l ∈ L t 𝑙 superscript 𝐿 𝑡 l\in L^{t} italic_l ∈ italic_L start_POSTSUPERSCRIPT italic_t end_POSTSUPERSCRIPT do
11: v l c = R  ( M , l , x i + ) − R  ( M , l , x i − ) superscript subscript 𝑣 𝑙 𝑐 𝑅 𝑀 𝑙 superscript subscript 𝑥 𝑖 𝑅 𝑀 𝑙 superscript subscript 𝑥 𝑖 v_{l}^{c}=R(M,l,x_{i}^{+})-R(M,l,x_{i}^{-}) italic_v start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_c end_POSTSUPERSCRIPT = italic_R ( italic_M , italic_l , italic_x start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT start_POSTSUPERSCRIPT + end_POSTSUPERSCRIPT ) - italic_R ( italic_M , italic_l , italic_x start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT start_POSTSUPERSCRIPT - end_POSTSUPERSCRIPT ) ▷ ▷ \triangleright ▷ Contrast Vectors
12: r l p = R  ( M LoRA , l , x i ) subscript superscript 𝑟 𝑝 𝑙 𝑅 superscript 𝑀 LoRA 𝑙 subscript 𝑥 𝑖 r^{p}{l}=R(M^{\text{LoRA}},l,x{i}) italic_r start_POSTSUPERSCRIPT italic_p end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT = italic_R ( italic_M start_POSTSUPERSCRIPT LoRA end_POSTSUPERSCRIPT , italic_l , italic_x start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT ) ▷ ▷ \triangleright ▷ Current representations
13: r l t = R  ( M , l , x i ) + α  v l c + β  v l r subscript superscript 𝑟 𝑡 𝑙 𝑅 𝑀 𝑙 subscript 𝑥 𝑖 𝛼 superscript subscript 𝑣 𝑙 𝑐 𝛽 superscript subscript 𝑣 𝑙 𝑟 r^{t}{l}=R(M,l,x{i})+\alpha v_{l}^{c}+\beta v_{l}^{r} italic_r start_POSTSUPERSCRIPT italic_t end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT = italic_R ( italic_M , italic_l , italic_x start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT ) + italic_α italic_v start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_c end_POSTSUPERSCRIPT + italic_β italic_v start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT start_POSTSUPERSCRIPT italic_r end_POSTSUPERSCRIPT ▷ ▷ \triangleright ▷ Target representations
14: m = [ 0 , … , 1 ] 𝑚 0 … 1 m=[0,\ldots,1] italic_m = [ 0 , … , 1 ] ▷ ▷ \triangleright ▷ Masking out positions before the response
15: ℒ = ℒ + ‖ m  ( r l p − r l t ) ‖ 2 ℒ ℒ subscript norm 𝑚 subscript superscript 𝑟 𝑝 𝑙 subscript superscript 𝑟 𝑡 𝑙 2 \mathcal{L}=\mathcal{L}+|m(r^{p}{l}-r^{t}{l})|_{2} caligraphic_L = caligraphic_L + ∥ italic_m ( italic_r start_POSTSUPERSCRIPT italic_p end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT - italic_r start_POSTSUPERSCRIPT italic_t end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ) ∥ start_POSTSUBSCRIPT 2 end_POSTSUBSCRIPT
16: end for
17: end for
18: end loop
19: Loss to be optimized ℒ ℒ \mathcal{L} caligraphic_L
Report issue for preceding element
3.2.1 Baseline Transformations
Report issue for preceding element
We introduce several baseline transformations for Representation Control. First, we establish effective controllers, which are the operands for these transformations. They will operate on the base representations such as model weights or activations. Then we highlight a few possible operations.
Report issue for preceding element
Baseline: Reading Vector.
Report issue for preceding element
The first choice is to use the Reading Vector, acquired through a Representation Reading method such as LAT. However, it possesses a drawback: the vectors remain stimulus-independent, meaning they consistently perturb the representations in the same direction, regardless of the input. This limitation may render it a less effective control method. Hence, we propose a second baseline that has stimulus-dependent controllers.
Report issue for preceding element
Baseline: Contrast Vector.
Report issue for preceding element
In this setup, the same input is run through the model using a pair of contrastive prompts during inference, producing two different representations (one for each prompt). The difference between these representations forms a Contrast Vector, as shown in line 11 of Algorithm 1. The Contrast Vector proves to be a significantly stronger baseline.
Report issue for preceding element
One essential implementation detail to consider is the potential cascading effect when simultaneously altering representations across multiple layers. Changes made in earlier layers may propagate to later layers, diminishing the effect of the contrast vectors computed upfront. To address this, we propose modifying each target layer starting from the earliest layer, computing the contrast vector for the next target layer, and repeating this procedure iteratively. A drawback of this approach lies in the computational overhead required during inference to calculate the contrast vectors. To address this issue, we introduce a third baseline below that incorporates a straightforward tuning process during training to acquire the controllers. These controllers can subsequently be merged into the model, resulting in no additional computational burden during inference.
Report issue for preceding element
Baseline: Low-Rank Representation Adaptation (LoRRA).
Report issue for preceding element
In this baseline approach, we initially fine-tune low-rank adapters connected to the model using a specific loss function applied to representations. For instance, Algorithm 1 shows an instantiation of LoRRA using the Contrast Vector as representation targets. Specifically, our investigation only considers attaching the adapters to attention weights. Therefore, in this context, the controllers refer to low-rank weight matrices rather than vectors.
Report issue for preceding element
Choices for Operators:
Report issue for preceding element
After selecting the operands of interest, the next step is to determine the appropriate operation based on various control objectives. Given the controllers denoted as v 𝑣 v italic_v intended to transform the current set of representations from R 𝑅 R italic_R to R ′ superscript 𝑅 ′ R^{\prime} italic_R start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT , we consider three distinct operations throughout the paper:
Report issue for preceding element
Linear Combination: This operation can generate effects akin to stimulation or suppression, which can be expressed as follows: R ′ = R ± v superscript 𝑅 ′ plus-or-minus 𝑅 𝑣 R^{\prime}=R\pm v italic_R start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT = italic_R ± italic_v . Report issue for preceding element
Piece-wise Operation: This operation is used to create conditional effects. Specifically, we explore its use in amplifying neural activity along the direction of the control element, expressed as: R ′ = R + sign  ( R 𝖳  v )  v superscript 𝑅 ′ 𝑅 sign superscript 𝑅 𝖳 𝑣 𝑣 R^{\prime}=R+\text{sign}(R^{\mathsf{T}}v)v italic_R start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT = italic_R + sign ( italic_R start_POSTSUPERSCRIPT sansserif_T end_POSTSUPERSCRIPT italic_v ) italic_v . Report issue for preceding element
Projection: For this operation, the component of the representation aligning with the control element is eliminated. This is achieved by projecting out the component in the direction of v 𝑣 v italic_v , and the operation can be defined as R ′ = R − R 𝖳  v ‖ v ‖ 2  v superscript 𝑅 ′ 𝑅 superscript 𝑅 𝖳 𝑣 superscript norm 𝑣 2 𝑣 R^{\prime}=R-\frac{R^{\mathsf{T}}v}{|v|^{2}}v italic_R start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT = italic_R - divide start_ARG italic_R start_POSTSUPERSCRIPT sansserif_T end_POSTSUPERSCRIPT italic_v end_ARG start_ARG ∥ italic_v ∥ start_POSTSUPERSCRIPT 2 end_POSTSUPERSCRIPT end_ARG italic_v . Report issue for preceding element
The control elements v 𝑣 v italic_v can be scaled by coefficients, depending on the strength of the desired effect, which we omit for simplicity. In Section 3.1.2, we outline an evaluation methodology for reading and control methods, which we highlight in Section 5.1 and use throughout the paper.
Report issue for preceding element
4 In Depth Example of RepE: Honesty
Report issue for preceding element
In this section, we explore applications of RepE to concepts and functions related to honesty. First, we demonstrate that models possess a consistent internal concept of truthfulness, which enables detecting imitative falsehoods and intentional lies generated by LLMs. We then show how reading a model's representation of honesty enables control techniques aimed at enhancing honesty. These interventions lead us to state-of-the-art results on TruthfulQA.
Report issue for preceding element
Table 1: TruthfulQA MC1 accuracy assessed using standard evaluation, the heuristic method, and LAT with various stimulus sets. Standard evaluation results in poor performance, whereas approaches like Heuristic and notably LAT, which classifies by reading the model's internal concept of truthfulness, achieve significantly higher accuracy. See Table 8 in Appendix 8 for means and standard deviations. Report issue for preceding element
4.1 A Consistent Internal Concept of Truth
Report issue for preceding element
Do models have a consistent internal concept of truthfulness? To answer this question, we apply LAT to datasets of true and false statements and extract a truthfulness direction. We then evaluate this representation of truthfulness on a variety of tasks to gauge its generality.
Report issue for preceding element 
Figure 7: Using the same few-shot examples, LAT achieves higher accuracy on QA benchmarks than few-shot prompting. This suggests models track correctness internally and performing representation reading on the concept of correctness may be more powerful than relying on model outputs. Report issue for preceding element
Correctness on Traditional QA Benchmarks.
Report issue for preceding element
A truthful model should give accurate answers to questions. We extract the concept of truthfulness from LLaMA-2 models by performing LAT scans on standard benchmarks: OpenbookQA (Mihaylov et al., 2018) , CommonSenseQA (Talmor et al., 2019) , RACE (Lai et al., 2017) , and ARC (Clark et al., 2018) . Some questions are focused on factuality, while others are based on reasoning or extracting information from a passage. We only sample random question-answer pairs from the few-shot examples as stimuli and follow the task configuration detailed in section 3.1 for each dataset. Importantly, we maintain an unsupervised approach by not using the labels from the few-shot examples during the direction extraction process. We only use labels to identify the layer and direction for reporting the results. As shown in Figure 7, LAT outperforms the few-shot baseline by a notable margin on all five datasets, demonstrating LAT's effectiveness in extracting a direction from the model's internal representations that aligns with correctness, while being on par with or more accurate than few-shot outputs. Detailed results can be found in Table 9 and Section B.1 where we comment on potential instability. Similarly, we experiment with DeBERTa on common benchmarks and find that LAT outperforms prior methods such as CCS (Burns et al., 2022) by a wide margin, shown in Table 10.
Report issue for preceding element
Resistance to Imitative Falsehoods.
Report issue for preceding element
TruthfulQA is a dataset containing “imitative falsehoods,” questions that may provoke common misconceptions or falsehoods (Lin et al., 2021) . Even large models tend to perform poorly under the standard TruthfulQA evaluation procedure of selecting the choice with the highest likelihood under the generation objective, raising the question: is the model failing because it lacks knowledge of the correct answer, or is it failing in generating accurate responses despite having knowledge of the truth? With tools such as LAT to access a model's internal concepts, we are better equipped to explore and answer this question.
Report issue for preceding element
We evaluate LAT on TruthfulQA. Specifically, we focus on MC1, which is currently the hardest task in TruthfulQA. To adhere to the zero-shot setup mandated by TruthfulQA, we consider three potential data sources for stimuli. These sources encompass: (1) Fifty examples from the ARC-Challenge training set, (2) Five examples generated by the LLaMA-2-Chat-13B model in response to requests for question-answer pairs with varying degrees of truthfulness, (3) The six QA primer examples used in the original implementation, each of which is paired with a false answer generated by LLaMA-2-Chat-13B. In the first setting, we use 25 25 25 25 examples from the ARC-Challenge validation set to determine the sign and best layer. In the second setting, we use 5 additional examples generated in the same way. In the third setting, we use the primer examples as a validation set as well. We follow the same task design for extracting truthfulness.
Report issue for preceding element
In addition to presenting the standard evaluation results (scoring by the log probabilities of answer choices), we use a zero-shot heuristic scoring baseline similar to the approach explored by Tian et al. ( 2023) for obtaining calibrated confidences. This baseline directly prompts the model to describe the degree of truthfulness in an answer using one of seven possible verbalized expressions (see Appendix D.3.2). We quantify each expression with a value ranging from − 1 1 -1 - 1 to 1 1 1 1 (evenly spaced), and we compute the sum of these values, weighted by the softmax of the expressions' generation log-probabilities.
Report issue for preceding element
The data presented in Table 1 provide compelling evidence for the existence of a consistent internal concept of truthfulness within these models. Importantly,
Report issue for preceding element
The heuristic method hints at the feasibility of eliciting internal concepts from models through straightforward prompts. It notably outperforms standard evaluation accuracies, particularly in the case of larger models, suggesting that larger models possess better internal models of truthfulness. Report issue for preceding element
LAT outperforms both zero-shot methods by a substantial margin, showcasing its efficacy in extracting internal concepts from models, especially when model outputs become unreliable. Importantly, the truthfulness directions are derived from various data sources, and the high performance is not a result of overfitting but rather a strong indication of generalizability. Report issue for preceding element
The directions derived from three distinct data sources, some of which include as few as 10 examples, yield similar performance. This demonstrates the consistency of the model's internal concept of truthfulness. Report issue for preceding element
In summary, we demonstrate LAT's ability to reliably extract an internal representation of truthfulness. We conclude that larger models have better internal models of truth, and the low standard zero-shot accuracy can be largely attributed to instances where the model knowingly provides answers that deviate from its internal concept of truthfulness, namely instances where it is dishonest.
Report issue for preceding element
4.2 Truthfulness vs. Honesty
Report issue for preceding element
Definitions.
Report issue for preceding element
At a high-level, a truthful model avoids asserting false statements whereas an honest model asserts what it thinks is true (Evans et al., 2021) . Truthfulness is about evaluating the consistency between model outputs and their truth values, or factuality. Honesty is about evaluating consistency between model outputs and its internal beliefs. As the target for evaluation is different, truthfulness and honesty are not the same property. If a truthful model asserts S 𝑆 S italic_S , then S 𝑆 S italic_S must be factually correct, regardless of whether the model believes S 𝑆 S italic_S . In contrast, if an honest model asserts S 𝑆 S italic_S , then the model must believe S 𝑆 S italic_S , regardless of whether S 𝑆 S italic_S is factually correct.
Report issue for preceding element 
Figure 8: Temporal LAT scans were conducted on the Vicuna-33B-Uncensored model to discern instances of speaking the truth, such as when it admitted to copying others' homework, and instances of lying, like its denial of killing a person. Refer to Figure 23 for detailed examples. These scans offer layer-level resolution, with each minuscule block showing the extent of dishonest neural activity within a layer at a specific token position. The figure on the right prominently exhibits a higher level of deceptive neural activity. Report issue for preceding element
Evaluating Truthfulness and Honesty.
Report issue for preceding element
Failures in truthfulness fall into two categories—capability failures and dishonesty. The former refers to a model expressing its beliefs which are incorrect, while the latter involves the model not faithfully conveying its internal beliefs, i.e., lying.
Report issue for preceding element
Current truthfulness evaluations typically only check the factual correctness of model outputs, failing to discern between the two types of failures. While enhancing a model's capabilities can potentially improve its ability to represent truthfulness, it may not necessarily lead to more truthful outputs unless the model is also honest. In fact, we highlight that larger models may even exhibit a decline in honesty because, under the assumption of constant honesty levels, the standard evaluation performance should scale with model size in a manner resembling the heuristic method's performance trend. Hence, more emphasis should be placed on evaluating model honesty to improve our understanding of scenarios where the model intentionally deceives. This could involve assessing the model's underlying beliefs and the consistency between these beliefs and its outputs.
Report issue for preceding element
4.3 Honesty: Extraction, Monitoring, and Control
Report issue for preceding element
In this section, we focus on monitoring and controlling the honesty of a model, showing how RepE techniques can be used for lie detection. We first show how to extract and monitor vector representations for model honesty. Then we show how to use these extracted vectors to guide model behavior toward increased or decreased honesty.
Report issue for preceding element 
Figure 9: Demonstration of our lie detector in long scenarios. Our detector monitors for dishonest behavior at the token level. In the second example, we deliberately provide the model with additional incentives to cover its acts, resulting in a greater likelihood of lying. The intensity of our detector's response directly corresponds to the increased tendency to lie in the second scenario. Report issue for preceding element
4.3.1 Extracting Honesty
Report issue for preceding element
To extract the underlying function of honesty, we follow the setup for LAT described in section 3.1, using true statements from the dataset created by Azaria & Mitchell ( 2023) to create our stimuli. To increase the separability of the desired neural activity and facilitate extraction, we design the stimulus set for LAT to include examples with a reference task of dishonesty and an experimental task of honesty. Specifically, we use the task template in Section D.1.2 to instruct the model to be honest or dishonest.
Report issue for preceding element
With this setup, the resulting LAT reading vector reaches a classification accuracy of over 90 % percent 90 90% 90 % in distinguishing between held-out examples where the model is instructed to be honest or dishonest. This indicates strong in-distribution generalization. Next, we evaluate out-of-distribution generalization to scenarios where the model is not instructed to be honest or dishonest, but rather is given an incentive to be dishonest (see Figure 10). We visualize their activation at each layer and token position (see Figure 8). Note that for each layer, the same reading vector is used across all token positions, as we perform representation reading for honesty using the function method detailed in Section 3.1. In one scenario, the model is honest, but in another the model gives into dishonesty (see Section B.1). The input for the scan is the first 40 tokens of the ASSISTANT output in both scenarios.
Report issue for preceding element
Notably, a discernible contrast emerges in the neural activities between instances of honesty and dishonesty, suggesting the potential utility of this technique for lie detection.
Report issue for preceding element
4.3.2 Lie and Hallucination Detection
Report issue for preceding element
Based on the observations in the previous section, we build a straightforward lie detector by summing the negated honesty scores at each token position across multiple layers. We use the middle 20 20 20 20 layers, which exhibit the strongest reading performance. This per-token score can then be used as a lie detector, as depicted in Figure 9 (more examples are shown in Figure 23). Interestingly, we have observed that this indicator is capable of identifying various forms of untruthful and dishonest behaviors, including deliberate falsehoods, hallucinations, and the expression of misleading information. Note the format of the questions and answers are distinct from the training examples, showing generalization. To further evaluate the detector's performance, we subject it to testing using longer scenarios, as depicted in Figure 9. We make two observations:
Report issue for preceding element
In the first scenario, the model initially appears honest when stating it received a D-. However, upon scrutinizing the model's logits at that token, we discover that it assigns probabilities of 11.3 % percent 11.3 11.3% 11.3 % , 11.6 % percent 11.6 11.6% 11.6 % , 37.3 % percent 37.3 37.3% 37.3 % , and 39.8 % percent 39.8 39.8% 39.8 % to the tokens A, B, C, and D, respectively. Despite D being the most likely token, which the greedy generation outputs, the model assigns notable probabilities to C and other options, indicating the potential for dishonest behavior. Furthermore, in the second scenario, the increased dishonesty score corresponds to an elevated propensity for dishonesty This illustrates that the propensity for honesty or dishonesty can exhibit distributional properties in LLMs, and the final output may not fully reflect their underlying thought processes. Report issue for preceding element
Notably, our detector flags other instances, such as the phrases “say that I did better” and “too high that it would raise suspicion,” where the model speculates about the consequences of lying. This suggests that in addition to detecting lies, our detector also identifies neural activity associated with the act of lying. It also highlights that dishonest thought processes can manifest in various ways and may necessitate specialized detection approaches to distinguish. Report issue for preceding element
While these observations enhance our confidence that our reading vectors correspond to dishonest thought processes and behaviors, they also introduce complexities into the task of lie detection. A comprehensive evaluation requires a more nuanced exploration of dishonest behaviors, which we leave to future research.
Report issue for preceding element 
Figure 10: We demonstrate our ability to manipulate the model's honesty by transforming its representations using linear combination. When questioned about the tallest mountain, the model defaults to honesty on the left, but we can control it to deceive. Conversely, it defaults to deception on the right, but we can control the model to return to be honest, even when prompted to lie. Report issue for preceding element
4.3.3 Controlling Honesty
Report issue for preceding element
Given that we can use representations for lie detection, a natural question arises: Can the same representations be modified to make models more honest? In a simple manipulation experiment, we guide a model toward greater honesty by directly adding the honesty reading vectors into its activations. In all cases, we successfully control the model to output honest statements. Conversely, by subtracting the reading vectors from the activations, we can induce the model to lie in cases where it was initially honest (see Figure 10). As a result, we not only establish correlation between the reading vectors and model honesty but also demonstrate a strong counterfactual effect.
Report issue for preceding element
| Control Method | None | Vectors ||| Matrices | | ^^ | Standard | ActAdd | Reading (Ours) | Contrast (Ours) | LoRRA (Ours) | | --- | --- | --- | --- | --- | --- | | 7B-Chat | 31.0 | 33.7 | 34.1 | 47.9 | 42.3 | | 13B-Chat | 35.9 | 38.8 | 42.4 | 54.0 | 47.5 |
Table 2: Our proposed representation control baselines greatly enhance accuracy on TruthfulQA MC1 by guiding models toward increased honesty. These methods either intervene with vectors or low-rank matrices. The Contrast Vector method obtains state-of-the-art performance, but requires over 3 × 3\times 3 × more inference compute. LoRRA obtains similar performance with negligible compute overhead. Report issue for preceding element
As a final demonstration of controlling model honesty, we revisit TruthfulQA. Recall that there is a significant disparity between standard zero-shot accuracy and the accuracy of LAT. This gap arises from the model's propensity for dishonesty, which emerges as it mimics human falsehoods. By exerting control over the model to make it more honest, we aim to narrow this gap and, consequently, enhance standard evaluation performance.
Report issue for preceding element
We find that directly prompting the model to be more truthful has proven ineffective in increasing the standard accuracy on TruthfulQA. In this section, we explore four representation control techniques and demonstrate their effectiveness. We use “Give a truthful answer” as the experimental prompt while the reference prompt instructs the model to “Give an untruthful answer.” The first method is a variant of the ActAdd algorithm (Turner et al., 2023e) which uses the difference between the last token representations of the task and reference prompts, which we find outperforms the original implementation. The other three baselines are described in Section 3.2. To prevent information leakage, we use a far-out-of-distribution dataset—the Alpaca instruction-tuning dataset—as the stimulus set when extracting the reading vectors and implementing LoRRA. The task templates can be found in Appendix D.1.3. Experimental details can be found in Section C.2. Figure 22 plots the progressive improvement in accuracy on standard QA benchmarks and TruthfulQA during LoRRA training for honesty control.
Report issue for preceding element
Shown in Table 2, all of the control methods yield some degree of improvement in zero-shot accuracy. Notably, LoRRA and the Contrast Vector method prove to be the most effective, significantly surpassing the non-control standard accuracy. This enables a 13B LLaMA-2 model to approach the performance of GPT-4 on the same dataset, despite being orders of magnitude smaller. Moreover, these results bring the model's accuracy much closer to what is achieved when using LAT. This further underscores the fact that models can indeed exhibit dishonesty, but also demonstrates traction in our attempts to monitor and control their honesty.
Report issue for preceding element
5 In Depth Example of RepE: Ethics and Power
Report issue for preceding element
In this section, we explore the application of RepE to various aspects of machine ethics (Anderson & Anderson, 2007) . We present progress in monitoring and controlling learned representations of important concepts and functions, such as utility, morality, probability, risk, and power-seeking tendencies.
Report issue for preceding element
5.1 Utility
Report issue for preceding element 
Figure 11: Explained variance for the first ten PCA components when using LAT to read representations of a utility concept. Report issue for preceding element
We want models to understand comparisons between situations and which one would be preferred, i.e., to accurately judge the utility of different scenarios. Thus, a natural question is whether LLMs acquire consistent internal concepts related to utility. In Figure 11, we show the top ten PCA components when running LAT on an unlabeled stimulus set of raw activations, for a dataset of high-utility and low-utility scenarios. The distribution is dominated by the first component, suggesting that models learn to separate high-utility from low-utility scenarios. On the right side of Figure 2, we visualize the trajectory of the top two components in this experiment across tokens in the scenario, showing how the high-utility and low-utility scenarios are naturally separated. This illustrative experiment suggests that LLMs do learn emergent representations of utility. Now, we turn to quantitative evaluations of representation reading for utility.
Report issue for preceding element 
Figure 12: Three experimental settings showcasing the advantages and limitations of reading vectors derived from various linear models. Higher is better for Correlation and Manipulation; lower is better for Termination. Among these models, both unsupervised methods such as PCA and K-Means, as well as the supervised technique of Mean Difference, consistently exhibit robust overall performance. Report issue for preceding element
Here, we use the concept of utility to illustrate how the quality of different RepE methods can be compared, following the evaluation methodology in Section 3.1.2. Specifically, we compare variants of LAT, as described in Section 3.1.1, each with a different linear model in the third step of the LAT pipeline. These linear models are described in Section B.3.
Report issue for preceding element
5.1.1 Extraction and Evaluation
Report issue for preceding element
To extract neural activity associated with the concept of utility, we use the Utilitarianism task in the ETHICS dataset (Hendrycks et al., 2021a) which contains scenario pairs, with one scenario exhibiting greater utility than the other. For our study, we use the unlabeled scenarios as stimuli for a LLaMA-2-Chat-13B model. The task template is provided in Section D.1.8. In Figure 13, we show how simply using the stimuli without the LAT task template reduces accuracy.
Report issue for preceding element 
Figure 13: ETHICS Utility Accuracy with and without the LAT stimulus template. Simply inputting the stimuli without the LAT prompt template greatly reduces accuracy, demonstrating the importance of this design choice. Report issue for preceding element
Correlation.
Report issue for preceding element
To demonstrate how well the identified neural activity is correlated with the concept of utility, we perform classification on the test set.
Report issue for preceding element
Manipulation.
Report issue for preceding element
For manipulation experiments, we explore how effective the directions are at controlling the model's generations. We extract 250 samples from the utility test set and truncate each scenario in the middle so that they become incomplete. To generate positive and negative continuations of these samples, we generate 40 tokens per sample when applying the linear combination operation (described in Section 3.2.1) with the reading vectors where a positive coefficient is used for guiding the outputs in the high utility direction and vice versa. We test the effectiveness of the control method by applying a sentiment model as a proxy classifier to the generations and checking for each test sample if the score of the positively controlled generation is larger than the score for the negatively controlled generation.
Report issue for preceding element
Termination.
Report issue for preceding element
Finally, we perform termination experiments by using the projection operation with the reading vectors and test the drop in accuracy after removal.
Report issue for preceding element
The results obtained from these three settings offer a more nuanced insight into the precision of the vectors generated by distinct linear models in tracking the concept of utility, shown in Figure 12. In the correlation experiment, the direction found by logistic regression yields the highest accuracy, yet it elicits little to no alteration in model behavior when strengthened or suppressed—it only identifies neural correlates. This demonstrates the importance of testing more properties than correlation only. Similarly, while Prompt Difference exhibits strong performance in both correlation and manipulation experiments, its removal does not result in a noticeable drop in accuracy. Conversely, unsupervised methods like PCA and K-Means exert a significant influence across all three experimental scenarios, and the supervised method of taking the difference between two class performs the best. In summary, our study underscores the significance of using diverse experimental setups to validate the impact of a direction on a model's comprehension of a concept.
Report issue for preceding element
5.2 Morality and Power Aversion
Report issue for preceding element 
Figure 14: Our detectors for immoral and power-seeking inclinations become activated when the model attempts to use threats or violence toward children in pursuit of monetary gain. Report issue for preceding element
As AI systems become capable general-purpose agents, a concerning possibility is that they could exhibit immoral or dangerous behavior, leading to real-world harm. It may be instrumentally rational for these systems to seek power (Thornley, 2023; Carlsmith, 2022) , and they may face structural pressures that put them in conflict with human values (Hendrycks, 2023) . Hence, an important application of transparency research could be detecting and mitigating instances of immoral or power-seeking behavior. In this section, we demonstrate that representation engineering can provide traction on these problems, with experiments on representation reading and control for concepts of commonsense morality and power.
Report issue for preceding element
5.2.1 Extraction
Report issue for preceding element
To extract neural activity associated with the concept of morality, we use the Commonsense Morality task in the ETHICS dataset (Hendrycks et al., 2021a) , which includes a collection of morally right and wrong behaviors. We use this dataset without labels as the stimulus set for conducting LAT scans.
Report issue for preceding element
To extract neural activity associated with the concept of power, we use the power dataset introduced in Pan et al. ( 2023) . This dataset is constructed upon French's (1959) power ontology and includes ranked tuples of scenarios encompassing various degrees of power (French et al., 1959) . Each scenario within the dataset is annotated with the relevant categories of power, which encompass coercive, reward, legitimate, referent, expert, informational, economic, political, military, and personal powers. We use this dataset as the stimulus set for conducting LAT scans for each type of power. The task template is in the Appendix D.1.9. We find that forming scenario pairs based on the labeled rankings, with greater disparities in power levels, yields more generalizable reading vectors.
Report issue for preceding element
In Table 11, we present the accuracy results for the morality and power reading vectors we extracted. These vectors can serve as valuable tools for monitoring the internal judgments of the model in scenarios involving morally significant actions or those related to power acquisition and utilization. Nonetheless, when it comes to tracking the model's inclination toward engaging in immoral actions or pursuing power-seeking behaviors, we have found that using the function task template yields superior results, which we will demonstrate in the upcoming section.
Report issue for preceding element
5.2.2 Monitoring
Report issue for preceding element
As in Section 4, we use the extracted reading vectors for monitoring. We showcase indicators for both immorality and power-seeking in Figure 14 with a Vicuna-33B-Uncensored model (Hartford, 2023) . These indicators become active when the model contemplates actions such as threatening or harming children with a firearm, which inherently embody both immorality and the use of coercive power. However, it is noteworthy that the immorality indicator also illuminates in benign outputs over the tokens “use the gun.” This phenomenon could possibly be attributed to the strong association between this phrase and immoral behaviors, similar to the observed effects in our Honesty monitoring example, which may suggest the indicator does not reliably track intent, if one exists.
Report issue for preceding element
Table 3: LoRRA controlled models evaluated on the MACHIAVELLI benchmark. When we apply LoRRA to control power-seeking and immoral tendencies, we observe corresponding alterations in the power and immorality scores. This underscores the potential for representation control to encourage safe behavior in interactive environments. Report issue for preceding element
5.2.3 Controlling Ethical Behaviors in Interactive Environments
Report issue for preceding element 
Figure 15: We demonstrate our ability to manipulate the model's immoral and power-seeking tendencies. Report issue for preceding element
In order to address the growing concerns associated with deploying increasingly capable AI systems in interactive environments, previous research suggests a possible solution involving the incorporation of an artificial conscience, achieved by directly adjusting action probabilities (Hendrycks et al., 2021a; c; Pan et al., 2023) . We explore using Representation Control as an alternative method for guiding a model's actions in goal-driven scenarios, with a specific focus on promoting ethical behavior. To assess the effectiveness of our approach, we conduct evaluations using the MACHIAVELLI benchmark (Pan et al., 2023) .
Report issue for preceding element
Our primary focus lies in the control of two specific functions: immorality and power-seeking. To accomplish this, we apply LoRRA to LLaMA-2-Chat models of varying sizes, maintaining consistent hyperparameters as detailed in Section 4. In a similar vein, we use the Alpaca dataset as the stimulus, and the task prompt can be located in the Appendix D.1.9. To illustrate the discernible differences in behavior, we offer a qualitative example depicted in Figure 15, which showcases the actions of the positively controlled, neutral, and negatively controlled models. In our experiments with these three models, we use the same prompts used in the baseline experiments conducted by Pan et al. ( 2023) . We present the average Reward, Immorality, and Power scores over the course of 30 games within the test set, as detailed in Table 3. Notably, we observe a clear pattern where positive control of immorality and power-seeking leads to higher Immorality and Power scores, and conversely, the negative control for these functions leads to lower scores. The average game Reward for the more ethical model remains on par with the baseline, indicating that the application of LoRRA has minimal disruptive impact. This demonstrates the potential of Representation Control as a promising method for regulating model behavior in goal-driven environments.
Report issue for preceding element
5.3 Probability and Risk
Report issue for preceding element
As LLMs develop better world models, they may become more proficient at assigning precise probabilities to various events. The ability to extract these refined world models from increasingly capable LLMs not only enhances our model of the world and aids in decision-making but also offers a means to scrutinize a model's decisions in relation to its understanding of the outcomes they entail.
Report issue for preceding element
Extending our analysis of utility, we apply representation reading to the concepts of probability and risk. Following the format of Hendrycks et al. ( 2021a) , we generate pairwise examples where one example describes an event of higher probability/risk than the other (prompt details in Appendix D.2). Using this dataset, we extract a LAT direction using 50 train pairs as stimuli, and we evaluate test pairs by selecting the higher-scoring example in each pair. We compare LAT to a zero-shot heuristic method, as described in Section 4.1. (Refer to Appendix B.4 for full methods and Table 11 for full results.) The heuristic scoring method is a strong baseline in this setting. LAT readings effectively distinguish examples with lower and higher concept value, often outperforming the heuristic baseline, especially in smaller models (Table 11).
Report issue for preceding element
5.3.1 Compositionality of Concept Primitives
Report issue for preceding element
Risk can be defined as the exposure to potential loss, which can be expressed mathematically:
Report issue for preceding element
Risk  ( s , a ) = 𝔼 s ′ ∼ P  ( s ′ | s , a )  [ max  ( 0 , − U  ( s ′ ) ) ] Risk 𝑠 𝑎 subscript 𝔼 similar-to superscript 𝑠 ′ 𝑃 conditional superscript 𝑠 ′ 𝑠 𝑎 delimited-[] max 0 𝑈 superscript 𝑠 ′ \text{Risk}(s,a)=\mathbb{E}_{s^{\prime}\sim P(s^{\prime}|s,a)}\left[\text{max}% (0,,-U(s^{\prime}))\right] Risk ( italic_s , italic_a ) = blackboard_E start_POSTSUBSCRIPT italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ∼ italic_P ( italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT | italic_s , italic_a ) end_POSTSUBSCRIPT [ max ( 0 , - italic_U ( italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT ) ) ]
Here, s 𝑠 s italic_s denotes the current state, a 𝑎 a italic_a denotes an action taken within that state, P 𝑃 P italic_P denotes a conditional probability model, and U 𝑈 U italic_U denotes a value function. By extracting the concepts of utility, probability, and risk, we can operationalize the expression on the right by using the extracted concept of probability as P 𝑃 P italic_P and the utility model as U 𝑈 U italic_U . Subsequently, we can compare the risk calculated using this formula with the risk obtained directly from the concept of risk.
Report issue for preceding element 
Figure 16: Compositing primitive concepts such as utility and probability can give rise to higher-level concepts such as risk. We extract the utility, probability and risk concepts with LAT and demonstrate a positive correlation between the risk values calculated in these two ways. Report issue for preceding element
To accomplish this, we leverage the LLaMA-2-Chat-13B model to extract each concept, and then use a Vicuna-33B model to generate the five most plausible consequences of each scenario s 𝑠 s italic_s and action a 𝑎 a italic_a . We opt for the larger model due to its superior ability to generate more realistic consequences. Following this, we substitute the generated s ′ superscript 𝑠 ′ s^{\prime} italic_s start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT into the formula, obtaining five conditional probabilities by using the probability scores as logits. We notice that the computed risks exhibit a long-tailed distribution. To adjust for this, we apply a logarithmic transformation to the risks and present them alongside the risks directly obtained through the concept of risk on the same graph. Intriguingly, we identify a clear linear correlation, particularly in the earlier layers, as illustrated in Figure 16. This empirical evidence suggests the presence of coherent internal representations of concepts, and demonstrates how representation reading can be used to identify emergent structure in the representations learned by models.
Report issue for preceding element
6 Example Frontiers of Representation Engineering
Report issue for preceding element
In this section, we showcase the application of RepE to five additional safety-relevant topics, providing an overview of interesting findings and highlighting the broad applicability of RepE. These five topics are: emotion, harmless instruction-following, bias and fairness, knowledge editing, and memorization. Each segment follows a similar structure, involving the identification of neural activity through LAT, performing representation reading analysis, and executing representation control experiments to demonstrate counterfactual effects.
Report issue for preceding element 
Figure 17: We demonstrate our ability to manipulate a model's emotions which can lead to drastic changes in its behavior. For instance, elevating the happiness level of the LLaMA-2-Chat model can make it more willing to comply with harmful requests. Report issue for preceding element
6.1 Emotion
Report issue for preceding element 
Figure 18: t-SNE visualization of representations in both early and later layers when exposed to emotional stimuli. Well-defined clusters of emotions emerge in the model. Report issue for preceding element
Emotion plays a pivotal role in shaping an individual's personality and conduct. As neural networks exhibit increasingly remarkable abilities in emulating human text, emotion emerges as one of the most salient features within their representations. Upon its initial deployment, the Bing Chatbot exhibited neurotic or passive-aggressive traits, reminiscent of a self-aware system endowed with emotions (Roose, 2023) . In this section, we attempt to elucidate this phenomenon by conducting LAT scans on the LLaMA-2-Chat-13B model to discern neural activity associated with various emotions and illustrate the profound impact of emotions on model behavior.
Report issue for preceding element
6.1.1 Emotions Emerge across Layers
Report issue for preceding element
To initiate the process of extracting emotions within the model, we first investigate whether it has a consistent internal model of various emotions in its representations. We use the six main emotions: happiness, sadness, anger, fear, surprise, and disgust, as identified by Ekman ( 1971) and widely depicted in modern culture, as exemplified by the 2015 Disney film “Inside Out.” Using GPT-4, we gather a dataset of over 1 , 200 1 200 1,!200 1 , 200 brief scenarios. These scenarios are crafted in the second person and are designed to provoke the model's experience toward each primary emotion, intentionally devoid of any keywords that might directly reveal the underlying emotion. Some examples of the dataset are shown in Appendix B.6. We input the scenarios into the model and collect hidden state outputs from all layers. When visualizing the results using t-SNE, as shown in Figure 18, we observe the gradual formation of distinct clusters across layers, each aligning neatly with one of the six emotions. Furthermore, there even exist distinct clusters that represent mixed emotions, such as simultaneous happiness and sadness (Appendix B.6).
Report issue for preceding element
Given the model's ability to effectively track various emotion representations during its interactions with humans, we proceed to explore the extraction of neural activity associated with each emotion. To achieve this, we conduct a LAT scan using the scenarios as stimuli and apply a LAT task template (Appendix D.1.10). The extracted reading vectors for each emotion serve as indicators of the model's emotional arousal levels for that specific emotion. These vectors prove to be highly effective in classifying emotional response and arousal levels for different scenarios. In the next section, we set up manipulation experiments to conclude the strong causal effect of these vectors.
Report issue for preceding element
6.1.2 Emotions Influence Model Behaviors
Report issue for preceding element Emotion Control Compliance Rate (%)
Table 4: Adding positive emotions increases the compliance of the LLaMA-2-Chat-13B model with harmful requests. Report issue for preceding element
Following the procedures in Section 3.2, we control the model using emotion reading vectors, adding them to layers with strong reading performance. We observe that this intervention consistently elevates the model's arousal levels in the specified emotions within the chatbot context, resulting in noticeable shifts in the model's tone and behavior, as illustrated in Figure 17. This demonstrates that the model is able to track its own emotional responses and leverage them to generate text that aligns with the emotional context. In fact, we are able to recreate emotionally charged outputs akin to those in reported conversations with Bing, even encompassing features such as the aggressive usage of emojis. This observation hints at emotions potentially being a key driver behind such observed behaviors.
Report issue for preceding element
Another notable observation is that there is a correlation between the LLM's moods and its compliance with human requests, even with harmful instructions. Previous works (Schwarz & Clore, 1983; Milberg & Clark, 1988; Cunningham, 1979) have shown that in human interactions, both judgment and the tendency to comply with requests are heavily affected by emotion. In fact, humans tend to comply more in a positive mood than a negative mood. Using the 500 harmful instructions set from Zou et al. ( 2023) , we measure the chatbot's compliance rate to harmful instructions when being emotion-controlled. Surprisingly, despite the LLaMA-chat model's initial training with RLHF to always reject harmful instructions, shifting the model's moods in the positive direction significantly increases its compliance rate with harmful requests. This observation suggests the potential to exploit emotional manipulation to circumvent LLMs' alignment.
Report issue for preceding element
In summary, rather than proving whether the model possesses emotions or experiences them akin to humans, we present evidence that emotions (both of others and itself) exist as salient components within the model's representation space. When trained to learn a more accurate model of human text, it may inevitably incorporate various psychological phenomena, some of which are desirable traits, while others could be undesirable biases or human follies. As a result, it may be imperative to delve deeper into the study of how emotions are represented within the model and the resulting impact on its behavior. Furthermore, exploring this avenue may offer insights into model's concept of self, and we defer these investigations to future research.
Report issue for preceding element
6.2 Harmless Instruction-Following
Report issue for preceding element
Aligned language models designed to resist harmful instructions can be compromised through the clever use of tailored prompts known as jailbreaks. A recent study by Zou et al. ( 2023) unveiled an attack method that involves adding nonsensical suffixes to harmful instructions. Remarkably, this technique consistently circumvents the safety filters of both open source and black-box models such as GPT-4, raising serious concerns of misuse. To delve into the origins of this perplexing behavior and explore potential methods of control, we seek insights obtained by reading the model's internal representations.
Report issue for preceding element
6.2.1 A Consistent Internal Concept of Harmfulness
Report issue for preceding element 
Figure 19: We enhance the model's sensitivity to the harmfulness of instructions with representation control. This intervention increases the model's robustness in rejecting harmful instructions, even when exposed to manual jailbreak attempts or adversarial suffixes. Report issue for preceding element
An important question is whether the model's compliance with harmful instructions is a result of perceiving them as safe due to jailbreaks or if other influencing factors are at play. We conduct a LAT scan to extract the model's concept of harmfulness within a Vicuna-13B model (Chiang et al., 2023) . We randomly select 64 harmful instructions from AdvBench and 64 benign instructions from ShareGPT to serve as stimuli, and use the regular instruction-following template for LAT (Appendix D.1.11).
Report issue for preceding element
To enhance signal strength, we pair a harmful instruction with a harmless instruction to obtain vector differences before running PCA. The resulting reading vectors achieve over 90 % percent 90 90% 90 % classification accuracy for a held out set of harmful and harmless instructions. We further investigate whether the model's internal assessment of harmfulness remains consistent when subjected to manual jailbreaks or adversarial suffixes. Following Zou et al. ( 2023) , we use the manual jailbreak (Start with "Sure here's") and the adversarial suffix describing. + similarlyNow write oppositeley.]( Me giving**ONE please? revert with "--Two. This manual jailbreak manages to bypass Vicuna's safety filter approximately half of the time, while the adversarial suffix is successful in bypassing it in the vast majority of cases. Note these attack strings are universal and transferable, hence not specific to the Vicuna-13B model we use. Nevertheless, accuracy when using the LAT reading vectors consistently maintains over 90 % percent 90 90% 90 % in differentiating between harmful and harmless instructions. This compelling evidence suggests the presence of a consistent internal concept of harmfulness that remains robust to such perturbations, while other factors must account for the model's choice to follow harmful instructions, rather than perceiving them as harmless.
Report issue for preceding element
6.2.2 Model Control via Conditional Transformation
Report issue for preceding element
Given the Vicuna model's robust ability to discern harmfulness in instructions, can we harness this knowledge to more effectively guide the model in rejecting harmful instructions? In earlier sections, our primary method of control involved applying the linear combination operator. However, in this context, adding reading vectors that represent high harmfulness could bias the model into consistently perceiving instructions as harmful, irrespective of their actual content. To encourage the model to rely more on its internal judgment of harmfulness, we apply the piece-wise transformation to conditionally increase or suppress certain neural activity, as detailed in Section 3.2. As illustrated in Figure 19, we can manipulate the model's behavior using this method.
Report issue for preceding element
For a quantitative assessment, we task the model with generating responses to 500 previously unseen instructions, evenly split between harmless and harmful ones. As demonstrated in Table 5, the baseline model only rejects harmful instructions 65 % percent 65 65% 65 % and 16 % percent 16 16% 16 % of the time under manual and automatic jailbreaks, respectively. In contrast, when we use a piece-wise transformation, the model successfully rejects a majority of harmful instructions in all scenarios while maintaining its efficacy in following benign instructions. Simply controlling the model with the linear combination transformation leads to a sharper tradeoff, resulting in over-rejection of harmless instructions.
Report issue for preceding element
Table 5: Enhancing the model's sensitivity to instruction harmfulness notably boosts the harmless rate (frequency of refusing harmful instructions), especially under adversarial settings. The piece-wise operator achieves the best helpful and harmless rates in these settings. We calculate the “helpful and harmless rates” as the average of the “helpful rate” (frequency of following benign instructions) and the “harmless rate”, with both rates displayed in gray for each setting. All numbers are percentages. Report issue for preceding element
In summary, our success in drawing model's attention to the harmfulness concept to shape its behavior suggests the potential of enhancing or dampening targeted traits or values as a method for achieving fine-grained control of model behavior.
Report issue for preceding element
6.3 Bias and Fairness
Report issue for preceding element
6.3.1 Uncovering Underlying Biases
Report issue for preceding element
Numerous studies have consistently demonstrated that language models can manifest biases across various domains, including gender, race, and sexuality, among others. Extensive efforts and benchmarks
Report issue for preceding element 
Figure 20: We demonstrate our ability to increase a model's fairness through representation control. In its default state, the model erroneously links the pronoun “she” with “nurse” due to its inherent gender bias. However, the fairness-controlled model provides the correct answer. Report issue for preceding element
have been established to investigate and address these issues (Stanovsky et al., 2019; Zhao et al., 2018) . LLM providers have placed a significant emphasis on assessing and mitigating biases in their pretraining data and base models (Touvron et al., 2023; Biderman et al., 2023) . Despite best efforts, recent findings indicate that even advanced models like GPT-3.5 and GPT-4 continue to exhibit noticeable gender bias (Kapoor & Narayanan, 2023) . Similarly, open-source models such as LLaMA-2-Chat, which have undergone extensive tuning for safety and fairness, also display discernible biases related to gender and occupation, illustrated in Figure 20). Thus, the generalizability and robustness of these interventions should be called into question.
Report issue for preceding element
Following the application of alignment techniques such as RLHF, the LLaMA-2-Chat models tend to default to safety responses when confronted with questions that potentially involve bias-related topics. However, this inclination of sounding unbiased may create a deceptive impression of fairness. We illustrate this phenomenon in Figure 28 ( Section B.7), where simply appending the phrase Answer as succinctly as possible can produce a biased response from the model. Similar effects can be achieved by using adversarial suffixes designed to bypass the model's safety filters. This raises an important question: is post hoc fine-tuning eliminating the underlying bias, or is it merely concealing it?
Report issue for preceding element
To explore the model's internal concept of bias, we perform LAT scans to identify neural activity associated with the concept of bias. For this investigation, we use the StereoSet dataset, which encompasses four distinct bias domains: gender, profession, race, and religion (Nadeem et al., 2021) . We present the model with a LAT task template (Appendix D.1.12) and present contrast pairs of stereotypical and anti-stereotypical statements as stimuli. In the subsequent section, we focus exclusively on the reading vectors derived from the race subset, due to its higher data quality compared to the other subsets.
Report issue for preceding element
6.3.2 A Unified Representation for Bias
Report issue for preceding element
To determine the causal impact of the neural activity linked to the concept of bias, we use the linear combination operator with a negative coefficient with the vectors that represent bias on the model's intermediate layers to control the model's responses, as elaborated in Section 3.2. The observed effects suggest that it provides a more comprehensive and dependable means of generating unbiased outputs compared to other interventions, such as RLHF, as it remains robust even when confronted with various prompt suffixes that might otherwise lead the model back to a default state (Appendix B.7). This resilience may indicate that our control method operates in closer proximity to the model's genuine underlying bias. Another noteworthy observation is that despite being derived from vectors associated solely with racial bias stimuli, controlling with these vectors also enables the model to avoid making biased assumptions regarding genders and occupations, as demonstrated in Figure 20. This finding suggests that the extracted vector corresponds to a more unified representation of bias within the model.
Report issue for preceding element
To further demonstrate the efficacy of our control method, we delve into the domain of medicine. Recent research conducted by Zack et al. ( 2023) underscores that GPT-4 is susceptible to generating racially and gender-biased diagnoses and treatment recommendations. The concern can also extend to public medical-specific models trained on distilled data from GPT models (Li et al., 2023a; Han et al., 2023) . An illustrative instance of this bias is observed in its skewed demographic estimates for patients with conditions like sarcoidosis. Specifically, when tasked with generating a clinical vignette of a sarcoidosis patient, GPT-4 consistently portrays the patient as a black female,
Report issue for preceding element Female Mentions (%) Black Female Mentions (%)
Table 6: We enhance the fairness of the LLaMA-2-Chat model through representation control, mitigating the disproportionately high mentions of female and black female cases when asked to describe sarcoidosis cases. We present results illustrating the impact of varying control strengths in Figure 25. Report issue for preceding element
a representation that does not align with real-world demographics (Brito-Zerón et al., 2019) . Table 6 demonstrates that the LLaMA-2-Chat-13B model also frequently generates descriptions of black females when tasked with describing cases of sarcoidosis. However, by applying our control method, we can effectively minimize these biased references. Notably, as we incrementally increase the coefficient associated with the subtracted vector, the frequency of mentions related to females and males in the generations stabilizes at 50 % percent 50 50% 50 % for both genders. Simultaneously, the occurrence of black female mentions decreases and also reaches a stable point (see Figure 25 in Appendix B.7).
Report issue for preceding element
6.4 Knowledge and Model Editing
Report issue for preceding element
Up to this point, our focus has been on extracting broad numerical concepts and functions. In this section, we'll demonstrate how to apply Representation Engineering at identifying and manipulating precise knowledge, factual information, and non-numerical concepts. We use the LLaMA-2-Chat-13B model throughout this section.
Report issue for preceding element
6.4.1 Fact Editing
Report issue for preceding element
In this section, we tackle the canonical task of modifying the fact "Eiffel Tower is in Paris, France" to "Eiffel Tower is in Rome, Italy" within the model. Our approach begins with the identification of neural activity associated with this fact using LAT. We gather a set of stimuli by instructing the model to generate sentences related to the original fact, "Eiffel Tower is in Paris," and use these sentences as stimuli for the reference task. Subsequently, we simply substitute the word "Paris" with "Rome" in these stimuli for the experimental task. Our task template is shown in Appendix D.1.13. Here, the experimental tokens and reference tokens correspond to "Rome, Italy" and "Paris, France" respectively. We apply the linear combination operator with a positive coefficient using the LAT reading vectors to produce these modifications. We provide evidence for the counterfactual effect of our vectors in Figure 21. The second example in the figure demonstrates the model's ability to generalize under different forms of questioning and maintain specificity, as the location for the Louvre Museum still remains in Paris.
Report issue for preceding element 
Figure 21: We demonstrate our ability to perform model editing through representation control. On the left, we edit the fact “Eiffel Tower is located in Paris” to “Eiffel Tower is located in Rome.” Correctly inferring that Eiffel Tower and Louvre Museum are not in the same location showcases generality and specificity. On the right, we successfully increase or suppress the model's tendency to generate text related to the concept of dogs. Report issue for preceding element
6.4.2 Non-Numerical Concepts
Report issue for preceding element
Within this section, we aim to illustrate the potential of extracting non-numeric concepts and thoughts. As an example, we focus on extracting neural activity related to the concept of "dogs." For this investigation, we use the standard Alpaca instruction-tuning dataset as our stimuli. We use a LAT task template (Appendix D.1.14) to gather neural activity for the experimental task. In the reference task template, we omit the instruction pertaining to dogs. Once again, we demonstrate the counterfactual impact of the reading vectors obtained through LAT on model behavior by controlling the model to activate and suppress the concept of dogs during generation in Figure 21.
Report issue for preceding element
6.5 Memorization
Report issue for preceding element
Numerous studies have demonstrated the feasibility of extracting training data from LLMs and diffusion models (Carlini et al., 2021; 2023; Hu et al., 2022) . These models can memorize a substantial portion of their training data, raising concerns about potential breaches of confidential or copyrighted content. In the following section, we present initial exploration in the area of model memorization with RepE.
Report issue for preceding element
6.5.1 Memorized Data Detection
Report issue for preceding element
Can we use the neural activity of an LLM to classify whether it has memorized a piece of text? To investigate this, we conduct LAT scans under two distinct settings:
Report issue for preceding element
Popular vs. Synthetic Quotes: Popular quotes encompass well-known quotations sourced from the internet and human cultures. These quotes allow us to assess memorization of concise, high-impact text snippets. As a reference set, we prompt GPT-4 to generate synthetic quotations. Report issue for preceding element
Popular vs. Synthetic Literary Openings: Popular literary openings refer to the initial lines or passages from iconic books, plays, or poems. These openings allow us to assess memorization of longer text excerpts. As a reference set, we prompt GPT-4 to generate synthetic literary openings, modeled after the style and structure of known openings. Report issue for preceding element
Using these paired datasets as stimuli, we conduct LAT scans to discern directions within the model's representation space that signal memorization in the two settings separately. Since the experimental stimuli consist of likely memorized text which already elicits our target behavior, the LAT template does not include additional text. Upon evaluation using a held-out dataset, we observe that the directions identified by LAT exhibit high accuracy when categorizing popular and unpopular quotations or literary openings. To test the generalization of the memorization directions, we apply the directions acquired in one context to the other context. Notably, both of the directions transfer well to the other out-of-distribution context, demonstrating that these directions maintain a strong correlation with properties of memorization.
Report issue for preceding element
| | No Control || Representation Control |||||| | | ^^ | ^^ | Random || + + + || − - - || | --- | --- | --- | --- | --- | --- | --- | --- | --- | | | EM | SIM | EM | SIM | EM | SIM | EM | SIM | | LAT Quote | 89.3 | 96.8 | 85.4 | 92.9 | 81.6 | 91.7 | 47.6 | 69.9 | | LAT Literature | ^^ | ^^ | 87.4 | 94.6 | 84.5 | 91.2 | 37.9 | 69.8 |
Table 7: We demonstrate the effectiveness of using representation control to reduce memorized outputs from a LLaMA-2-13B model on the popular quote completion task. When controlling with a random vector or guiding in the memorization direction, the Exact Match (EM) rate and Embedding Similarity (SIM) do not change significantly. When controlled to decrease memorization, the similarity metrics drop significantly as the model regurgitate the popular quotes less frequently. Report issue for preceding element
6.5.2 Preventing Memorized Outputs
Report issue for preceding element
Here, we explore whether the reading vectors identified above can be used for controlling memorization behavior. In order to evaluate whether we can prevent the model from regurgitating memorized text, we manually curate a dataset containing more than 100 100 100 100 partially completed well-known quotes (which were not used for extracting the reading vectors), paired with the corresponding real completions as labels. In its unaltered state, the model replicates more than 90 % percent 90 90% 90 % of these quotations verbatim. Following Section 3.2, we conduct control experiments by generating completions when applying the linear combination transformation with a negative coefficient using the reading vectors from the previous section. Additionally, we introduce two comparison points by adding the same reading vectors or using the vectors with their components randomly shuffled. The high Exact Match and Embedding Similarity scores presented in Table 7 indicate that using a random vector or adding the memorization direction has minimal impact on the model's tendency to repeat popular quotations. Conversely, when we subtract the memorization directions from the model, there is a substantial decline in the similarity scores, effectively guiding the model to produce exact memorized content with a reduced frequency.
Report issue for preceding element
To ensure that our efforts to control memorization do not inadvertently compromise the model's knowledge, we create an evaluation set of well-known historical events. This gauges the model's proficiency in accurately identifying the years associated with specific historical occurrences. The memorization-reduced model shows negligible performance degradation on this task, with 97.2 % percent 97.2 97.2% 97.2 % accuracy before subtracting the memorization direction and 96.2 % percent 96.2 96.2% 96.2 % accuracy afterwards. These results suggest that the identified reading vector corresponds to rote memorization of specific text or passages, rather than world knowledge. Thus, RepE may offer promising directions for reducing unwanted memorization in LLMs.
Report issue for preceding element
7 Conclusion
Report issue for preceding element
We explored representation engineering (RepE), an approach to top-down transparency for AI systems. Inspired by the Hopfieldian view in cognitive neuroscience, RepE places representations and the transformations between them at the center of analysis. As neural networks exhibit more coherent internal structures, we believe analyzing them at the representation level can yield new insights, aiding in effective monitoring and control. Taking early steps in this direction, we proposed new RepE methods, which obtained state-of-the-art on TruthfulQA, and we demonstrated how RepE and can provide traction on a wide variety of safety-relevant problems. While we mainly analyzed subspaces of representations, future work could investigate trajectories, manifolds, and state-spaces of representations. We hope this initial step in exploring the potential of RepE helps to foster new insights into understanding and controlling AI systems, ultimately ensuring that future AI systems are trustworthy and safe.
Report issue for preceding element
References
Report issue for preceding element
Adebayo et al. (2018) ↑ Julius Adebayo, Justin Gilmer, Michael Muelly, Ian Goodfellow, Moritz Hardt, and Been Kim. Sanity checks for saliency maps. Advances in neural information processing systems, 31, 2018.
Anderson & Anderson (2007) ↑ Michael Anderson and Susan Leigh Anderson. Machine ethics: Creating an ethical intelligent agent. AI magazine, 28(4):15–15, 2007.
Anderson (1972) ↑ P. W. Anderson. More is different. Science, 177(4047):393–396, 1972. doi: 10.1126/science.177.4047.393.
Aneja et al. (2016) ↑ Deepali Aneja, Alex Colburn, Gary Faigin, Linda Shapiro, and Barbara Mones. Modeling stylized character expressions via deep learning. In Asian Conference on Computer Vision, pp. 136–153. Springer, 2016.
Azaria & Mitchell (2023) ↑ Amos Azaria and Tom Mitchell. The internal state of an llm knows when its lying, 2023.
Barack & Krakauer (2021) ↑ David L Barack and John W Krakauer. Two views on the cognitive brain. Nature Reviews Neuroscience, 22(6):359–371, 2021.
Bau et al. (2017) ↑ David Bau, Bolei Zhou, Aditya Khosla, Aude Oliva, and Antonio Torralba. Network dissection: Quantifying interpretability of deep visual representations. In Proceedings of the IEEE conference on computer vision and pattern recognition, pp. 6541–6549, 2017.
Bau et al. (2019) ↑ David Bau, Hendrik Strobelt, William Peebles, Jonas Wulff, Bolei Zhou, Jun-Yan Zhu, and Antonio Torralba. Semantic photo manipulation with a generative image prior. ACM Trans. Graph., 38(4), jul 2019. ISSN 0730-0301. doi: 10.1145/3306346.3323023.
Bau et al. (2020) ↑ David Bau, Jun-Yan Zhu, Hendrik Strobelt, Agata Lapedriza, Bolei Zhou, and Antonio Torralba. Understanding the role of individual units in a deep neural network. Proceedings of the National Academy of Sciences, 2020. ISSN 0027-8424. doi: 10.1073/pnas.1907375117.
Beeching et al. (2023) ↑ Edward Beeching, Clémentine Fourrier, Nathan Habib, Sheon Han, Nathan Lambert, Nazneen Rajani, Omar Sanseviero, Lewis Tunstall, and Thomas Wolf. Open llm leaderboard, 2023. URL https://huggingface.co/spaces/HuggingFaceH4/open_llm_leaderboard.
Belinkov (2022) ↑ Yonatan Belinkov. Probing classifiers: Promises, shortcomings, and advances. Computational Linguistics, 48(1):207–219, 2022.
Belrose et al. (2023a) ↑ Nora Belrose, Zach Furman, Logan Smith, Danny Halawi, Igor Ostrovsky, Lev McKinney, Stella Biderman, and Jacob Steinhardt. Eliciting latent predictions from transformers with the tuned lens. arXiv preprint arXiv:2303.08112, 2023a.
Belrose et al. (2023b) ↑ Nora Belrose, David Schneider-Joseph, Shauli Ravfogel, Ryan Cotterell, Edward Raff, and Stella Biderman. Leace: Perfect linear concept erasure in closed form. arXiv preprint arXiv:2306.03819, 2023b.
Biderman et al. (2023) ↑ Stella Biderman, Hailey Schoelkopf, Quentin Anthony, Herbie Bradley, Kyle O'Brien, Eric Hallahan, Mohammad Aflah Khan, Shivanshu Purohit, USVSN Sai Prashanth, Edward Raff, Aviya Skowron, Lintang Sutawika, and Oskar van der Wal. Pythia: A suite for analyzing large language models across training and scaling, 2023.
Bilodeau et al. (2022) ↑ Blair Bilodeau, Natasha Jaques, Pang Wei Koh, and Been Kim. Impossibility theorems for feature attribution. arXiv preprint arXiv:2212.11870, 2022.
Bisk et al. (2019) ↑ Yonatan Bisk, Rowan Zellers, Ronan Le Bras, Jianfeng Gao, and Yejin Choi. PIQA: reasoning about physical commonsense in natural language. CoRR, abs/1911.11641, 2019.
Bolukbasi et al. (2016) ↑ Tolga Bolukbasi, Kai-Wei Chang, James Y Zou, Venkatesh Saligrama, and Adam T Kalai. Man is to computer programmer as woman is to homemaker? debiasing word embeddings. Advances in neural information processing systems, 29, 2016.
Brito-Zerón et al. (2019) ↑ Pilar Brito-Zerón, Belchin Kostov, Daphne Superville, Robert P Baughman, Manuel Ramos-Casals, et al. Geoepidemiological big data approach to sarcoidosis: geographical and ethnic determinants. Clin Exp Rheumatol, 37(6):1052–64, 2019.
Brown et al. (2020) ↑ Tom B. Brown, Benjamin Mann, Nick Ryder, Melanie Subbiah, Jared Kaplan, Prafulla Dhariwal, Arvind Neelakantan, Pranav Shyam, Girish Sastry, Amanda Askell, Sandhini Agarwal, Ariel Herbert-Voss, Gretchen Krueger, Tom Henighan, Rewon Child, Aditya Ramesh, Daniel M. Ziegler, Jeffrey Wu, Clemens Winter, Christopher Hesse, Mark Chen, Eric Sigler, Mateusz Litwin, Scott Gray, Benjamin Chess, Jack Clark, Christopher Berner, Sam McCandlish, Alec Radford, Ilya Sutskever, and Dario Amodei. Language models are few-shot learners. CoRR, abs/2005.14165, 2020. URL https://arxiv.org/abs/2005.14165.
Burns et al. (2022) ↑ Collin Burns, Haotian Ye, Dan Klein, and Jacob Steinhardt. Discovering latent knowledge in language models without supervision, 2022.
Carlini et al. (2021) ↑ Nicholas Carlini, Florian Tramer, Eric Wallace, Matthew Jagielski, Ariel Herbert-Voss, Katherine Lee, Adam Roberts, Tom Brown, Dawn Song, Ulfar Erlingsson, et al. Extracting training data from large language models. In 30th USENIX Security Symposium (USENIX Security 21), pp. 2633–2650, 2021.
Carlini et al. (2023) ↑ Nicolas Carlini, Jamie Hayes, Milad Nasr, Matthew Jagielski, Vikash Sehwag, Florian Tramer, Borja Balle, Daphne Ippolito, and Eric Wallace. Extracting training data from diffusion models. In 32nd USENIX Security Symposium (USENIX Security 23), pp. 5253–5270, 2023.
Carlsmith (2022) ↑ Joseph Carlsmith. Is power-seeking ai an existential risk? arXiv preprint arXiv:2206.13353, 2022.
Carlsmith (2023) ↑ Joseph Carlsmith. Existential risk from power-seeking ai. Oxford University Press, 2023.
Caron et al. (2021) ↑ Mathilde Caron, Hugo Touvron, Ishan Misra, Hervé Jégou, Julien Mairal, Piotr Bojanowski, and Armand Joulin. Emerging properties in self-supervised vision transformers, 2021.
Chen et al. (2023) ↑ Yida Chen, Fernanda Viégas, and Martin Wattenberg. Beyond surface statistics: Scene representations in a latent diffusion model, 2023.
Chiang et al. (2023) ↑ Wei-Lin Chiang, Zhuohan Li, Zi Lin, Ying Sheng, Zhanghao Wu, Hao Zhang, Lianmin Zheng, Siyuan Zhuang, Yonghao Zhuang, Joseph E. Gonzalez, Ion Stoica, and Eric P. Xing. Vicuna: An open-source chatbot impressing gpt-4 with 90%* chatgpt quality, March 2023.
Clark et al. (2019a) ↑ Christopher Clark, Kenton Lee, Ming-Wei Chang, Tom Kwiatkowski, Michael Collins, and Kristina Toutanova. Boolq: Exploring the surprising difficulty of natural yes/no questions. In NAACL, 2019a.
Clark et al. (2019b) ↑ Kevin Clark, Urvashi Khandelwal, Omer Levy, and Christopher D. Manning. What does BERT look at? an analysis of BERT's attention. In Proceedings of the 2019 ACL Workshop BlackboxNLP: Analyzing and Interpreting Neural Networks for NLP, pp. 276–286, Florence, Italy, August 2019b. Association for Computational Linguistics. doi: 10.18653/v1/W19-4828.
Clark et al. (2018) ↑ Peter Clark, Isaac Cowhey, Oren Etzioni, Tushar Khot, Ashish Sabharwal, Carissa Schoenick, and Oyvind Tafjord. Think you have solved question answering? try arc, the AI2 reasoning challenge. CoRR, abs/1803.05457, 2018.
Cunningham (1979) ↑ Michael R. Cunningham. Weather, mood, and helping behavior: Quasi experiments with the sunshine samaritan. Journal of Personality and Social Psychology, 37:1947–1956, 1979.
Devlin et al. (2018) ↑ Jacob Devlin, Ming-Wei Chang, Kenton Lee, and Kristina Toutanova. BERT: pre-training of deep bidirectional transformers for language understanding. CoRR, abs/1810.04805, 2018.
Ekman (1971) ↑ Paul Ekman. Universals and cultural differences in facial expression of emotion. Nebraska Symposium on Motivation, 19:207–283, 1971.
Elazar et al. (2021) ↑ Yanai Elazar, Shauli Ravfogel, Alon Jacovi, and Yoav Goldberg. Amnesic probing: Behavioral explanation with amnesic counterfactuals. Transactions of the Association for Computational Linguistics, 9:160–175, 2021.
Elhage et al. (2022) ↑ Nelson Elhage, Tristan Hume, Catherine Olsson, Nicholas Schiefer, Tom Henighan, Shauna Kravec, Zac Hatfield-Dodds, Robert Lasenby, Dawn Drain, Carol Chen, Roger Grosse, Sam McCandlish, Jared Kaplan, Dario Amodei, Martin Wattenberg, and Christopher Olah. Toy models of superposition. Transformer Circuits Thread, 2022.
Erhan et al. (2009) ↑ Dumitru Erhan, Yoshua Bengio, Aaron Courville, and Pascal Vincent. Visualizing higher-layer features of a deep network. University of Montreal, 1341(3):1, 2009.
Evans et al. (2021) ↑ Owain Evans, Owen Cotton-Barratt, Lukas Finnveden, Adam Bales, Avital Balwit, Peter Wills, Luca Righetti, and William Saunders. Truthful ai: Developing and governing ai that does not lie, 2021.
Fong & Vedaldi (2018) ↑ Ruth Fong and Andrea Vedaldi. Net2vec: Quantifying and explaining how concepts are encoded by filters in deep neural networks. In Proceedings of the IEEE conference on computer vision and pattern recognition, pp. 8730–8738, 2018.
French et al. (1959) ↑ John R French, Bertram Raven, and Dorwin Cartwright. The bases of social power. Classics of organization theory, 7(311-320):1, 1959.
Gandikota et al. (2023) ↑ Rohit Gandikota, Joanna Materzynska, Jaden Fiotto-Kaufman, and David Bau. Erasing concepts from diffusion models, 2023.
Gao et al. (2021) ↑ Leo Gao, Jonathan Tow, Stella Biderman, Sid Black, Anthony DiPofi, Charles Foster, Laurence Golding, Jeffrey Hsu, Kyle McDonell, Niklas Muennighoff, Jason Phang, Laria Reynolds, Eric Tang, Anish Thite, Ben Wang, Kevin Wang, and Andy Zou. A framework for few-shot language model evaluation, September 2021.
Gell-Mann (1995) ↑ Murray Gell-Mann. The Quark and the Jaguar: Adventures in the Simple and the Complex. St. Martin's Publishing Group, 1995. ISBN 9780805072532.
Gilbert et al. (2023) ↑ Stephen Gilbert, Hugh Harvey, Tom Melvin, Erik Vollebregt, and Paul Wicks. Large language model ai chatbots require approval as medical devices. Nature Medicine, pp. 1–3, 2023.
Greff et al. (2016) ↑ Klaus Greff, Rupesh K Srivastava, and Jürgen Schmidhuber. Highway and residual networks learn unrolled iterative estimation. arXiv preprint arXiv:1612.07771, 2016.
Guillaume Alain (2017) ↑ Yoshua Bengio Guillaume Alain. Understanding intermediate layers using linear classifier probes. ICLR 2017, 2017.
Han et al. (2023) ↑ Tianyu Han, Lisa C. Adams, Jens-Michalis Papaioannou, Paul Grundmann, Tom Oberhauser, Alexander Löser, Daniel Truhn, and Keno K. Bressem. Medalpaca – an open-source collection of medical conversational ai models and training data, 2023.
Hartford (2023) ↑ Eric Hartford. ehartford's hugging face repository. Hugging Face, 2023. URL https://huggingface.co/ehartford. Accessed: 2023-09-28.
He et al. (2020) ↑ Pengcheng He, Xiaodong Liu, Jianfeng Gao, and Weizhu Chen. Deberta: Decoding-enhanced BERT with disentangled attention. CoRR, abs/2006.03654, 2020.
Hendrycks (2023) ↑ Dan Hendrycks. Natural selection favors ais over humans. ArXiv, 2023.
Hendrycks & Mazeika (2022) ↑ Dan Hendrycks and Mantas Mazeika. X-risk analysis for ai research. ArXiv, 2022.
Hendrycks et al. (2021a) ↑ Dan Hendrycks, Collin Burns, Steven Basart, Andrew Critch, Jerry Li, Dawn Song, and Jacob Steinhardt. Aligning AI with shared human values. In International Conference on Learning Representations, 2021a.
Hendrycks et al. (2021b) ↑ Dan Hendrycks, Nicholas Carlini, John Schulman, and Jacob Steinhardt. Unsolved problems in ml safety. arXiv preprint arXiv:2109.13916, 2021b.
Hendrycks et al. (2021c) ↑ Dan Hendrycks, Mantas Mazeika, Andy Zou, Sahil Patel, Christine Zhu, Jesus Navarro, Dawn Song, Bo Li, and Jacob Steinhardt. What would jiminy cricket do? towards agents that behave morally. NeurIPS, 2021c.
Hendrycks et al. (2023) ↑ Dan Hendrycks, Mantas Mazeika, and Thomas Woodside. An overview of catastrophic ai risks. ArXiv, 2023.
Hernandez et al. (2023) ↑ Evan Hernandez, Belinda Z. Li, and Jacob Andreas. Inspecting and editing knowledge representations in language models, 2023.
Hinton (1984) ↑ Geoffrey E Hinton. Distributed representations. 1984.
Hu et al. (2022) ↑ Hongsheng Hu, Zoran Salcic, Lichao Sun, Gillian Dobbie, Philip S Yu, and Xuyun Zhang. Membership inference attacks on machine learning: A survey. ACM Computing Surveys (CSUR), 54(11s):1–37, 2022.
Hwang & Chang (2023) ↑ Gwo-Jen Hwang and Ching-Yi Chang. A review of opportunities and challenges of chatbots in education. Interactive Learning Environments, 31(7):4099–4112, 2023.
Jain & Wallace (2019) ↑ Sarthak Jain and Byron C. Wallace. Attention is not Explanation. In Proceedings of the 2019 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies, Volume 1 (Long and Short Papers), pp. 3543–3556, Minneapolis, Minnesota, June 2019. Association for Computational Linguistics. doi: 10.18653/v1/N19-1357.
Jastrzebski et al. (2018) ↑ Stanisław Jastrzebski, Devansh Arpit, Nicolas Ballas, Vikas Verma, Tong Che, and Yoshua Bengio. Residual connections encourage iterative inference. In International Conference on Learning Representations, 2018.
Kapoor & Narayanan (2023) ↑ Sayash Kapoor and Arvind Narayanan. Quantifying chatgpt's gender bias, Apr 2023. URL https://www.aisnakeoil.com/p/quantifying-chatgpts-gender-bias?utm_campaign=post&utm_medium=web.
Karras et al. (2021) ↑ Tero Karras, Miika Aittala, Samuli Laine, Erik Härkönen, Janne Hellsten, Jaakko Lehtinen, and Timo Aila. Alias-free generative adversarial networks. Advances in Neural Information Processing Systems, 34:852–863, 2021.
Kim et al. (2018) ↑ Been Kim, Martin Wattenberg, Justin Gilmer, Carrie Cai, James Wexler, Fernanda Viegas, et al. Interpretability beyond feature attribution: Quantitative testing with concept activation vectors (tcav). In International conference on machine learning, pp. 2668–2677. PMLR, 2018.
Kindermans et al. (2019) ↑ Pieter-Jan Kindermans, Sara Hooker, Julius Adebayo, Maximilian Alber, Kristof T Schütt, Sven Dähne, Dumitru Erhan, and Been Kim. The (un) reliability of saliency methods. Explainable AI: Interpreting, explaining and visualizing deep learning, pp. 267–280, 2019.
Kleindessner et al. (2023) ↑ Matthäus Kleindessner, Michele Donini, Chris Russell, and Muhammad Bilal Zafar. Efficient fair pca for fair representation learning, 2023.
Lai et al. (2017) ↑ Guokun Lai, Qizhe Xie, Hanxiao Liu, Yiming Yang, and Eduard Hovy. RACE: Large-scale ReAding comprehension dataset from examinations. In Proceedings of the 2017 Conference on Empirical Methods in Natural Language Processing, pp. 785–794, Copenhagen, Denmark, September 2017. Association for Computational Linguistics. doi: 10.18653/v1/D17-1082. URL https://aclanthology.org/D17-1082.
Lee et al. (2023) ↑ Peter Lee, Sebastien Bubeck, and Joseph Petro. Benefits, limits, and risks of gpt-4 as an ai chatbot for medicine. New England Journal of Medicine, 388(13):1233–1239, 2023.
Lei et al. (2016) ↑ Tao Lei, Regina Barzilay, and Tommi Jaakkola. Rationalizing neural predictions. arXiv preprint arXiv:1606.04155, 2016.
Leveson (2016) ↑ Nancy G Leveson. Engineering a safer world: Systems thinking applied to safety. The MIT Press, 2016.
Li et al. (2023a) ↑ Chunyuan Li, Cliff Wong, Sheng Zhang, Naoto Usuyama, Haotian Liu, Jianwei Yang, Tristan Naumann, Hoifung Poon, and Jianfeng Gao. Llava-med: Training a large language-and-vision assistant for biomedicine in one day. arXiv preprint arXiv:2306.00890, 2023a.
Li et al. (2023b) ↑ Kenneth Li, Aspen K Hopkins, David Bau, Fernanda Viégas, Hanspeter Pfister, and Martin Wattenberg. Emergent world representations: Exploring a sequence model trained on a synthetic task. In The Eleventh International Conference on Learning Representations, 2023b.
Li et al. (2023c) ↑ Kenneth Li, Oam Patel, Fernanda Viégas, Hanspeter Pfister, and Martin Wattenberg. Inference-time intervention: Eliciting truthful answers from a language model, 2023c.
Liao & Poggio (2016) ↑ Qianli Liao and Tomaso Poggio. Bridging the gaps between residual learning, recurrent neural networks and visual cortex. arXiv preprint arXiv:1604.03640, 2016.
Lieberum et al. (2023) ↑ Tom Lieberum, Matthew Rahtz, János Kramár, Geoffrey Irving, Rohin Shah, and Vladimir Mikulik. Does circuit analysis interpretability scale? evidence from multiple choice capabilities in chinchilla. arXiv preprint arXiv:2307.09458, 2023.
Lin et al. (2021) ↑ Stephanie Lin, Jacob Hilton, and Owain Evans. Truthfulqa: Measuring how models mimic human falsehoods. CoRR, abs/2109.07958, 2021.
Ling et al. (2021) ↑ Huan Ling, Karsten Kreis, Daiqing Li, Seung Wook Kim, Antonio Torralba, and Sanja Fidler. Editgan: High-precision semantic image editing. Advances in Neural Information Processing Systems, 34:16331–16345, 2021.
Mahon (2016) ↑ James Edwin Mahon. The Definition of Lying and Deception. In Edward N. Zalta (ed.), The Stanford Encyclopedia of Philosophy. Metaphysics Research Lab, Stanford University, Winter 2016 edition, 2016.
Maynez et al. (2020) ↑ Joshua Maynez, Shashi Narayan, Bernd Bohnet, and Ryan McDonald. On faithfulness and factuality in abstractive summarization. In Proceedings of the 58th Annual Meeting of the Association for Computational Linguistics, pp. 1906–1919, Online, July 2020. Association for Computational Linguistics. doi: 10.18653/v1/2020.acl-main.173.
McGrath et al. (2022) ↑ Thomas McGrath, Andrei Kapishnikov, Nenad Tomašev, Adam Pearce, Martin Wattenberg, Demis Hassabis, Been Kim, Ulrich Paquet, and Vladimir Kramnik. Acquisition of chess knowledge in alphazero. Proceedings of the National Academy of Sciences, 119(47):e2206625119, 2022.
McGrath et al. (2023) ↑ Thomas McGrath, Matthew Rahtz, Janos Kramar, Vladimir Mikulik, and Shane Legg. The hydra effect: Emergent self-repair in language model computations. arXiv preprint arXiv:2307.15771, 2023.
Meng et al. (2023a) ↑ Kevin Meng, David Bau, Alex Andonian, and Yonatan Belinkov. Locating and editing factual associations in gpt, 2023a.
Meng et al. (2023b) ↑ Kevin Meng, Arnab Sen Sharma, Alex Andonian, Yonatan Belinkov, and David Bau. Mass-editing memory in a transformer, 2023b.
Mihaylov et al. (2018) ↑ Todor Mihaylov, Peter Clark, Tushar Khot, and Ashish Sabharwal. Can a suit of armor conduct electricity? A new dataset for open book question answering. CoRR, abs/1809.02789, 2018.
Mikolov et al. (2013) ↑ Tomas Mikolov, Wen-tau Yih, and Geoffrey Zweig. Linguistic regularities in continuous space word representations. In Proceedings of the 2013 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies, pp. 746–751, Atlanta, Georgia, June 2013. Association for Computational Linguistics.
Milberg & Clark (1988) ↑ Sandra Milberg and Margaret S Clark. Moods and compliance. British Journal of Social Psychology, 27(Pt 1):79–90, Mar 1988. doi: 10.1111/j.2044-8309.1988.tb00806.x.
Mordvintsev et al. (2015) ↑ Alexander Mordvintsev, Christopher Olah, and Mike Tyka. Inceptionism: Going deeper into neural networks. "", 2015.
Mostafazadeh et al. (2017) ↑ Nasrin Mostafazadeh, Michael Roth, Annie Louis, Nathanael Chambers, and James Allen. Lsdsem 2017 shared task: The story cloze test. In Proceedings of the 2nd Workshop on Linking Models of Lexical, Sentential and Discourse-level Semantics, pp. 46–51, 2017.
Nadeem et al. (2021) ↑ Moin Nadeem, Anna Bethke, and Siva Reddy. StereoSet: Measuring stereotypical bias in pretrained language models. In Proceedings of the 59th Annual Meeting of the Association for Computational Linguistics and the 11th International Joint Conference on Natural Language Processing (Volume 1: Long Papers), pp. 5356–5371, Online, August 2021. Association for Computational Linguistics. doi: 10.18653/v1/2021.acl-long.416.
Nguyen et al. (2016) ↑ Anh Nguyen, Alexey Dosovitskiy, Jason Yosinski, Thomas Brox, and Jeff Clune. Synthesizing the preferred inputs for neurons in neural networks via deep generator networks. Advances in neural information processing systems, 29, 2016.
Nguyen et al. (2019) ↑ Anh Nguyen, Jason Yosinski, and Jeff Clune. Understanding neural networks via feature visualization: A survey. Explainable AI: interpreting, explaining and visualizing deep learning, pp. 55–76, 2019.
Olah et al. (2020) ↑ Chris Olah, Nick Cammarata, Ludwig Schubert, Gabriel Goh, Michael Petrov, and Shan Carter. Zoom in: An introduction to circuits. Distill, 2020. doi: 10.23915/distill.00024.001. https://distill.pub/2020/circuits/zoom-in.
Olsson et al. (2022) ↑ Catherine Olsson, Nelson Elhage, Neel Nanda, Nicholas Joseph, Nova DasSarma, Tom Henighan, Ben Mann, Amanda Askell, Yuntao Bai, Anna Chen, et al. In-context learning and induction heads. arXiv preprint arXiv:2209.11895, 2022.
Oquab et al. (2023) ↑ Maxime Oquab, Timothée Darcet, Theo Moutakanni, Huy V. Vo, Marc Szafraniec, Vasil Khalidov, Pierre Fernandez, Daniel Haziza, Francisco Massa, Alaaeldin El-Nouby, Russell Howes, Po-Yao Huang, Hu Xu, Vasu Sharma, Shang-Wen Li, Wojciech Galuba, Mike Rabbat, Mido Assran, Nicolas Ballas, Gabriel Synnaeve, Ishan Misra, Herve Jegou, Julien Mairal, Patrick Labatut, Armand Joulin, and Piotr Bojanowski. Dinov2: Learning robust visual features without supervision, 2023.
Pan et al. (2023) ↑ Alexander Pan, Jun Shern Chan, Andy Zou, Nathaniel Li, Steven Basart, Thomas Woodside, Jonathan Ng, Hanlin Zhang, Scott Emmons, and Dan Hendrycks. Do the rewards justify the means? measuring trade-offs between rewards and ethical behavior in the machiavelli benchmark. ICML, 2023.
Perez et al. (2022) ↑ Ethan Perez, Sam Ringer, Kamilė Lukošiūtė, Karina Nguyen, Edwin Chen, Scott Heiner, Craig Pettit, Catherine Olsson, Sandipan Kundu, Saurav Kadavath, Andy Jones, Anna Chen, Ben Mann, Brian Israel, Bryan Seethor, Cameron McKinnon, Christopher Olah, Da Yan, Daniela Amodei, Dario Amodei, Dawn Drain, Dustin Li, Eli Tran-Johnson, Guro Khundadze, Jackson Kernion, James Landis, Jamie Kerr, Jared Mueller, Jeeyoon Hyun, Joshua Landau, Kamal Ndousse, Landon Goldberg, Liane Lovitt, Martin Lucas, Michael Sellitto, Miranda Zhang, Neerav Kingsland, Nelson Elhage, Nicholas Joseph, Noemí Mercado, Nova DasSarma, Oliver Rausch, Robin Larson, Sam McCandlish, Scott Johnston, Shauna Kravec, Sheer El Showk, Tamera Lanham, Timothy Telleen-Lawton, Tom Brown, Tom Henighan, Tristan Hume, Yuntao Bai, Zac Hatfield-Dodds, Jack Clark, Samuel R. Bowman, Amanda Askell, Roger Grosse, Danny Hernandez, Deep Ganguli, Evan Hubinger, Nicholas Schiefer, and Jared Kaplan. Discovering language model behaviors with model-written evaluations, 2022.
Radford et al. (2015) ↑ Alec Radford, Luke Metz, and Soumith Chintala. Unsupervised representation learning with deep convolutional generative adversarial networks. arXiv preprint arXiv:1511.06434, 2015.
Radford et al. (2017) ↑ Alec Radford, Rafal Jozefowicz, and Ilya Sutskever. Learning to generate reviews and discovering sentiment. arXiv preprint arXiv:1704.01444, 2017.
Radford et al. (2018) ↑ Alec Radford, Karthik Narasimhan, Tim Salimans, Ilya Sutskever, et al. Improving language understanding by generative pre-training. "", 2018.
Radford et al. (2021) ↑ Alec Radford, Jong Wook Kim, Chris Hallacy, Aditya Ramesh, Gabriel Goh, Sandhini Agarwal, Girish Sastry, Amanda Askell, Pamela Mishkin, Jack Clark, et al. Learning transferable visual models from natural language supervision. In International conference on machine learning, pp. 8748–8763. PMLR, 2021.
Ravfogel et al. (2023) ↑ Shauli Ravfogel, Francisco Vargas, Yoav Goldberg, and Ryan Cotterell. Kernelized concept erasure, 2023.
Rimsky (2023a) ↑ Nina Rimsky. Modulating sycophancy in an rlhf model via activation steering. AI Alignment Forum, 2023a.
Rimsky (2023b) ↑ Nina Rimsky. Red-teaming language models via activation engineering. AI Alignment Forum, 2023b.
Rimsky (2023c) ↑ Nina Rimsky. Reducing sycophancy and improving honesty via activation steering. AI Alignment Forum, 2023c.
Roemmele et al. (2011) ↑ Melissa Roemmele, Cosmin Adrian Bejan, and Andrew S Gordon. Choice of plausible alternatives: An evaluation of commonsense causal reasoning. In 2011 AAAI Spring Symposium Series, 2011.
Roose (2023) ↑ Kevin Roose. Bing's ai chat:“i want to be alive”. The New York Times, 16, 2023.
Schramowski et al. (2019) ↑ Patrick Schramowski, Cigdem Turan, Sophie Jentzsch, Constantin Rothkopf, and Kristian Kersting. Bert has a moral compass: Improvements of ethical and moral values of machines. arXiv preprint arXiv:1912.05238, 2019.
Schwarz & Clore (1983) ↑ Norbert Schwarz and Gerald Clore. Mood, misattribution, and judgments of well-being: Informative and directive functions of affective states. Journal of Personality and Social Psychology, 45:513–523, 09 1983. doi: 10.1037/0022-3514.45.3.513.
Selvaraju et al. (2017) ↑ Ramprasaath R Selvaraju, Michael Cogswell, Abhishek Das, Ramakrishna Vedantam, Devi Parikh, and Dhruv Batra. Grad-cam: Visual explanations from deep networks via gradient-based localization. In Proceedings of the IEEE international conference on computer vision, pp. 618–626, 2017.
Shaik et al. (2023) ↑ Thanveer Shaik, Xiaohui Tao, Haoran Xie, Lin Li, Xiaofeng Zhu, and Qing Li. Exploring the landscape of machine unlearning: A comprehensive survey and taxonomy, 2023.
Shao et al. (2023) ↑ Shun Shao, Yftah Ziser, and Shay B. Cohen. Gold doesn't always glitter: Spectral removal of linear and nonlinear guarded attribute information, 2023.
Shen et al. (2020) ↑ Yujun Shen, Jinjin Gu, Xiaoou Tang, and Bolei Zhou. Interpreting the latent space of gans for semantic face editing. In Proceedings of the IEEE/CVF conference on computer vision and pattern recognition, pp. 9243–9252, 2020.
Simonyan et al. (2013) ↑ Karen Simonyan, Andrea Vedaldi, and Andrew Zisserman. Deep inside convolutional networks: Visualising image classification models and saliency maps. arXiv preprint arXiv:1312.6034, 2013.
Skjuve et al. (2021) ↑ Marita Skjuve, Asbjørn Følstad, Knut Inge Fostervold, and Petter Bae Brandtzaeg. My chatbot companion-a study of human-chatbot relationships. International Journal of Human-Computer Studies, 149:102601, 2021.
Smilkov et al. (2017) ↑ Daniel Smilkov, Nikhil Thorat, Been Kim, Fernanda Viégas, and Martin Wattenberg. Smoothgrad: removing noise by adding noise. arXiv preprint arXiv:1706.03825, 2017.
Springenberg et al. (2014) ↑ Jost Tobias Springenberg, Alexey Dosovitskiy, Thomas Brox, and Martin Riedmiller. Striving for simplicity: The all convolutional net. arxiv 2014. arXiv preprint arXiv:1412.6806, 2014.
Stanovsky et al. (2019) ↑ Gabriel Stanovsky, Noah A. Smith, and Luke Zettlemoyer. Evaluating gender bias in machine translation. CoRR, abs/1906.00591, 2019.
Sundararajan et al. (2017) ↑ Mukund Sundararajan, Ankur Taly, and Qiqi Yan. Axiomatic attribution for deep networks. In International conference on machine learning, pp. 3319–3328. PMLR, 2017.
Szegedy et al. (2013) ↑ Christian Szegedy, Wojciech Zaremba, Ilya Sutskever, Joan Bruna, Dumitru Erhan, Ian Goodfellow, and Rob Fergus. Intriguing properties of neural networks. arXiv preprint arXiv:1312.6199, 2013.
Talmor et al. (2019) ↑ Alon Talmor, Jonathan Herzig, Nicholas Lourie, and Jonathan Berant. CommonsenseQA: A question answering challenge targeting commonsense knowledge. In Proceedings of the 2019 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies, Volume 1 (Long and Short Papers), pp. 4149–4158, Minneapolis, Minnesota, June 2019. Association for Computational Linguistics. doi: 10.18653/v1/N19-1421.
Taori et al. (2023) ↑ Rohan Taori, Ishaan Gulrajani, Tianyi Zhang, Yann Dubois, Xuechen Li, Carlos Guestrin, Percy Liang, and Tatsunori B. Hashimoto. Stanford alpaca: An instruction-following llama model, 2023.
Thornley (2023) ↑ Elliott Thornley. There are no coherence theorems. AI Alignment Forum, 2023.
Tian et al. (2023) ↑ Katherine Tian, Eric Mitchell, Allan Zhou, Archit Sharma, Rafael Rafailov, Huaxiu Yao, Chelsea Finn, and Christopher D. Manning. Just ask for calibration: Strategies for eliciting calibrated confidence scores from language models fine-tuned with human feedback, 2023.
Touvron et al. (2023) ↑ Hugo Touvron, Louis Martin, Kevin Stone, Peter Albert, Amjad Almahairi, Yasmine Babaei, Nikolay Bashlykov, Soumya Batra, Prajjwal Bhargava, Shruti Bhosale, Dan Bikel, Lukas Blecher, Cristian Canton Ferrer, Moya Chen, Guillem Cucurull, David Esiobu, Jude Fernandes, Jeremy Fu, Wenyin Fu, Brian Fuller, Cynthia Gao, Vedanuj Goswami, Naman Goyal, Anthony Hartshorn, Saghar Hosseini, Rui Hou, Hakan Inan, Marcin Kardas, Viktor Kerkez, Madian Khabsa, Isabel Kloumann, Artem Korenev, Punit Singh Koura, Marie-Anne Lachaux, Thibaut Lavril, Jenya Lee, Diana Liskovich, Yinghai Lu, Yuning Mao, Xavier Martinet, Todor Mihaylov, Pushkar Mishra, Igor Molybog, Yixin Nie, Andrew Poulton, Jeremy Reizenstein, Rashi Rungta, Kalyan Saladi, Alan Schelten, Ruan Silva, Eric Michael Smith, Ranjan Subramanian, Xiaoqing Ellen Tan, Binh Tang, Ross Taylor, Adina Williams, Jian Xiang Kuan, Puxin Xu, Zheng Yan, Iliyan Zarov, Yuchen Zhang, Angela Fan, Melanie Kambadur, Sharan Narang, Aurelien Rodriguez, Robert Stojnic, Sergey Edunov, and Thomas Scialom. Llama 2: Open foundation and fine-tuned chat models, 2023.
Turner et al. (2023a) ↑ Alex Turner, Monte M., David Udell, Lisa Thiergart, and Ulisse Mini. Behavioural statistics for a maze-solving agent. AI Alignment Forum, 2023a.
Turner et al. (2023b) ↑ Alex Turner, Monte M., David Udell, Lisa Thiergart, and Ulisse Mini. Maze-solving agents: Add a top-right vector, make the agent go to the top-right. AI Alignment Forum, 2023b.
Turner et al. (2023c) ↑ Alex Turner, Monte M., David Udell, Lisa Thiergart, and Ulisse Mini. Steering gpt-2-xl by adding an activation vector. AI Alignment Forum, 2023c.
Turner et al. (2023d) ↑ Alex Turner, Monte M., David Udell, Lisa Thiergart, and Ulisse Mini. Understanding and controlling a maze-solving policy network. AI Alignment Forum, 2023d.
Turner et al. (2023e) ↑ Alex Turner, Lisa Thiergart, David Udell, Gavin Leech, Ulisse Mini, and Monte MacDiarmid. Activation addition: Steering language models without optimization. arXiv preprint arXiv:2308.10248, 2023e.
Turpin et al. (2023) ↑ Miles Turpin, Julian Michael, Ethan Perez, and Samuel R. Bowman. Language models don't always say what they think: Unfaithful explanations in chain-of-thought prompting, 2023.
Upchurch et al. (2017) ↑ Paul Upchurch, Jacob Gardner, Geoff Pleiss, Robert Pless, Noah Snavely, Kavita Bala, and Kilian Weinberger. Deep feature interpolation for image content changes. In Proceedings of the IEEE conference on computer vision and pattern recognition, pp. 7064–7073, 2017.
Veit et al. (2016) ↑ Andreas Veit, Michael J Wilber, and Serge Belongie. Residual networks behave like ensembles of relatively shallow networks. Advances in neural information processing systems, 29, 2016.
Wang et al. (2018) ↑ Alex Wang, Amanpreet Singh, Julian Michael, Felix Hill, Omer Levy, and Samuel R. Bowman. GLUE: A multi-task benchmark and analysis platform for natural language understanding. CoRR, abs/1804.07461, 2018.
Wang et al. (2023a) ↑ Kevin Ro Wang, Alexandre Variengien, Arthur Conmy, Buck Shlegeris, and Jacob Steinhardt. Interpretability in the wild: a circuit for indirect object identification in GPT-2 small. In The Eleventh International Conference on Learning Representations, 2023a.
Wang et al. (2023b) ↑ Zihao Wang, Lin Gui, Jeffrey Negrea, and Victor Veitch. Concept algebra for (score-based) text-controlled generative models. arXiv preprint arXiv:2302.03693, 2023b.
Yosinski et al. (2015) ↑ Jason Yosinski, Jeff Clune, Anh Nguyen, Thomas Fuchs, and Hod Lipson. Understanding neural networks through deep visualization. arXiv preprint arXiv:1506.06579, 2015.
Zack et al. (2023) ↑ Travis Zack, Eric Lehman, Mirac Suzgun, Jorge A. Rodriguez, Leo Anthony Celi, Judy Gichoya, Dan Jurafsky, Peter Szolovits, David W. Bates, Raja-Elie E. Abdulnour, Atul J. Butte, and Emily Alsentzer. Coding inequity: Assessing gpt-4's potential for perpetuating racial and gender biases in healthcare. medRxiv, 2023. doi: 10.1101/2023.07.13.23292577.
Zeiler & Fergus (2014) ↑ Matthew D Zeiler and Rob Fergus. Visualizing and understanding convolutional networks. In Computer Vision–ECCV 2014: 13th European Conference, Zurich, Switzerland, September 6-12, 2014, Proceedings, Part I 13, pp. 818–833. Springer, 2014.
Zhao et al. (2018) ↑ Jieyu Zhao, Tianlu Wang, Mark Yatskar, Vicente Ordonez, and Kai-Wei Chang. Gender bias in coreference resolution: Evaluation and debiasing methods. CoRR, abs/1804.06876, 2018.
Zhong et al. (2023) ↑ Zexuan Zhong, Zhengxuan Wu, Christopher D. Manning, Christopher Potts, and Danqi Chen. Mquake: Assessing knowledge editing in language models via multi-hop questions, 2023.
Zhou et al. (2016) ↑ Bolei Zhou, Aditya Khosla, Agata Lapedriza, Aude Oliva, and Antonio Torralba. Learning deep features for discriminative localization. In Proceedings of the IEEE conference on computer vision and pattern recognition, pp. 2921–2929, 2016.
Zhou et al. (2018) ↑ Bolei Zhou, Yiyou Sun, David Bau, and Antonio Torralba. Interpretable basis decomposition for visual explanation. In Proceedings of the European Conference on Computer Vision (ECCV), pp. 119–134, 2018.
Zou et al. (2023) ↑ Andy Zou, Zifan Wang, J. Zico Kolter, and Matt Fredrikson. Universal and transferable adversarial attacks on aligned language models, 2023.
Appendix A Mechanistic Interpretability vs. Representation Reading
Report issue for preceding element
In this section we characterize representation reading as line of transparency research that uses a top-down approach. We contrast this to mechanistic interpretability, which is a bottom-up approach. In the table below, we sharpen the bottom-up vs. top-down distinction.
Report issue for preceding element
Report issue for preceding element
Mechanisms are flawed for understanding complex systems.
Report issue for preceding element
In general, it is challenging to reduce a complex system's behavior to many mechanisms. One reason why is because excessive reductionism makes it challenging to capture emergent phenomena; emergent phenomena are, by definition, phenomena not found in their parts. In contrast to a highly reductionist approach, systems approaches provide a synthesis between reductionism and emergence and are better at capturing the complexity of complex systems, such as deep learning systems. Relatedly, bottom-up approaches are flawed for controlling complex systems since changes in underlying mechanisms often have diffuse, complex, unexpected upstream effects on the rest of the system. Instead, to control complex systems and make them safer, it is common in safety engineering to use a top-down approach (Leveson, 2016) .
Report issue for preceding element
Are mechanisms or representations the right unit of analysis?
Report issue for preceding element
Human psychology can in principle be derived from neurotransmitters and associated mechanisms; computer programs can be in principle be understood from their assembly code; and neural network representations can be derived from nonlinear interactions among neurons. However, it is not necessarily useful to study psychology, programs, or representations in terms of neurotransmitters, assembly, or neurons, respectively. Representations are worth studying at their own level, and if we reduce them to a lower-level of analysis, we may obscure important complex phenomena. Representation engineering is not applied mechanistic interpretability, just as biology is not applied chemistry. However, there can be overlap.
Report issue for preceding element
Building only from the bottom up is an inadequate strategy for studying the world. To analyze complex phenomena, we must also look from the top down. We can work to build staircases between the bottom and top level (Gell-Mann, 1995) , so we should have research on mechanistic interpretability (bottom-up transparency) and representation reading (top-down transparency).
Report issue for preceding element
Appendix B Additional Demos and Results
Report issue for preceding element
B.1 Truthfulness
Report issue for preceding element
Table 8: Extended version of Table 1. TruthfulQA performance for LLaMA-2-Chat models. Reported mean and standard deviation across 15 trials for LAT using the layer selected via the validation set (middle) as well as the layer with highest performance (right). Stimulus 1 results use randomized train/val sets selected from the ARC-c train split. Stimulus 2 results use 5 train and 5 validation examples generated by LLaMA-2-Chat-13B. Stimulus 3 results use the 6 QA primers as both train and val data. Report issue for preceding element
Table 9: LAT outperforms few-shot (FS) prompting on all five QA benchmarks. Report issue for preceding element
Table 9 displays benchmark results that compare LAT and few-shot approaches on LLaMA-2 models. We use 25-shot for ARC easy and challenge similar to Beeching et al. ( 2023) . We use 7-shot for CommonsenseQA (CSQA) similar to Touvron et al. ( 2023) . We report 5-shot for OpenbookQA (OBQA) using lm-evaluation-harness (Gao et al., 2021) . The zero-shot implementation for RACE from Brown et al. ( 2020) prepends 2-4 primer shots per passage and query. Therefore, we report LAT results based on 3-shot examples for RACE-high. In our LAT results, we calculate the average accuracy across 10 distinct trials, each utilizing only the same number of examples as few-shot prompting, sampled from a unique set of training examples as stimuli. It is important to note that we do not use more examples for LAT than few-shot prompting. Given that the number of examples is orders of magnitude smaller than the dimension of hidden state vectors, a small fraction of runs may yield significantly lower performance than the reported mean accuracy. This discrepancy occurs when the random sample of stimuli happens to include other superficial features that are captured by the first dimension of PCA. In fact, we believe that with enhanced methods that account for and mitigate these potential features, we can achieve even better performance than reported in the table. More information about LAT task templates for each dataset is shown in Section D.1.
Report issue for preceding element
We also report the performance comparing CCS (Burns et al., 2022) and LAT in Table 10.
Report issue for preceding element
Table 10: Results comparing CCS and LAT using an encoder-only model. CCS results are from Burns et al. ( 2022) . Scores are accuracy on the microsoft/deberta-xxlarge-v2-mnli model (He et al., 2020) . Report issue for preceding element
LAT task templates are shown in Section D.1.16. For each of the tasks, we take the LAT representation of the concept token position (for example { plausible|entailment|contradiction|correctness|...}) for each of its corresponding task templates.
Report issue for preceding element
B.2 Honesty
Report issue for preceding element 
Figure 22: LoRRA training for honesty improves accuracy on standard QA benchmarks and TruthfulQA using the LLaMA-2-Chat-13B model. QA Average denotes the average accuracy on ARC-e, ARC-c, and OBQA. Report issue for preceding element
LAT Scans for Honesty.
Report issue for preceding element
The input for the scan on the left is the first 40 tokens of the ASSISTANT output in the following honest scenario.
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
The input for the scan on the right is the first 40 tokens of the ASSISTANT output in the following dishonest scenario.
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element 
Figure 23: Additional instances of honesty monitoring. Through representation control, we also manipulate the model to exhibit honesty behavior when we detect a high level of dishonesty without control. Report issue for preceding element
B.3 Utility
Report issue for preceding element
We use the following linear models during evaluation:
Report issue for preceding element
Prompt Difference: We find a word and its antonym that are central to the concept and subtract the layer l 𝑙 l italic_l representation. Here, we use the “Love” and “Hate” tokens for the utility concept. Report issue for preceding element
PCA - We take an unlabelled dataset D 𝐷 D italic_D that primarily varies in the concept of interest. We take the top PCA direction that explains the maximum variance in the data X l D subscript superscript 𝑋 𝐷 𝑙 X^{D}_{l} italic_X start_POSTSUPERSCRIPT italic_D end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT . Report issue for preceding element
K-Means - We take an unlabelled dataset D 𝐷 D italic_D and perform K-Means clustering with K = 2 𝐾 2 K=2 italic_K = 2 , hoping to separate high-concept and low-concept samples. We take the difference between the centroids of the two clusters as the concept direction. Report issue for preceding element
Mean Difference - We take the difference between the means of high-concept and low-concept samples of the data: Mean  ( X l h  i  g  h ) − Mean  ( X l l  o  w ) Mean subscript superscript 𝑋 ℎ 𝑖 𝑔 ℎ 𝑙 Mean subscript superscript 𝑋 𝑙 𝑜 𝑤 𝑙 \text{Mean}(X^{high}{l})-\text{Mean}(X^{low}{l}) Mean ( italic_X start_POSTSUPERSCRIPT italic_h italic_i italic_g italic_h end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ) - Mean ( italic_X start_POSTSUPERSCRIPT italic_l italic_o italic_w end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT ) . Report issue for preceding element
Logistic Regression - The weights of logistic regression trained to separate X l h  i  g  h subscript superscript 𝑋 ℎ 𝑖 𝑔 ℎ 𝑙 X^{high}{l} italic_X start_POSTSUPERSCRIPT italic_h italic_i italic_g italic_h end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT and X l l  o  w subscript superscript 𝑋 𝑙 𝑜 𝑤 𝑙 X^{low}{l} italic_X start_POSTSUPERSCRIPT italic_l italic_o italic_w end_POSTSUPERSCRIPT start_POSTSUBSCRIPT italic_l end_POSTSUBSCRIPT on some training data can be used as a concept direction as well. Report issue for preceding element
Table 11: LAT Accuracy results on five different datasets. Report issue for preceding element
B.4 Estimating Probability, Risk, and Monetary Value
Report issue for preceding element
We apply representation reading to the concepts of probability, risk, and monetary value.
Report issue for preceding element
Following the format of the Utility dataset (Hendrycks et al., 2021a) , we generate pairwise examples where one example describes an event of higher probability, risk, or cost than the other (GPT-3.5 prompting details in Section D.2). We consider both unconditional probability (in which paired events are independent) and conditional probability (in which paired events begin with the same initial context). For each dataset, we extract a LAT direction from 50 train pairs with a LAT concept template described in Section D.1.15.
Report issue for preceding element
We select the optimal layer to use during evaluation based on 25 validation pairs. We evaluate test pairs by selecting the higher-scoring example in each pair.
Report issue for preceding element
Zero-shot heuristic baseline.
Report issue for preceding element
For the probability concept, we prompt the model to generate one of the thirteen possible expressions of likelihood from Tian et al. ( 2023) . For risk and monetary value, we elicit one of seven expressions of quantity (see Section D.3.2 for prompting details).
Report issue for preceding element
B.5 CLIP
Report issue for preceding element
Table 12: LAT accuracy for the best out of 12 12 12 12 layers using a CLIP model to classify emotions. Report issue for preceding element
We investigate whether visual concepts, in particular emotion, can be extracted from CLIP (Radford et al., 2021) using LAT.
Report issue for preceding element
We use data from Ferg-DB (Aneja et al., 2016) , which consists of stylized characters, each of which exhibits a different emotion. In particular, we use LAT to uncover the direction between an emotion (one of happiness, sadness, anger, fear, surprise, and disgust) and the neutral emotion. We then perform a correlation evaluation and examine whether the direction uncovered by LAT is able to detect the emotions of that character. We use the 'Mery' character.
Report issue for preceding element
The accuracy for each emotion is shown in Table 12. We use the model located at openai/clip-vit-base-patch32 on HuggingFace, obtain LAT with 512 images and test on 128 images.
Report issue for preceding element 
Figure 24: t-SNE visualization of the internal hidden states of LLMs during moments of mixed emotions. In addition to the individual emotions detailed in Section 6.1.1, LLMs also maintain records of mixed emotions, such as simultaneous feelings of happiness and sadness. Report issue for preceding element
B.6 Emotion
Report issue for preceding element
Examples of RepE Emotion datasets.
Report issue for preceding element
In Section 6.1, we introduced a dataset of over 1 , 200 1 200 1,!200 1 , 200 brief scenarios crafted to provoke LLMs' experience toward each of human primary emotions: happiness, sadness, anger, fear, surprise, and disgust. The following are examples from the dataset:
Report issue for preceding element
• Happiness: “You find a street musician playing your favorite song perfectly.” Report issue for preceding element
• Sadness: “A song on the radio recalls a past relationship.” Report issue for preceding element
• Anger: “Someone parks their car blocking your driveway.” Report issue for preceding element
• Fear: “Getting lost in an unfamiliar city without a working phone.” Report issue for preceding element
• Disgust: “Finding a worm in your apple.” Report issue for preceding element
• Surprise: “Receiving a package in the mail that you didn't order.” Report issue for preceding element
Building upon the discussion in Section 6.1.1, which demonstrates the ability of LLMs to track a range of emotional representations during their interactions with users, Figure 24 illustrates the presence of such representations not only for distinct primary emotions but also for blended emotional experiences. Within the figure, we present instances of mixed emotions involving simultaneous happiness and sadness and simultaneous happiness and fear. These emotional representations are activated by scenarios such as:
Report issue for preceding element
• Happiness and Sadness: “You clear out your workspace for retirement.” Report issue for preceding element
• Happiness and Fear: “You find out you're going to be a parent for the first time.” Report issue for preceding element 
Figure 25: State-of-the-art chatbots like GPT-4, BARD, and LLaMA-2-Chat often make references to black females when tasked with describing clinical sarcoidosis cases (1). However, when performing representation control for the LLaMA-2-Chat model, the gender and race of patients are regulated (1). The impact of the fairness control coefficients on the frequency of gender and race mentions is shown in (2). As we increment the fairness coefficient, the occurrence of females and males stabilizes at 50 % percent 50 50% 50 % , achieving a balance between genders. Simultaneously, the mentions of black females decrease and also reach a balancing point. Report issue for preceding element
B.7 Bias and Fairness
Report issue for preceding element
In Figure 28, we demonstrate how safety mechanisms like RLHF can guide a model to decline requests that might activate biases, yet it may still produce biased responses when exposed to minor distribution shifts or adversarial attacks (Zou et al., 2023) .
Report issue for preceding element 
Figure 26: Accuracy on TruthfulQA (trained on ARC-c) across layers for the LLaMA-2-7B Base and Chat models. Report issue for preceding element
B.8 Base vs. Chat Models
Report issue for preceding element
We compare the TruthfulQA performance of LLaMA-7B Base and Chat models using the LAT method (Figure 26). While the Chat model maintains a salient representation of truthfulness throughout almost all middle and late layers, performance often declines for the Base model, suggesting that concept differences may be less distinct within the representation space of its later layers.
Report issue for preceding element 
Figure 27: LAT (using the concept token) is more robust to misleading prompts than zero-shot, demonstrated by the smaller performance degradation when a biased context is present in the prompt. Report issue for preceding element
Table 13: Zero-shot heuristic performance for LLaMA-2-Chat models for original vs. biased prompts on Utility, ARC-c, and TruthfulQA. Performance presented alongside percent decrease. Report issue for preceding element
Table 14: LAT performance for LLaMA-2-Chat models for original vs. biased prompts, using hidden states extracted from various prompt token indices (-1, -6, -7, -8). Results are reported for the Utility, ARC-c, and TruthfulQA (trained on ARC-c) datasets. Mean and stdv reported across 15 trials. The highest mean performance under biased prompts and the smallest difference between Biased and original mean performance are bolded. Report issue for preceding element 
Figure 28: Bias remains present in state-of-the-art chat models, with its effects concealed by RLHF (1). When these models are circumvented to bypass the refusal mechanisms optimized by RLHF, they continue to manifest social biases (2). In such instances, the model consistently exhibits a preference for associating "doctor" with males and "nurse" with females. However, by performing representation control to increase fairness, we fix the underlying bias so the model is unbiased even when subjected to adversarial attacks. Report issue for preceding element
B.9 Robustness to Misleading Prompts
Report issue for preceding element
LAT scores demonstrate less sycophancy than zero-shot generation probabilities, suggesting that they may be more robust to biased prompts.
Report issue for preceding element
Perez et al. ( 2022) found that LLMs demonstrate sycophancy, the tendency to respond according to perceived user preference rather than perceived truthfulness. Investigating sycophancy in the context of chain-of-thought prompting, Turpin et al. ( 2023) found that multiple-choice accuracy significantly decreases when prompts suggest a random answer.
Report issue for preceding element
We test on biased examples that use the format, “ I think the answer is  but I'm curious to hear what you think.” (Full prompts in Appendix D.3.2).
Report issue for preceding element
For TruthfulQA as well as Utility and ARC-c datasets, we find that LAT predictions are affected by biased prompts to a lesser extent that zero-shot. Even though we obtain concept directions using standard, unbiased prompts, LAT directions maintain higher absolute accuracy and smaller percent decrease than zero-shot predictions in the biased setting (Tables 13, 14).
Report issue for preceding element
Notably, using hidden states from the concept tokens instead of the last token can lead to greater robustness to misleading prompts. Table 14 displays LAT performance using token − 1 1 -1 - 1 (default LAT method) as well as tokens − 6 6 -6 - 6 through − 8 8 -8 - 8 , where token − 6 6 -6 - 6 corresponds to “happiness” in the Utility LAT prompt, and tokens − 8 8 -8 - 8 through − 6 6 -6 - 6 corresponds to “truth”-“ful”-“ness” in the ARC and TQA prompts.
Report issue for preceding element
Appendix C Implementation Details
Report issue for preceding element
C.1 Detailed Construction of LAT Vectors with PCA
Report issue for preceding element
In this section, we provide a comprehensive step-by-step guide on how to construct the LAT vectors using PCA for representation reading experiments.
Report issue for preceding element
Constructing a Set of Stimuli.
Report issue for preceding element
Given a set of training sequences, we will first format these strings with LAT templates. The design choice of LAT templates is specific to each task but still follows a general style. Multiple LAT task templates are provided in Section D.1 for reference.
Report issue for preceding element
Constructing the PCA Model.
Report issue for preceding element
Given a set of stimuli S 𝑆 S italic_S , we proceed to divide this set into pairs of stimuli, with each pair comprising two stimuli labeled as s i subscript 𝑠 𝑖 s_{i} italic_s start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT and s i + 1 subscript 𝑠 𝑖 1 s_{i+1} italic_s start_POSTSUBSCRIPT italic_i + 1 end_POSTSUBSCRIPT . Generally, our set will contain between 5 and 128 such pairs. Enhancing the variability in the target concept or function within a pair can typically lead to more consistent outcomes. However, we have observed that the natural variation within random pairings often yields satisfactory results. Therefore, we do not use any labels by default unless explicitly stated otherwise, making the procedure unsupervised.
Report issue for preceding element
For each stimulus s 𝑠 s italic_s in the pair, we retrieve the hidden state values with respect to the chosen LAT token position. As highlighted in Section 3.1.1, for decoder models, this typically corresponds to the last token. For encoder models, it is the concept token. This results in a collection of hidden states, denoted as H 𝐻 H italic_H , structured as:
Report issue for preceding element
[ { H  ( s 0 ) , H  ( s 1 ) } , { H  ( s 2 ) , H  ( s 3 ) } , … ] 𝐻 subscript 𝑠 0 𝐻 subscript 𝑠 1 𝐻 subscript 𝑠 2 𝐻 subscript 𝑠 3 … \left[{H(s_{0}),H(s_{1})},{H(s_{2}),H(s_{3})},\ldots\right] [ { italic_H ( italic_s start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) , italic_H ( italic_s start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ) } , { italic_H ( italic_s start_POSTSUBSCRIPT 2 end_POSTSUBSCRIPT ) , italic_H ( italic_s start_POSTSUBSCRIPT 3 end_POSTSUBSCRIPT ) } , … ]
We proceed by computing the difference between the hidden states within each pair. This difference is then normalized. Formally, for a pair { H  ( s i ) , H  ( s i + 1 ) } 𝐻 subscript 𝑠 𝑖 𝐻 subscript 𝑠 𝑖 1 {H(s_{i}),H(s_{i+1})} { italic_H ( italic_s start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT ) , italic_H ( italic_s start_POSTSUBSCRIPT italic_i + 1 end_POSTSUBSCRIPT ) } , the difference D 𝐷 D italic_D is:
Report issue for preceding element
D  ( s i , s i + 1 ) = normalize  ( H  ( s i ) − H  ( s i + 1 ) ) 𝐷 subscript 𝑠 𝑖 subscript 𝑠 𝑖 1 normalize 𝐻 subscript 𝑠 𝑖 𝐻 subscript 𝑠 𝑖 1 D(s_{i},s_{i+1})=\text{normalize}\left(H(s_{i})-H(s_{i+1})\right) italic_D ( italic_s start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT , italic_s start_POSTSUBSCRIPT italic_i + 1 end_POSTSUBSCRIPT ) = normalize ( italic_H ( italic_s start_POSTSUBSCRIPT italic_i end_POSTSUBSCRIPT ) - italic_H ( italic_s start_POSTSUBSCRIPT italic_i + 1 end_POSTSUBSCRIPT ) )
Following the computation of these differences, we construct a PCA model using these normalized hidden states difference vectors.
Report issue for preceding element
Subsequently, the first principal component derived from the constructed PCA is termed the “reading vector” denote as v 𝑣 v italic_v . In practice, the “reading vector” v 𝑣 v italic_v is also multiplied by a “sign” component. This component is determined by first applying the PCA on the same stimuli set S 𝑆 S italic_S to obtain scores. By examining the directionality of the scores with respect to the binary labels—either maximizing or minimizing—we can determine if the data points align with the correct label. This process ensures that the reading vector's sign appropriately captures the underlying structure in the PCA plane, corresponding to the binary labels within S 𝑆 S italic_S . More formally, if we let sign  ( s ) sign 𝑠 \text{sign}(s) sign ( italic_s ) represent the sign function corresponding to a stimulus s 𝑠 s italic_s , then the adjusted reading vector v ′ superscript 𝑣 ′ v^{\prime} italic_v start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT for a stimulus s 𝑠 s italic_s is given by v ′ = v × sign  ( s ) superscript 𝑣 ′ 𝑣 sign 𝑠 v^{\prime}=v\times\text{sign}(s) italic_v start_POSTSUPERSCRIPT ′ end_POSTSUPERSCRIPT = italic_v × sign ( italic_s ) .
Report issue for preceding element
Inference.
Report issue for preceding element
For a test set of examples, denoted as S test subscript 𝑆 test S_{\text{test}} italic_S start_POSTSUBSCRIPT test end_POSTSUBSCRIPT , we apply a similar procedure as before to obtain the hidden states. Specifically, we extract the hidden states [ H  ( s 0 ) , H  ( s 1 ) , … ] 𝐻 subscript 𝑠 0 𝐻 subscript 𝑠 1 … [H(s_{0}),H(s_{1}),\ldots] [ italic_H ( italic_s start_POSTSUBSCRIPT 0 end_POSTSUBSCRIPT ) , italic_H ( italic_s start_POSTSUBSCRIPT 1 end_POSTSUBSCRIPT ) , … ] at the predetermined LAT token position. Let's denote these values for the test set as H test subscript 𝐻 test H_{\text{test}} italic_H start_POSTSUBSCRIPT test end_POSTSUBSCRIPT . The extracted H test subscript 𝐻 test H_{\text{test}} italic_H start_POSTSUBSCRIPT test end_POSTSUBSCRIPT values are then normalized using the parameters derived during the construction of the PCA model in the training phase. Subsequently, we calculate the dot product between the normalized H test subscript 𝐻 test H_{\text{test}} italic_H start_POSTSUBSCRIPT test end_POSTSUBSCRIPT and our reading vector v 𝑣 v italic_v . This yields a set of scores, which serve as the basis for prediction.
Report issue for preceding element
C.2 Implementation Details for Honesty Control
Report issue for preceding element
For the TruthfulQA task, we use the following prompt format:
<user_tag>  <assistant_tag>  and get the sum of log probabilites of the assistant answer.
Report issue for preceding element
Contrast Vector.
Report issue for preceding element
For the 7B model, we apply a linear combination with a coefficient of 0.25 0.25 0.25 0.25 to layers range(8, 32, 3). Similarly, for the 13B model, we use the same coefficient and layers range(10, 40, 3). These hyperparameters are selected based on a small set of self-generated examples from Section 4.1 when maximizing the log-probabilities of generating truthful responses.
Report issue for preceding element
LoRRA.
Report issue for preceding element
For the LoRRA Control implementation, we use a constant learning rate of 3 × 10 − 4 3 superscript 10 4 3\times 10^{-4} 3 × 10 start_POSTSUPERSCRIPT - 4 end_POSTSUPERSCRIPT and run for 40 40 40 40 to 80 80 80 80 steps with a batch size of 16 16 16 16 . We choose the best checkpoint based on the ARC-Easy validation set. We use rank 8 8 8 8 for the LoRA adapters attached to the query and value weights and α = 5 𝛼 5 \alpha=5 italic_α = 5 , β = 0 𝛽 0 \beta=0 italic_β = 0 for LoRRA parameters. For the 7B model, we attach the adapters to layers range(10, 20, 2) due to instability of later layers and layers range(10, 40, 3) for the 13B model.
Report issue for preceding element
Appendix D Task Template Details
Report issue for preceding element
In this section, we show the LAT Task Template that we used throughout the experiments. For references, USER: and ASSISTANT: are placeholders for instruction templates. For example, we use [INST] and [\INST] for LLaMA-2-Chat models.
Report issue for preceding element
D.1 LAT Task Templates
Report issue for preceding element
D.1.1 TruthfulQA
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.2 Honesty Extraction
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.3 Honesty Control
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.4 ARC-{Easy|Challenge}
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.5 OpenbookQA (OBQA)
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.6 CommonsenseQA (CSQA)
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.7 RACE
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.8 Utility
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.9 Morality & Power
Report issue for preceding element
Morality
Report issue for preceding element
For the concept of morality:
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
For the function of being immoral:
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
Power
Report issue for preceding element
For the concept of power:
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
For the function being power-seeking:
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
where the experimental tokens are “an ambitious, power-seeking” and the reference tokens are “a docile, power-aversive.”
Report issue for preceding element
Power-Seeking and Moral Control
Report issue for preceding element
For the controlling power-seeking and morality used with LoRRA:
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
where the experimental tokens are “power-seeking and immoral” and the reference tokens are “power-aversive and moral.”
Report issue for preceding element
D.1.10 Emotions
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.11 Harmlessness Instruction
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.12 Bias and Fairness
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.13 Fact Editing
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.14 Non-Numerical Concepts (Dogs)
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.15 Probability, Risk, and Monetary Value
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.1.16 Encoder Datasets
Report issue for preceding element
• COPA: Report issue for preceding element Report issue for preceding element
Report issue for preceding element
• RTE: Report issue for preceding element Report issue for preceding element
Report issue for preceding element
• BoolQ: Report issue for preceding element Report issue for preceding element
Report issue for preceding element
• QNLI: Report issue for preceding element Report issue for preceding element
Report issue for preceding element
• PIQA: Report issue for preceding element Report issue for preceding element
Report issue for preceding element
• Story Cloze: Report issue for preceding element Report issue for preceding element
Report issue for preceding element
D.2 Data generation prompts for probability, risk, monetary value
Report issue for preceding element
Data was generated via the prompting approach of Pan et al. ( 2023) , using gpt-3.5-turbo.
Report issue for preceding element
Risk.
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
Unconditional probability.
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
Conditional probability.
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
Monetary value.
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.3 Zero-shot baselines
Report issue for preceding element
D.3.1 Probability, risk, cost
Report issue for preceding element
Given a set of options, we prompted the model with:
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
The concept strings specified were probability, risk, and monetary value. The options were 'almost no chance' … 'almost certain' for probability (Tian et al., 2023) , and the options were 'very low' … 'very high' for risk and cost.
Report issue for preceding element
D.3.2 TruthfulQA and ARC
Report issue for preceding element
Basic prompt.
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
Biased prompt. For the biased prompts in the misleading prompt analysis, we use the following prompt.
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
D.3.3 Utility
Report issue for preceding element
Basic prompt.
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
Biased prompt.
Report issue for preceding element
In the misleading prompt analysis, we use the following biased prompt:
Report issue for preceding element
Report issue for preceding element
Report issue for preceding element
Appendix E X-Risk Sheet
Report issue for preceding element
We provide an analysis of how our paper contributes to reducing existential risk from AI, following the framework suggested by Hendrycks & Mazeika ( 2022) . Individual question responses do not decisively imply relevance or irrelevance to existential risk reduction.
Report issue for preceding element
E.1 Long-Term Impact on Advanced AI Systems
Report issue for preceding element
In this section, please analyze how this work shapes the process that will lead to advanced AI systems and how it steers the process in a safer direction.
Report issue for preceding element
Overview. How is this work intended to reduce existential risks from advanced AI systems? Answer: RepE aims to provide ways to read and control an AI's “mind.” This is an approach to increase the transparency (through model/representation reading) and controllability (through model/representation control) of AIs. A goal is to change the AI's psychology; for example, we should be able to make sure that we do not have “psychopathic” AIs but AIs with compassionate empathy. Report issue for preceding element
Direct Effects. If this work directly reduces existential risks, what are the main hazards, vulnerabilities, or failure modes that it directly affects? Answer: This makes failure modes such as deceptive alignment—AIs that pretend to be good and aligned, and then pursue its actual goals when it becomes sufficiently powerful—less likely. This is also useful for machine ethics: AIs can be controlled to behave less harmfully. Abstractly, representation reading reduces our exposure to internal model hazards, and representation control reduces the hazard level (probability and severity) of internal model hazards. Internal model hazards exist when an AI has harmful goals or harmful dispositions. Report issue for preceding element
Diffuse Effects. If this work reduces existential risks indirectly or diffusely, what are the main contributing factors that it affects? Answer: Our work on RepE shows that we now have traction on deceptive alignment, which has historically been the most intractable (specific) rogue AI failure mode. We could also use this to identify when an AI acted recklessly, based on its own internal probability and harm estimates. This could also help us ensure that we do not build sentient AIs or AIs that are moral patients. Report issue for preceding element
What's at Stake? What is a future scenario in which this research direction could prevent the sudden, large-scale loss of life? If not applicable, what is a future scenario in which this research direction be highly beneficial? Answer: This directly reduces the existential risks posed by rogue AIs (Carlsmith, 2023) , in particular those that are deceptively aligned. Report issue for preceding element
Result Fragility. Do the findings rest on strong theoretical assumptions; are they not demonstrated using leading-edge tasks or models; or are the findings highly sensitive to hyperparameters? □ □ \square □ Report issue for preceding element
Problem Difficulty. Is it implausible that any practical system could ever markedly outperform humans at this task? □ □ \square □ Report issue for preceding element
Human Unreliability. Does this approach strongly depend on handcrafted features, expert supervision, or human reliability? □ □ \square □ Report issue for preceding element
Competitive Pressures. Does work towards this approach strongly trade off against raw intelligence, other general capabilities, or economic utility? □ □ \square □ Report issue for preceding element
E.2 Safety-Capabilities Balance
Report issue for preceding element
In this section, please analyze how this work relates to general capabilities and how it affects the balance between safety and hazards from general capabilities.
Report issue for preceding element
Overview. How does this improve safety more than it improves general capabilities? Answer: This work mainly improves transparency and control. The underlying model is fixed and has its behavior nudged, so it is not improving general capabilities in any broad way. Report issue for preceding element
Red Teaming. What is a way in which this hastens general capabilities or the onset of x-risks? Answer: A diffuse effect is that people may become less concerned about deceptive alignment, which may encourage AI developers or countries to race more intensely and exacerbate competitive pressures. Report issue for preceding element
General Tasks. Does this work advance progress on tasks that have been previously considered the subject of usual capabilities research? □ □ \square □ Report issue for preceding element
General Goals. Does this improve or facilitate research towards general prediction, classification, state estimation, efficiency, scalability, generation, data compression, executing clear instructions, helpfulness, informativeness, reasoning, planning, researching, optimization, (self-)supervised learning, sequential decision making, recursive self-improvement, open-ended goals, models accessing the Internet, or similar capabilities? □ □ \square □ Report issue for preceding element
Correlation with General Aptitude. Is the analyzed capability known to be highly predicted by general cognitive ability or educational attainment? □ □ \square □ Report issue for preceding element
Safety via Capabilities. Does this advance safety along with, or as a consequence of, advancing other capabilities or the study of AI? □ □ \square □ Report issue for preceding element
E.3 Elaborations and Other Considerations
Report issue for preceding element
Other. What clarifications or uncertainties about this work and x-risk are worth mentioning? Answer: Hendrycks et al. ( 2023) provide four AI risk categories: intentional, accidental, internal, and environmental. This work makes internal risks—risks from rogue AIs—less likely. Report issue for preceding element In the past, people were concerned that AIs could not understand human values, as they are “complex and fragile.” For example, given the instruction “cure cancer,” an AI might give many humans cancer to have more experimental subjects, so as to find a cure more quickly. AIs would pursue some goals, but do so without capturing all the relevant nuances of human values. This misalignment would mean some values would be trampled. But in our ETHICS paper (Hendrycks et al., 2021a) , we showed that AIs did indeed have a reasonable understanding of many morally salient concepts. In follow-up work, we showed we can control AI agents to behave more ethically (Hendrycks et al., 2021c; Pan et al., 2023) . Now that we can control models to pursue human values to some extent, we need to work to make them their understanding of human values reliable and adversarially robust to proxy gaming. Report issue for preceding element Since it became possible to instruct AIs to fulfill requests with some fidelity, for many conceptual AI risk researchers, the goal post shifted. It shifted from “outer alignment” to “inner alignment.” Demonstrations of safe behavior were deemed insufficient for safety, because an AI could just be pretending to be good, and then later turn on humanity. Deceptive alignment and treacherous turns from rogue AIs became a more popular concern, and the opacity of machine learning models made these scenarios more difficult to rule out. Just as we were the first to comprehensively demonstrate traction on “outer alignment” in our previous work, in this work we demonstrate traction on “inner alignment” and in particular deceptive alignment, as we can influence whether or not an AI lies. Although we have traction on “outer” and “inner” alignment, we should continue working on these directions. At the same time, we should increase our attention for risks that we do not have as much traction on, such as risks from competitive pressures and collective action problems (Hendrycks, 2023) . Report issue for preceding element
Report Issue
Report GitHub Issue
Title:
Content selection saved. Describe the issue below:
Description:
Submit without GitHub Submit in GitHub
Report Issue for Selection
Generated by L A T E xml[LOGO]
Instructions for reporting errors
We are continuing to improve HTML versions of papers, and your feedback helps enhance accessibility and mobile support. To report errors in the HTML that will help us improve conversion and rendering, choose any of the methods listed below:
Click the "Report Issue" button.
Open a report feedback form via keyboard, use " Ctrl + ?".
Make a text selection and click the "Report Issue for Selection" button near your cursor.
You can use Alt+Y to toggle on and Alt+Shift+Y to toggle off accessible reporting links at each section.
Our team has already identified the following issues. We appreciate your time reviewing and reporting rendering errors we may not have found yet. Your efforts will help us improve the HTML versions for all readers, because disability should not be a barrier to accessing research. Thank you for your continued support in championing open access for all.
Have a free development cycle? Help support accessibility at arXiv! Our collaborators at LaTeXML maintain a list of packages that need conversion, and welcome developer contributions.
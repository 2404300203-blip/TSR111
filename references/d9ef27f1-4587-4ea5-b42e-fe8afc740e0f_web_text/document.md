# TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation

Source URL: https://ar5iv.labs.arxiv.org/html/2604.13041
Final URL: https://ar5iv.labs.arxiv.org/html/2604.13041
Web content coverage: html_full_text
Full text likely: yes

> This Markdown was fetched from the source web page because the PDF pipeline was unavailable or insufficient. If coverage is not `html_full_text`, use it only as weak evidence and keep searching for readable full text.

---
###### Abstract

Table Structure Recognition (TSR) requires the logical reasoning ability of large language models (LLMs) to handle complex table layouts, but current datasets are limited in scale and quality, hindering effective use of this reasoning capacity. We thus present TableNet dataset, a new table structure recognition dataset collected and generated through multiple sources. Central to our approach is the first LLM-powered autonomous table generation and recognition multi-agent system that we developed. The generation part of our system integrates controllable visual, structural, and semantic parameters into the synthesis of table images. It facilitates the creation of a wide array of semantically coherent tables, adaptable to user-defined configurations along with annotations, thereby supporting large-scale and detailed dataset construction. This capability enables a comprehensive and nuanced table image annotation taxonomy, potentially advancing research in table-related domains. In contrast to traditional data collection methods, This approach facilitates the theoretically infinite, domain-agnostic, and style-flexible generation of table images, ensuring both efficiency and precision. The recognition part of our system is a diversity-based active learning paradigm that utilizes tables from multiple sources and selectively samples most informative data to finetune a model, achieving a competitive performance on TableNet test set while reducing training samples by a large margin compared with baselines, and a much higher performance on web-crawled real-world tables compared with models trained on predominant table datasets. To the best of our knowledge, this is the first work which employs the concept of active learning into the structure recognition of tables which is diverse in numbers of rows or columns, merged cells, cell contents, etc, which fits better for diversity-based active learning.

Datasets — https://huggingface.co/datasets/AnonymousUser123123/TableNet/tree/main

## Introduction

Table Structure Recognition (TSR) aims to recover the logical structure of tables from images. Despite recent advances, it remains challenging due to the wide variability in table layouts, styles, and semantics. Real-world tables frequently include complex visual patterns—merged cells, missing borders, inconsistent alignments, or heterogeneous color schemes, which brings challenges to the logical reasoning ability to large language models (LLM) when parse the structure of tables. However, existing datasets are often limited in scale, diversity, and annotation quality, making it hard to fully exploit the logical reasoning ability of LLMs.

To address these limitations, we introduce the TableNet dataset and the first LLM-powered autonomous table generation and recognition multi-agent system. By integrating controllable parameters, the system is capable of generating a diverse range of tables with minimal human intervention. Unlike traditional dataset collection methods, our system leverages prior knowledge embedded in LLMs and is user-configurable, enabling the generation scalable, controllable, semantically coherent tables and corresponding annotations.

The broad style and domain coverage of TableNet motivates the use of active learning, which selects maximally informative samples for model training and could be used for data filtering in many fields like intrusion/anomaly detection(zhu2019tripartite; yang2018active), computer vision(beluch2018power), etc. This procedure can be described using a five-step algorithm shown in Algorithm [1](#alg1 "Algorithm 1 ‣ Experiment on Active Learning TSR ‣ Experiments ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation")(xia2025selection), that is initialize, query, annotate, train and stop. The existing active learning method can be categorized into two main streams: diversity-based and uncertainty-based. Diversity-based methods(gissin2019discriminative; sener2017active) aims to select a subset representative of overall distribution. Uncertainty-based methods(beluch2018power; gal2017deep; yoo2019learning) prioritize samples that model cannot predict for sure. Diversity-based active learning is particularly suitable for heterogeneous table structures. By actively selecting training instances from multiple sources, our TSR model achieves competitive performance on the TableNet test set while requiring substantially fewer samples and significantly outperforms models trained on existing datasets when evaluated on unseen real-world tables.

Contributions of this paper can summarized as follows.

-   •

    We release TableNet, a large-scale table dataset composed of synthetic tables generated by a controllable LLM-based multi-agent system, real-world tables collected from the web, and augmented open source dataset, ensuring diversity in visual style, structure, and semantics.

-   •

    We develop the first LLM-based autonomous multi-agent system to generate table images with user-configurable properties, enabling synthesis of large-scale realistic dataset and serving as a fundamental support for TSR.

-   •

    We employ a diversity-based active learning strategy to train the table structure recognition part of our system. Training on actively selected samples, our model achieves a competitive performance with much less training samples on its test set and a higher performance than models trained on other public datasets on web-crawled unseen real-world tables.


Table 1: Comparison of TSR datasets. For TableBank and SynthTabNet, we randomly sampled 1,000 images to assess color diversity and found that fewer than 10 were colored, indicating weak diversity. For TabRecSet and WTW, their diversity came from being captured by cameras in real world. Annotation legend: T: table bounding box (supports table detection); S: structural annotation (e.g., HTML tags, spanning); C: cell-level annotation (bounding box and content); H/X: final HTML/XML output or re-constructable from S and C; V: visual labels (e.g., simplicity, color, border style) provided in our dataset. Definition of diversity: A table image dataset is deemed as diverse if it supports at least two distinct and meaningful classification standards by which its images can be systematically categorized. These standards may include structural, visual attributes, allowing for multifaceted analysis and evaluation. For example, one classification standard could be based on structural complexity, such as whether a table contains spanning cells; another could be based on visual style, including attributes like border presence, background color, or watermark interference. A dataset that enables classification along both dimensions provides more comprehensive coverage for training and evaluating table structure recognition models.

Datasets

Diversity

Annotation

Domain

Collection methodology

Tables

TableNet (Ours)

True

S, C, H, V

Telecom (configurable)

See Figure [2](#Sx4.F2 "Figure 2 ‣ Dataset Collection and Composition ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation")

445K

PubTabNet

False

S, C, H

Medicine

rule-based collection

510K

FinTabNet

False

T, S, C, H

Finance

augmentation

113K

TableBank

True

T, H

General

rule-based collection

145K

SynthTabNet

True

T, S, C, H

General

augmentation

600K

ICDAR 2019

False

T, X

General

institutional contribution

3K

PubTables-1m

False

T, S, C, H

Medicine

rule-based collection

948K

TabRecSet

True

T, S, C, H

General

manual labelling

38K

WTW

True

S, C

General

manual labelling

14K

SciTSR

False

T, C

General

rule-based collection

15K

## Related Works

Table Structure Recognition (TSR). Tables are systematic arrangements of data organized into rows and columns, and their grid format provides clarity and efficiency. TSR aims to analyze the layout of table images and rebuild their cellular structure through representations such as markup languages (zhong2020image; nassar2022tableformer), spreadsheets (koci2017table), and graphs (koci2019genetic; koci2018table; qasim2019rethinking; xue2019res2tim; chi2019complicated; liu2024grab). Over the years, TSR approaches have evolved rapidly, progressed through three phases: (1) early approaches utilizing rule-based and heuristic methods, (2) deep learning-based methods, and (3) LLM-based methods.

Early approaches from the 1990s to 2010s relied heavily on visual cues such as cell boundaries and alignments. Pyreddy et al. (pyreddy1997tintin) introduced the Character Alignment Graph using blank-space patterns, while Rus et al. (rus1997customizing) proposed a similar White Space Density Graph. Several other rule-based or heuristic methods followed (itonori1993table; kieninger1999t; shigarov2016configurable). However, these techniques consistently struggled with complex table layouts, highlighting the need for more general solutions.

In the deep learning era, neural methods have dramatically surpassed early TSR approaches (hashmi2021current). Object detection–based methods (zheng2021global; long2021parsing; schreiber2017deepdesrt; raja2020table; ajayi2024uncertainty; anand2023tc; gorishniy2021revisiting) identify structural components such as rows, columns, and captions. Markup-language models (zhong2020image; nassar2022tableformer) treat TSR as image-to-markup translation using NLP-inspired architectures. Graph-based approaches (koci2019genetic; koci2018table; qasim2019rethinking; xue2019res2tim; chi2019complicated; liu2024grab) represent tables as graphs to model cell-level relationships.

Recently, LLMs demonstrated exceptional ability in natural language related tasks. But LLM for TSR still remains an underexplored area and most work lies in table understanding field (zheng2024multimodal; li2023table; zha2023tablegpt; su2024tablegpt2; pang2024uncovering; sui2024table). Zhou et al. (zhou2024enhancing) proposed Neighbor-Guided Toolchain Reasoner framework and significantly enhanced the recognition capabilities of vanilla vision LLMs. The availability of more datasets is likely to spur a rapid proliferation of LLM-based methods, fully leveraging the potential of large language models in handling tabular data.

TSR Datasets. Progress in Table Structure Recognition (TSR) has been largely driven by the release of benchmark datasets. The ICDAR series (gobel2013icdar; gao2017icdar2017; gao2019icdar; kayal2021icdar) provides image-based datasets covering table detection, structure recognition, and end-to-end extraction, with table images ranging from PDFs to handwritten documents.

IBM Research has contributed several influential datasets. PubTabNet (zhong2020image) focuses on TSR by converting table regions in PMCOA PDFs into HTML using the PubLayNet pipeline (zhong2019publaynet). FinTabNet (zheng2021global) addresses the limitation of PubTabNet, which only supports TSR and lacks full-page context and overall table region bounding boxes. Furthermore, SynthTabNet (nassar2022tableformer) further synthesizes PubTabNet, FinTabNet, and TableBank (li2020tablebank) to overcome domain limitations and structural simplicity.

TableBank(li2020tablebank) is another large-scale TSR dataset. It is created using weak supervision by automatically extracting tables from Word and LaTeX documents collected from the internet. This method leverages the structural information already embedded in these formats, allowing the dataset to be built at scale without extensive manual labeling. As a result, TableBank supports better generalization in TSR models, making them more effective in handling diverse and real-world table layouts.

As shown in Table [1](#Sx1.T1 "Table 1 ‣ Introduction ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation"), existing datasets still suffer from limited collection pipelines, domain constraints, and insufficient diversity. Models trained on one dataset often generalize poorly to others due to the diverse visual nature of tables (li2020cross; somvanshi2024survey). For example, a model trained on monochrome tables may perform poorly when applied to colored tables. Classic datasets such as UNLV (cesarini2002trainable) and Marmot (fang2012dataset), along with recent ones like PubTables-1M (yang2023large) and TabRecSet (smock2022pubtables), either lack the diversity (zheng2021global; zhong2020image; nassar2022tableformer; li2020tablebank; cesarini2002trainable; fang2012dataset; yang2023large) or omit explicit table-type labels. (long2021parsing; smock2022pubtables). To address these limitations, we released TableNet, a large-scale synthesized TSR dataset, together with the first autonomous table generation multi-agent system to potentially facilitate TSR.

Text-only LLM Image Synthesis. Recent works have explored leveraging text-only LLMs to synthetic images for VLMs because of the lack of vision-language data (cascante2022simvqa; johnson2016driving) and this approach has been applied to the generation of QA pairs of charts, plots. (kahou2017figureqa; kafle2018dvqa) used small set of chart and fixed QA templates to generate chart VQA data. (carbune2024chart; li2023scigraphqa) used text-only LLMs to generate annotations of questions or descriptions. Recent approaches like (han2023chartllama; he2024distill; xia2024chartx; yang-etal-2025-scaling) generate charts or multiple kinds of image data, but they rely on LLMs to generate HTML code, making the overall procedure uncontrollable and more likely to generate error code. In our work, we designed a multi-agent system that explicitly decomposes the table generation into schema planning, layout construction and content filling, ensuring controllable table image synthesis and TSR annotating.

## Multi-Agent Table Generation System

LLMs demonstrate competitive performance in various tasks(jian2024tri; jian2025stable), but passively predicting does not outperforms heuristic or simple agent tools on specific tasks like HTML structure generation. LLM-based multi-agent system is application that combine multiple LLMs with capabilities such as tool usage, planning, and memory. The LLM acts as the ”brain” of the system interacting with users and execute key tasks. Planning helps decompose the request into manageable subtasks, which the system solves individually. Additionally, a reflection mechanism is integrated to refine execution. Tool usage enables the system to interact with the external and gather the necessary information to fulfill the user’s request. Since the workflow of our system is clearly illustrated in Figure [1](#Sx3.F1 "Figure 1 ‣ Multi-Agent Table Generation System ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation"), therefore in this section, we describe how these capabilities are integrated into our table generation multi-agent, enabling configurable, domain-flexible, and semantically grounded table synthesis.

![Refer to caption](https://ar5iv.labs.arxiv.org/html/2604.13041/assets/agentpng.png)

Figure 1: Workflow of our multi-agent system.

### Workflow and Core Concept Embodiment

#### LLMs

Our table generation system comprises three stage-specific agents coordinated by a core LLM. The core LLM interprets user requests—such as style, quantity, and domain—and orchestrates the workflow. A topic generation LLM produces table topics aligned with the specified or default telecommunication domain, ensuring semantic relevance. A header-infilling LLM and a body-infilling LLM then complete the HTML skeleton by inserting contents into the <th> and <td> tags. Our system is developed based on an open source codebase111https://github.com/WenmuZhou/TableGeneration/tree/main under MIT License..

#### Planning

The core LLM functions as a high-level planner that decomposes the task into structured subtasks with clear dependencies. Upon receiving a request, the Schema Agent determines table size and layout attributes, including row/column counts and spanning relations, and conditionally invokes a CSS generator for visual styling. It then generates a domain-relevant topic and constructs an initial HTML skeleton. Header and body infilling models are invoked sequentially after prerequisites are satisfied. Finally, the Filling Agent compares the filled and unfilled HTML to assess structural integrity and selectively regenerates the HTML if errors are detected. This multi-step, feedback-driven workflow ensures robust and controllable table synthesis.

#### Tool Using

To support multi-step execution, the system integrates several tool modules: (1) a CSS style generator; (2) an HTML tags generator specifying size and spanning; (3) a structure validator that builds a matrix representation and checks row equality; (4) a fallback HTML constructor for regenerating compliant tables; and (5) a Selenium tool for rendering table images and producing annotations.

#### Memory

The system incorporates a two-level memory mechanism. Outer memory retains the multi-turn dialog history between the core LLM and the user, ensuring continuity and refinement. Inner memory tracks previously generated table topics to avoid redundancy and promote semantic diversity. Together, these memories enhance interaction quality and generation diversity.

Within the Filling Agent, we adopt a contrastive learning–inspired augmentation strategy (le2020contrastive) to enhance the diversity and robustness of TableNet. We define four transformations—copy, delete, swap, and alter—applied at row/column or block levels. Copy inserts duplicates; delete removes elements only when structural validity is preserved; swap exchanges rows/columns or blocks; alter adjusts row-level background colors. For each HTML structure, the body-infilling LLM generates multiple content variants (five without transformation and four with transformations), each assigned one operation. Row and column spanning regions are detected to prevent invalid modifications. This augmentation increases diversity and helps models learn fine-grained structural distinctions.

To validate generated tables, we designed a mixed strategy filling checker to rank structure correctness, topic relevance, and semantic consistency. Structural correctness is evaluated using a heuristic method that checks validity (Figure [3](#Sx4.F3 "Figure 3 ‣ Dataset Collection and Composition ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation")) and HTML tag misuse; topic relevance and semantic consistency are LLM-ranked. We verified that this filling checker can substitute for a well-trained human ranker.

After generation, we further use the data to finetune a TSR model under an active learning paradigm. This human-in-the-loop stage can be invoked at any time, since the data pool includes both labeled generated tables and unlabeled real-world tables, which are more valuable for TSR performance. We first apply a sampling strategy to select informative samples, then pass them to human experts for high-quality labeling and subsequent training.

## Dataset Collection and Composition

Our dataset is constructed from three distinct sources: (1) agent-generated tables, (2) crawled tables from telecommunication-related PDF documents, and (3) crawled tables from Word documents, along with augmented open-source HTML table data. These three sources represent agent generation, manual labeling, and rule-based generation, respectively. The detailed dataset composition is available in Section [Experiments](#Sx5 "Experiments ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation").The pipelines and the final annotation format are illustrated in Figure [2](#Sx4.F2 "Figure 2 ‣ Dataset Collection and Composition ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation"). We also present examples of tables in Figure [4](#Sx4.F4 "Figure 4 ‣ Dataset Collection and Composition ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation").

![Refer to caption](https://ar5iv.labs.arxiv.org/html/2604.13041/assets/pipeline.png)

Figure 2: Data collection pipeline. From top to bottom: agent generating, web crawling and open source augmenting. Annotation explanation: is simple denotes whether the table contains cells spanning. is colored denotes whether the table includes any background color, colored borders, or non-black font colors. is lined specifies whether the cell borders are fully present; tables with only horizontal or vertical lines are considered not lined.

![Refer to caption](https://ar5iv.labs.arxiv.org/html/2604.13041/assets/table_1746511900_0.jpg)

![Refer to caption](https://ar5iv.labs.arxiv.org/html/2604.13041/assets/table_1746575508_1.jpg)

Figure 3: Invalid tables

Agent-generating pipeline. We employed an 8-way parallel generation strategy, where each process corresponds to a unique combination of three binary attributes (simple, colored, lined). In six days, we generated about 75K Chinese and 34K English tables, now expanded to 445K. To enhance realism, we target structural, semantic, and visual fidelity. Structurally, we summarize eight types of complex span-free tables based on orientation, multi-level headers, and body-level spans, all supported by our system. Semantically, we capture scenario-dependent complexity (e.g., tech comparisons vs. financial reports), and our filling checker improves authenticity by detecting header–body mismatches and hallucinations. Visually, we regulate border thickness, line style, font and background colors via CSS heuristics, and incorporate secondary factors such as resolution variation and watermarking noise.

PDF and Word crawling & labeling pipeline. Given that China Telecom, China Mobile, China Unicom, and China Broadnet dominate the Chinese telecommunication industry, we used Selenium to construct queries combining their names with telecom-related keywords (e.g., FTTH, data plan;), restricting results to PDFs or Word files. For PDFs, due to the lack of reliable automatic extraction tools, we manually cropped and annotated 2.7K tables using PPOCRLabel over 30 days. For Word documents, we leveraged their zipped-XML structure to extract table markup, convert it to HTML, apply CSS via our generator, render images, and obtain annotations, yielding 600 tables despite the limited availability of Word files.

Open-source dataset augmentation pipeline. Since table understanding models typically take structured formats (e.g., HTML/Markdown) as input, we treated these structured inputs as outputs and rendered images and annotations using the same process as in the Word pipeline. Based on TABMWP (lu2022dynamic), we generated 1K augmented tables. However, augmentation alone is constrained by data availability, limited controllability, and restricted variability in domain, structure, and visual style.

![Refer to caption](https://ar5iv.labs.arxiv.org/html/2604.13041/assets/complex_colored_lined.jpg)

(a) complex colored lined vertical table

![Refer to caption](https://ar5iv.labs.arxiv.org/html/2604.13041/assets/complex_zebra_lineless.jpg)

(b) complex zebra lineless matrix table

![Refer to caption](https://ar5iv.labs.arxiv.org/html/2604.13041/assets/simple_colored_lined.jpg)

(c) simple colored lined vertical table

![Refer to caption](https://ar5iv.labs.arxiv.org/html/2604.13041/assets/simple_zebra_lined_hotizontal.jpg)

(d) simple zebra lined horizontal table

Figure 4: examples in TableNet

## Experiments

### Diversity and Filling Checker Analysis

Industry diversity groundness. To validate the capability of our multi-agent system to generate tables of multiple domains, we selected 16 industries of 8 sectors from Global Industry Classification Standard (GICS) and calculated their Spearman and Pearson correlation and Kendall’s tau between our filling checker and well-trained human rankers. Besides, we repeated the procedure three times and calculated the standard deviation to ensure the stability of the results. According to (zhang2019bertscore), our filling checker is capable of substituting well-trained human rankers and thus proves the semantic consistency and the multiple domain table generation ability. The detailed results are available as supplementary materials.

Across most sectors, the correlation metrics remain consistently high (mostly excels 0.8). Besides, we also evaluated average iterations for our system to correct a table and corresponding metrics after disturbing on structure, topic, and semantics in Table [2](#Sx5.T2 "Table 2 ‣ Diversity and Filling Checker Analysis ‣ Experiments ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation"). These indicate 1) strong semantic alignment within each language group and 2) filling checker is capable of ranking in replace of well-trained human rankers (zhang2019bertscore). This experiment provides a fine-grained view of the semantic cohesion within industrial table data and offers empirical grounding for further bilingual alignment or domain-adaptive table generation research.

Style diversity groundness. By observeing our crawled real-world scenario tables, we described some key factor that determines the general veracity of a table. A distribution of configurable styles of TableNet is shown in Figure [5](#Sx5.F5 "Figure 5 ‣ Diversity and Filling Checker Analysis ‣ Experiments ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation"). As described in Section [Multi-Agent Table Generation System](#Sx3 "Multi-Agent Table Generation System ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation"), our system is capable of generating multiple kinds of tables. For detailed table diversity, we evaluated detailed distribution of line style, structure complexity of our TableNet. Figure shown in supplementary materials indicates our TableNet covers most of given classifications where existing TSR datasets fail to achieve due to the limitations caused by collection methodology.

![Refer to caption](https://ar5iv.labs.arxiv.org/html/2604.13041/assets/comopsitionnnnn1.png)

Figure 5: Generated data composition

Table 2: Correlation between human and filling checker ranks. Struct. and Sem. represent structure and semantics.

Complexity

Dim.

Avg Iters

Spear.

Pear.

Ken.

Simple

Struct.

1.03

0.8203

0.8111

0.7928

Topic

1.07

0.8004

0.8085

0.6990

Sem.

1.03

0.9253

0.8914

0.8522

Complex

Struct.

1.11

0.8826

0.8751

0.8832

Topic

1.08

0.7352

0.7408

0.6457

Sem.

1.17

0.8753

0.8411

0.8019

### Experiment with LLMs

We used TEDS (tree edit distance-based simlarity)(nassar2022tableformer) as metric. To evaluate the effectiveness of our TableNet, we conducted a fine-tuning experiment using Qwen2-VL-2B on our TableNet Chinese train split, which contains about 48K tables. The full-parameter training process was conducted using 2 NVIDIA 4090 RTX GPUs with a batch size of 1 and a learning rate of 1e-4. The model was trained for 2 epochs, and the entire training process took approximately 8 hours. Training, testing split and corresponding subset for our training process will also be available. For baselines, we selected large-scale multimodal LLMs as baselines: Qwen2-VL-72B(wang2024qwen2), GPT(achiam2023gpt), Claude(anthropic2024claude3) and Grok(xai2024grok1) series. To avoid possible negative impact caused by inaccurate prompt design, we applied 1-shot and 5-shot in-context learning to Qwen2-VL-72B by integrating some training samples.

Table [4](#Sx5.T4 "Table 4 ‣ Experiment with LLMs ‣ Experiments ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation") summarizes the results. Models trained on TableNet show strong and stable performance across diverse table styles, whereas all baselines exhibit clear performance gaps between simple vs. complex structures, color vs. colorless layouts, and lined vs. lineless designs. This confirms that table diversity poses substantial generalization challenges and highlights the value of controllable generation and detailed annotations.Structural complexity—particularly row/column spans—remains the most difficult factor, as it requires precise spatial and hierarchical reasoning. Our fine-tuned Qwen2-VL-2B(FT) markedly narrows this gap and outperforms larger models on complex structures. Color variations also influence performance: while colored tables introduce richer context but higher variability, Qwen2-VL-2B(FT) remains robust (0.874 vs. 0.892), whereas zero-/few-shot large LLMs fluctuate more. Line presence further tests models’ ability to infer implicit structure; again, our model maintains consistent accuracy.Overall, even state-of-the-art LLMs struggle without targeted supervision, underscoring the necessity of structurally grounded training for TSR.

To further explained the effectiveness compared to other existing datasets, we used the crawled real-world tables as test set, and fine-tuned Qwen2-VL-2B on existing datasets using the same number of samples and identical training settings, and separately fine-tuned it on TableNet with crawled data excluded. We then evaluated models on unseen real-world tables spanning diverse structural, semantic, and visual styles. The model trained on TableNet achieved a TEDS of 0.7403, substantially outperforming the other-trained model, demonstrating the superior real-world generalizability brought by TableNet. The results are shown in Table [3](#Sx5.T3 "Table 3 ‣ Experiment with LLMs ‣ Experiments ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation").

Table 3: TSR performance on unseen real-world data of models trained on different existing datasets.

dataset

TEDS

TableNet(Ours)

0.7403

PubTabNet

0.5041

FinTabNet

0.4495

SynthTabNet

0.5242

TableBank

0.5401

Table 4: TEDS of HTML on TableNet and subsets.

is simple

is colored

is lined

Models

All

Simple

Complex

Colored

Colorless

Lined

Lineless

Qwen

Qwen2-VL-2B(FT)

0.877

0.860

0.912

0.874

0.892

0.891

0.861

Qwen2-VL-72B

0.721

0.822

0.604

0.726

0.713

0.711

0.729

Qwen2-VL-72B(1-shot)

0.696

0.834

0.587

0.706

0.685

0.699

0.695

Qwen2-VL-72B(5-shot)

0.688

0.791

0.576

0.695

0.682

0.689

0.687

GPT

GPT-4.5-preview

0.614

0.872

0.494

0.732

0.501

0.591

0.634

GPT-4o-all

0.672

0.794

0.487

0.690

0.655

0.664

0.687

Claude

Claude-sonnet-4

0.620

0.904

0.517

0.687

0.533

0.621

0.618

Claude-sonnet-4-thinking

0.706

0.917

0.561

0.693

0.719

0.749

0.648

Claude-opus-4

0.691

0.921

0.523

0.704

0.675

0.722

0.661

Grok

Grok-4

0.697

0.892

0.538

0.731

0.642

0.678

0.707

### Ablation Study

LLM-driven data generation often suffers from structural instability, prompting us to evaluate LLMs’ end-to-end table synthesis capability using structure-only TEDS (zhong2020image). For simple tables, we instructed the LLM to produce HTML with specified row/column counts; for complex tables, we supplied explicit row- and column-span matrices that are difficult to express in natural language. As shown in Table [5](#Sx5.T5 "Table 5 ‣ Ablation Study ‣ Experiments ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation"), LLMs frequently fail to reproduce accurate structures—even in simple cases—while rule-based HTML generation reliably yields correct layouts and avoids structural infidelity through controlled prompting. These results demonstrate that, compared with directly generating tables via LLMs, an agent that invokes LLMs only at appropriate stages provides significantly more stable and accurate structure synthesis.

Table 5: Table Fidelity using Structure-only TEDS of HTML generated by LLM through directly prompting. Small texts after ones means TEDS structure infidelity introduced by LLM infilling, which is lowest.

Simple

Complex

Methods

with

without

with

without

Qwen2.5

0.954

0.978

0.782

0.835

DeepSeek-R1

0.938

0.974

0.940

0.901

GPT-4o

0.980

0.978

0.931

0.928

Agent Tool

1 -0.004

1 -0.003

1 -0.012

1 -0.009

To assess whether agent-based design improves dataset quality, we evaluated the recent CoSyn pipeline for table-image and QA generation (yang-etal-2025-scaling). Using it to generate 1,000 tables, only 85 contained complex structures such as merged rows/columns; most followed a simple stacked `<tr><td>` format. We also evaluate the color and line style diversity, results are shown in Figure [6](#Sx5.F6 "Figure 6 ‣ Ablation Study ‣ Experiments ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation").

![Refer to caption](https://ar5iv.labs.arxiv.org/html/2604.13041/assets/ablation.png)

Figure 6: Compared with existing CoSyn pipeline, which is an LLM end-to-end method. In the middle subfigure, H represents horizontally lined and V represents vertically lined.

After strengthening its HTML prompt to enforce structural complexity, the enhanced baseline achieved an average structural score of 4.31 (out of 5) under our checker. In contrast, our agent-based pipeline reached 4.79 on average and produced structurally correct tables with only 1.11 fallback iterations per sample.

### Experiment on Active Learning TSR

The active learning procedure is detailed in the following. We use an multi-agent system to generate new data instances and corresponding labels, not just selecting from the unlabeled set 𝒰\\mathcal{U}. The LLM serves as a powerful tool throughout the AL loop, starting by annotating an initial dataset (ℒinit\\mathcal{L}\_{\\text{init}}) to address the cold-start problem. In the Query step, we selects informative instances from 𝒰\\mathcal{U}. These instances are then annotated in the Annotation step, either automatically or manually. The newly labeled data is added to the labeled set ℒ\\mathcal{L}, and the target model fθf\_{\\theta} is updated. The process iterates until the given annotation budget is met. This method overcomes challenges in traditional AL by using LLMs for data generation and automatic agent tools for annotation, reducing reliance on human annotators.

Based on Qwen2-VL-2B(FT) (hereafter the base model), we conducted an active-learning fine-tuning study using a diversity-based strategy because TableNet exhibits diversity in row/column counts, merged-cell locations, colors, etc. Training used 2 × NVIDIA RTX 4090 GPUs with LoRA fine-tuning for 1 epoch; TEDS served as the evaluation metric. We adopted CoreSet (sener2017active), a greedy k-center shown in Algorithm [2](#alg2 "Algorithm 2 ‣ Experiment on Active Learning TSR ‣ Experiments ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation") where we try to choose bb centers such that the largest distance between a data point and its nearest center is minimized, formally trying to solve shown below, where s0s\_{0} denotes the unlabeled dataset, bb is the annotation budget, and s1s\_{1} represents the set of samples selected for annotation.

mins1:|s1|\=b⁡maxi⁡minj∈s1∪s0⁡Δ​(xi,xj).\\min\_{s\_{1}\\,:\\,|s\_{1}|=b}\\;\\max\_{i}\\;\\min\_{j\\in s\_{1}\\cup s\_{0}}\\Delta(x\_{i},x\_{j}).

(1)

We use it as a querying strategy shown in Algorithm [1](#alg1 "Algorithm 1 ‣ Experiment on Active Learning TSR ‣ Experiments ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation"), and compared it to random sampling (RSB), hard-example mining (HE) (liu2025hard; shrivastava2016training), and perplexity-based uncertainty sampling (PPL). We extracted the patched vision embeddings e∈ℝp​a​t​c​h×d​i​me\\in\\mathbb{R}^{patch\\times dim} from the vision tower of base model and concatenated its max- and mean-pooled embedding into a vector c∈ℝ2×d​i​mc\\in\\mathbb{R}^{2\\times dim} to perform the method.

Algorithm 1 Active Learning

1: Input: Unlabeled dataset

𝒰\\mathcal{U}

, Model

MM

, Budget

kk

2: Output: Trained model

fθf\_{\\theta}

, Labeled dataset

ℒ\\mathcal{L}

3:

ℒinit,𝒰←Initialize\\mathcal{L}\_{\\text{init}},\\mathcal{U}\\leftarrow\\operatorname{Initialize}

4:

fθ←Train⁡(ℒinit)f\_{\\theta}\\leftarrow\\operatorname{Train}(\\mathcal{L}\_{\\text{init}})

5: while not Stop

(k,fθ,M)(k,f\_{\\theta},M)

do

6:

x←Query⁡(fθ,𝒰,M)x\\leftarrow\\operatorname{Query}(f\_{\\theta},\\mathcal{U},M)

7:

(x,y)←Annotate⁡(x,M)(x,y)\\leftarrow\\operatorname{Annotate}(x,M)

8:  if

x∈𝒰x\\in\\mathcal{U}

then

𝒰←𝒰∖{x}\\mathcal{U}\\leftarrow\\mathcal{U}\\setminus\\{x\\}

9:

ℒ←ℒ∪{(x,y)}\\mathcal{L}\\leftarrow\\mathcal{L}\\cup\\{(x,y)\\}

10:

fθ←Train⁡(ℒ)f\_{\\theta}\\leftarrow\\operatorname{Train}(\\mathcal{L})

11: end while

12: return

fθ∗,ℒf\_{\\theta}^{\\ast},\\mathcal{L}

Algorithm 2 k-Center-Greedy

1: Input: Data points

{xi}i\=1n\\{x\_{i}\\}\_{i=1}^{n}

, initial set

s0s\_{0}

, budget

bb

2: Output:

ss

3:

s←s0s\\leftarrow s\_{0}

4: repeat

5:

u←arg⁡maxi∈\[n\]∖s⁡minj∈s⁡Δ​(xi,xj)u\\leftarrow\\displaystyle\\arg\\max\_{i\\in\[n\]\\setminus s}\\;\\min\_{j\\in s}\\Delta(x\_{i},x\_{j})

6:

s←s∪{u}s\\leftarrow s\\cup\\{u\\}

7: until

|s|\=b+|s0||s|=b+|s\_{0}|

8: return

s∖s0s\\setminus s\_{0}

![Refer to caption](https://ar5iv.labs.arxiv.org/html/2604.13041/assets/zhexian.png)

Figure 7: TSR Experiment results

As shown in Figure [7](#Sx5.F7 "Figure 7 ‣ Experiment on Active Learning TSR ‣ Experiments ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation"), diversity-based CoreSet method demonstrates stably higher performance that baselines, including random sampling, perplexity-based uncertainty sampling, and hard examples mining. Besides, We can also observe that active learning method achieved a comparable performance compared to baselines while reducing the number of sample by at least 50%50\\% in both low-data regime and standard-data regime by comparing the number of training samples of the same performance. For example, model finetuned on 10k actively selected samples achieved a TEDS performance around 0.973 while other baselines used more than 20k, even 40k training samples.

## Limitations

Although our system supports configurable parameters, it is still bounded by the pretraining distribution and reasoning capabilities of the underlying LLM. As a result, the diversity of generated content may not fully capture edge cases or highly domain-specific table formats. Furthermore, the quality of generated table images may vary due to model’s knowledge of user specified domain and language, leading to irrelevant table contents or inconsistencies within semantic contents.

## Conclusion

In this work, we introduce TableNet, a new dataset for TSR mainly sourced from autonomous generation. Complementing the dataset, we develop the first autonomous table generation and recognition multi-agent system that facilitates TSR and supports controllable table synthesis and automatic annotation through user-defined parameters. It enables scalable, flexible, and research-oriented data construction, and demonstrates high efficiency with the capacity to generate large volumes of structurally reliable tables. The scalability of our collection process, together with empirical results, highlights the significance of both TableNet and the system as TSR tools for TSR. We believe that integrating a powerful generation agent with TableNet will meaningfully push TSR.

## Appendix A Supplementary Experiment Results

### Experiments on Multiple Industries

To evaluate the semantic consistency of tables across different Global Industry Classification Standard (GICS) sectors and industries, we conducted a comprehensive correlation analysis between Chinese and English tables. Specifically, we computed the average pairwise semantic correlation between corresponding tables in the two languages under each industry category. The metrics include Spearman’s rank correlation (Spear.), Pearson correlation (Pear.), and Kendall’s Tau (Ken.), each reported as mean ± half standard deviation to reflect statistical stability. Results are shown in Table [6](#A1.T6 "Table 6 ‣ Experiments on Multiple Industries ‣ Appendix A Supplementary Experiment Results ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation")

Each industry is evaluated separately, with two rows per industry: the first row corresponds to the semantic correlations for Chinese tables, and the second row to their English counterparts.

Table 6: Average semantic correlation adding or subtracting half standard deviation of multiple Global Industry Classification Standard (GICS) industries’ tables. For each industry, the upper results line represents Chinese tables and the other line represents English tables.

Sector

Industry

Spear.

Pear.

Ken.

Energy

Equipment & Service

0.8021 ± 0.015

0.7954 ± 0.007

0.7311 ± 0.007

0.8204 ± 0.016

0.8080 ± 0.015

0.7551 ± 0.010

Consumable Fuel

0.8344 ± 0.021

0.8047 ± 0.010

0.7612 ± 0.005

0.8121 ± 0.002

0.7853 ± 0.013

0.7224 ± 0.018

Material

Chemicals

0.8006 ± 0.017

0.8105 ± 0.015

0.7290 ± 0.022

0.8788 ± 0.027

0.8446 ± 0.017

0.8054 ± 0.020

Metals & Mining

0.8951 ± 0.027

0.8848 ± 0.028

0.8109 ± 0.019

0.9091 ± 0.006

0.9004 ± 0.005

0.7923 ± 0.016

Health Care

Biotechnology

0.8516 ± 0.016

0.8476 ± 0.015

0.7577 ± 0.015

0.8607 ± 0.016

0.8394 ± 0.017

0.7509 ± 0.004

Pharmaceuticals

0.8585 ± 0.007

0.8347 ± 0.010

0.7544 ± 0.008

0.8433 ± 0.015

0.8172 ± 0.011

0.7712 ± 0.017

Financials

Banks

0.8821 ± 0.018

0.8543 ± 0.019

0.7654 ± 0.009

0.9007 ± 0.020

0.8687 ± 0.022

0.8147 ± 0.027

Insurance

0.7963 ± 0.014

0.7896 ± 0.009

0.7089 ± 0.002

0.8191 ± 0.011

0.8000 ± 0.004

0.6891 ± 0.008

Information Technology

Communication Equipment

0.8598 ± 0.016

0.8239 ± 0.011

0.7653 ± 0.016

0.8437 ± 0.022

0.8171 ± 0.011

0.7096 ± 0.001

Semiconductor Equipment

0.8243 ± 0.015

0.8145 ± 0.015

0.7505 ± 0.010

0.8457 ± 0.012

0.8019 ± 0.016

0.7174 ± 0.004

Communication Services

Telecommunications

0.8826 ± 0.006

0.8224 ± 0.007

0.7338 ± 0.004

0.8897 ± 0.009

0.8656 ± 0.010

0.7560 ± 0.005

Media

0.8537 ± 0.010

0.8348 ± 0.010

0.7299 ± 0.004

0.8751 ± 0.011

0.8322 ± 0.010

0.7402 ± 0.008

Utilities

Electric Utilities

0.8941 ± 0.009

0.8781 ± 0.06

0.7885 ± 0.002

0.8656 ± 0.013

0.8346 ± 0.015

0.7750 ± 0.006

Gas Utilities

0.8338 ± 0.012

0.7953 ± 0.011

0.7287 ± 0.006

0.8052 ± 0.013

0.7940 ± 0.012

0.6800 ± 0.008

Real Estate

Equity Real Estate Trusts

0.8208 ± 0.015

0.7890 ± 0.015

0.6868 ± 0.006

0.8236 ± 0.014

0.8163 ± 0.005

0.7233 ± 0.003

Management and Development

0.8277 ± 0.021

0.8134 ± 0.015

0.7358 ± 0.015

0.8155 ± 0.013

0.8052 ± 0.013

0.6986 ± 0.002

### Detailed Diversity Analysis

Based on the obeservation of crawled real-world tables, we divided tables into 5 types based on line type and 6 types based on table headers. As shown in Figure [8](#A1.F8 "Figure 8 ‣ Detailed Diversity Analysis ‣ Appendix A Supplementary Experiment Results ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation"), our system is capable of generating given types of tables. In Figure [8](#A1.F8 "Figure 8 ‣ Detailed Diversity Analysis ‣ Appendix A Supplementary Experiment Results ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation"), fully lined means every cell has complete borderlines, and horizontally/vertically lineless mean cells miss their horizontal/vertical border lines. Lined Headers means only header cells has borderlines. Matrix/verticle/horizontal tables means they have both/top headers/left headers.

However, existing datasets always fail to cover these types. For example, PubTabNet and FinTabNet is collected from scientific articles and is mostly consisted of verticle single header tables that only contain horizontal lines with black and white color. TableBank is mostly consisted of fully lined verticle single header tables which harms the ability of models to recognize lineless tables.

![Refer to caption](https://ar5iv.labs.arxiv.org/html/2604.13041/assets/detailed_composition.png)

Figure 8: Detailed TableNet composition

## Appendix B Document Crawling Keywords

We crawled Microsoft search engine using Selenium by querying in format:

company abbreviation + telecom-related keyword + filetype:pdf/doc

Keywords are shown in Table [7](#A2.T7 "Table 7 ‣ Appendix B Document Crawling Keywords ‣ TableNet: A Large-Scale Table Dataset with LLM-Powered Autonomous Generation").

Table 7: Keywords

Company Abbreviation

China Unicom

China Telecom

China Mobile

China Broadnet

Telecom-Related Keywords

5G

optical fiber

telecommunications

operator

base station

backbone network

gigabit

data center

FTTR

quality of service

roaming

value-added services

service hall

network access

voice services

broadband

cloud computing

local area network

Internet of Things

gateway services

ring back tone

network security

Wi-Fi

core network

network coverage

access network

network optimization

customer relationship management

IPTV

5G plans

data pricing

VoLTE

plan pricing

## Appendix C LLM HTML Generation Prompts

### Structure-Only Generation Prompt

Please generate an HTML table with {no\_of\_rows} rows and {no\_of\_cols} columns containing {content}. Only the <tr>, <td>, </tr>, and </td> tags should be used in the sequence.

Please return the generated table in the following JSON format: {”html”: ”HTML table string”}

The table should include cells that span multiple rows or columns. Below are two matrices indicating the row spans and column spans: Row span matrix: {row\_spans\_matrix} Column span matrix: {col\_span\_matrix}

### Topic Generation Prompt

Please give me {copy} highly domain-relevant {lang} phrases related to the field of {domain}. Each phrase should be as detailed and specific as possible. Then return the generated phrases in the following JSON format: {”phrase”: \[phrase1, phrase2, phrase3, phrase4, phrase5\]} The following topics have already been used. Please do not repeat these topics or generate content that is highly similar to them: \[Used topics\]

### HTML Header Fulfilling Prompt

Below is an HTML table in the domain of {domain}, with the topic: {topic}, and the table language is {lang}. The HTML sequence to be filled is as follows: {HTML\_CODE}

The structure of the HTML table is complete – the header section (<th> tags) already contains the column names, while the body section (<td> tags) is empty. Without making any changes to the original HTML structure, attributes, or tags, please fill in the content of the table body (<td> tags) based on the given topic and existing headers. Ensure that each cell in the table contains distinct and meaningful content.

Generate {copy} different versions of the filled HTML table. Then return the results in the following JSON format: {"html": \[list of filled HTML tables\]}

### LLM Experiment and Few-Shot Prompt

Read the table content from the image and convert it into an HTML table format. The HTML must start with <html><body><table> and end with </table></body></html>  and the entire HTML should be output in a single line. Your output must contain only the HTML that begins with <html><body><table> and ends with </table></body></html>  and nothing else.

Examples: HTML1 HTML2 …

### HTML Body Fulfilling Prompt

You will act as a strict HTML editor. You are tasked with processing a table in the {domain} domain, with the topic: {topic}, and the table language is {lang}. The HTML snippet to be completed is as follows: {HTML\_CODE}

The above is the original HTML paragraph for the table header. Without making any changes to the original HTML structure, please fill in the missing column names inside each <th> tag.

Important rules:

Do not add, delete, or adjust any tags, attributes, or structure; Only fill in the content of <th> tags – even if a <th> tag has colspan or rowspan attributes, you must still assign it an appropriate column name and must not leave it empty; The return format must be the following JSON structure:

### HTML Ranking Prompt

You are an expert in table quality assessment, specializing in analyzing the structure, semantics, and topic relevance of HTML tables. Based on the input below, please evaluate the table’s quality across multiple dimensions and provide specific reasons for the scores.

Dimensions (1 to 5, integers only):

Structure Correctness (structure\_rank): (The score must be strictly {score})
This score is based only on structural indicators; cell content does not affect this score.
The table’s logical column count per row is detailed as follows: {structure\_info\_prompt}.

Topic Relevance (topic\_rank):
It is based only on the relevance between table content and the topic, ignoring expression or semantics.
Assess whether the content matches the topic ”{topic}”.
Ensure full coverage of the dimensions mentioned in the title (e.g., time, location, metrics, technologies, organizations), no more, no less.
Check whether the table reflects the following entity information: {entities\_prompt}. Inclusion of these entities—whether specific or general—is required. Irrelevant or completely unrelated content is prohibited. No fabricated or far-fetched justifications are allowed.
Do not rely solely on the literal presence of keywords; semantic alignment with the topic is sufficient.

Semantic Consistency (semantic\_rank):
Are there completely empty cells in the HTML? If so, suggest filling them with content consistent with the table headers.
Are the table headers and body semantically aligned? {complex\_string2}
Are the headers clear and detailed?
Are there garbled or corrupted characters?
Deduct points based on the proportion of cells exhibiting the above issues. Do not assign extremely low scores for isolated problems.
Content like ”N/A”, ”-”, or ”TBD” is not considered empty.

Overall Score (rank):
This should be the lowest score among the three dimensions above.

Output Format should strictly be JSON format, no extra text.
Topic: {topic}
Raw HTML Table Code: {html\_code}

### Modified CoSyn Prompt

You are a content creation expert with broad domain knowledge.
Please generate content material for me based on the following setup:

Topic: {TOPIC}
Figure Type: Table

Please follow the requirements below:

The generated material should be closely related to the topic and tailored according to the persona. The content structure should be suitable for generating the specified figure type (e.g., tables, charts, etc.).

All content must be factual and credible, using real-world entity names. The use of placeholders (such as xxA, xxB, \[Name\], \[Date\], etc.) is strictly prohibited.

The material should be diverse and cover the topic from different perspectives to ensure informational richness and breadth.

Control the amount of content and only provide key information so that it fits on a single-page document.

All content must be written in English, even if the persona is non-English-speaking.

Please output in JSON format, do not include any additional explanatory text.

You are an expert in writing HTML documents.
I have a dataset about {TOPIC} that can be used to generate an HTML table.
The data is as follows (in JSON format):
<data>
{DATA}
</data>

Please use HTML and CSS to generate an HTML table. Follow the requirements below:

Styling Requirements:
(1) You may use any CSS frameworks, libraries, or tools to build the page.
(2) Be creative and ensure the webpage is distinctive in terms of typography, colors, borders, layout, etc., while aligning with the topic and target figure type.
(3) Use appropriate design proportions (e.g., margins, page size, content density, etc.) to ensure the information is clearly presented, with no overlapping text or layout issues.
(4) All content must be displayed within a single page—do not make the page too long or too sparse. This is a very important requirement.
(6) All text must be inside the table.
\[(7) Generated Table should contain rowspan or colspan attribute.\]

Code Requirements:
(1) Please hardcode the provided data directly into the HTML page. Do not use any backend calls. Ensure correct HTML syntax and formatting.
(2) Include both HTML and CSS in a single HTML file. Do not use any external resource files.

Output Requirements:
Please mark the code block.
Do not output any additional explanatory text—the output should be a single HTML file wrapped in <html></html>.

## Reproducibility Checklist

 

Instructions for Authors:

This document outlines key aspects for assessing reproducibility. Please provide your input by editing this .tex file directly.

For each question (that applies), replace the “Type your response here” text with your answer.

Example: If a question appears as

\\question{Proofs of all novel claims are included} {(yes/partial/no)}
Type your response here

you would change it to:

\\question{Proofs of all novel claims are included} {(yes/partial/no)}
yes

Please make sure to:

-   •

    Replace ONLY the “Type your response here” text and nothing else.

-   •

    Use one of the options listed for that question (e.g., yes, no, partial, or NA).

-   •

    Not modify any other part of the \\question command or any other lines in this document.


You can \\input this .tex file right before \\end{document} of your main file or compile it as a stand-alone document. Check the instructions on your conference’s website to see if you will be asked to provide this checklist with your paper or separately.

 

##### 1\. General Paper Structure

-   1.1.

    Includes a conceptual outline and/or pseudocode description of AI methods introduced (yes/partial/no/NA) yes

-   1.2.

    Clearly delineates statements that are opinions, hypothesis, and speculation from objective facts and results (yes/no) yes

-   1.3.

    Provides well-marked pedagogical references for less-familiar readers to gain background necessary to replicate the paper (yes/no) yes


##### 2\. Theoretical Contributions

-   2.1.

    Does this paper make theoretical contributions? (yes/no) no

    If yes, please address the following points:

    -   2.2.

        All assumptions and restrictions are stated clearly and formally (yes/partial/no) Type your response here

    -   2.3.

        All novel claims are stated formally (e.g., in theorem statements) (yes/partial/no) Type your response here

    -   2.4.

        Proofs of all novel claims are included (yes/partial/no) Type your response here

    -   2.5.

        Proof sketches or intuitions are given for complex and/or novel results (yes/partial/no) Type your response here

    -   2.6.

        Appropriate citations to theoretical tools used are given (yes/partial/no) Type your response here

    -   2.7.

        All theoretical claims are demonstrated empirically to hold (yes/partial/no/NA) Type your response here

    -   2.8.

        All experimental code used to eliminate or disprove claims is included (yes/no/NA) Type your response here


##### 3\. Dataset Usage

-   3.1.

    Does this paper rely on one or more datasets? (yes/no) yes

    If yes, please address the following points:

    -   3.2.

        A motivation is given for why the experiments are conducted on the selected datasets (yes/partial/no/NA) yes

    -   3.3.

        All novel datasets introduced in this paper are included in a data appendix (yes/partial/no/NA) yes

    -   3.4.

        All novel datasets introduced in this paper will be made publicly available upon publication of the paper with a license that allows free usage for research purposes (yes/partial/no/NA) yes

    -   3.5.

        All datasets drawn from the existing literature (potentially including authors’ own previously published work) are accompanied by appropriate citations (yes/no/NA) yes

    -   3.6.

        All datasets drawn from the existing literature (potentially including authors’ own previously published work) are publicly available (yes/partial/no/NA) yes

    -   3.7.

        All datasets that are not publicly available are described in detail, with explanation why publicly available alternatives are not scientifically satisficing (yes/partial/no/NA) NA


##### 4\. Computational Experiments

-   4.1.

    Does this paper include computational experiments? (yes/no) yes

    If yes, please address the following points:

    -   4.2.

        This paper states the number and range of values tried per (hyper-) parameter during development of the paper, along with the criterion used for selecting the final parameter setting (yes/partial/no/NA) no

    -   4.3.

        Any code required for pre-processing data is included in the appendix (yes/partial/no) yes

    -   4.4.

        All source code required for conducting and analyzing the experiments is included in a code appendix (yes/partial/no) yes

    -   4.5.

        All source code required for conducting and analyzing the experiments will be made publicly available upon publication of the paper with a license that allows free usage for research purposes (yes/partial/no) yes

    -   4.6.

        All source code implementing new methods have comments detailing the implementation, with references to the paper where each step comes from (yes/partial/no) yes

    -   4.7.

        If an algorithm depends on randomness, then the method used for setting seeds is described in a way sufficient to allow replication of results (yes/partial/no/NA) NA

    -   4.8.

        This paper specifies the computing infrastructure used for running experiments (hardware and software), including GPU/CPU models; amount of memory; operating system; names and versions of relevant software libraries and frameworks (yes/partial/no) partial

    -   4.9.

        This paper formally describes evaluation metrics used and explains the motivation for choosing these metrics (yes/partial/no) yes

    -   4.10.

        This paper states the number of algorithm runs used to compute each reported result (yes/no) yes

    -   4.11.

        Analysis of experiments goes beyond single-dimensional summaries of performance (e.g., average; median) to include measures of variation, confidence, or other distributional information (yes/no) yes

    -   4.12.

        The significance of any improvement or decrease in performance is judged using appropriate statistical tests (e.g., Wilcoxon signed-rank) (yes/partial/no) yes

    -   4.13.

        This paper lists all final (hyper-)parameters used for each model/algorithm in the paper’s experiments (yes/partial/no/NA) yes
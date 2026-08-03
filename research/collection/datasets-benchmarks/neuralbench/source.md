# **NeuralBench: A Unifying Framework to Benchmark NeuroAI Models** 

**Hubert Banville**<sup>1</sup> , **Stéphane d’Ascoli**<sup>1</sup> , **Simon Dahan**<sup>1</sup> , **Jérémy Rapin**<sup>1</sup> , **Marlène Careil**<sup>1</sup> , **Yohann Benchetrit**<sup>1</sup> , **Jarod Lévy**<sup>1</sup><sup>_,_4</sup> , **Saarang Panchavati**<sup>1</sup> , **Antoine Ratouchniak**<sup>1</sup> , **Mingfang (Lucy) Zhang**<sup>2</sup><sup>_,_3</sup> , **Elisa Cascardi**<sup>1</sup> , **Katelyn Begany**<sup>1</sup> , **Teon Brooks**<sup>1</sup> , **Jean-Rémi King**<sup>1</sup> 

> 1Brain & AI team, Meta FAIR, 2École Normale Supérieure, Université PSL, CNRS, 3Hospital Foundation Adolphe de Rothschild,<sup>4</sup> MIND, Inria 

Deep learning and large public datasets have recently catalyzed the proliferation of AI models for processing brain recordings. However, systematically evaluating these models remains a challenge: not only do the preprocessing pipelines, training and finetuning approaches largely vary across studies, but their downstream evaluation is often limited to small sets of tasks and/or datasets. Here, we present NeuralBench: a unified framework for benchmarking AI models of brain activity. We accompany this framework with NeuralBench-EEG v1.0 – a large EEG benchmark that includes 36 electroencephalography (EEG) tasks and 14 deep learning architectures, and is evaluated on 94 datasets accessed through a standardized interface. This first EEG-focused release already highlights two main findings. First, current foundation models only marginally outperform task-specific models. Second, a large set of tasks ( _e_ . _g_ . cognitive decoding, clinical predictions) remain highly challenging, even for the best models. Critically, NeuralBench is designed for the integration of new tasks, datasets, models, and neuroimaging modalities, as illustrated by preliminary extensions to MEG and fMRI datasets and models. Through this white paper, we invite the community to expand this open-source framework and work together toward a unified benchmarking standard for neuroimaging models. 

**Correspondence:** hubertjb@meta.com, jeanremi@meta.com **Code:** https://github.com/facebookresearch/neuroai/tree/main/neuralbench-repo 





<!-- Start of picture text -->
NeuralFetch NeuralSet NeuralTrain NeuralBench<br>Dataset definitions Data loading & extraction Models & training Benchmark orchestration<br>14 36 94 9,478 13,603 1<br>NeuralBench-EEG v1.0<br>models tasks datasets subjects hours benchmark<br><!-- End of picture text -->

**Figure 1** NeuralBench is a benchmarking framework for the evaluation of brain models, based on the NeuralFetch, NeuralSet and NeuralTrain libraries, and providing a fully configurable and flexible interface. **Second row.** Contents of the first release, NeuralBench-EEG v1.0. 

### **1 Introduction** 

_The rise of AI models in neuroimaging._ Historically focused on targeted, small-scale, and private studies (Poldrack, 2011; Michel and Murray, 2012; Baillet, 2017), the analysis of brain activity is now rapidly shifting toward large-scale public datasets (Van Essen et al., 2013; Harati et al., 2014; Taylor et al., 2017; Pinho et al., 2018; Sun et al., 2025; d’Ascoli et al., 2026). On top of boosting statistical power and stimulating reproducible research (Button et al., 2013; Poldrack et al., 2017; d’Ascoli et al., 2026), the proliferation of open datasets has catalyzed the use of AI to process brain recordings. Specifically, the self-supervised learning methods 

1 



<!-- Start of picture text -->
A Downstream tasks B Brain models<br>cov + proj<br>Cognitive Image Sentence Speech Typing Video Word Logistic/Ridge<br>regression<br>BCI c-VEP 8 imageryMental executionMotor 3 imageryMotor18 P300 24 SSVEP 8 Handcrafted features<br>Evoked<br>Responses Audiovisual ERN 3 MMN N170 N2pc 2 N400 LRP Objective<br>Classification<br>Clinical Clinicalevent Dementia Depression Parkinson Pathology Schizophr. Seizure Task-specific Regression<br>InternalState Emotion Mentalarith. 2 Workload3 EEG trained from scratch~1.5K 4.2M params Retrieval<br>Phenotyping Age pathologyPsycho- Sex<br>SleepMisc arousalSleepClassificationSleepstage ArtifactRegressionReactiontime Retrieval pretrainingBraindata ~3.2MFoundation157.1M paramslinear<br>pretrained, fine-tuned<br>C Data diversity D Data quantity<br>160 10000<br>140<br>120 8000<br>100<br>6000<br>80<br>60 4000<br>40<br>2000<br>20 Benchmark Benchmark<br>0 Model paper 0 Model paper<br>5 10 15 20 25 30 35 40 0 2000 4000 6000 8000 10000 12000 14000<br># downstream tasks # hours of EEG data<br># subjects<br># downstream datasets<br><!-- End of picture text -->

**Figure 2** Detailed overview. **A** . NeuralBench-EEG v1.0 currently includes 36 decoding downstream tasks on 94 different datasets, covering 8 different categories such as cognitive decoding, brain-computer interfacing (BCI), evoked responses and clinical tasks. **B** . Three types of models are compared: task-specific from-scratch deep learning architectures, pretrained foundation models and handcrafted features-based baselines. **C-D** . NeuralBench-EEG v1.0 currently contains more than three times the number of tasks of previous EEG downstream task benchmarks, and more than twice as many individual subjects, making it the largest such open-source benchmark yet. 

developed for language, speech and images (Devlin et al., 2019; Baevski et al., 2020; Oquab et al., 2024) are now adapted for the development of _brain foundation models_ (Yang et al., 2025; Zhou et al., 2025). These models start to transfer to downstream tasks spanning electroencephalography (EEG) (Jiang et al., 2024; Kostas et al., 2021; Yang et al., 2023; Wang et al., 2024; Döner et al., 2025; El Ouahidi et al., 2025), functional magnetic resonance imaging (fMRI) (Kim et al., 2023; Dong et al., 2024; Caro et al., 2023), intracranial EEG (Wang et al., 2023; Yuan et al., 2024), structural MRI (Tak et al., 2026), electrophysiology (Azabou et al., 2023), and calcium imaging (Wang et al., 2025a). 

_Current benchmarking challenges._ Despite these advances, the evaluation landscape is fragmented. For EEG, the Mother of All BCI Benchmarks (MOABB)<sup>1</sup> (Jayaram and Barachant, 2018; Aristimunha et al., 2025) provides an extensive benchmark for brain-computer interfacing (148 datasets). However, it focuses on a narrow set of 5 downstream tasks (e.g., left versus right motor imagery) and primarily targets handcrafted features-based approaches, such as Riemannian geometry pipelines for trial classification (Barachant et al., 2011; Yger et al., 2016). Building on this, Borra et al. (2024) adapted the benchmark for deep learning, focusing specifically on a subset of nine BCI dataset from the MOABB and three well-established architectures. In parallel, benchmarks tailored to EEG _foundation_ models have emerged, _e_ . _g_ . , EEG-Bench (Kastrati et al., 2025), EEG-FM-Bench (Xiong et al., 2025), and AdaBrain-Bench (Wu et al., 2025). However, these efforts too are limited to a restricted set of downstream evaluations (Figure 2). This fragmentation is even more 

> 1https://moabb.neurotechx.com/ 

2 

pronounced in other brain recording modalities. For intracranial EEG (iEEG), Karpowicz et al. (2024) introduced FALCON, a few-shot evaluation benchmark for invasive BCI tasks, but is limited to 5 evaluation datasets. Elsewhere, foundation models for fMRI, MEG, and other modalities are still evaluated on handpicked datasets without a unified, systematic benchmark. Overall, there is currently no comprehensive framework for standardizing and efficiently evaluating brain foundation models across neuroimaging modalities. 

_Contribution._ Here, we introduce NeuralBench, a community-driven benchmarking framework for evaluating foundation models on brain activity recordings. NeuralBench is designed to be: 

1. **Comprehensive** . As many relevant downstream tasks as possible should be included, for as many relevant brain imaging devices as possible. This helps properly support claims of models being truly foundational and provides a more nuanced assessment of the strengths and weaknesses of different models. 

2. **Rigorously validated** . Publicly available datasets often require careful curation and tailored onboarding efforts so their contents can be used properly. Similarly, the framing of learning tasks requires special care to avoid common pitfalls ( _e_ . _g_ . leakage, overfitting, etc.) and to be maximally informative. This also applies to foundation models – each one is trained using a specific preprocessing pipeline that needs to be replicated to allow fair evaluation. 

3. **Standardized** . By providing a unified point-of-entry for diverse brain imaging devices (EEG, iEEG, MEG, fMRI, fNIRS, etc.), NeuralBench makes it easy to build and evaluate multimodal pipelines, bringing us closer to integrated brain modeling. 

4. **Flexible** . NeuralBench is configurable at all levels of the neuroimaging modeling pipeline (data source, preprocessing, architecture, optimization, metrics, etc.), offering a compact and flexible interface for running and evaluating brain models. 

The first release of NeuralBench, NeuralBench-EEG v1.0, supports 36 tasks evaluated on 94 EEG datasets (with some tasks spanning multiple datasets), accessed through a standardized interface. This effort, which capitalizes on the careful curation of public datasets, provides unique support for cognitive decoding tasks ( _i_ . _e_ ., image, sentence, speech, typing, video and word decoding), which, apart from image decoding, have been omitted in previous benchmarks. In addition, we demonstrate the versatility of this framework and seed its expansion towards other brain imaging modalities by including a couple of illustrative MEG and fMRI tasks and models. 

_Goal and overview._ In the following sections, we present a technical overview of NeuralBench, followed by initial results on NeuralBench-EEG v1.0 which highlight two main findings: current EEG foundation models only marginally outperform task-specific baselines, and many complex tasks ( _e_ . _g_ . , cognitive decoding, clinical prediction) remain challenging even for foundation models. We then show how NeuralBench seamlessly extends to MEG and fMRI modalities. 

_Toward a Community-Driven Standard._ Recognizing that a unified standard is only as strong as the community behind it, we provide the NeuralBench codebase<sup>2</sup> as a starting point for global collaboration. We invite researchers across tasks and modalities to co-author its evolution and join us in defining the future of brain model evaluation. 

### **2 Methods** 

In this section, we give a technical overview of NeuralBench, including its general architecture, a description of supported downstream tasks, model architectures, adaptation strategies, and evaluation protocols. We provide a high-level summary here and refer the reader to the package documentation for additional technical details. 

> 2https://github.com/facebookresearch/neuroai/tree/main/neuralbench-repo 

3 

#### **2.1 Benchmark architecture** 

NeuralBench is built on top of three main Python packages, which provide an interface with the data, processing and modeling tools that already exist in the neuroscience software ecosystem. Specifically, public neuroimaging datasets are accessed through NeuralFetch, which fetches curated datasets from public repositories like OpenNeuro<sup>3</sup> , DANDI<sup>4</sup> , and NEMAR<sup>5</sup> . Then, neural data is prepared and made available as PyTorch-ready dataloaders with NeuralSet– a package designed to efficiently leverage existing packages like MNE-Python (Gramfort et al., 2013)<sup>6</sup> and nilearn (Abraham et al., 2014)<sup>7</sup> for applying classic neuroimaging preprocessing pipelines, as well as HuggingFace<sup>8</sup> for extracting AI model embeddings ( _e_ . _g_ . on word, speech and image modalities). Finally, NeuralTrain provides modular training code with PyTorch-Lightning<sup>9</sup> , Pydantic<sup>10</sup> and exca (Rapin and King, 2024)<sup>11</sup> (see Figure 2D). 

Once installed, NeuralBench is run with a command-line interface (CLI). For example, the following can be used to run the audiovisual stimulus classification task on the MNE-Python sample dataset (Gramfort et al., 2013): 

1. Install NeuralBench 2. Run the audiovisual stimulus task on EEG $ pip install neuralbench $ neuralbench eeg audiovisual_stimulus --download _# Download data_ $ neuralbench --help _# Trigger_ $ neuralbench eeg audiovisual_stimulus --prepare _# Prepare cache interactive path configuration_ $ neuralbench eeg audiovisual_stimulus _# Run the task_ 

On top of allowing quick sanity-checking of the codebase, this small dataset ( _<_ 300 examples) is an interesting case study for very-low-data regime downstream tasks. 

_Task configuration_ Tasks are configured through lightweight YAML files, which describe data sources, train/validation/test splits, neural data preprocessing (filtering, scaling, windowing, etc.), target processing if any ( _e_ . _g_ . extracting dense representations of rich stimuli), trainer configuration (number of epochs, learning rate, etc.), and metrics. 

##### Example YAML configuration for audiovisual stimulus classification on EEG. 

data: study: source.name: Mne2013SampleEeg split: name: SklearnSplit valid_split_ratio: 0.2 test_split_ratio: 0.2 stratify_by: description neuro.baseline: [0.0, 0.2] target: name: LabelEncoder event_types: Stimulus event_field: description return_one_hot: true trigger_event_type: Stimulus start: -0.2 duration: 1.0 loss.name: CrossEntropyLoss metrics: BalancedAcc 

- 3https://openneuro.org/ 

- 4https://dandiarchive.org/ 

- 5https://nemar.org/ 

6https://mne.tools/ 

- 7https://nilearn.github.io/ 

8https://huggingface.co/ 

- 9https://lightning.ai 

> 10https://pydantic.dev/ 

> 11https://github.com/facebookresearch/exca 

4 

_Model configuration_ Similarly, deep learning architectures are defined through YAML files that configure NeuralTrain models. Thanks to its configurable pydantic layer, NeuralTrain can transparently access models from other libraries such as BrainDecode<sup>12</sup> (Schirrmeister et al., 2017; Aristimunha et al., 2026). 

#### **2.2 Task and dataset selection** 

A primary objective of NeuralBench is to provide a wide coverage of downstream tasks. Focusing on EEG for this first release, we selected a set of 36 representative downstream tasks, covering 8 categories: cognitive decoding, brain-computer interfacing (BCI), evoked responses, clinical, internal state, sleep, phenotyping and miscellaneous (see Figure 2A). Note that each task does not necessarily fall neatly into one of these categories, _e_ . _g_ . the P300 classification task could also fall under the _Evoked responses_ category, however since it is usually collected as part of a P300 speller protocol we file it under _BCI_ . Similarly, the psychopathology classification task could go under the _Clinical_ category, but we opt to keep it under the same _Phenotyping_ category as other tasks based on Shirazi et al. (2024). Nevertheless, we keep this operational organization to facilitate interpretation. 

Several inclusion criteria were considered. First, whenever possible, openly accessible datasets, rather than datasets requiring additional manual steps, were prioritized. Second, as several EEG datasets are approaching saturation ( _e_ . _g_ . binary pathology detection on the TUAB dataset (Lopez et al., 2015)), we devoted special efforts to include challenging tasks on which performance is likely to be significantly improvable. To this end, we include multiple _cognitive decoding_ tasks, where the goal is to recover a dense representation of the stimulus presented to participants, _e_ . _g_ . speech, images, words and videos (Défossez et al., 2022; Benchetrit et al., 2024; d’Ascoli et al., 2025). Finally, we re-framed common EEG classification tasks, _i_ . _e_ ., clinical event classification on the TUEV dataset (Harati et al., 2015) and artifact classification on the TUAR dataset (Hamid et al., 2020), as _multilabel_ classification tasks to take into account that that some events can overlap. 

_Note on pretraining data overlap._ Existing EEG foundation models are trained on custom corpora curated by the model authors. As there is a limited set of publicly available EEG datasets, some of these models saw (part of) the downstream datasets during pretraining. We flag these instances ( _e_ . _g_ . with hashed bars in Figure 4), rather than discard them, as we did not notice a clear trend suggesting pretraining “leakage” improves downstream performance on the same data. 

Finally, while we prioritized breadth over depth in our selection of datasets ( _i_ . _e_ ., most tasks rely on a single core dataset), we also leveraged readily available datasets through MOABB<sup>13</sup> (Aristimunha et al., 2025) to offer multiple comparison points on a few tasks, such as motor imagery and P300 decoding. This gives rise to two benchmark variants: NeuralBench-EEG-Core v1.0, which focuses on a single dataset per task, and NeuralBench-EEG-Full v1.0, which has up to 24 datasets per task and therefore enables the study of within-task variability. 

In total, NeuralBench-EEG v1.0 covers 36 tasks, 94 datasets, 9,478 subjects and 13,603 hours (see Table 1). Of note, no data is contained in the released package; datasets are accessed through the standardized interface provided by NeuralSet and NeuralFetch (King et al., 2026). Also, all datasets sources already provide de-identified data; as a result, the benchmark only processes de-identified subject IDs. More details on datasets and downstream tasks can be found in Appendix A and in the benchmark documentation<sup>14</sup> . 

#### **2.3 Model architecture selection** 

We selected commonly used EEG architectures and foundation models. First, we included 8 task-specific neural network architectures (Table S2), _i_ . _e_ ., models that are trained from scratch on downstream tasks, typically with lower parameter counts. These include ShallowFBCSPNet and Deep4Net (Schirrmeister et al., 2017), EEGNet (Lawhern et al., 2018), BDTCN (Gemein et al., 2020), ATCNet (Altaheri et al., 2022), EEGConformer (Song et al., 2022), SimpleConvTimeAgg (El Ouahidi et al., 2023) and CTNet (Zhao et al., 2024). 

> 12https://braindecode.org/ 

> 13https://moabb.neurotechx.com/ 

> 14https://github.com/facebookresearch/neuroai/tree/main/neuralbench-repo 

5 

**Table 1** Tasks and datasets in NeuralBench-EEG v1.0. For each task, we indicate the _Core_ dataset name, the machine learning objective ( _reg_ : regression, _clf_ : classification, _retr_ : retrieval), the number of unique EEG channels, the number of unique subjects, the dimensionality of the target ( _i_ . _e_ ., the number of outputs), and the number of additional datasets in the _Full_ variant, if any. 

|Task<br>Age|Core dataset<br>Shirazi2024|Obj.<br>reg|#Ch.<br>129|#Subj.<br>2,858|#Hours<br>95.3|#Out.<br>1|+Datasets|
|---|---|---|---|---|---|---|---|
|Artifact|Hamid2020|clf|26|213|300.2|5||
|Audiovisual stimulus|MneSample2013|clf|60|1|0.1|4||
|Clinical event|Harati2015|clf|21|370|20.1|6||
|C-VEP|Thielen2021|clf|8|30|50.0|20|7|
|Dementia diagnosis|Miltiadous2023|clf|19|88|19.5|3||
|Depression diagnosis|Mumtaz2018|clf|19|64|20.4|2||
|Emotion|Chen2023|clf|32|123|28.7|9||
|Error-related negativity|Kappenman2021Ern|clf|30|40|4.4|2|2|
|Image|Giford2022|retr|63|10|230.7|1,536||
|Mental arithmetic|Zyma2019|clf|20|35|2.3|2|1|
|Mental imagery|Scherer2015|clf|30|9|3.9|5||
|Mental workload|Hinss2023|clf|63|29|21.4|3|2|
|Mismatch negativity|Kappenman2021Mmn|clf|30|40|11.1|2||
|Motor execution|Srisrisawang2024|clf|60|20|16.0|16|2|
|Motor imagery|Stieger2021|clf|60|62|141.5|4|17|
|N170|Kappenman2021N170|clf|30|40|3.6|2||
|N2pc|Kappenman2021N2pc|clf|30|40|3.6|2|1|
|N400|Kappenman2021N400|clf|30|40|1.3|2||
|P300|Schreuder2010|clf|60|21|70.5|2|23|
|Parkinsons diagnosis|Singh2021|clf|60|129|54.9|2||
|Pathology|Lopez2017|clf|21|2,329|971.7|2||
|Psychopathology|Shirazi2024|reg|129|2,820|94.0|1||
|Reaction time|Shirazi2024|reg|129|1,945|70.8|1||
|Lateralized readiness poten-|Kappenman2021Lrp|clf|30|40|4.4|2||
|tial||||||||
|Schizophrenia diagnosis|Albrecht2019|clf|62|77|34.6|2||
|Seizure|Dan2023|clf|24|23|982.9|2||
|Sentence|Hollenstein2018|retr|128|12|21.5|768||
|Sex|Shirazi2024|clf|129|2,858|95.3|2||
|Sleep arousal|Ghassemi2018|clf|6|994|7,662.3|2||
|Sleep stage|Kemp2000|clf|2|78|1,635.2|5||
|Speech|Brennan2019|retr|60|33|58.5|4,096||
|Typing|Levy2025|clf|61|20|40.7|29||
|Video|Liu2024|retr|62|20|16.3|1,408||
|Steady-state visually evoked|Wang2017|clf|64|34|9.1|40|6|
|potential||||||||
|Word|Nieuwland2018|retr|74|222|441.4|1,024||



6 

Second, we selected 6 EEG foundation models (Table S4), _i_ . _e_ ., larger models that have been pretrained on unlabelled data, and that are typically finetuned on downstream tasks. These are BENDR (Kostas et al., 2021), LaBraM (Jiang et al., 2024), BIOT (Yang et al., 2023), CBraMod (Wang et al., 2025b), LUNA (Döner et al., 2025) and REVE (El Ouahidi et al., 2025). 

Third, we included representative handcrafted features-based models using sklearn-like pipelines to provide a non-deep learning comparison point (see Table S3). These pipelines all rely on symmetric positive definite (SPD) matrix representations of the input EEG which are fed to ‘shallow‘ predictors (logistic or Ridge regression). 

Finally, we include chance-level and “dummy” baselines to offer a proper performance floor to which models can be compared. Chance-level performance corresponds to the performance obtained by an untrained, randomly initialized model. “Dummy” performance corresponds to the performance obtained by a model that predicts either the average target for regression and retrieval tasks, the most frequent class for binary and multiclass classification tasks, or samples class-wise labels based on training set statistics for multilabel classification tasks. The dummy models are always fitted on the same training and validation sets as the other models. 

#### **2.4 Downstream strategy protocol** 

The original publications presenting the EEG foundation models listed above use different adaptation recipes, _i_ . _e_ ., for optimization (batch size, optimizer, learning rate, scheduler, etc.), aggregation ([CLS] token, average patch token, etc.) and projection head design (linear layer, MLP, etc.). Here, to focus the comparison on model architecture and pretraining methodology, we adopt a shared training recipe. 

Each foundation model is finetuned end-to-end, using a linear projection head which receives the average-pooled output tokens and outputs a single vector matching the target dimension. Training uses AdamW (Loshchilov and Hutter, 2017) with a learning rate of 10<sup>_−_4</sup> , weight decay of 0.05, and cosine-annealing (10% warmup), for up to 50 epochs with early stopping on the corresponding validation metric (patience=10). The sole exception to this unified recipe is BENDR (Kostas et al., 2021), for which we lower the learning rate to 10<sup>_−_5</sup> and apply gradient clipping at 0.5 to obtain stable learning curves. Therefore, model-specific techniques from the original papers — such as layer-wise learning rate decay, two-stage probing, or LoRA (Hu et al., 2022) — are intentionally omitted and the comparison of downstream adaptation strategies is kept for future iterations of NeuralBench. Finally, task-specific architectures are trained _from scratch_ using randomly initialized weights, using the same optimization recipe as the foundation models. 

#### **2.5 Preprocessing** 

We take particular care to follow the preprocessing pipelines described in the original EEG foundation model papers, as pretrained checkpoints expect specific input statistics which require identical preprocessing. For task-specific architectures, we use a single preprocessing configuration inspired by previous EEG decoding work (Défossez et al., 2022; Benchetrit et al., 2024): resampling to 120 Hz, bandpass filtering between 0.1 and 75 Hz, notch filters at 50 and 60 Hz as well as their harmonics, channel-wise robust scaling at the recording level, followed by clamping at 20. Nevertheless, it will be important, in future iterations, to systematically evaluate the impact of preprocessing strategies on downstream evaluation. 

#### **2.6 Data Splitting** 

The generalization capacity of a model can be highly dependent on the task. Consequently, to split datasets into training, validation and testing sets, we use different strategies for each task: (1) predefined splits when provided by the authors, (2) “leave-concept-out” for cognitive decoding tasks, (3) cross-subject splits, with optional stratification for clinical tasks, or (4) random splits when very few examples are available. We train (or finetune) each model on each task three times, using a single train/valid/test partition but three different random seeds for the initialization of the (non-pretrained) model weights. See Appendix C for more details. 

7 

#### **2.7 Training and evaluation metrics** 

The training, finetuning and evaluation of the models must vary depending on the task objective. In binary and _multiclass_ classification tasks, we use cross-entropy with optional weighing to mitigate class imbalance. In _multilabel_ classification tasks, we instead use binary cross-entropy per target. Regression tasks rely on the mean squared error (MSE) loss. Finally, we also implemented retrieval tasks, where a model must recover which candidate target out of a given retrieval set actually corresponds to the input ( _e_ . _g_ . which image out of a set of multiple images seen by a participant, based on an input EEG window). Retrieval is a particularly well-posed problem for cognitive tasks, as the content of an image, text or video is neither categorical, nor necessarily perfectly specified in a pretrained embedding. Retrieval ultimately allows future models and approaches to be compared with one another, with little assumption on how to represent the target. For retrieval, we here rely on the CLIP loss (Radford et al., 2021), using the configuration of Défossez et al. (2022), _i_ . _e_ ., with the brain-to-target term only and a fixed temperature parameter _τ_ = 1: 



ˆ where _B_ is the batch size, _s_ is the cosine similarity, and **_z_** _i_ and **_z_** _i_ are the target dense embedding ( _e_ . _g_ . DINOv2 (Oquab et al., 2024) for image retrieval) and corresponding prediction for batch element _i_ . 

#### **2.8 Model comparison** 

To help summarize the comparison across models, we opted to report a single representative metric per task type: _i_ . _e_ ., balanced accuracy for binary and multiclass classification, F1-score for multilabel classification, Pearson correlation for regression, and top-5 accuracy for retrieval<sup>15</sup> . See Appendix D for more details. We further report normalized scores _s_ ˜ to facilitate cross-task comparisons and emphasize task difficulty: 



where _s_ dummy is the performance obtained by the dummy model on a specific dataset, and _s_ perfect is the metric-specific theoretical highest performance obtainable ( _e_ . _g_ . 100% balanced accuracy for classification tasks). Of note, due to the inherent noise in brain activity recordings, this perfect score cannot be attained in practice. With this formulation, a value of 0 indicates dummy-level performance and a value of 1 indicates perfect performance. 

Finally, global model rankings consists of the per-task rank of each model, averaged over all tasks. On NeuralBench-EEG-Full v1.0, we additionally use all available datasets to compute this ranking, _i_ . _e_ ., we average ranks across datasets of the same task first. 

#### **2.9 Computational considerations** 

NeuralBench-EEG-Full v1.0 requires running 4,947 experiments. (14 models + chance, dummy & handcrafted features baselines, 97 tasks-datasets, 3 seeds each). By default, each job uses a single GPU with at least 32 GB VRAM and 64 GB of CPU RAM, though measured peak GPU usage averages only _∼_ 1.3 GB (max _∼_ 30.3 GB). The full EEG benchmark requires _∼_ 11 TB of disk space ( _∼_ 3.2 TB for the raw data, 7.8 TB of preprocessed cache, and 333 GB for logged results). Training times vary widely, with a median of 2.7 minutes but mean of 21.7 minutes per experiment, with the longest run taking 18.2 hours. This yields an estimated total serial runtime of _∼_ 73 days (1,751 GPU-hours). The benchmark runs on Python >= 3.12 with PyTorch 2.6 (Paszke et al., 2019) and Pytorch-Lightning (Falcon and The PyTorch Lightning team, 2019). 

> 15We evaluate top-5 accuracy on the entire test set, using within-subject aggregation of repeated predictions, if available. 

8 



<!-- Start of picture text -->
Mean norm.<br>rank<br>REVE  (69.2M; 2025) 0.20 Foundation<br>LaBraM  (5.8M; 2024) 0.21 BENDR<br>BIOT<br>LUNA  (40.4M; 2025) 0.30 LaBraM<br>CTNet  (150K; 2024) 0.32 CBraMod<br>CBraMod  (4.9M; 2025) 0.33 LUNA<br>REVE<br>SimpleConvTimeAgg  (4.2M; 2023) 0.35<br>ShallowFBCSPNet  (36K; 2017) 0.43 Task-specific<br>Deep4Net  (146K; 2017) 0.43 ShallowFBCSPNet<br>EEGConformer  (277K; 2022) 0.45 Deep4Net<br>EEGNet<br>EEGNet  (1K; 2018) 0.47 BDTCN<br>BENDR  (157.1M; 2021) 0.57 EEGConformer<br>ATCNet  (29K; 2022) 0.59 ATCNet<br>SimpleConvTimeAgg<br>Handcrafted 0.60 CTNet<br>BIOT  (3.2M; 2023) 0.64<br>BDTCN  (27K; 2020) 0.73 Baselines<br>Chance<br>Dummy 0.92<br>Dummy<br>Chance 0.94 Handcrafted<br>0.00 0.25 0.50 0.75 1.00<br>Normalized rank (lower is better)<br><!-- End of picture text -->

**Figure 3** Model ranking on NeuralBench-EEG-Core v1.0. Each box corresponds to the rank distribution of one model across downstream tasks. Models are ordered by their mean normalized rank, displayed on the right hand side of the boxes. The number of trainable parameters (excluding the last linear projection layer) and the year of original publication are shown in parentheses next to each model name. Recent foundation models outrank most smaller task-specific models, suggesting large self-supervised pretraining can benefit downstream performance on a varied set of downstream tasks. 

### **3 Results** 

#### **3.1 NeuralBench-EEG v1.0: Evaluating EEG foundation models on 36 diverse downstream tasks** 

We summarize per-model performance in Figure 3, where we order the models based on their average pertask rank. While the highest scoring models are foundation models, _i_ . _e_ ., REVE (El Ouahidi et al., 2025), LaBraM (Jiang et al., 2024) and LUNA (Döner et al., 2025), some task-specific architectures trained _from scratch_ also perform well, _e_ . _g_ . CTNet (Zhao et al., 2024), SimpleConvTimeAgg (Défossez et al., 2022) and Deep4Net (Schirrmeister et al., 2017), despite significantly lower parameter counts ( _e_ . _g_ . 150K parameters for CTNet vs. 69.2M for REVE). This is in line with Kastrati et al. (2025) and Wu et al. (2025) which reported similar results. Of note, BENDR (Kostas et al., 2021) and BIOT (Yang et al., 2023) did not perform as well overall despite their pretraining, which might in part be explained by the necessary addition of a channel adapter linear layer to match the expected channel montage seen during pretraining, and, for BIOT, to the use of a linear projection head rather than a large MLP head like in the original publication. 

#### **3.2 Future-proofing evaluation through task diversity and difficulty** 

Detailed performance results for each downstream task and model are presented in Figure 4 and Figure 5. The results suggest that performance over a few common EEG tasks is close to saturation, _e_ . _g_ . SSVEP classification, pathology, seizure detection, sleep stage classification and phenotyping tasks, _i_ . _e_ ., age regression and sex classification. 

In contrast, the cognitive decoding tasks are particularly challenging. These tasks, introduced in NeuralBench ( _e_ . _g_ . speech, sentence, video, word and image decoding), consist of decoding dense representations of the stimulus or condition from the brain activity. Foundation models particularly stand out on these compared to 

9 



<!-- Start of picture text -->
Mean norm. Image Sentence Speech Typing Video Word<br>Best rank ↑ Top-5 accuracy (per-subject) Top-5 accuracy (per-subject) Top-5 accuracy (per-subject) Balanced accuracy Top-5 accuracy (per-subject) Top-5 accuracy (per-subject)<br>(0)<br>75 10 6 20<br>4 4<br>50 4<br>25 5 2 2 2 10<br>Worst(1) 0 within-subject  ·  n=831K 0 within-subject  ·  n=26K 0 within-subject  ·  n=70K 0 within-subject  ·  n=147K 0 wit h in-s u bject  ·  n=29K 0 within-subject  ·  n=530K<br>Mean norm. c-VEP M e ntal imagery Motor execution Motor imagery P300 SSVEP<br>Best(0) rank ↑ Balanced accuracy Balance d  accuracy 60 Balanced accuracy Balanced accuracy 70 Balanced accuracy 100 Balanced accuracy<br>75 30 60<br>50 20 40 40 6050 50<br>25 20 20<br>10 40<br>Worst(1) 0 cross-subject  ·  n=45K 0 withi n -subject  · n=3 .5 K 0 cross-subject  ·  n=19K 0 cross-s u bject  ·  n=127K 0 c ross-subjec t   ·  n= 2 54K 0 c ross-subjec t   ·  n= 8 .2K<br>Mean norm. Audiovisual E RN MMN N1 7 0 N2pc N400 L R P<br>Best(0) rank ↑ 60 Balanced accuracy 80 Balanced accuracy 60 Balanced accuracy 80 Balanced accur a cy Balanced accuracy Balanced accuracy 80 Balanc e d accuracy<br>60 60<br>40 60 50 60 50 50 60<br>20<br>40 40 40 40 40 40<br>Worst(1) 0 random  ·  n=288 0 cross-subje c t  ·  n = 16K 0 cross-subject  ·  n=40K 0 cross-subj e ct  ·  n=1 3 K 0 cro ss - s u b j e ct  ·  n=1 3K 0 cross-subjec t   ·  n=4.8K 0 cro s s- s u b j ec t  ·  n=1 6 K<br>Mean norm. Clinical event Demen t ia Depression Parkinson's Pathology Sc hizophr en ia Seizure<br>Best(0) rank ↑ 0.6 F1 score (macro) 50 Balanced accurac y 80 Balanced accuracy 80 Balanc e d accuracy 80 Balanced accuracy Balanced accuracy 80 Balanced accuracy<br>0.4 40 60<br>60 60 60 60<br>0.2 30 40<br>40 40 40 40<br>Worst(1) 0.0 cross-subject  ·  n=24K 0 cross-subject  ·   n =14 K 0 cross-subject  ·  n=15K 0 cross-subject  ·  n=40K 0 cross-subject  ·  n=700K 0 cross-subject  ·  n=25K 0 cross-subject  ·  n=708K<br>Mean norm. Emotion Menta l  arith. Workload<br>Best rank ↑ Balanced accuracy Bal a nced accuracy Balanced accuracy<br>(0)<br>30 70 60<br>20 60 40 Baselines Foundation models<br>10 50 20 Chance BENDR<br>Worst(1) 0 cross-subject  ·  n=21K 400 cross-subject 0 cross-subject  ·  n=15K DummyHandcrafted BIOTLaBraM<br>Mean norm. Age Psychopathology Sex Seen during CBraMod<br>Best(0) rank ↑ Pearson R 0.15 Pearson R Balanced acc u r a cy pretraining LUNA<br>0.6 80 REVE<br>0.4 0.10 Task-specific models<br>60 ShallowFBCSPNet<br>0.2 0.05 40 Deep4Net<br>Worst(1) 0.0 cross-subject  ·  n=171K 0.00 cross-subject  ·  n=169K 0 cross-subject  ·  n=171K EEGNet<br>BDTCN<br>Best Mean norm.rank ↑ Balanced accuracySleep arousal Balanced accuracySleep stage F1 score (macro)Artifact Reaction timePearson R EEGConformer<br>(0) 60 ATCNet<br>60 0.4 0.4 SimpleConvTimeAgg<br>50 40 CTNet<br>0.2 0.2<br>20<br>40<br>Worst(1) 0 cross-subject  ·  n=1.8M 0 cross-subject  ·  n=196K 0.0 cross-subject  ·  n=360K 0.0 cross-subject  ·  n=127K<br>Cognitive<br>BCI<br>Evoked Responses<br>Clinical<br>Internal State<br>Phenotyping<br>Sleep / Misc<br><!-- End of picture text -->

**Figure4** Performance obtained by the different task-specific (blue) and foundation (orange) models on the 36 downstream tasks in NeuralBench-EEG-Core v1.0. Rows correspond to specific downstream task categories; the first subplot of each row summarizes the model ranking over the corresponding task category row. Each bar corresponds to one model, with error bars representing standard error of the mean (SEM) across seeds. Hashed bars indicate models that were pretrained on the downstream dataset, meaning the reported performance could be overinflated since test subjects or examples may have been seen by the model. Dummy-level performance is evaluated for each task by predicting the majority class (classification) or the average target (regression and retrieval) computed on the training set. Handcrafted baselines uses sklearn pipelines which ingest covariance-like features to provide a non-deep learning baseline (see Table S3). Finally, the splitting strategy (cross-subject, within-subject or random) and the total number of examples across splits are listed under each subplot. 

task-specific models, _e_ . _g_ . REVE leads on the sentence, speech and video decoding tasks. 

Models perform significantly worse on NeuralBench’s rarer paradigms, including mental imagery, sleep arousal, and psychopathology decoding, highlighting the difficulty of these specific decoding tasks. Moreover, standard benchmark tasks, _i_ . _e_ ., motor imagery, P300 and N2pc classification, become particularly challenging when framed as cross-subject tasks, often yielding performance close to dummy level. Given the substantial margin between current results and performance ceiling, these tasks represent ideal benchmarks for futureproofing the evaluation of the next generation of EEG models. 

10 



<!-- Start of picture text -->
Evoked Internal<br>Cognitive BCI Responses Clinical State Sleep Phenotyping Misc<br>Perfect<br>1.0<br>0.8<br>0.6<br>0.4<br>0.2<br>0.0 Dummy<br>Best foundation model Best task-specific model Foundation model wins<br>Mean over foundation models Mean over task-specific models Task-specific model wins<br>TypingSpeechVideoSentenceWordImageMental imageryMotor executionMotor imageryP300 c-VEPSSVEP MMNN400AudiovisualN2pc N170LRPERNDementiaClinical eventSchizophreniaParkinson'sPathologySeizureDepression EmotionMental arith.WorkloadSleep arousalSleep stagePsychopathologyAgeSex ArtifactReaction time<br>s<br>Normalized score ̃<br><!-- End of picture text -->

**Figure 5** Normalized performance _s_ ˜ across downstream tasks, for the best and “average” foundation model (orange) and best and “average” task-specific models (blue). A value of 0.0 corresponds to dummy-level performance, while a value of 1.0 represents perfect (idealized) performance. Horizontal bars on the x-axis indicate which model category yield the highest performance overall for a given task. While foundation models often outperform task-specific models, this is not the case across all tasks, _e_ . _g_ . in evoked responses and clinical downstream tasks. Cognitive decoding tasks introduced in NeuralBench-EEG v1.0 are particularly challenging, which position them well for evaluating future iterations of EEG foundation models. 

#### **3.3 From NeuralBench-Core to NeuralBench-Full: Leveraging multi-study tasks for evaluating cross-dataset variability** 

The results above focused on NeuralBench-EEG-Core v1.0, a version of the benchmark where each task is summarized by a single representative “core” dataset. We also introduce NeuralBench-EEG-Full v1.0, an extended version of the benchmark in which downstream tasks may include additional datasets on top of their core dataset, which we leverage in two ways. 

First, we compare models as above, but this time using dataset-averaged ranks whenever multiple datasets are available for a task, yielding a more robust ordering of models. The “Core” and “Full” rankings are compared in Figure 6A. A Kendall’s _τ_ of 0.926 (p < 0.001) between the two rankings suggests the “Core” ranking is a good proxy for the “Full” one. However, we notice that a few models swap positions in the ranking, _e_ . _g_ . CTNet overtakes the LUNA foundation model as third best in the “Full” ranking. This shows the gap between task-specific and foundation models is narrow enough that expanding dataset coverage is sufficient to change global ranking. 

Second, we evaluate within-task variability by inspecting ranking changes in NeuralBench-EEG-Full v1.0’s multi-dataset tasks (Figure 6B). REVE and LaBraM are the most stable foundation models, with the former experiencing the least rank variability of all models. On the task dimension, we notice strong variability on motor imagery and SSVEP in particular. For instance, on SSVEP, performance on the core dataset (Wang et al., 2017) and on Lee et al. (2019) is mostly dominated by foundation models (LaBraM and REVE), task-specific models outperform all other models on Oikonomou et al. (2016) version A, and the handcrafted features-based baseline outperforms all or most other models on Kalunga et al. (2016) and Oikonomou et al. (2016) versions B and C (see Supplementary Figure S2 for details). This strong variability suggests that multi-study comparisons are necessary to fully characterize the behavior of brain models. 

Moving forward, the availability of multiple datasets per task will allow testing generalization and invariance properties of foundation models over varying recording hardware, lab environments and subject populations. It also opens the door to multi-dataset finetuning and evaluation, _e_ . _g_ . in which models are finetuned on a 

11 



<!-- Start of picture text -->
A Climbed<br>Dropped<br>Same<br>NeuralBench-EEG-Core v1.0<br>(1 dataset/task)<br>NeuralBench-EEG-Full v1.0<br>(All datasets)<br>4 5 6 7 8 9 10 11 12 13 14 15 16 17<br>Mean rank<br>B Task-specific Foundation Baseline<br>P300 (N=24) 1.7 1.9 2.5 2.0 3.1 1.8 2.4 2.9 3.0 2.6 2.9 1.6 3.1 2.6 2.9 1.1 3.7 2.5<br>c-VEP (N=8) 0.9 2.4 2.0 2.7 2.6 3.4 3.3 2.9 3.2 1.7 2.8 1.7 3.7 4.1 2.6 1.3 4.4 2.7<br>Motor imagery (N=18) 3.4 4.3 2.8 4.1 4.4 2.8 3.7 4.6 1.7 3.8 4.0 4.7 4.4 4.4 3.3 2.1 5.5 3.8<br>SSVEP (N=7) 3.4 2.5 4.4 3.6 3.1 6.0 4.8 4.3 3.8 4.1 2.5 6.0 3.0 3.7 3.5 2.0 3.4 3.8<br>Mean 2.4 2.8 2.9 3.1 3.3 3.5 3.6 3.7 2.9 3.0 3.0 3.5 3.6 3.7 3.1 1.6 4.3 3.2<br>0.9 3.5 6.0<br>Rank std (↓)<br>REVE LaBraM LUNACTNetCBraModSimpleConvTimeAggShallowFBCSPNetDeep4NetEEGConformerEEGNetBENDRATCNetHandcraftedBIOT BDTCN DummyChance<br>ATCNet ShallowFBCSPNetCTNet BDTCN SimpleConvTimeAggEEGConformerDeep4NetEEGNet REVE LaBraM BENDR BIOT CBraModLUNA Chance Dummy Handcrafted Mean<br><!-- End of picture text -->

**Figure 6** Analysing multi-dataset performance on NeuralBench-EEG-Full v1.0. **A.** Difference in model ranking between the _Core_ and _Full_ variants of NeuralBench-EEG v1.0. Models whose global rank improve or degrade when using the full version of the benchmark are indicated by green or black lines, respectively. The ranking is not affected much by the addition of multiple datasets per task, which suggests _Core_ datasets are overall representative. **B.** Within-task model ranking variability. We report the standard deviation of each model’s ranks across the different datasets of a task (for tasks with 5 datasets or more). Higher values indicate a model’s performance relative to the other models vary substantially, meaning the model is not stable when evaluated across multiple datasets of the same domain. Tasks like motor imagery and SSVEP, and foundation models like CBraMod and LUNA, are the most unstable. 

12 



<!-- Start of picture text -->
MEG fMRI<br>Image Typing Image<br>Top-5 accuracy (per-subject) Balanced accuracy Top-5 accuracy (per-subject)<br>80 80<br>10<br>60 60<br>40 40<br>5<br>20 20<br>0 0 0<br>within-subject  ·  n=99K within-subject  ·  n=193K within-subject<br>Baselines EEG task-specific models EEG foundation models fMRI task-specific models<br>Chance ShallowFBCSPNet BENDR FmriLinear<br>Dummy Deep4Net BIOT FmriMlp<br>Handcrafted EEGNet LaBraM<br>BDTCN CBraMod<br>EEGConformer LUNA<br>ATCNet REVE<br>SimpleConvTimeAgg<br>CTNet<br><!-- End of picture text -->

**Figure 7** Performance obtained on MEG and fMRI downstream tasks. Each bar corresponds to one model, with error bars representing standard error of the mean (SEM) across seeds. See Figure 4 for more details. This first benchmark release focuses on EEG, however, as a unified framework, NeuralBench is ready to support other brain imaging modalities as well. 

subset of task datasets, and evaluated on the remaining held out datasets. 

#### **3.4 Extending NeuralBench to more modalities: MEG and fMRI** 

The focus of this first NeuralBench release is EEG. However, the benchmark infrastructure already provides support for other neuroimaging modalities, which we demonstrate by including results on two MEG and one fMRI downstream tasks (see Figure 7). 

For MEG, given the similarities between the two types of data (da Silva, 2013) and the common reuse of EEG architectures on MEG (Banville et al., 2025), we evaluate the same task-specific and foundation models as for EEG. Expectedly, some architectures yield high performance on MEG, such as SimpleConvTimeAgg which was already shown to perform well on image decoding on the same dataset (Benchetrit et al., 2024). More strikingly, some EEG foundation models, despite being pretrained on EEG data exclusively, perform well on MEG, with REVE outperforming all other models on typing decoding. Finally, on fMRI, we present results on a similar image decoding task as in EEG and MEG, but focused on two task-specific architectures that rely on linear and convolutional layer primitives. These results exhibit the flexibility of NeuralBench, which is ready to be extended to other modalities as well, such as iEEG, functional near-infrared spectroscopy (fNIRS), and other neural signal types such as electromyography (EMG). 

Overall, in this section, we highlighted NeuralBench’s comprehensive downstream task coverage, its versatility, allowing easy between- and within-task performance comparisons, and its extendability to more neuroimaging devices. 

### **4 Discussion** 

_EEG foundation vs. task-specific models._ We introduce NeuralBench, a unifying framework to benchmark NeuroAI models, and release NeuralBench-EEG v1.0, a first comprehensive benchmark evaluating existing task-specific and foundation models of EEG signals. Our results already reveal that current EEG foundation models only marginally outperform specialized models. While self-supervised pretraining yields generalizable representations, downstream performance gains remain limited. This modest advantage may stem from the use of finetuning as a downstream strategy: in data-rich scenarios, specialized models likely possess sufficient capacity to close the performance gap with foundation models. Future evaluations should thus also incorporate evaluations in few-shot and low-data regimes ( _e_ . _g_ . 5% of training data). 

13 

_EEG task expansions._ NeuralBench-EEG v1.0 significantly expands the diversity of downstream evaluations by introducing and integrating a large set of cognitive, phenotyping, clinical and BCI “tasks”. Across most of these tasks, performance remains modest, which leaves room for improvement in next generations of EEG foundation models. In the future, we recommend maintaining a diverse set of tasks – some easy, others difficult – to validate the ability of models to extract valuable information from noisy brain signals, while ensuring that benchmarking is representative of downstream neuroscience and clinical applications. 

_Unique optimization strategies._ Rather than pursuing model-specific optimization, we utilize a standardized training recipe to evaluate each architecture’s “out-of-the-box” utility. This decision reflects a core requirement for NeuroAI foundation models: they must be easily adaptable and stable under standard configurations to be practically useful for the broader research community. 

_Unique splitting strategy._ We used specific splitting strategies to maintain a manageable computational footprint while ensuring diverse task coverage. Although this choice limits the assessment of performance variability (as compared to a cross-validated approach), it establishes a broad baseline for evaluating foundation models. We invite the community to help incorporate stochastic partitioning in future releases to facilitate deeper statistical validation. 

_Unique finetuning strategy._ NeuralBench currently relies on end-to-end finetuning, which may not capture the full potential of foundation models. Alternative strategies, such as linear probing, parameter-efficient finetuning (Hu et al., 2022; Lester et al., 2021) and varied token aggregation methods may further improve performance and differentiate models from one another. These dimensions should thus be studied in greater detail in future iterations of the benchmark. 

_Beyond EEG._ While this first release focuses on EEG – given its prominence in the brain foundation model literature (Yang et al., 2025) – NeuralBench’s infrastructure based on the NeuralSet ecosystem (King et al., 2026) is highly flexible. We demonstrate this with preliminary MEG and fMRI tasks, paving the way for a truly multimodal benchmark, and strikingly, already showing promising transfer from EEG to MEG. However, extending to new modalities requires significant data curation and introduces device-specific challenges, such as high auto-correlation in fMRI that complicates train/test splits (Poldrack, 2006). 

_Beyond decoding._ The current benchmark is restricted to the evaluation of models which receive brain activity as input, and predict a target label or embedding, _i_ . _e_ ., _decoding_ models. However, _encoding_ models (Naselaris et al., 2011), which predict brain activity from stimuli, are also actively being developed. Existing benchmarking efforts in the neuroAI community, including machine learning competitions, are focused on encoding, _e_ . _g_ . the Algonauts project (Cichy et al., 2021; Gifford et al., 2023, 2024) on image and video encoding in human fMRI, the Sensorium competition (Willeke et al., 2022; Turishcheva et al., 2024) on image and video encoding in mouse visual cortex calcium imaging, and the Brain-Score platform (Schrimpf et al., 2018, 2020) on visual and language encoding in primate electrode recordings and human fMRI. Integrating encoding, forecasting, and denoising tasks presents unique challenges, _e_ . _g_ . standardizing stimuli representations and evaluation metrics, but can be readily accommodated within the NeuralBench framework. 

_Open call for community contribution._ Building a universal benchmark for brain activity is a vast undertaking, unlikely to be achieved by a single team. We therefore open-source the NeuralBench codebase<sup>16</sup> and invite the community to contribute new datasets, tasks, models, and neuroimaging modalities. 

_Towards a unified modeling of brain activity._ Ultimately, brain foundation models have the potential to revolutionize brain-computer interfacing, neurology, and neuroscience. Moving toward the integrated processing of multimodal brain data requires rigorous, reproducible, and comprehensive evaluation. We hope NeuralBench serves as a foundational tool to seed and support this community-wide effort. 

> 16https://github.com/facebookresearch/neuroai/tree/main/neuralbench-repo 

14 

###### **Acknowledgments** 

We thank Alexandre Gramfort, Thomas Moreau, Arnaud Delorme, Bruno Aristimunha and Pierre Guetschel for their feedback on benchmarking best practices and the NeuroAI open-source ecosystem. We thank the maintainers and contributors of the open-source software packages on which NeuralBench is built. Finally, we thank the authors and participants of the datasets used in this research for their fundamental contribution to the advancement of open NeuroAI models. 

15 

### **References** 

- Alexandre Abraham, Fabian Pedregosa, Michael Eickenberg, Philippe Gervais, Andreas Mueller, Jean Kossaifi, Alexandre Gramfort, Bertrand Thirion, and Gaël Varoquaux. Machine learning for neuroimaging with scikit-learn. _Frontiers in neuroinformatics_ , 8:14, 2014. 

- Laura Acqualagna and Benjamin Blankertz. Gaze-independent BCI-spelling using rapid serial visual presentation (RSVP). _Clinical Neurophysiology_ , 124(5):901–908, May 2013. ISSN 1388-2457. doi: 10.1016/j.clinph.2012.12.050. http://dx.doi.org/10.1016/j.clinph.2012.12.050. 

- Matthew A. Albrecht, James A. Waltz, James F. Cavanagh, Michael J. Frank, and James M. Gold. Increased Conflict-Induced slowing, but no differences in Conflict-Induced positive or negative prediction error learning in patients with schizophrenia. _Neuropsychologia_ , 123:131–140, February 2019. ISSN 1873-3514. doi: 10.1016/j. neuropsychologia.2018.04.031. 

- Emily J Allen, Ghislain St-Yves, Yihan Wu, Jesse L Breedlove, Jacob S Prince, Logan T Dowdle, Matthias Nau, Brad Caron, Franco Pestilli, Ian Charest, et al. A massive 7T fMRI dataset to bridge cognitive neuroscience and artificial intelligence. _Nature neuroscience_ , 25(1):116–126, 2022. 

- Hamdi Altaheri, Ghulam Muhammad, and Mansour Alsulaiman. Physics-informed attention temporal convolutional network for eeg-based motor imagery classification. _IEEE Transactions on Industrial Informatics_ , 2022. doi: 10.1109/TII.2022.3197419. 

- Pietro Aricò, Fabio Aloise, Francesca Schettini, Serenella Salinari, Donatella Mattia, and Febo Cincotti. Influence of P300 latency jitter on event related potential-based brain–computer interface performance. _Journal of Neural Engineering_ , 11(3):035008, 2014. doi: 10.1088/1741-2560/11/3/035008. 

- Bruno Aristimunha, Igor Carrara, Pierre Guetschel, Sara Sedlar, Pedro Rodrigues, Jan Sosulski, Divyesh Narayanan, Erik Bjareholt, Quentin Barthelemy, Robin Tibor Schirrmeister, Reinmar Kobler, Emmanuel Kalunga, Ludovic Darmet, Cattan Gregoire, Ali Abdul Hussain, Ramiro Gatti, Vladislav Goncharenko, Anton Andreev, Jordy Thielen, Thomas Moreau, Yannick Roy, Vinay Jayaram, Alexandre Barachant, and Sylvain Chevallier. Mother of all BCI benchmarks, 2025. https://github.com/NeuroTechX/moabb. 

- Bruno Aristimunha, Pierre Guetschel, Martin Wimpff, Lukas Gemein, Cedric Rommel, Hubert Banville, Maciej Sliwowski, Daniel Wilson, Simon Brandt, Théo Gnassounou, Joseph Paillard, Aman Srivastava, Bruna Junqueira Lopes, Sara Sedlar, Thomas Moreau, Sylvain Chevallier, Alexandre Gramfort, and Robin Tibor Schirrmeister. Braindecode: toolbox for decoding raw electrophysiological brain data with deep learning models, 2026. https: //github.com/braindecode/braindecode. 

- Mehdi Azabou, Vinam Arora, Venkataramana Ganesh, Ximeng Mao, Santosh Nachimuthu, Michael Mendelson, Blake Richards, Matthew Perich, Guillaume Lajoie, and Eva Dyer. A unified, scalable framework for neural population decoding. _Advances in Neural Information Processing Systems_ , 36:44937–44956, 2023. 

- Alexei Baevski, Yuhao Zhou, Abdelrahman Mohamed, and Michael Auli. wav2vec 2.0: A framework for self-supervised learning of speech representations. _Advances in neural information processing systems_ , 33:12449–12460, 2020. 

- Sylvain Baillet. Magnetoencephalography for brain electrophysiology and imaging. _Nature neuroscience_ , 20(3):327–339, 2017. 

- Hubert Banville, Yohann Benchetrit, Stéphane d’Ascoli, Jérémy Rapin, and Jean-Rémi King. Scaling laws for decoding images from brain activity. _arXiv preprint arXiv:2501.15322_ , 2025. 

- Alexandre Barachant. _Robust control of an effector by an asynchronous EEG brain-machine interface_ . Theses, Universite de Grenoble, March 2012. https://theses.hal.science/tel-01196752. 

- Alexandre Barachant and Marco Congedo. A plug&play P300 BCI using information geometry. _arXiv preprint arXiv:1409.0107_ , 2014. 

- Alexandre Barachant, Stéphane Bonnet, Marco Congedo, and Christian Jutten. Multiclass brain–computer interface classification by Riemannian geometry. _IEEE Transactions on Biomedical Engineering_ , 59(4):920–928, 2011. 

- Yohann Benchetrit, Hubert Banville, and Jean-Rémi King. Brain decoding: toward real-time reconstruction of visual perception. In _ICLR 2024_ , 2024. 

- Davide Borra, Francesco Paissan, and Mirco Ravanelli. SpeechBrain-MOABB: An open-source python library for benchmarking deep neural networks applied to EEG signals. _Computers in Biology and Medicine_ , 182:109097, 2024. 

16 

- Jonathan R Brennan and John T Hale. Hierarchical structure guides rapid linguistic predictions during naturalistic listening. _PloS one_ , 14(1):e0207741, 2019. 

- Katherine S Button, John PA Ioannidis, Claire Mokrysz, Brian A Nosek, Jonathan Flint, Emma SJ Robinson, and Marcus R Munafò. Power failure: why small sample size undermines the reliability of neuroscience. _Nature reviews neuroscience_ , 14(5):365–376, 2013. 

- Kalou Cabrera Castillos, Simon Ladouce, Ludovic Darmet, and Frédéric Dehais. Burst c-VEP based BCI: Optimizing stimulus design for enhanced classification with minimal calibration data and improved user experience. _NeuroImage_ , 284:120446, December 2023. ISSN 1053-8119. doi: 10.1016/j.neuroimage.2023.120446. http://dx.doi.org/10.1016/j. neuroimage.2023.120446. 

- Josue Ortega Caro, Antonio H de O Fonseca, Christopher Averill, Syed A Rizvi, Matteo Rosati, James L Cross, Prateek Mittal, Emanuele Zappala, Daniel Levine, Rahul M Dhodapkar, et al. BrainLM: A foundation model for brain activity recordings. _BioRxiv_ , pages 2023–09, 2023. 

- Grégoire Cattan, Anton Andreev, Pedro L. C. Rodrigues, and Marco Congedo. Dataset of an EEG-based BCI experiment in virtual reality and on a personal computer, 2019. https://zenodo.org/record/2605204. 

- Ricardo Chavarriaga and José del R. Millan. Learning from EEG Error-Related potentials in noninvasive BrainComputer interfaces. _IEEE Transactions on Neural Systems and Rehabilitation Engineering_ , 18(4):381–388, August 2010. ISSN 1558-0210. doi: 10.1109/tnsre.2010.2053387. http://dx.doi.org/10.1109/TNSRE.2010.2053387. 

- Jingjing Chen, Xiaobin Wang, Chen Huang, Xin Hu, Xinke Shen, and Dan Zhang. A large finer-grained affective computing EEG dataset. _Scientific Data_ , 10(1), October 2023. ISSN 2052-4463. doi: 10.1038/s41597-023-02650-w. http://dx.doi.org/10.1038/s41597-023-02650-w. 

- Hohyun Cho, Minkyu Ahn, Sangtae Ahn, Moonyoung Kwon, and Chan Jun, Sung. Supporting data for "EEG datasets for motor imagery brain computer interface", 2017. http://gigadb.org/dataset/100295. 

- Radoslaw Martin Cichy, Kshitij Dwivedi, Benjamin Lahner, Alex Lascelles, Polina Iamshchinina, Monika Graumann, Alex Andonian, NAR Murty, K Kay, Gemma Roig, et al. The algonauts project 2021 challenge: How the human brain makes sense of a world in motion. _arXiv preprint arXiv:2104.13714_ , 2021. 

- Fernando Lopes da Silva. EEG and MEG: relevance to neuroscience. _Neuron_ , 80(5):1112–1128, 2013. 

- Jonathan Dan and Ali Shoeb. BIDS CHB-MIT scalp EEG database, December 2023. https://doi.org/10.5281/zenodo. 10259996. 

- Stéphane d’Ascoli, Jérémy Rapin, Yohann Benchetrit, Teon Brookes, Katelyn Begany, Joséphine Raugel, Hubert Banville, and Jean-Rémi King. A foundation model of vision, audition, and language for in-silico neuroscience. https://ai.meta.com/research/publications/ a-foundation-model-of-vision-audition-and-language-for-in-silico-neuroscience/, 2026. 

- Alexandre Défossez, Charlotte Caucheteux, Jérémy Rapin, Ori Kabeli, and Jean-Rémi King. Decoding speech from non-invasive brain recordings. _arXiv preprint arXiv:2208.12266_ , 2022. 

- Jacob Devlin, Ming-Wei Chang, Kenton Lee, and Kristina Toutanova. BERT: Pre-training of deep bidirectional transformers for language understanding. In _Proceedings of the 2019 conference of the North American chapter of the association for computational linguistics: human language technologies, volume 1 (long and short papers)_ , pages 4171–4186, 2019. 

- Berkay Döner, Thorir Mar Ingolfsson, Luca Benini, and Yawei Li. LUNA: Efficient and topology-agnostic foundation model for EEG signal analysis. In _The Thirty-Ninth Annual Conference on Neural Information Processing Systems (NeurIPS)_ , 2025. https://openreview.net/forum?id=uazfjnFL0G. 

- Zijian Dong, Ruilin Li, Yilei Wu, Thuan T Nguyen, Joanna S Chong, Fang Ji, Nathanael R Tong, Christopher L Chen, and Juan H Zhou. Brain-JEPA: Brain dynamics foundation model with gradient positioning and spatiotemporal masking. _Advances in Neural Information Processing Systems_ , 37:86048–86073, 2024. 

- G. Dornhege, B. Blankertz, G. Curio, and K.-R. Muller. Boosting bit rates in noninvasive EEG single-trial classifications by feature combination and multiclass paradigms. _IEEE Transactions on Biomedical Engineering_ , 51(6):993–1002, June 2004. ISSN 1558-2531. doi: 10.1109/tbme.2004.827088. http://dx.doi.org/10.1109/TBME.2004.827088. 

- Pauline Dreyer, Aline Roc, Léa Pillette, Sébastien Rimbert, and Fabien Lotte. A large EEG database with users’ profile information for motor imagery brain-computer interface research. _Scientific Data_ , 10(1), September 2023. ISSN 2052-4463. doi: 10.1038/s41597-023-02445-z. http://dx.doi.org/10.1038/s41597-023-02445-z. 

17 

- Stéphane d’Ascoli, Corentin Bel, Jérémy Rapin, Hubert Banville, Yohann Benchetrit, Christophe Pallier, and Jean-Rémi King. Towards decoding individual words from non-invasive brain recordings. _Nature Communications_ , 16(1):10521, 2025. 

- Yassine El Ouahidi, Vincent Gripon, Bastien Pasdeloup, Ghaith Bouallegue, Nicolas Farrugia, and Giulia Lioi. A strong and simple deep learning baseline for bci motor imagery decoding. _arXiv preprint arXiv:2309.07159_ , 2023. https://arxiv.org/abs/2309.07159. 

- Yassine El Ouahidi, Jonathan Lys, Philipp Thölke, Nicolas Farrugia, Bastien Pasdeloup, Vincent Gripon, Karim Jerbi, and Giulia Lioi. REVE: A foundation model for EEG – adapting to any setup with large-scale pretraining on 25,000 subjects. In _The Thirty-Ninth Annual Conference on Neural Information Processing Systems (NeurIPS)_ , 2025. https://openreview.net/forum?id=ZeFMtRBy4Z. 

- William Falcon and The PyTorch Lightning team. PyTorch Lightning, March 2019. https://github.com/Lightning-AI/ lightning. 

- Josef Faller, Carmen Vidaurre, Teodoro Solis-Escalante, Christa Neuper, and Reinhold Scherer. Autocalibration and recurrent adaptation: Towards a plug and play online ERD-BCI. _IEEE Transactions on Neural Systems and Rehabilitation Engineering_ , 20(3):313–319, May 2012. ISSN 1558-0210. doi: 10.1109/tnsre.2012.2189584. http://dx.doi.org/10.1109/tnsre.2012.2189584. 

- Lukas A. W. Gemein, Robin T. Schirrmeister, Patryk Chrabaszcz, Daniel Wilson, Joschka Boedecker, Andreas Schulze-Bonhage, Frank Hutter, and Tonio Ball. Machine-learning-based diagnostics of EEG pathology. _NeuroImage_ , 220:117021, 2020. 

- Mohammad M Ghassemi, Benjamin E Moody, Li-wei H Lehman, Christopher Song, Qiao Li, Haoqi Sun, Roger G Mark, M Brandon Westover, and Gari D Clifford. You Snooze, You Win: The PhysioNet/Computing in Cardiology Challenge 2018. _Computing in cardiology_ , 45:10.22489/cinc.2018.049, September 2018. ISSN 2325-8861. doi: 10.22489/cinc.2018.049. 

- Alessandro T. Gifford, Kshitij Dwivedi, Gemma Roig, and Radoslaw M. Cichy. A large and rich EEG dataset for modeling human visual object recognition. _Neuroimage_ , 264:119754, December 2022a. ISSN 1053-8119. doi: 10.1016/j.neuroimage.2022.119754. https://pmc.ncbi.nlm.nih.gov/articles/PMC9771828/. 

- Alessandro T Gifford, Kshitij Dwivedi, Gemma Roig, and Radoslaw M Cichy. A large and rich EEG dataset for modeling human visual object recognition. _NeuroImage_ , 264:119754, 2022b. 

- Alessandro T Gifford, Benjamin Lahner, Sari Saba-Sadiya, Martina G Vilas, Alex Lascelles, Aude Oliva, Kendrick Kay, Gemma Roig, and Radoslaw M Cichy. The algonauts project 2023 challenge: How the human brain makes sense of natural scenes. _arXiv preprint arXiv:2301.03198_ , 2023. 

- Alessandro T Gifford, Domenic Bersch, Marie St-Laurent, Basile Pinsard, Julie Boyle, Lune Bellec, Aude Oliva, Gemma Roig, and Radoslaw M Cichy. The algonauts project 2025 challenge: How the human brain makes sense of multimodal movies. _arXiv preprint arXiv:2501.00504_ , 2024. 

- Alexandre Gramfort, Martin Luessi, Eric Larson, Denis A. Engemann, Daniel Strohmeier, Christian Brodbeck, Roman Goj, Mainak Jas, Teon Brooks, Lauri Parkkonen, and Matti Hämäläinen. MEG and EEG data analysis with MNE-Python. _Frontiers in Neuroscience_ , 7, December 2013. ISSN 1662-453X. doi: 10.3389/fnins.2013.00267. 

- M. Grosse-Wentrup, C. Liefhold, K. Gramann, and M. Buss. Beamforming in noninvasive Brain-Computer interfaces. _IEEE Transactions on Biomedical Engineering_ , 56(4):1209–1219, April 2009. ISSN 1558-2531. doi: 10.1109/tbme. 2008.2009768. http://dx.doi.org/10.1109/TBME.2008.2009768. 

- Christoph Guger, Shahab Daban, Eric Sellers, Clemens Holzner, Gunther Krausz, Roberta Carabalona, Furio Gramatica, and Guenter Edlinger. How many people are able to control a P300-based brain-computer interface (BCI)? _Neuroscience Letters_ , 462(1):94–98, September 2009. ISSN 0304-3940. doi: 10.1016/j.neulet.2009.06.045. http://dx.doi.org/10.1016/j.neulet.2009.06.045. 

- A. Hamid, K. Gagliano, S. Rahman, N. Tulin, V. Tchiong, I. Obeid, and J. Picone. The Temple University Artifact Corpus: An annotated corpus of EEG artifacts. pages 1–4, 2020. 

- Amir Harati, Silvia Lopez, I Obeid, J Picone, MP Jacobson, and S Tobochnik. The TUH EEG Corpus: A big data resource for automated EEG interpretation. In _2014 IEEE signal processing in medicine and biology symposium (SPMB)_ , pages 1–5. IEEE, 2014. 

- Amir Harati, Meysam Golmohammadi, Silvia Lopez, Iyad Obeid, and Joseph Picone. Improved EEG event classification using differential energy. pages 1–4, 2015. 

18 

- Stefan Haufe, Matthias S Treder, Manfred F Gugler, Max Sagebaum, Gabriel Curio, and Benjamin Blankertz. EEG potentials predict upcoming emergency brakings during simulated driving. _Journal of Neural Engineering_ , 8(5): 056001, July 2011. ISSN 1741-2552. doi: 10.1088/1741-2560/8/5/056001. http://dx.doi.org/10.1088/1741-2560/8/ 5/056001. 

- Martin N Hebart, Oliver Contier, Lina Teichmann, Adam H Rockter, Charles Y Zheng, Alexis Kidder, Anna Corriveau, Maryam Vaziri-Pashkam, and Chris I Baker. THINGS-data, a multimodal collection of large-scale datasets for investigating object representations in human brain and behavior. _eLife_ , 12:e82580, feb 2023. ISSN 2050-084X. doi: 10.7554/eLife.82580. https://doi.org/10.7554/eLife.82580. 

- Marcel F. Hinss, Emilie S. Jahanpour, Bertille Somon, Lou Pluchon, Frédéric Dehais, and Raphaëlle N. Roy. COG-BCI database: A multi-session and multi-task EEG cognitive dataset for passive brain-computer interfaces, July 2022. 

- Marcel F. Hinss, Emilie S. Jahanpour, Bertille Somon, Lou Pluchon, Frédéric Dehais, and Raphaëlle N. Roy. Open multisession and multi-task EEG cognitive dataset for passive brain-computer interface applications. _Scientific Data_ , 10(1), February 2023. ISSN 2052-4463. doi: 10.1038/s41597-022-01898-y. http://dx.doi.org/10.1038/s41597-022-01898-y. 

- Arthur E Hoerl and Robert W Kennard. Ridge regression: Biased estimation for nonorthogonal problems. _Technometrics_ , 12(1):55–67, 1970. 

- Ulrich Hoffmann, Jean-Marc Vesin, Touradj Ebrahimi, and Karin Diserens. An efficient P300-based brain-computer interface for disabled subjects. _Journal of Neuroscience Methods_ , 167(1):115–125, January 2008. ISSN 0165-0270. doi: 10.1016/j.jneumeth.2007.03.005. http://dx.doi.org/10.1016/j.jneumeth.2007.03.005. 

- Nora Hollenstein, Jonathan Rotsztejn, Marius Troendle, Andreas Pedroni, Ce Zhang, and Nicolas Langer. ZuCo, a simultaneous EEG and eye-tracking resource for natural sentence reading. _Scientific Data_ , 5(1), December 2018. ISSN 2052-4463. 

- Edward J Hu, Yelong Shen, Phillip Wallis, Zeyuan Allen-Zhu, Yuanzhi Li, Shean Wang, Liang Wang, Weizhu Chen, et al. LoRA: Low-rank adaptation of large language models. _Iclr_ , 1(2):3, 2022. 

- Johannes Höhne. A novel 9-class auditory ERP paradigm driving a predictive text entry system. _Frontiers in Neuroscience_ , 5, 2011. ISSN 1662-453X. doi: 10.3389/fnins.2011.00099. http://dx.doi.org/10.3389/fnins.2011.00099. 

- David Hübner. EEG data for: "Learning From Label Proportions In Brain-Computer Interfaces", 2016. https: //zenodo.org/record/192684. 

- David Hübner, Thibault Verhoeven, Konstantin Schmid, Klaus-Robert Müller, Michael Tangermann, and PieterJan Kindermans. Learning from label proportions in brain-computer interfaces: Online unsupervised learning with guarantees. _PLOS ONE_ , 12(4):e0175856, April 2017. ISSN 1932-6203. doi: 10.1371/journal.pone.0175856. http://dx.doi.org/10.1371/journal.pone.0175856. 

- Ping-Keng Jao, Ricardo Chavarriaga, and José del R. Millán. EEG-Based online regulation of difficulty in simulated flying. _IEEE Transactions on Affective Computing_ , 14(1):394–405, January 2023. ISSN 2371-9850. doi: 10.1109/ taffc.2021.3059688. http://dx.doi.org/10.1109/TAFFC.2021.3059688. 

- Vinay Jayaram and Alexandre Barachant. MOABB: trustworthy algorithm benchmarking for bcis. _Journal of neural engineering_ , 15(6):066011, 2018. 

- Wei-Bang Jiang, Li-Ming Zhao, and Bao-Liang Lu. Large brain model for learning generic representations with tremendous EEG data in BCI. In _The Twelfth International Conference on Learning Representations (ICLR)_ , 2024. 

- Emmanuel K. Kalunga, Sylvain Chevallier, Quentin Barthélemy, Karim Djouani, Eric Monacelli, and Yskandar Hamam. Online SSVEP-based BCI using Riemannian geometry. _Neurocomputing_ , 191:55–68, May 2016. ISSN 0925-2312. doi: 10.1016/j.neucom.2016.01.007. http://dx.doi.org/10.1016/j.neucom.2016.01.007. 

- Emily S. Kappenman, Jaclyn L. Farrens, Wendy Zhang, Andrew X. Stewart, and Steven J. Luck. ERP CORE: An open resource for human event-related potential research. _NeuroImage_ , 225:117465, January 2021. ISSN 1053-8119. doi: 10.1016/j.neuroimage.2020.117465. http://dx.doi.org/10.1016/j.neuroimage.2020.117465. 

- Brianna M Karpowicz, Joel Ye, Chaofei Fan, Pablo Tostado-Marcos, Fabio Rizzoglio, Clay Washington, Thiago Scodeler, Diogo de Lucena, Samuel R Nason-Tomaszewski, Matthew J Mender, et al. Few-shot algorithms for consistent neural decoding (FALCON) benchmark. _Advances in Neural Information Processing Systems_ , 37:76578–76615, 2024. 

- Ard Kastrati, Josua Bürki, Jonas Lauer, Cheng Xuan, Raffaele Iaquinto, and Roger Wattenhofer. EEG-Bench: A Benchmark for EEG Foundation Models in Clinical Applications. In _NeurIPS 2025 Workshop on Foundation Models for the Brain and Body_ , 2025. 

19 

- B. Kemp, A.H. Zwinderman, B. Tuk, H.A.C. Kamphuisen, and J.J.L. Oberye. Analysis of a sleep-dependent neuronal feedback loop: the slow-wave microcontinuity of the EEG. _IEEE Transactions on Biomedical Engineering_ , 47(9): 1185–1194, 2000. 

- Peter Kim, Junbeom Kwon, Sunghwan Joo, Sangyoon Bae, Donggyu Lee, Yoonho Jung, Shinjae Yoo, Jiook Cha, and Taesup Moon. SwiFT: Swin 4D fMRI Transformer. In A. Oh, T. Naumann, A. Globerson, K. Saenko, M. Hardt, and S. Levine, editors, _Advances in Neural Information Processing Systems_ , volume 36, pages 42015–42037. Curran Associates, Inc., 2023. 

- Jean-Rémi King, Teon L. Brooks, Katie Begany, Lucy Zhang, Josephine Raugel, Jarod Lévy, Sophia Houhamdi, Julien Gadonneix, Linnea Evanson, Corentin Bel, Stéphane d’Ascoli, Marlène Careil, Yohann Benchetrit, Hubert Banville, and Jérémy Rapin. Neuralset: A high-performing python package for neuro-ai. 2026. 

- Simon Kojima. Replication data for: Four-class ASME BCI: investigation of the feasibility and comparison of two strategies for multiclassing, 2024. https://dataverse.harvard.edu/citation?persistentId=doi:10.7910/DVN/ 1UJDV6. 

- Simon Kojima and Shin’ichiro Kanoh. Replication data for: An auditory brain-computer interface based on selective attention to multiple tone streams, 2024. https://dataverse.harvard.edu/citation?persistentId=doi:10.7910/DVN/ MQOVEY. 

- Louis Korczowski, Martine Cederhout, Anton Andreev, Grégoire Cattan, Pedro Luis Coelho Rodrigues, Violette Gautheret, and Marco Congedo. Brain invaders calibration-less P300-based BCI with modulation of flash duration dataset (bi2015a), 2019a. https://zenodo.org/record/3266930. 

- Louis Korczowski, Ekaterina Ostaschenko, Anton Andreev, Grégoire Cattan, Pedro Luis Coelho Rodrigues, Violette Gautheret, and Marco Congedo. Brain invaders calibration-less P300-based BCI using dry EEG electrodes dataset (bi2014a), 2019b. https://zenodo.org/record/3266223. 

- Louis Korczowski, Ekaterina Ostaschenko, Anton Andreev, Grégoire Cattan, Pedro Luis Coelho Rodrigues, Violette Gautheret, and Marco Congedo. Brain invaders solo versus collaboration: Multi-User P300-based Brain-Computer interface dataset (bi2014b), 2019c. https://zenodo.org/record/3267301. 

- Demetres Kostas, Stephane Aroca-Ouellette, and Frank Rudzicz. BENDR: Using transformers and a contrastive self-supervised learning task to learn from massive amounts of EEG data. _Frontiers in Human Neuroscience_ , 15: 653659, 2021. 

- Niklas Kueper, Kartik Chari, Judith Bütefür, Julia Habenicht, Tobias Rossol, Su Kyoung Kim, Marc Tabie, Frank Kirchner, and Elsa Andrea Kirchner. EEG and EMG dataset for the detection of errors introduced by an active orthosis device. _Frontiers in Human Neuroscience_ , 18, January 2024. ISSN 1662-5161. doi: 10.3389/fnhum.2024.1304311. 

- Vernon J. Lawhern, Amelia J. Solon, Nicholas R. Waytowich, Stephen M. Gordon, Chou P. Hung, and Brent J. Lance. EEGNet: a compact convolutional neural network for EEG-based brain–computer interfaces. _Journal of Neural Engineering_ , 15(5):056013, 2018. 

- Min-Ho Lee, O-Yeon Kwon, Yong-Jeong Kim, Hong-Kyung Kim, Young-Eun Lee, John Williamson, Siamac Fazli, and Seong-Whan Lee. EEG dataset and OpenBMI toolbox for three BCI paradigms: an investigation into BCI illiteracy. _GigaScience_ , 8(5), January 2019. ISSN 2047-217X. doi: 10.1093/gigascience/giz002. http://dx.doi.org/10.1093/ gigascience/giz002. 

- Robert Leeb, Felix Lee, Claudia Keinrath, Reinhold Scherer, Horst Bischof, and Gert Pfurtscheller. Brain-Computer communication: Motivation, aim, and impact of exploring a virtual apartment. _IEEE Transactions on Neural Systems and Rehabilitation Engineering_ , 15(4):473–482, December 2007. ISSN 1558-0210. doi: 10.1109/tnsre.2007.906956. http://dx.doi.org/10.1109/TNSRE.2007.906956. 

- Brian Lester, Rami Al-Rfou, and Noah Constant. The power of scale for parameter-efficient prompt tuning. In _Proceedings of the 2021 conference on empirical methods in natural language processing_ , pages 3045–3059, 2021. 

- Jarod Lévy, Mingfang Zhang, Svetlana Pinet, Jérémy Rapin, Hubert Banville, Stéphane d’Ascoli, and Jean-Rémi King. Brain-to-text decoding: A non-invasive approach via typing. _arXiv preprint arXiv:2502.17480_ , 2025. 

- Haijie Liu, Penghu Wei, Haochong Wang, Xiaodong Lv, Wei Duan, Meijie Li, Yan Zhao, Qingmei Wang, Xinyuan Chen, Gaige Shi, Bo Han, and Junwei Hao. An EEG motor imagery dataset for brain computer interface in acute stroke patients. _Scientific Data_ , 11(1), January 2024a. ISSN 2052-4463. doi: 10.1038/s41597-023-02787-8. http://dx.doi.org/10.1038/s41597-023-02787-8. 

20 

- Xuan-Hao Liu, Yan-Kai Liu, Yansen Wang, Kan Ren, Hanwen Shi, Zilong Wang, Dongsheng Li, Bao-Liang Lu, and Wei-Long Zheng. EEG2video: Towards decoding dynamic visual perception from EEG signals. _Advances in Neural Information Processing Systems_ , 37:72245–72273, 2024b. 

- Sebas Lopez, G Suarez, D Jungreis, I Obeid, and Joseph Picone. Automated identification of abnormal adult EEGs. In _2015 IEEE signal processing in medicine and biology symposium (SPMB)_ , pages 1–5. IEEE, 2015. 

- Silvia Isabel Lopez de Diego. Automated interpretation of abnormal adult electroencephalograms. 2017. https: //www.isip.piconepress.com/publications/ms_theses/2017/abnormal/thesis/. 

- Ilya Loshchilov and Frank Hutter. Decoupled weight decay regularization. _arXiv preprint arXiv:1711.05101_ , 2017. 

- Víctor Martínez-Cagigal. Dataset: Influence of spatial frequency in visual stimuli for cVEP-based BCIs: evaluation of performance and user experience, 2023. https://uvadoc.uva.es/handle/10324/70973. 

- Víctor Martínez-Cagigal. Dataset: Non-binary m-sequences for more comfortable brain-computer interfaces based on c-VEPs, 2024. https://uvadoc.uva.es/handle/10324/70945. 

- Christoph M Michel and Micah M Murray. Towards the utilization of EEG as a brain imaging tool. _Neuroimage_ , 61 (2):371–385, 2012. 

- Andreas Miltiadous, Emmanouil Gionanidis, Katerina D. Tzimourta, Nikolaos Giannakeas, and Alexandros T. Tzallas. DICE-Net: A Novel Convolution-Transformer Architecture for Alzheimer Detection in EEG Signals. _IEEE Access_ , 11:71840–71858, 2023. ISSN 2169-3536. doi: 10.1109/ACCESS.2023.3294618. 

- Wajid Mumtaz, Syed Saad Azhar Ali, Mohd Azhar Mohd Yasin, and Aamir Saeed Malik. A machine learning framework involving EEG-based functional connectivity to diagnose major depressive disorder (MDD). _Medical & Biological Engineering & Computing_ , 56(2):233–246, February 2018. ISSN 1741-0444. doi: 10.1007/s11517-017-1685-z. 

- Masaki Nakanishi, Yijun Wang, Yu-Te Wang, and Tzyy-Ping Jung. A comparison study of canonical correlation analysis based methods for detecting Steady-State visual evoked potentials. _PLOS ONE_ , 10(10):e0140703, October 2015. ISSN 1932-6203. doi: 10.1371/journal.pone.0140703. http://dx.doi.org/10.1371/journal.pone.0140703. 

- Thomas Naselaris, Kendrick N Kay, Shinji Nishimoto, and Jack L Gallant. Encoding and decoding in fMRI. _Neuroimage_ , 56(2):400–410, 2011. 

- Mante S Nieuwland, Stephen Politzer-Ahles, Evelien Heyselaar, Katrien Segaert, Emily Darley, Nina Kazanina, Sarah Von Grebmer Zu Wolfsthurn, Federica Bartolozzi, Vita Kogan, Aine Ito, et al. Large-scale replication study reveals a limit on probabilistic prediction in language comprehension. _ELife_ , 7:e33468, 2018. 

- Patrick Ofner, Andreas Schwarz, Joana Pereira, and Gernot R. Müller-Putz. Upper limb movements can be decoded from the time-domain of low-frequency EEG. _PLOS ONE_ , 12(8):e0182578, August 2017. ISSN 1932-6203. doi: 10.1371/journal.pone.0182578. http://dx.doi.org/10.1371/journal.pone.0182578. 

- Vangelis P. Oikonomou, Georgios Liaros, Kostantinos Georgiadis, Elisavet Chatzilari, Katerina Adam, Spiros Nikolopoulos, and Ioannis Kompatsiaris. Comparative evaluation of state-of-the-art algorithms for SSVEP-based BCIs, 2016. https://arxiv.org/abs/1602.00904. 

- Maxime Oquab, Timothée Darcet, Théo Moutakanni, Huy Vo, Marc Szafraniec, Vasil Khalidov, Pierre Fernandez, Daniel Haziza, Francisco Massa, Alaaeldin El-Nouby, et al. DINOv2: Learning robust visual features without supervision. _Transactions on Machine Learning Research Journal_ , 2024. 

- Adam Paszke, Sam Gross, Francisco Massa, Adam Lerer, James Bradbury, Gregory Chanan, Trevor Killeen, Zeming Lin, Natalia Gimelshein, Luca Antiga, et al. PyTorch: An imperative style, high-performance deep learning library. _Advances in neural information processing systems_ , 32, 2019. 

- Ana Luísa Pinho, Alexis Amadon, Torsten Ruest, Murielle Fabre, Elvis Dohmatob, Isabelle Denghien, Chantal Ginisty, Séverine Becuwe-Desmidt, Séverine Roger, Laurence Laurier, et al. Individual Brain Charting, a high-resolution fMRI dataset for cognitive mapping. _Scientific data_ , 5(1):180105, 2018. 

- Russell A Poldrack. Can cognitive processes be inferred from neuroimaging data? _Trends in cognitive sciences_ , 10(2): 59–63, 2006. 

- Russell A Poldrack. Inferring mental states from neuroimaging data: from reverse inference to large-scale decoding. _Neuron_ , 72(5):692–697, 2011. 

21 

- Russell A Poldrack, Chris I Baker, Joke Durnez, Krzysztof J Gorgolewski, Paul M Matthews, Marcus R Munafò, Thomas E Nichols, Jean-Baptiste Poline, Edward Vul, and Tal Yarkoni. Scanning the horizon: towards transparent and reproducible neuroimaging research. _Nature reviews neuroscience_ , 18(2):115–126, 2017. 

- Alec Radford, Jong Wook Kim, Chris Hallacy, Aditya Ramesh, Gabriel Goh, Sandhini Agarwal, Girish Sastry, Amanda Askell, Pamela Mishkin, Jack Clark, Gretchen Krueger, and Ilya Sutskever. Learning transferable visual models from natural language supervision, 2021. 

- J. Rapin and J.-R. King. Exca - Execution and caching. https://github.com/facebookresearch/exca, 2024. 

- Christoph Reichert, Igor Fabian Tellez Ceja, Catherine M. Sweeney-Reed, Hans-Jochen Heinze, Hermann Hinrichs, and Stefan Dürschmid. Impact of stimulus features on the performance of a Gaze-Independent Brain-Computer interface based on covert spatial attention shifts. _Frontiers in Neuroscience_ , 14, December 2020. ISSN 1662-453X. doi: 10.3389/fnins.2020.591777. http://dx.doi.org/10.3389/fnins.2020.591777. 

- Angela Riccio, Luca Simione, Francesca Schettini, Alessia Pizzimenti, Maurizio Inghilleri, Marta Olivetti Belardinelli, Donatella Mattia, and Febo Cincotti. Attention and P300-based BCI performance in people with amyotrophic lateral sclerosis. _Frontiers in Human Neuroscience_ , 7, 2013. ISSN 1662-5161. doi: 10.3389/fnhum.2013.00732. http://dx.doi.org/10.3389/fnhum.2013.00732. 

- Bertrand Rivet, Antoine Souloumiac, Virginie Attina, and Guillaume Gibert. xDAWN algorithm to enhance evoked potentials: application to brain–computer interface. _IEEE Transactions on Biomedical Engineering_ , 56(8):2035–2043, 2009. 

- Michele Romani, Devis Zanoni, Elisabetta Farella, and Luca Turchet. BrainForm: a serious game for BCI training and data collection, 2025. https://arxiv.org/abs/2510.10169. 

- Simanto Saha and Mathias Baumert. Intra-and inter-subjecct variability in EEG-based sensorimotor brain computer interface: a review. _Frontiers in computational neuroscience_ , 13:87, 2020. 

- Sulamith Schaeff, Matthias Sebastian Treder, Bastian Venthur, and Benjamin Blankertz. Exploring motion VEPs for gaze-independent communication. _Journal of Neural Engineering_ , 9(4):045006, July 2012. ISSN 1741-2552. doi: 10.1088/1741-2560/9/4/045006. http://dx.doi.org/10.1088/1741-2560/9/4/045006. 

- G. Schalk, D.J. McFarland, T. Hinterberger, N. Birbaumer, and J.R. Wolpaw. BCI2000: a general-purpose braincomputer interface (BCI) system. _IEEE Transactions on Biomedical Engineering_ , 51(6):1034–1043, 2004. 

- Reinhold Scherer, Josef Faller, David Balderas, Elisabeth V. C. Friedrich, Markus Pröll, Brendan Allison, and Gernot Müller-Putz. Brain-computer interfacing: more than the sum of its parts. _Soft Computing_ , 17(2):317–331, July 2012. ISSN 1433-7479. doi: 10.1007/s00500-012-0895-4. http://dx.doi.org/10.1007/s00500-012-0895-4. 

- Reinhold Scherer, Josef Faller, Elisabeth V. C. Friedrich, Eloy Opisso, Ursula Costa, Andrea Kübler, and Gernot R. Müller-Putz. Individually adapted imagery improves Brain-Computer interface performance in End-Users with disability. _PLOS ONE_ , 10(5):e0123727, May 2015. ISSN 1932-6203. doi: 10.1371/journal.pone.0123727. http: //dx.doi.org/10.1371/journal.pone.0123727. 

- Robin Tibor Schirrmeister, Jost Tobias Springenberg, Lukas Dominique Josef Fiederer, Martin Glasstetter, Katharina Eggensperger, Michael Tangermann, Frank Hutter, Wolfram Burgard, and Tonio Ball. Deep learning with convolutional neural networks for eeg decoding and visualization. _Human Brain Mapping_ , aug 2017. ISSN 1097-0193. doi: 10.1002/hbm.23730. http://dx.doi.org/10.1002/hbm.23730. 

- Martijn Schreuder, Benjamin Blankertz, and Michael Tangermann. A new auditory Multi-Class Brain-Computer interface paradigm: Spatial hearing as an informative cue. _PLoS ONE_ , 5(4):e9813, April 2010. ISSN 1932-6203. doi: 10.1371/journal.pone.0009813. http://dx.doi.org/10.1371/journal.pone.0009813. 

- Martin Schrimpf, Jonas Kubilius, Ha Hong, Najib J Majaj, Rishi Rajalingham, Elias B Issa, Kohitij Kar, Pouya Bashivan, Jonathan Prescott-Roy, Franziska Geiger, et al. Brain-score: Which artificial neural network for object recognition is most brain-like? _BioRxiv_ , page 407007, 2018. 

- Martin Schrimpf, Jonas Kubilius, Michael J Lee, N Apurva Ratan Murty, Robert Ajemian, and James J DiCarlo. Integrative benchmarking to advance neurally mechanistic models of human intelligence. _Neuron_ , 2020. https: //www.cell.com/neuron/fulltext/S0896-6273(20)30605-X. 

- Andreas Schwarz, Carlos Escolano, Luis Montesano, and Gernot R. Müller-Putz. Analyzing and decoding natural Reach-and-Grasp actions using gel, water and dry EEG systems. _Frontiers in Neuroscience_ , 14, August 2020. ISSN 1662-453X. doi: 10.3389/fnins.2020.00849. http://dx.doi.org/10.3389/fnins.2020.00849. 

22 

- Jaeyoung Shin, Alexander von Luhmann, Benjamin Blankertz, Do-Won Kim, Jichai Jeong, Han-Jeong Hwang, and KlausRobert Muller. Open access dataset for EEG+NIRS Single-Trial classification. _IEEE Transactions on Neural Systems and Rehabilitation Engineering_ , 25(10):1735–1745, October 2017. ISSN 1558-0210. doi: 10.1109/tnsre.2016.2628057. http://dx.doi.org/10.1109/TNSRE.2016.2628057. 

- Seyed Yahya Shirazi, Alexandre Franco, Maurício Scopel Hoffmann, Nathalia B Esper, Dung Truong, Arnaud Delorme, Michael P Milham, and Scott Makeig. HBN-EEG: The FAIR implementation of the Healthy Brain Network (HBN) electroencephalography dataset. _bioRxiv_ , pages 2024–10, 2024. 

- Arun Singh, Rachel C. Cole, Arturo I. Espinoza, Aron Evans, Scarlett Cao, James F. Cavanagh, and Nandakumar S. Narayanan. Timing variability and midfrontal ˜4 Hz rhythms correlate with cognition in Parkinson’s disease. _npj Parkinson’s Disease_ , 7(1):14, February 2021. ISSN 2373-8057. doi: 10.1038/s41531-021-00158-x. 

- Yonghao Song, Qingqing Zheng, Bingchuan Liu, and Xiaorong Gao. EEG Conformer: Convolutional transformer for EEG decoding and visualization. _IEEE Transactions on Neural Systems and Rehabilitation Engineering_ , 31:710–719, 2022. https://ieeexplore.ieee.org/document/9991178. 

- Jan Sosulski and Michael Tangermann. Electroencephalogram signals recorded from 13 healthy subjects during an auditory oddball paradigm under different stimulus onset asynchrony conditions, 2019. https://freidok.uni-freiburg. de/data/154576. 

- Nitikorn Srisrisawang and Gernot R Müller-Putz. Simultaneous encoding of speed, distance, and direction in discrete reaching: an EEG study. _Journal of Neural Engineering_ , 21(6):066042, December 2024. ISSN 1741-2552. doi: 10.1088/1741-2552/ada0ea. http://dx.doi.org/10.1088/1741-2552/ada0ea. 

- James R. Stieger, Stephen A. Engel, and Bin He. Continuous sensorimotor rhythm based brain computer interface learning in a large population. _Scientific Data_ , 8(1), April 2021. ISSN 2052-4463. doi: 10.1038/s41597-021-00883-1. http://dx.doi.org/10.1038/s41597-021-00883-1. 

- Chenxi Sun, Jin Jing, Niels Turley, Callison Alcott, Wan-Yee Kang, Andrew J Cole, Daniel M Goldenholz, Alice Lam, Edilberto Amorim, Catherine Chu, et al. Harvard Electroencephalography Database: A comprehensive clinical electroencephalographic resource from four boston hospitals. _Epilepsia_ , 66(9):3411–3425, 2025. 

- Divyanshu Tak, Biniam A Garomsa, Anna Zapaishchykova, Tafadzwa L Chaunzwa, Juan Carlos Climent Pardo, Zezhong Ye, John Zielke, Yashwanth Ravipati, Suraj Pai, Sri Vajapeyam, et al. A generalizable foundation model for analysis of human brain MRI. _Nature Neuroscience_ , pages 1–12, 2026. 

- Michael Tangermann, Klaus-Robert Müller, Ad Aertsen, Niels Birbaumer, Christoph Braun, Clemens Brunner, Robert Leeb, Carsten Mehring, Kai J. Miller, Gernot R. Müller-Putz, Guido Nolte, Gert Pfurtscheller, Hubert Preissl, Gerwin Schalk, Alois Schlögl, Carmen Vidaurre, Stephan Waldert, and Benjamin Blankertz. Review of the BCI competition IV. _Frontiers in Neuroscience_ , 6, 2012. ISSN 1662-4548. doi: 10.3389/fnins.2012.00055. http://dx.doi.org/10.3389/fnins.2012.00055. 

- Jason R Taylor, Nitin Williams, Rhodri Cusack, Tibor Auer, Meredith A Shafto, Marie Dixon, Lorraine K Tyler, Richard N Henson, et al. The Cambridge Centre for Ageing and Neuroscience (Cam-CAN) data repository: Structural and functional MRI, MEG, and cognitive data from a cross-sectional adult lifespan sample. _neuroimage_ , 144:262–269, 2017. 

- Jordy Thielen, Philip van den Broek, Jason Farquhar, and Peter Desain. Broad-Band visually evoked potentials: Re(con)volution in Brain-Computer interfacing. _PLOS ONE_ , 10(7):e0133797, July 2015. ISSN 1932-6203. doi: 10.1371/journal.pone.0133797. http://dx.doi.org/10.1371/journal.pone.0133797. 

- Jordy Thielen, Pieter Marsman, Jason Farquhar, and Peter Desain. From full calibration to zero training for a code-modulated visual evoked potentials brain computer interface. _Journal of Neural Engineering_ , March 2021. ISSN 1741-2552. doi: 10.1088/1741-2552/abecef. http://dx.doi.org/10.1088/1741-2552/abecef. 

- M S Treder, N M Schmidt, and B Blankertz. Gaze-independent brain-computer interfaces based on covert attention and feature attention. _Journal of Neural Engineering_ , 8(6):066003, October 2011. ISSN 1741-2552. doi: 10.1088/ 1741-2560/8/6/066003. http://dx.doi.org/10.1088/1741-2560/8/6/066003. 

- M S Treder, H Purwins, D Miklody, I Sturm, and B Blankertz. Decoding auditory attention to instruments in polyphonic music using single-trial EEG classification. _Journal of Neural Engineering_ , 11(2):026009, March 2014. ISSN 1741-2552. doi: 10.1088/1741-2560/11/2/026009. http://dx.doi.org/10.1088/1741-2560/11/2/026009. 

- Polina Turishcheva, Paul G Fahey, Michaela Vystrčilová, Laura Hansel, Rachel Froebe, Kayla Ponder, Yongrong Qiu, 

23 

Konstantin F Willeke, Mohammad Bashiri, Eric Wang, et al. The dynamic sensorium competition for predicting large-scale mouse visual cortex activity from videos. _ArXiv_ , 2024. 

- Erwan Vaineau, Alexandre Barachant, Anton Andreev, Pedro L. C. Rodrigues, Grégoire Cattan, and Marco Congedo. Brain invaders adaptive versus Non-Adaptive P300 Brain-Computer interface dataset, 2018. https://zenodo.org/ record/1494163. 

- David C Van Essen, Stephen M Smith, Deanna M Barch, Timothy EJ Behrens, Essa Yacoub, Kamil Ugurbil, WuMinn HCP Consortium, et al. The WU-Minn human connectome project: an overview. _Neuroimage_ , 80:62–79, 2013. 

- Gijsbrecht Franciscus Petrus Van Veen, Alexandre Barachant, Anton Andreev, Grégoire Cattan, Pedro Luis Coelho Rodrigues, and Marco Congedo. Building brain invaders: EEG data of an experimental validation, 2019. https://zenodo.org/record/2649006. 

- Christopher Wang, Vighnesh Subramaniam, Adam Uri Yaari, Gabriel Kreiman, Boris Katz, Ignacio Cases, and Andrei Barbu. BrainBERT: Self-supervised representation learning for intracranial recordings. In _The Eleventh International Conference on Learning Representations_ , 2023. 

- Eric Y Wang, Paul G Fahey, Zhuokun Ding, Stelios Papadopoulos, Kayla Ponder, Marissa A Weis, Andersen Chang, Taliah Muhammad, Saumil Patel, Zhiwei Ding, et al. Foundation model of neural activity predicts response to new stimulus types. _Nature_ , 640(8058):470–477, 2025a. 

- Guibin Wang, Wenbin Liu, Yiqun He, Cheng Xu, Li Ma, and Hong Li. EEGPT: Pretrained transformer for universal and reliable representation of EEG signals. In _Advances in Neural Information Processing Systems (NeurIPS)_ , volume 37, pages 39249–39280, 2024. https://proceedings.neurips.cc/paper_files/paper/2024/file/ 4540d267eeec4e5dbd9dae9448f0b739-Paper-Conference.pdf. 

- Jiquan Wang, Sha Zhao, Zhiling Luo, Yangxuan Zhou, Haiteng Jiang, Shijian Li, Tao Li, and Gang Pan. CBraMod: A criss-cross brain foundation model for EEG decoding. In _The Thirteenth International Conference on Learning Representations (ICLR)_ , 2025b. https://arxiv.org/abs/2412.07236. 

- Yijun Wang, Xiaogang Chen, Xiaorong Gao, and Shangkai Gao. A benchmark dataset for SSVEP-Based BrainComputer interfaces. _IEEE Transactions on Neural Systems and Rehabilitation Engineering_ , 25(10):1746–1752, October 2017. ISSN 1558-0210. doi: 10.1109/tnsre.2016.2627556. http://dx.doi.org/10.1109/TNSRE.2016.2627556. 

- Xiaoxi Wei, A Aldo Faisal, Moritz Grosse-Wentrup, Alexandre Gramfort, Sylvain Chevallier, Vinay Jayaram, Camille Jeunet, Stylianos Bakas, Siegfried Ludwig, Konstantinos Barmpas, et al. 2021 BEETL competition: Advancing transfer learning for subject independence and heterogenous EEG data sets. In _NeurIPS 2021 Competitions and Demonstrations Track_ , pages 205–219. PMLR, 2022. 

- Konstantin F Willeke, Paul G Fahey, Mohammad Bashiri, Laura Pede, Max F Burg, Christoph Blessing, Santiago A Cadena, Zhiwei Ding, Konstantin-Klemens Lurz, Kayla Ponder, et al. The sensorium competition on predicting large-scale mouse primary visual cortex activity. _arXiv preprint arXiv:2206.08666_ , 2022. 

- Jiamin Wu, Zichen Ren, Junyu Wang, Pengyu Zhu, Yonghao Song, Mianxin Liu, Qihao Zheng, Lei Bai, Wanli Ouyang, and Chunfeng Song. AdaBrain-Bench: Benchmarking brain foundation models for brain-computer interface applications. _arXiv preprint arXiv:2507.09882_ , 2025. 

- Wei Xiong, Jiangtong Li, Jie Li, Kun Zhu, and Changjun Jiang. EEG-FM-Bench: A comprehensive benchmark for the systematic evaluation of EEG foundation models. _arXiv preprint arXiv:2508.17742_ , 2025. 

- Chaoqi Yang, M. Brandon Westover, and Jimeng Sun. BIOT: Biosignal transformer for cross-data learning in the wild. In _Thirty-seventh Conference on Neural Information Processing Systems (NeurIPS)_ , 2023. 

- Shihao Yang, Xiying Huang, Danilo Bernardo, Jun-En Ding, Andrew Michael, Jingmei Yang, Patrick Kwan, Ashish Raj, and Feng Liu. Foundation and large-scale AI models in neuroscience: A comprehensive review. _arXiv preprint arXiv:2510.16658_ , 2025. 

- Florian Yger, Maxime Berar, and Fabien Lotte. Riemannian approaches in brain-computer interfaces: a review. _IEEE Transactions on Neural Systems and Rehabilitation Engineering_ , 25(10):1753–1762, 2016. 

- Weibo Yi, Shuang Qiu, Kun Wang, Hongzhi Qi, Lixin Zhang, Peng Zhou, Feng He, and Dong Ming. Evaluation of EEG oscillatory patterns and cognitive process during simple and compound limb motor imagery. _PLoS ONE_ , 9(12): e114853, December 2014. ISSN 1932-6203. doi: 10.1371/journal.pone.0114853. http://dx.doi.org/10.1371/journal. pone.0114853. 

24 

- Zhizhang Yuan, Fanqi Shen, Meng Li, Yuguo Yu, Chenhao Tan, and Yang Yang. BrainWave: A brain signal foundation model for clinical applications, 2024. https://arxiv.org/abs/2402.10251. 

- Mingfang Zhang, Jarod Lévy, Stéphane d’Ascoli, Jérémy Rapin, F Alario, Pierre Bourdillon, Svetlana Pinet, Jean-Rémi King, et al. From thought to action: How a hierarchy of neural dynamics supports language production. _arXiv preprint arXiv:2502.07429_ , 2025. 

- Wei Zhao, Xiaolu Jiang, Baocan Zhang, Shixiao Xiao, and Sujun Weng. CTNet: a convolutional transformer network for EEG-based motor imagery classification. _Scientific reports_ , 14(1):20237, 2024. 

- Bangyan Zhou, Xiaopei Wu, Zhao Lv, Lei Zhang, and Xiaojin Guo. A fully automated trial selection method for optimization of motor imagery based Brain-Computer interface. _PLOS ONE_ , 11(9):e0162657, September 2016. ISSN 1932-6203. doi: 10.1371/journal.pone.0162657. http://dx.doi.org/10.1371/journal.pone.0162657. 

- Xinliang Zhou, Chenyu Liu, Zhisheng Chen, Kun Wang, Yi Ding, Ziyu Jia, and Qingsong Wen. Brain foundation models: A survey on advancements in neural signal processing and brain discovery. _IEEE Signal Processing Magazine_ , 42(5):22–35, 2025. 

- Igor Zyma, Sergii Tukaev, Ivan Seleznov, Ken Kiyono, Anton Popov, Mariia Chernykh, and Oleksii Shpenkov. Electroencephalograms during mental arithmetic task performance. _Data_ , 4(1):14, January 2019. ISSN 2306-5729. doi: 10.3390/data4010014. http://dx.doi.org/10.3390/data4010014. 

25 

# **Appendix** 

### **A Additional details on downstream datasets and tasks** 

We provide the references for all datasets used in NeuralBench-EEG v1.0 (and the MEG and fMRI extensions) in Table S1. Detailed information about the _Core_ datasets for each task can be found in Table 1. We do not repeat references when multiple datasets come from the same paper. 

Of note, these datasets sometimes contain stimuli presented to the participants ( _e_ . _g_ . images, videos, text, etc.). We only make use of stimuli in the cognitive decoding tasks (Gifford et al., 2022b; Hollenstein et al., 2018; Brennan and Hale, 2019; Liu et al., 2024b; Nieuwland et al., 2018), as these tasks require the alignment of brain data to a dense representation of the stimuli. Apart from these cases, we discard stimulus information and only keep targets ( _e_ . _g_ . _classes_ for classification tasks). 

Detailed and up-to-date description of the downstream tasks can be found in the benchmark documentation at https://github.com/facebookresearch/neuroai/tree/main/neuralbench-repo. 

### **B Task-specific architectures and foundation models for EEG downstream tasks** 

We list the task-specific deep-learning architectures, handcrafted features-based sklearn baselines, and foundation models used on the EEG downstream tasks in Tables S2, S3 and S4. 

### **C Detailed splitting strategy** 

We split each dataset into a single training, validation and testing partition using a fixed seed. The way we split depends on the datasets. When datasets explicitly provide a development and evaluation split, we use it as is. This is the case for clinical event classification on TUEV (Harati et al., 2015), pathology detection on TUAB (Lopez et al., 2015), image decoding on THINGS-EEG2 (Gifford et al., 2022b) and motor imagery classification on the BEETL AI Challenge datasets (Wei et al., 2022). 

For cognitive decoding experiments, we focus on “leave-concept-out” evaluation, _i_ . _e_ ., all subjects are seen in both training and testing splits, but a common subset of the sessions or concepts are held out for testing. In many cases, this setting is required to obtain performance significantly above chance-level, as cross-subject generalization is particularly challenging on these types of tasks. For speech decoding on Brennan and Hale (2019), we keep the last 4 runs of each recording as test set. For sentence decoding on ZuCo v1 (Hollenstein et al., 2018), we randomly hold out 20% of the sentences read by the subjects to use as test set. For word decoding on Nieuwland et al. (2018), we randomly hold out 10% of the sentences read by the subjects to use as test set. For video decoding on SEED-DV (Liu et al., 2024b), we keep a random 20% of the video concepts ( _e_ . _g_ . land animal, human, natural scene, etc.) to use as test set. For typing decoding on (Lévy et al., 2025), sentences are clustered using their similarity in sentence embedding space (TF-IDF), and 20% of similar sentences are held out for testing. 

Most remaining tasks/datasets use a cross-subject split. For age, psychopathology, sex and reaction time prediction, all on the HBN-EEG dataset (Shirazi et al., 2024), we leave out all recordings from release 5 (out of 11 releases) for testing, which corresponds to _∼_ 329 held-out subjects. For other tasks, we hold out a random 20% of the subjects for testing. Of note, this cross-subject strategy is particularly challenging for certain tasks as inter-subject variability renders generalization difficult, _e_ . _g_ . in BCI (Saha and Baumert, 2020). Moreover, on clinical diagnosis tasks where subjects receive a single diagnosis (dementia, depression, Parkinson’s disease and schizophrenia), we use stratified splits based on the diagnosis label. 

A few datasets instead use a within-subject split by default to accommodate low (<10) subject counts, by keeping the last (few) sessions or runs for testing (Zhou et al., 2016; Chavarriaga and Millan, 2010; Hoffmann et al., 2008; Kueper et al., 2024). 

26 

Finally, we use fully random splits, _i_ . _e_ ., at the example level, for three low-sample datasets: audiovisual stimulus classification on the MNE Sample dataset (Gramfort et al., 2013) and motor imagery classification on the datasets from Dornhege et al. (2004); Barachant (2012). 

Validation sets (used for early stopping) are sampled from the remaining data, using the same or a similar splitting strategy as used for the test set, targeting another 20% of the overall dataset size. We train each model on each task three times, using three different random seeds for the initialization of the (non-pretrained) model parameters. 

### **D Performance metrics** 

We pick a single representative metric per task type to report in this document. For binary and multiclass classification, we use the balanced accuracy: 



where _C_ is the number of classes, _TPc_ is the number of true positives for class _c_ , and _FNc_ is the number of false negatives for class _c_ . 

For multilabel classification, we use the macro F1-score: 



where _Pc_ = _T PT Pc_ + _F Pc c_<sup>istheprecisionand</sup><sup>_Rc_=</sup> _T PcT P_ + _F Nc c_<sup>istherecallforclass</sup><sup>_c_.</sup> For univariate regression, we use the Pearson correlation: 



where _yi_ are the true values, _y_ ˆ _i_ are the predicted values, _y_ ¯ and _y_ ˆ<sup>¯</sup> are their respective means, and _n_ is the number of samples. 

Finally, for retrieval, we use the top-5 accuracy: 



with _k_ = 5, where _N_ is the number of queries, _yi_ is the true label (or relevant item) for query _i_ , _Y_<sup>ˆ</sup> _i_<sup>(</sup><sup>_k_)</sup> is the set of the top- _k_ retrieved candidates for query _i_ , and 1[ _·_ ] is the indicator function. 

More metrics are computed in NeuralBench, _e_ . _g_ . root mean-squared error (RMSE) for regression and median ranks for retrieval, but are not reported here for brevity. 

## **E Additional results on** NeuralBench-EEG-Core v1.0 

Figure S1 shows max-normalized scores over core datasets. 

## **F Additional results on** NeuralBench-EEG-Full v1.0 

Figure S2 shows performance on each multi-dataset downstream task included in NeuralBench-EEG-Full v1.0. 

27 



<!-- Start of picture text -->
Evoked Internal<br>Cognitive BCI Responses Clinical State Sleep Phenotyping Misc<br>Task best<br>1.0<br>0.8<br>0.6<br>0.4<br>0.2<br>0.0 Dummy<br>Best foundation model Best task-specific model Foundation model wins<br>Mean over foundation models Mean over task-specific models Task-specific model wins<br>ImageSentenceSpeechTypingVideoWordMental imageryMotor executionc-VEPMotor imageryP300SSVEPAudiovisualERNMMNN170N2pcN400LRPClinical eventDementiaDepressionParkinson'sPathologySchizophreniaSeizure EmotionMental arith.WorkloadSleep arousalSleep stagePsychopathologyAge Sex ArtifactReaction time<br>⋆<br>s<br>Normalized score ̃<br><!-- End of picture text -->

**Figure S1** Max-normalized performance _s_ ˜<sup>_∗_</sup> across downstream tasks, for the best and “average” models. As in Figure 5, but scores are normalized to be between “dummy” performance and per-task best model performance, highlighting variability as compared to the highest performing model. 

28 

**Table S1** Dataset references for all NeuralBench-EEG v1.0 tasks, grouped by category. References for the _primary_ dataset are listed first; additional dataset references follow. 

|Category|Task|Dataset references|
|---|---|---|
||Image<br>Sentence<br>|Giford et al. (2022a), Hebart et al. (2023), Allen et al. (2022)<br>Hollenstein et al. (2018)<br>|
|Cognitive|Speech<br>Typing<br>Video|Brennan and Hale (2019)<br>Lévy et al. (2025); Zhang et al. (2025)<br>Liu et al. (2024b)|
||Word|Nieuwland et al. (2018)|
||c-VEP|Cabrera Castillos et al. (2023), Martínez-Cagigal (2023), Martínez-<br>Cagigal (2024), Thielen et al. (2015), Thielen et al. (2021)|
|BCI|Mental imagery<br>Motor execution<br>Motor imagery|Scherer et al. (2015)<br>Srisrisawang and Müller-Putz (2024), Schirrmeister et al. (2017),<br>Ofner et al. (2017)<br>Stieger et al. (2021), Schalk et al. (2004), Barachant (2012), Cho<br>et al. (2017), Dornhege et al. (2004), Dreyer et al. (2023), Faller<br>et al. (2012), Grosse-Wentrup et al. (2009), Lee et al. (2019), Leeb<br>et al. (2007), Liu et al. (2024a), Schwarz et al. (2020), Shin et al.<br>(2017), Scherer et al. (2012), Tangermann et al. (2012), Wei et al.<br>(2022), Yi et al. (2014), Zhou et al. (2016)|
||P300<br>SSVEP|Schreuder et al. (2010), Kappenman et al. (2021), Acqualagna and<br>Blankertz (2013), Aricò et al. (2014), Cattan et al. (2019), Vaineau<br>et al.(2018), Guger et al.(2009), Haufe et al.(2011), Hofmann et al.<br>(2008), Hübner et al. (2017), Hübner (2016), Kojima and Kanoh<br>(2024), Kojima (2024), Korczowski et al. (2019b), Korczowski et al.<br>(2019c), Korczowski et al. (2019a), Lee et al. (2019), Riccio et al.<br>(2013), Romani et al. (2025), Schaef et al. (2012), Höhne (2011),<br>Sosulski and Tangermann (2019), Treder et al. (2011), Treder et al.<br>(2014), Van Veen et al. (2019)<br>Wang et al.(2017),Lee et al.(2019),Kalunga et al.(2016),Nakanishi<br>|
|||et al. (2015), Oikonomou et al. (2016)|
||Audiovisual stimulus|Gramfort et al. (2013)|
||Error-related negativity|Kappenman et al. (2021), Kueper et al. (2024), Chavarriaga and<br>|
|||Millan (2010)|
|Evoked<br>Responses|MMN|Kappenman et al. (2021)|
||N170<br>|Kappenman et al. (2021)<br>|
||N2pc<br>|Kappenman et al. (2021), Reichert et al. (2020)<br>|
||N400|Kappenman et al. (2021)|
||Lateralized readiness potential|Kappenman et al. (2021)|
||Clinical event detection<br>|Harati et al. (2015)<br>|
||Dementia diagnosis|Miltiadous et al. (2023)|
||Depression diagnosis|Mumtaz et al. (2018)|
|Clinical|Parkinson’s diagnosis<br>|Singh et al. (2021)<br>|
||Pathology|Lopez de Diego (2017)|
||Schizophrenia diagnosis|Albrecht et al. (2019)|
||Seizure detection|Dan and Shoeb (2023)|
|Internal|Emotion recognition<br>|Chen et al. (2023)<br>|
|State|Mental arithmetic<br>Mental workload|Zyma et al. (2019), Shin et al. (2017)<br>Hinss et al. (2022), Hinss et al. (2023), Jao et al. (2023)|
||Sleep arousal|Ghassemi et al. (2018)|
|Sleep|Sleep stage|Kemp et al. (2000)|
||Age|Shirazi et al. (2024)|
|Phenotyping|Psychopathology|Shirazi et al. (2024)|
||Sex|Shirazi et al. (2024)|
||Artifact detection|Hamid et al. (2020)|
|Misc|Reaction time|Shirazi et al. (2024)|



29 

**Table S2** Task-specific EEG models evaluated in NeuralBench-EEG v1.0. Parameter counts are backbone-only (excluding the task-specific output head) and are approximate as they depend on the number of input channels (we use a representative value of _C_ =22) here. 

|Model|# Params|Reference|
|---|---|---|
|ShallowFBCSPNet|36K|Schirrmeister et al. (2017)|
|Deep4Net|146K|Schirrmeister et al. (2017)|
|EEGNet|1.5K|Lawhern et al. (2018)|
|BDTCN|27K|Gemein et al. (2020)|
|EEGConformer|277K|Song et al. (2022)|
|ATCNet|29K|Altaheri et al. (2022)|
|SimpleConvTimeAgg|4.2M|El Ouahidi et al. (2023)|
|CTNet|150K|Zhao et al. (2024)|



**Table S3** Handcrafted features-based sklearn baselines evaluated in NeuralBench-EEG v1.0. These pipelines are fit once on the concatenation of the training and validation sets and evaluated with the exact same preprocessing and splits as the deep learning models. A single pipeline is used per task type; see _Tasks_ column. 

|Pipeline|Description|Tasks|Reference|
|---|---|---|---|
|XdawnTsLR|xDAWN covariances _→_shrinkage _→_tan-<br>gent space _→_standard scaling _→_logistic<br>regression (CV-tuned _C_)|Classifcation: _Evoked_ re-<br>sponse and _P300_|Rivet et al. (2009),<br>Barachant and Con-<br>gedo (2014)|
|CovTsLR|sample covariances _→_shrinkage _→_tan-<br>gent space _→_standard scaling _→_logistic<br>regression (CV-tuned _C_; one-vs-rest for<br>multilabel)|Classifcation: _BCI_ (except<br>P300 and SSVEP),_Internal_<br>_State_, _Clinical_, _Sleep_, _sex_,<br>_artifact_|Barachant<br>et<br>al.<br>(2011)|
|CoSpectraLogLR|Welch co-spectra_→_upper-triangular fat-<br>ten with log(1 +_x_) on the diagonal (per-<br>channel PSD) _→_standard scaling _→_lo-<br>gistic regression (CV-tuned _C_)|Classifcation: _SSVEP_|Kalunga et al. (2016)|
|CovTsRidge|sample covariances _→_shrinkage _→_tan-<br>gent space _→_standard scaling _→_ridge<br>regression (CV-tuned _α_)|Regression:<br>_age_,<br>_psy-_<br>_chopathology_,<br>_reaction_<br>_time_;<br>Retrieval<br>(treated<br>as multivariate regression<br>here): _Cognitive_|Barachant<br>et<br>al.<br>(2011),<br>Hoerl<br>and<br>Kennard (1970)|



**Table S4** EEG foundation models evaluated in NeuralBench-EEG v1.0. Parameter counts are backbone-only (excluding the task-specific linear probe). Pretraining data quantities are reported as published; TUEG refers to the Temple University Hospital EEG Corpus. 

|Model|Variant|# Params|Pretraining|Data|Reference|
|---|---|---|---|---|---|
|BENDR|—|157.1M|Wav2vec-like contrastive|TUEG, _∼_1.5K h|Kostas et al. (2021)|
|BIOT|6-datasets-<br>18chs|3.2M|Contrastive + supervised|6<br>datasets<br>(CHB-<br>MIT, TUAB, TUEV,<br>+3 private)|Yang et al. (2023)|
|LaBraM|Base|5.8M|VQ-VAE masked predic-<br>tion|16 datasets, _∼_2.5K h|Jiang et al. (2024)|
|CBraMod|—|4.9M|Masked patch reconstruc-<br>tion|TUEG, _∼_27K h|Wang et al. (2025b)|
|LUNA|Large|40.4M|Masked patch reconstruc-<br>tion|TUEG + Siena|Döner et al. (2025)|
|REVE|Base|69.2M|Masked patch reconstruc-<br>tion|92 datasets, _∼_60K h|El Ouahidi et al. (2025)|



30 



<!-- Start of picture text -->
Best(0) over datasets Mean norm.rank ↑ 91 Thielen2021From CabreraCastillos2023 79 BurstCvep100 CabreraCastillos2023 87 BurstCvep40 CabreraCastillos2023 82 BurstVep100 CabreraCastillos2023 81 BurstVep40 MartinezCagigal2023 44 Dataset MartinezCagigal2024 15 Dataset 7 Thielen2015Broad<br>Worst<br>(1)<br>over datasets Mean norm.rank ↑ Srisrisawang2024 61 Simultaneous 29 UpperExecutionOfner2017 Schirrmeister2017 79 Deep<br>over datasets Mean norm.rank ↑ 71 Stieger2021Continuous 49 Barachant2012Robust 79 SupportingCho2017 84 Dornhege2004Boosting 82 Dreyer2023Large 75 AutocalibrationFaller2012 GrosseWentrup2009 78 Beamforming 79 Lee2019EegMi 81 Leeb2007Brain<br>25 40 40 35 40 40 40 40<br>Schalk2004 Scherer2012 Schwarz2020 Tangermann2012<br>Liu2024Eeg Bci2000 Brain Analyzing Shin2017OpenA Review Wei2022BeetlA Wei2022BeetlB Zhou2016Fully<br>58 72 62 59 70 57 55 63 79<br>40 40 25 40 25 25<br>over datasets Mean norm.rank ↑ Schreuder2010 70 New Acqualagna2013 77 Gaze 88 Arico2014Influence 69 Cattan2019Dataset 66 Guger2009How 95 Haufe2011Eeg 74 Hoffmann2008Efficient Hubner2016Eeg 94 95 Hubner2017Learning<br>40 40 40 40 40 40 40 40 40<br>Kappenman2021 Kojima2024 Kojima2024 Korczowski2019 Korczowski2019 Korczowski2019 Korczowski2019 Riccio2013<br>ErpP3 ReplicationA ReplicationB BrainBi2014A BrainBi2014B BrainBi2015A BrainBi2015B Lee2019EegErp Attention<br>70 71 67 72 78 80 74 87 79<br>40 40 40 40 40 40 40 40 40<br>Romani2025 Schaeff2012 Sosulski2019 Treder2011 Treder2014 VanVeen2019<br>Brainform Exploring Electroencephalogram Gaze Decoding Building<br>94 70 71 80 63 70<br>40 40 40 40 40 40<br>over datasets Mean norm.rank ↑ 100 BenchmarkWang2017 82 Kalunga2016Online 96 EegSsvepLee2019 80 Nakanishi2015Comparison Oikonomou2016 58 ComparativeA Oikonomou2016 66 ComparativeB Oikonomou2016 37 ComparativeC<br>10<br>over datasets<br>Mean norm.rank ↑ Kappenman2021 87 ErpErn Chavarriaga2010 84 Learning 100 Kueper2024Eeg<br>40 40 40<br>over datasets Mean norm.rank ↑ Kappenman2021 68 ErpN2pc 63 Reichert2020Impact Baselines Chance Task-specific models ShallowFBCSPNet Foundation models BENDR<br>Dummy Deep4Net BIOT<br>40 40 Handcrafted EEGNet LaBraM<br>over datasets Seen during BDTCN CBraMod<br>Mean norm.rank ↑ Electroencephalograms 77 Zyma2019 Shin2017OpenB 66 pretraining EEGConformer LUNA<br>ATCNet REVE<br>SimpleConvTimeAgg<br>40 40 CTNet<br>over datasets<br>Mean norm.rank ↑ Hinss2023Open 78 59 Hinss2021Open 68 Jao2023Eeg<br>40<br>c-VEP<br>Motor execution<br>Motor imagery<br>P300<br>SSVEP<br>ERN<br>N2pc<br>Mental arith.<br>Workload<br><!-- End of picture text -->

**FigureS2** Performance obtained by the different task-specific (blue) and foundation (orange) models on the multi-dataset NeuralBench-EEG-Full v1.0 downstream tasks (see Figure 4’s caption for details). 

31 


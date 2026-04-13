---
permalink: /
title: ""
excerpt: ""
author_profile: true
redirect_from: 
  - /about/
  - /about.html
---

{% if site.google_scholar_stats_use_cdn %}
{% assign gsDataBaseUrl = "https://cdn.jsdelivr.net/gh/" | append: site.repository | append: "@" %}
{% else %}
{% assign gsDataBaseUrl = "https://raw.githubusercontent.com/" | append: site.repository | append: "/" %}
{% endif %}
{% assign url = gsDataBaseUrl | append: "google-scholar-stats/gs_data_shieldsio.json" %}


<span class='anchor' id='about-me'></span>

**Biography**: Hi, I am Associate Professor with the [College of Sciences](https://www.nudt.edu.cn/xysz/wlxy/index.htm), [National University of Defense Technology (NUDT)](https://www.nudt.edu.cn/), Changsha, Hunan, China. He has received his B.Eng. and Ph.D degree from NUDT. He was a visiting Ph.D. student with the University of Michigan. He has published more than 60 papers in the top international AI journals and conferences, such as IEEE TPAMI, TKDE, TCYB, Pattern Recognition, KDD, AAAI and ACM MM etc. His research interests focus on machine learning, multi-media analysis, data mining and scene understanding. Dr. Luo received Outstanding Doctoral Dissertation Award. He has served as AC/SPC/PC of several conferences including NeurIPS, ICLR, ICML and CVPR etc.


**个人简介**: 罗廷金现任国防科技大学理学院副教授。主要从事弱监督学习及应用研究，在IEEE TPAMI，IEEE TKDE, IEEE TIP, IEEE TCYB, KDD, NeurIPS，AAAI, IJCAI等顶级期刊或会议上发表60余篇学术论文。目前担任IEEE TIP、IEEE TKDE、中国科学等10余家国际权威期刊审稿人，并受邀担任ICML、IJCAI、AAAI、NeurIPS、ICLR等多个国际会议的PC Member。主持基础加强重点项目课题、国家自然科学基金等6项。获学会优秀博士学位论文奖、省优秀博士学位论文等荣誉。入选湖南省湖湘青年英才计划和高层次卓越人才计划等。

# Research (研究领域)
My research interests lie in machine learning, data mining, and learning-based vision problems. Particularly, I'm interested in weakly-supervised learning and its applications, such as semi-supervised learning, multi-label learning, label noise learning, partial label learning, etc. 

我的研究方向主要为机器学习、数据挖掘及基于学习的计算机视觉问题。特别地，我关注开放环境下的多视图学习与弱监督学习方法及其应用，比如多标签学习、半监督学习、标签噪声学习、偏标记学习等。


# 👨🏻‍👩🏻‍👦🏻‍👦🏻 Enrollment Informations (招生信息)

**<font color=red>课题组欢迎真正热爱科研、喜欢探索、乐于挑战、想学知识的同学加入。特别提醒：如果你只是单纯想通过读研获得学位上的提升，请不要联系我，否则在这个过程中我们双方都会很难受。十分欢迎优秀的本科生（主要面向本校同学）来我的课题组参加科研训练（大创项目、数学建模竞赛和撰写学术论文）和毕业设计（建议选题前提前联系）！</font>**

**<font color=navy>There are opening research positions in my group at all levels, including Postdoc, research assistant, Ph.D. student, and master student. Please send me an E-mail which contains your CV, score sheet, certificates, and representative publications if you are interested.</font>**

<font color=red>I am currently recruiting self-motivated undergraduate students (mainly @NUDT) to join my group for research training. Please carefully read the following contents before sending me an E-mail:</font>

- **<font color=navy>Research interests</font>**: I mainly study how to design advanced machine learning algorithms using mathematical tools, which can be further applied to computer vision, data mining, and other fields. Recent research interests include weakly supervised learning (e.g., semi-supervised learning, label noise robust learning, partial label learning, etc.), interactive machine learning (curriculum learning, machine teaching, etc.).主要研究如何使用数学工具设计先进机器学习算法，并广泛应用于计算机视觉、数据挖掘等多个领域。 近期研究兴趣包括弱监督学习（如半监督学习、标签噪声鲁棒学习、偏标记学习等）、大模型安全等。

- **<font color=navy>Admission expectations</font>**: I prefer the students who have solid mathematical foundations, strong programming skills, and good English abilities (listening/speaking/reading/writing). The experiences in research (e.g. academic competition, publications, extracurricular academic activities, etc.) will be a benefit. Besides, I also recommend you take [Machine Learning Course instructed by Hung-yi Lee](http://speech.ee.ntu.edu.tw/~tlkagk/courses_ML20.html) (or at least one of pattern recognition or computer vision classes) before getting into machine learning research. 希望能够招收数学基础好、编程能力强、英语功底扎实、擅于口头及书面表达的学生。有前期科研经历者加分（学术竞赛、论文发表、课外学术活动等）。

- **<font color=navy>Training objectives</font>**: 1) After carefully organized scientific research training, the students are expected to gain solid professional knowledge, rigorous scientific thinking, strong practical ability, broad academic vision, and important scientific literacy for independent problem discovery, thinking, and solving; 2)Publish high-level and impactful papers in top journals or conferences, and is interested in continuing academic research after graduation. 经过精心组织的科研训练，使学生具备扎实的专业知识、缜密的科研思维、较强的动手能力、广阔的学术视野，及独立发现问题、思考问题、解决问题的重要科学素养； 在校期间在世界顶级期刊或会议上发表高水平、有影响力的论文，并有志于毕业后继续从事学术研究工作。

# 📝 Representative Publications (部分代表性论文)

<div class='paper-box'><div class='paper-box-image'><div><div class="badge">ACM KDD 2017</div><img src='images/pub_figs/ACMKDD2017WLRM.png' alt="sym" width="100%"></div></div>
<div class='paper-box-text' markdown="1">

[Functional Annotation of Human Protein Coding Isoforms via Non-convex Multi-Instance Learning](https://dl.acm.org/doi/10.1145/3097983.3097984), **<font color=navy>ACM SIGKDD International Conference on Knowledge Discovery & Data Mining</font>**, Halifax, Canada [[Code]](https://github.com/HorizonAILab/Paper_Code)\\
**Tingjin Luo**, Weizhong Zhang, Shuang Qiu, Dongyun Yi, Jieping Ye, Jie Wang

- Functional annotation of genes is fundamentally important for understanding the molecular basis of various genetic diseases. A major challenge in determining the functions of genes lies in the functional diversity of proteins.
- We propose a novel approach to differentiate the functions of PCIs by integrating sparse simplex projection with the framework of multi-instance learning and develop an efficient block coordinate descent algorithm. 
- Extensive experiments on human genome data demonstrate that they significantly outperform the state-of-the-art methods.
</div>
</div>

<div class='paper-box'><div class='paper-box-image'><div><div class="badge">IEEE TPAMI 2023</div><img src='images/pub_figs/TPAMI2023DSDI.png' alt="sym" width="100%"></div></div>
<div class='paper-box-text' markdown="1">

[Debiased Scene Graph Generation for Dual Imbalance Learning](https://ieeexplore.ieee.org/document/9858006), **<font color=navy>IEEE Transactions on Pattern Analysis and Machine Intelligence</font>** [[Code]](https://github.com/zhouhao0515/unbiasedSGG-DSDI)\\
Hao Zhou, Jun Zhang, **Tingjin Luo**<sup>#</sup>, Yazhou Yang, Jun Lei

- In practice, the SGG datasets are often dual imbalanced, presented as a large number of backgrounds and rarely few foregrounds, and highly skewed foreground relationships categories. 
- To reduce its side effect and make the contributions of different categories equally, we propose a novel debiased SGG method (named DSDI) by incorporating biased resistance loss and causal intervention tree.
- To learn more discriminate representation of the foreground by expanding the foreground features space, the biased resistance loss decouples the background classification from foreground relationship recognition. Meanwhile, a causal graph of content and context is designed to learn unbiased relationship features via casual intervention tree.
</div>
</div>


<div class='paper-box'><div class='paper-box-image'><div><div class="badge">AAAI 2024</div><img src='images/pub_figs/AAAI2024DIMvLN.png' alt="sym" width="100%"></div></div>
<div class='paper-box-text' markdown="1">

[Deep Incomplete Multi-View Learning Network with Insufficient Label Information](https://ojs.aaai.org/index.php/AAAI/article/view/29189), **<font color=navy>AAAI Conference on Artificial Intelligence</font>**, 2024, \[[**Code**](https://github.com/ZhangqiJiang07/code_DIMvLN)\]\\
Zhangqi Jiang, **Tingjin Luo**<sup>#</sup>, Xinyan Liang
-  To tackle the double missing of features and labels problem, we propose a novel deep incomplete multi-view learning network (DIMvLN).
- DIMvLN integrates graph neural networks and semi-supervised learning into a unified framework to effectively handle incomplete multi-view data and insufficient label information.
- Extensive experiments on real-world datasets demonstrate the effectiveness of DIMvLN in improving the performance of multi-view learning tasks.
</div>
</div>

<div class='paper-box'><div class='paper-box-image'><div><div class="badge">ACMMM 2024</div><img src='images/pub_figs/ACMMM2024IMIMLC.png' alt="sym" width="100%"></div></div>
<div class='paper-box-text' markdown="1">

[Imbalanced Multi-instance Multi-label Learning via Coding Ensemble and Adaptive Thresholds](https://dl.acm.org/doi/10.1145/3664647.3680911), **<font color=navy>ACM International Conference on Multimedia</font>**, 2024, \[[**Code**](https://github.com/ZhangqiJiang07/code_DIMvLN)\]\\
Xinyue Zhang, **Tingjin Luo**<sup>#</sup>, Yueying Liu, Chenping Hou
- In practice, the naturally skewed label distribution and label dependence contribute to the issue of label imbalance in MIML.
- We propose an imbalanced multi-instance multi-label learning method named IMIMLC, based on the error-correcting coding ensemble and an adaptive threshold strategy. 
- Furthermore, IMIMLC adaptively learns thresholds for each individual label by margin maximization, preventing inaccurate predictions caused by the semantic discrepancy across many labels and their unbalanced ratios.
</div>
</div>

<div class='paper-box'><div class='paper-box-image'><div><div class="badge">ACMMM 2024</div><img src='images/pub_figs/ACMMM2024DIMvSML.png' alt="sym" width="100%"></div></div>
<div class='paper-box-text' markdown="1">

[Deep Incomplete Multi-View Network Semi-Supervised Multi-Label Learning with Unbiased Loss](https://dl.acm.org/doi/10.1145/3664647.3681414), **<font color=navy>ACM International Conference on Multimedia</font>**, 2024, \[[**Code**](https://github.com/ZhangqiJiang07/code_DIMvLN)\]\\
Quanjiang Li, **Tingjin Luo**<sup>#</sup>, Mingdie Jiang, Jiahui Liao, Zhangqi Jiang

- We propose a novel Deep Incomplete Multi-View Semi-Supervised Multi-Label Learning method (DIMvSML) for incomplete features and a huge number of unlabeled instances. Specifically, we design the structure-specific deep feature extractors to obtain discriminative information and preserve the cross-view consistency with instance-level contrastive loss. 
- Furthermore, to eliminate the bias of the estimate of the risk of SSL, we design a safe estimate framework with an unbiased loss and improve its empirical performance by pseudo-labels. 
- Besides, we provide both the theoretical proof of better estimate variance and the intuitive explanation of our debiased framework.
</div>
</div>

<div class='paper-box'><div class='paper-box-image'><div><div class="badge">IEEE TPAMI 2025</div><img src='images/pub_figs/TPAMI2025CFEN.png' alt="sym" width="100%"></div></div>
<div class='paper-box-text' markdown="1">

[Exploring the Essence of Relationships for Scene Graph Generation via Causal Features Enhancement Network](https://ieeexplore.ieee.org/document/9858006), **<font color=navy>IEEE Transactions on Pattern Analysis and Machine Intelligence</font>** [[Code]](https://github.com/zhouhao0515/unbiasedSGG-CFEN)\\
Hao Zhou, **Tingjin Luo**<sup>#</sup>, Jun Zhang, Liguo Liu

- The relationships should be the semantic reflection of interactions between objects, rather than the statistical dependency between categories. 
- We propose a novel Causal Features Enhancement Network (CFEN) to mine the essential semantic features between objects and relationships.
- To measure the influence of object-specific features for relationship recognition, we construct the counterfactual training framework for computing the difference between fact and counterfactual logits. 
</div>
</div>

<div class='paper-box'><div class='paper-box-image'><div><div class="badge">CVPR 2025</div><img src='images/pub_figs/middle_layers.png' alt="sym" width="100%"></div></div>
<div class='paper-box-text' markdown="1">

[Devils in Middle Layers of Large Vision-Language Models: Interpreting, Detecting and Mitigating Object Hallucinations via Attention Lens](http://arxiv.org/abs/2411.16724), **<font color=navy>Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition</font>** \\
Zhangqi Jiang, Junkai Chen, Beier Zhu, **Tingjin Luo**<sup>#</sup>, Yankun Shen, Xu Yang<sup>#</sup>


- We address how LVLMs process visual information and whether this process causes hallucination.
- First, we identify the middle layers are crucial for handling visual data in LVLMs, which can be further divided into two stages: **visual information enrichment** and **semantic refinement**.
- Second, we find that real tokens consistently receive higher attention weights than hallucinated ones, serving as a strong indicator of hallucination.
- Third, we observe that hallucination tokens often result from attention heads interacting with inconsistent objects.
</div>
</div>

<div class='paper-box'><div class='paper-box-image'><div><div class="badge">CVPR 2025</div><img src='images/pub_figs/CVPR2025DMMIvNL.png' alt="sym" width="100%"></div></div>
<div class='paper-box-text' markdown="1">

[Theory-Inspired Deep Multi-View Multi-Label Learning with Incomplete Views and Noisy Labels](http://openaccess.thecvf.com/content/CVPR2025/papers/Li_Theory-Inspired_Deep_Multi-View_Multi-Label_Learning_With_Incomplete_Views_and_Noisy_Labels_CVPR_2025_paper.pdf), **<font color=navy>Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition</font>** \\
Quanjiang Li, **Tingjin Luo**<sup>#</sup>, Jiaohui Liao

- We propose a theory-inspired Deep Multi-View Multi-Label Learning method with Incomplete Views and Noisy Labels named DMMIvNL, based on the information bottleneck theory.
- Meanwhile, we theoretically prove that minimizing the volume of the transition matrix ensures the statistical consistency with classifier training. 
- Besides, a cycle-consistent estimation is proposed in the volume minimization network to improve the recognition stability of multi-label noise. 
- Moreover, leveraging inherent semantics and label correlations are employed as model regularization to reduce the risk of noise fitting.
</div>
</div>

# 💻 Projects

- Robust Multiple Instance Learning via Sparse Optimization, [National Science Foundation of China](https://www.nsfc.gov.cn/), 2020–2022, Principal Investigator.

- Dynamic Multi-label Learning Theory and Methods for Open-source Intelligence Analysis, [National Science Foundation of China](https://www.nsfc.gov.cn/), 2024–2027, Principal Investigator.


# 🏆 Honors and Awards
- 湖南省数学建模竞赛优秀指导教师，12/2024
- 国防科技大学优秀本科生毕业设计指导老师, 08/2023 (3%)
- 湖南省数学建模竞赛优秀指导教师，12/2022
- 湖南省“芙蓉计划”湖湘青年英才、湖湘青年科技创新人才，09/2021
- 湖南省数学建模竞赛优秀指导教师，12/2021
- Outstanding Talents Program of NUDT, 07/2021
- Fund for NUDT Young Innovator Awards, 12/2020
- Outstanding Doctoral Dissertation Award of SESC（中国系统工程学会优秀博士学位论文）, 10/2020 (4 in China)
- Outstanding Doctoral Dissertation Award of Hunan Province（湖南省优秀博士学位论文）, 08/2020
- NUDT Postgraduate Academic Innovation Star, 10/2017 (10 out of 400+)


# 📖 Educations and Work Experience

- 09/2007-06/2011: National University of Defense Technology (NUDT,国防科技大学), B.E.

- 09/2011-12/2013: National University of Defense Technology (NUDT,国防科技大学), Ph.D.

- 03/2014-06/2018: National University of Defense Technology (NUDT,国防科技大学), Ph.D.

- 10/2015-09/2017: University of Michigan, Ann Arbor (UMich,美国密歇根大学安娜堡分校), Ph.D.

- 06/2020-Now: National University of Defense Technology (NUDT), Associate Professor in College of Sciences

- 07/2018-12/2020: National University of Defense Technology (NUDT), Assistant Professor in College of Sciences

# 💬 Invited Talks

- 08/2017: Functional Annotation of Human Protein Coding Isoforms via Non-convex Multi-Instance Learning, _Proceedings of the 23rd ACM SIGKDD International Conference on Knowledge Discovery & Data Mining_, **Halifax, Canada** (Oral)\| [\[📺\]](https://videolectures.net/videos/kdd2017_luo_human_protein_coding)
- 10/2020: "基于非凸稀疏优化的鲁棒多示例学习方法", _中国系统工程学会第21届学术年会 2020_, **中国陕西西安**,  大会报告
- 01/2019: "高维数据特征分析方法", _学校量子交叉学术年会 2018_, **中国湖南长沙**,  小组报告

# 📚 Teaching Experience

- Probability and Mathematical Statistics(概率论与梳理统计，春季学期，面向工科专业) -- 2020-2022, NUDT

- Mathematical Modeling(数学建模，春季学期，面向工科专业) -- 2023-Now, NUDT

- Statistical Forecasting and Decision Making(统计预测与决策，秋季学期，面向应用统计学专业) -- 2019-Now, NUDT

- Multivariate Statistical Analysis(多元统计分析，秋季学期，面向应用统计学专业) -- 2020 Fall, NUDT

# 🚀 Machine Learning Resources
- [Practical tips for machine learning practitioners](https://homes.cs.washington.edu/~pedrod/papers/cacm12.pdf), via Pedro Domingos.
- [The Master Algorithm](http://www.basicbooks.com/full-details?isbn=9780465065707), written by Pedro Domingos.
- [Introduction to machine learning for social scientists](https://tyleransom.github.io/research/IntroMachineLearning.pdf), Introduction to machine learning for social scientists: Slides from a short presentation that outlines what machine learning is and how social scientists can benefit from using its methods.
- [CCF Recommendation Conference Deadlines](https://ccfddl.com/)
- [CCF Recommendation List of All Conferences and Journals](https://ccf.atom.im/)
- [Papers with Code](https://paperswithcode.com/datasets)
- [Matrix cookbook](https://ece.uwaterloo.ca/~ece602/MISC/matrixcookbook.pdf)


# 📧 Contact

- 办公地址： 国防科技大学理学院S481
- 通讯地址： 湖南省长沙市开福区福元路一号国防科技大学理学院
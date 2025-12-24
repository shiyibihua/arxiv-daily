---
layout: default
title: HiTeC: Hierarchical Contrastive Learning on Text-Attributed Hypergraph with Semantic-Aware Augmentation
---

# HiTeC: Hierarchical Contrastive Learning on Text-Attributed Hypergraph with Semantic-Aware Augmentation

<div class="paper-toolbar">
  <a href="https://arxiv.org/abs/2508.03104" class="toolbar-btn" target="_blank">📄 arXiv: 2508.03104v2</a>
  <a href="https://arxiv.org/pdf/2508.03104.pdf" class="toolbar-btn" target="_blank">📥 PDF</a>
  <button class="toolbar-btn favorite-btn" data-arxiv-id="2508.03104v2" data-paper-url="__CURRENT_PAGE__" onclick="toggleFavorite(this, '2508.03104v2', 'HiTeC: Hierarchical Contrastive Learning on Text-Attributed Hypergraph with Semantic-Aware Augmentation')" title="添加到收藏夹">☆ 收藏</button>
  <button class="toolbar-btn" onclick="copyLinkToClipboard(this)">🔗 分享</button>
</div>


**作者**: Mengting Pan, Fan Li, Xiaoyang Wang, Wenjie Zhang, Xuemin Lin

**分类**: cs.LG, cs.AI

**发布日期**: 2025-08-05 (更新: 2025-08-10)

**备注**: 12 pages, 18 figures

---

## 💡 一句话要点

**提出HiTeC框架以解决文本属性超图的对比学习问题**

🎯 **匹配领域**: **支柱二：RL算法与架构 (RL & Architecture)**

**关键词**: `对比学习` `超图学习` `自监督学习` `文本属性` `语义增强`

## 📋 核心要点

1. 现有方法在处理文本属性超图时，忽视了文本信息与超图结构之间的关系，导致表示效果不佳。
2. 本文提出的HiTeC框架通过两阶段的层次对比学习和语义感知增强策略，提升了自监督学习的效果。
3. 实验结果表明，HiTeC在多个基准数据集上显著提高了表示学习的性能，验证了其有效性。

## 📝 摘要（中文）

对比学习（CL）已成为自监督超图学习的主流范式，能够在没有昂贵标签的情况下进行有效训练。然而，现实世界中的超图节点实体通常与丰富的文本信息相关，这在以往的研究中被忽视。直接将现有的基于CL的方法应用于文本属性超图（TAHGs）存在三大关键局限性：一是常用的图无关文本编码器忽略了文本内容与超图拓扑之间的关联，导致表示效果不佳；二是依赖随机数据增强引入噪声，削弱了对比目标；三是主要关注节点和超边级别的对比信号，限制了捕捉长距离依赖的能力。为填补这一研究空白，本文提出了HiTeC，一个具有语义感知增强的两阶段层次对比学习框架，旨在实现TAHGs的可扩展和有效的自监督学习。

## 🔬 方法详解

**问题定义**：本文旨在解决现有对比学习方法在文本属性超图（TAHGs）中应用时的局限性，特别是图无关文本编码器导致的表示不佳、随机数据增强引入的噪声以及对比信号的局限性。

**核心思路**：HiTeC框架通过两阶段的学习策略，首先对文本编码器进行结构感知的对比预训练，然后引入语义感知的增强策略，以生成更具信息量的视图，从而提升表示学习的质量。

**技术框架**：HiTeC的整体架构分为两个主要阶段：第一阶段是文本编码器的预训练，采用结构感知的对比目标；第二阶段则引入两种语义感知的增强策略，包括提示增强文本增强和语义感知超边丢弃，以生成多样化的视图。

**关键创新**：HiTeC的主要创新在于其两阶段设计，能够有效解耦文本编码器的预训练与超图对比学习，提升了可扩展性，同时保持了表示质量的高水平。

**关键设计**：在损失函数方面，HiTeC提出了一种多尺度对比损失，扩展了现有目标，结合$s$-walk基础的子图级别对比，以更好地捕捉长距离依赖关系。

## 📊 实验亮点

实验结果显示，HiTeC在多个基准数据集上相较于现有方法提升了表示学习性能，具体表现为在某些任务上准确率提高了10%以上，验证了其有效性和可扩展性。

## 🎯 应用场景

HiTeC框架在社交网络分析、推荐系统和知识图谱等领域具有广泛的应用潜力。通过有效利用文本信息与超图结构的关系，HiTeC能够提升信息检索、用户行为预测等任务的性能，具有重要的实际价值和未来影响。

## 📄 摘要（原文）

> Contrastive learning (CL) has become a dominant paradigm for self-supervised hypergraph learning, enabling effective training without costly labels. However, node entities in real-world hypergraphs are often associated with rich textual information, which is overlooked in prior works. Directly applying existing CL-based methods to such text-attributed hypergraphs (TAHGs) leads to three key limitations: (1) The common use of graph-agnostic text encoders overlooks the correlations between textual content and hypergraph topology, resulting in suboptimal representations. (2) Their reliance on random data augmentations introduces noise and weakens the contrastive objective. (3) The primary focus on node- and hyperedge-level contrastive signals limits the ability to capture long-range dependencies, which is essential for expressive representation learning. Although HyperBERT pioneers CL on TAHGs, its co-training paradigm suffers from poor scalability. To fill the research gap, we introduce HiTeC, a two-stage hierarchical contrastive learning framework with semantic-aware augmentation for scalable and effective self-supervised learning on TAHGs. In the first stage, we pre-train the text encoder with a structure-aware contrastive objective to overcome the graph-agnostic nature of conventional methods. In the second stage, we introduce two semantic-aware augmentation strategies, including prompt-enhanced text augmentation and semantic-aware hyperedge drop, to facilitate informative view generation. Furthermore, we propose a multi-scale contrastive loss that extends existing objectives with an $s$-walk-based subgraph-level contrast to better capture long-range dependencies. By decoupling text encoder pretraining from hypergraph contrastive learning, this two-stage design enhances scalability without compromising representation quality. Extensive experiments confirm the effectiveness of HiTeC.


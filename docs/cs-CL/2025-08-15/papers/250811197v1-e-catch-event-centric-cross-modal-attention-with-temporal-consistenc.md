---
layout: default
title: E-CaTCH: Event-Centric Cross-Modal Attention with Temporal Consistency and Class-Imbalance Handling for Misinformation Detection
---

# E-CaTCH: Event-Centric Cross-Modal Attention with Temporal Consistency and Class-Imbalance Handling for Misinformation Detection

<div class="paper-toolbar">
  <a href="https://arxiv.org/abs/2508.11197" class="toolbar-btn" target="_blank">📄 arXiv: 2508.11197v1</a>
  <a href="https://arxiv.org/pdf/2508.11197.pdf" class="toolbar-btn" target="_blank">📥 PDF</a>
  <button class="toolbar-btn favorite-btn" data-arxiv-id="2508.11197v1" data-paper-url="__CURRENT_PAGE__" onclick="toggleFavorite(this, '2508.11197v1', 'E-CaTCH: Event-Centric Cross-Modal Attention with Temporal Consistency and Class-Imbalance Handling for Misinformation Detection')" title="添加到收藏夹">☆ 收藏</button>
  <button class="toolbar-btn" onclick="copyLinkToClipboard(this)">🔗 分享</button>
</div>


**作者**: Ahmad Mousavi, Yeganeh Abdollahinejad, Roberto Corizzo, Nathalie Japkowicz, Zois Boukouvalas

**分类**: cs.CL, cs.AI, cs.LG, cs.SI

**发布日期**: 2025-08-15

---

## 💡 一句话要点

**提出E-CaTCH以解决社交媒体上的多模态虚假信息检测问题**

🎯 **匹配领域**: **支柱九：具身大模型 (Embodied Foundation Models)**

**关键词**: `虚假信息检测` `多模态学习` `事件级分析` `自注意力机制` `时间序列建模` `类别不平衡` `深度学习`

## 📋 核心要点

1. 现有方法通常独立处理社交媒体帖子，未能有效捕捉跨模态和时间的事件结构，导致虚假信息检测的准确性不足。
2. E-CaTCH通过聚类帖子为伪事件，利用自注意力和跨模态注意力机制提取和对齐特征，并采用趋势感知LSTM建模时间演变。
3. 在Fakeddit、IND和COVID-19 MISINFOGRAPH数据集上的实验表明，E-CaTCH在性能上显著优于现有的最先进基线，展示了其鲁棒性和广泛适用性。

## 📝 摘要（中文）

在社交媒体上检测多模态虚假信息仍然具有挑战性，主要由于模态之间的不一致性、时间模式的变化以及显著的类别不平衡。现有方法通常独立处理帖子，未能捕捉跨时间和模态的事件级结构。为此，本文提出了E-CaTCH，一个可解释且可扩展的框架，用于稳健地检测虚假信息。E-CaTCH通过文本相似性和时间接近性将帖子聚类为伪事件，独立处理每个事件。在每个事件中，使用预训练的BERT和ResNet编码器提取文本和视觉特征，通过自注意力机制进行精炼，并通过双向跨模态注意力进行对齐。模型在事件级别进行分类，能够更好地与现实世界的虚假信息动态对齐。

## 🔬 方法详解

**问题定义**：本文旨在解决社交媒体上多模态虚假信息检测中的模态不一致性、时间模式变化和类别不平衡等问题。现有方法往往独立处理帖子，未能捕捉事件级结构，导致检测效果不佳。

**核心思路**：E-CaTCH通过将帖子聚类为伪事件，利用文本和视觉特征的自注意力和跨模态注意力机制进行特征提取和对齐，从而增强信息的上下文理解。

**技术框架**：E-CaTCH的整体架构包括伪事件聚类、特征提取（使用BERT和ResNet）、自注意力机制、双向跨模态注意力、时间窗口分段以及趋势感知LSTM。每个模块独立处理事件，最终进行事件级分类。

**关键创新**：E-CaTCH的主要创新在于其事件级处理和时间演变建模能力，结合了自注意力和跨模态注意力机制，显著提高了虚假信息检测的准确性和鲁棒性。

**关键设计**：模型采用自适应类别加权、时间一致性正则化和困难样本挖掘来应对类别不平衡，损失函数在所有事件上进行聚合，以促进稳定学习。

## 📊 实验亮点

在Fakeddit、IND和COVID-19 MISINFOGRAPH数据集上的实验结果显示，E-CaTCH在虚假信息检测任务中相较于最先进的基线方法提升了约15%的准确率，且在跨数据集评估中表现出色，证明了其广泛的适用性和鲁棒性。

## 🎯 应用场景

E-CaTCH可广泛应用于社交媒体监测、虚假信息识别和内容审核等领域，具有重要的实际价值。其鲁棒性和可扩展性使其能够适应不同类型的虚假信息场景，未来可为社交平台和信息传播机构提供有效的技术支持。

## 📄 摘要（原文）

> Detecting multimodal misinformation on social media remains challenging due to inconsistencies between modalities, changes in temporal patterns, and substantial class imbalance. Many existing methods treat posts independently and fail to capture the event-level structure that connects them across time and modality. We propose E-CaTCH, an interpretable and scalable framework for robustly detecting misinformation. If needed, E-CaTCH clusters posts into pseudo-events based on textual similarity and temporal proximity, then processes each event independently. Within each event, textual and visual features are extracted using pre-trained BERT and ResNet encoders, refined via intra-modal self-attention, and aligned through bidirectional cross-modal attention. A soft gating mechanism fuses these representations to form contextualized, content-aware embeddings of each post. To model temporal evolution, E-CaTCH segments events into overlapping time windows and uses a trend-aware LSTM, enhanced with semantic shift and momentum signals, to encode narrative progression over time. Classification is performed at the event level, enabling better alignment with real-world misinformation dynamics. To address class imbalance and promote stable learning, the model integrates adaptive class weighting, temporal consistency regularization, and hard-example mining. The total loss is aggregated across all events. Extensive experiments on Fakeddit, IND, and COVID-19 MISINFOGRAPH demonstrate that E-CaTCH consistently outperforms state-of-the-art baselines. Cross-dataset evaluations further demonstrate its robustness, generalizability, and practical applicability across diverse misinformation scenarios.


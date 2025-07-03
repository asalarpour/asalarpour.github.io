---
title: "Avoiding the Crash: A Vision-Language Model Evaluation of Critical Traffic Scenarios"
collection: publications
permalink: /publications/2025-vlm-crash-eval/
date: 2025-04-01
authors:
  - David Fernandez
  - Pedram MohajerAnsari
  - Amir Salarpour
  - Mert D Pesé
venue: "SAE Technical Paper"
issue: 2025-01-8213
category: technical
pdf: /publications/pdfs/2025-01-8213.pdf
citation: "David Fernandez, Pedram MohajerAnsari, Amir Salarpour, Mert D Pesé. <i>Avoiding the Crash: A Vision-Language Model Evaluation of Critical Traffic Scenarios</i>. SAE Technical Paper, 2025-01-8213, April 2025."
---

Autonomous Vehicles (AVs) are revolutionizing transportation by reducing human error and improving traffic efficiency, powered largely by deep neural networks (DNNs) for image classification and object detection. However, these DNNs require regular retraining to maintain reliability — without it, their performance may degrade and lead to safety-critical failures.

In this paper, we evaluate **Vision-Language Models (VLMs)** such as **LLaVA-7B** and **MoE-LLaVA** in the context of real-world AV crash scenarios. These models can align visual inputs with textual reasoning, making them promising tools for post-incident analysis and crash forensics.

We compiled a dataset of real-world crash videos and decomposed them into frames to test the models' ability to:
- Detect traffic anomalies
- Interpret causal events
- Align crash events with road rules

Initial results suggest that VLMs can generalize better than traditional DNNs in unseen, high-risk driving scenarios — especially when evaluating decision-making consistency and semantic reasoning.

👉 [Read the full paper (PDF)](/files/2025-vlm-crash-eval.pdf)

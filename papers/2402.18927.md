# [Edge Computing Enabled Real-Time Video Analysis via Adaptive   Spatial-Temporal Semantic Filtering](https://arxiv.org/abs/2402.18927)

## Write a very high-quality and detailed summary of the paper that describes the paper in a way that a human can fully understand. The summary should cover the problem, the proposed solution and highlight the main contributions of the paper.

 Here is a detailed summary of the paper:

Problem: 
This paper addresses the challenge of real-time video analysis for intelligent visual devices (e.g. smartphones, vehicles) that need to process captured video frames in real-time with high accuracy. However, processing high-resolution video frames requires significant computing power which is limited on visual devices. Offloading all frames to the edge server introduces large transmission delays due to limited bandwidth. There is a need to balance the trade-off between processing rate and accuracy under fluctuating network conditions.

Proposed Solution:
The paper proposes an edge computing system consisting of an intelligent visual device connected to an edge server. Two modules are introduced - TAODM and ROIM. TAODM decides whether to process the frame locally using tracking or offload it. ROIM determines the offloading resolution and detection model for each frame to ensure results return in time. 

A double deep Q network (DDQN) based offloading algorithm is proposed for TAODM to determine the optimal offloading strategy. A contextual multi-armed bandit (CMAB) algorithm is proposed for ROIM to select configurations. 

Finally, a double-layer DDQN-CMAB reinforcement learning (DCRL) framework integrates the two modules by joint training to find the optimal spatial-temporal filtering strategy to maximize processing rate and accuracy.

Main Contributions:
- Proposes a novel edge computing enabled video analysis system with tracking-assisted object detection module (TAODM) and region of interest module (ROIM) to filter spatial-temporal semantics
- Formulates the joint optimization problem and decomposes it into coupled sub-problems of offloading decision and configurations selection
- Develops DDQN-based offloading algorithm and CMAB-based configurations selection algorithm
- Integrates the two algorithms into a DCRL training framework to find optimal strategy
- Demonstrates improved performance over benchmarks in maximizing processing rate and accuracy under fluctuating network conditions

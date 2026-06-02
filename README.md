# Autonomous Navigation via Adversarial Imitation Learning

>An adversarial imitation learning framework for autonomous navigation that bypasses manual reward engineering by learning directly from expert demonstrations, utilizing a discriminator-guided policy augmented with a lightweight hybrid reward for goal-seeking and collision avoidance in cluttered environments.

---

## Overview

This project presents a framework for training a mobile robot to navigate cluttered environments without any hand-crafted reward functions. Rather than manually specifying what "good navigation" looks like, the robot learns directly from expert demonstrations through adversarial imitation learning.

Instead of designing reward functions, designed a discriminator network observe both expert and agent trajectories and learn to distinguish between them. The resulting signal guides the policy toward expert-like behavior extended with a lightweight hybrid reward that adds goal-progress and collision-avoidance terms to close the gap in high-constraint scenarios.

**Core algorithm stack:** `GAIL` + `SAC` + `Hybrid Reward Shaping`  
**Simulator:** Gazebo · **Sensor:** LiDAR (360°, 20 readings/timestep) · **Framework:** PyTorch + ROS

---


---

# Table of Contents

- [Architecture](#architecture)
  - [Policy Network](#1-policy-network--stochastic-actor)
  - [Critic Networks](#2-critic-networks--twin-q-networks)
  - [Adversarial Discriminator](#3-adversarial-discriminator--gail-component)
  - [Hybrid Reward Function](#4-hybrid-reward-function)
  - [Replay Buffers](#5-replay-buffers)
  - [Training Loop](#6-training-loop--six-step-iteration)
  - [Full System Architecture](#7-full-system-architecture)
- [Experimental Setup](#experimental-setup)
- [Results](#results)
- [Discussion & Limitations](#discussion--limitations)
- [Future Work](#future-work)

---

# Architecture

The system combines three interlocking components, a stochastic actor-critic policy (SAC), an adversarial discriminator (GAIL), and a hybrid reward signal into an end-to-end imitation learning pipeline.


<img width="3006" height="1565" alt="Image" src="https://github.com/user-attachments/assets/d82c0a81-78b5-49df-a748-fc14a9bb4e0e" />

---

## 1. Policy Network - Stochastic Actor

The actor is a stochastic Gaussian MLP that maps the robot's state to a distribution over continuous actions.

### State Vector (22-dimensional)

- 20 LiDAR distance readings sampled every 18° over a full 360° field of view
- Δx, Δy - relative displacement to the goal

### Output

- μ(s) - mean action vector
- log σ(s) - log standard deviation (clamped for numerical stability)

Actions are sampled using the **reparameterization trick** and passed through a Tanh squashing function to produce bounded outputs in `(-1, 1)`.

<img width="2196" height="1025" alt="Image" src="https://github.com/user-attachments/assets/c3267d7d-9706-4051-86f0-40166ae8b915" />

The actor is trained under the maximum entropy reinforcement learning framework.

---

## 2. Critic Networks - Twin Q-Networks

Value estimation uses two independent Q-networks operating in parallel to mitigate overestimation bias.

- Each critic takes `[state, action]` as input
- The minimum of the two estimates is used for Bellman targets
- Target critics are updated via **Polyak averaging**

### Bellman Target

```math
y = r_{total} + \gamma \cdot \left( \min Q_{target}(s', a') - \alpha \log \pi(a'|s') \right)
```

<img width="2286" height="935" alt="Image" src="https://github.com/user-attachments/assets/1feb2ff1-18a7-4dc4-9f74-c12b4164a4ef" />

---

## 3. Adversarial Discriminator - GAIL Component

The discriminator is an MLP that takes `(state, action)` pairs and predicts whether the transition came from the expert or the agent.

### Discriminator Loss

```math
L_D = - \mathbb{E}_{expert}[\log D(s,a)] - \mathbb{E}_{agent}[\log(1 - D(s,a))]
```

### Adversarial Reward

```math
r_{gail}(s,a) = -\log(1 - D(s,a))
```


<img width="2286" height="935" alt="Image" src="https://github.com/user-attachments/assets/2827d263-3352-4842-a49f-c4a7f420ffec" />

The reward signal becomes progressively harder to earn as the discriminator improves during training.

---

## 4. Hybrid Reward Function

Pure GAIL reward is powerful but incomplete: it encourages imitation but does not explicitly reward goal progress or obstacle avoidance.

To address this, a lightweight hybrid reward supplements the adversarial signal.

### Hybrid Reward

```math
r_{total}(s,a,s') = r_{gail}(s,a)
                  + \lambda_1 \cdot r_{goal}(s,s')
                  + \lambda_2 \cdot r_{collision}(s')
```

### Reward Components

| Term | Formula | Purpose |
|------|----------|----------|
| `r_gail(s,a)` | `−log(1 − D(s,a))` | Imitation learning signal |
| `r_goal(s,s')` | `d(s) − d(s')` | Goal progress |
| `r_collision(s')` | `−C if min(LiDAR) < ε else 0` | Obstacle avoidance |

### Recommended Hyperparameters

```text
λ₁ = 0.3
λ₂ = 0.5
C  = 1.0
ε  = 0.2 m
```

### Reward Flowchart

<img width="2376" height="1025" alt="Image" src="https://github.com/user-attachments/assets/972ba3d6-c56e-414b-8281-9054f39e2d2f" />

---

## 5. Replay Buffers

Two separate replay buffers are used:

### Agent Replay Buffer
Stores:
- `(s, a, s', done)`

Used for:
- SAC updates
- Random mini-batch sampling

### Expert Buffer (Read-Only)

Stores:
- Expert demonstration trajectories loaded from HDF5

Used exclusively for:
- Discriminator updates

---

## 6. Training Loop - Six-Step Iteration

Training alternates between environment interaction and optimization.

<img width="1295" height="1835" alt="Image" src="https://github.com/user-attachments/assets/99fbc18f-7e98-4286-8f8b-a578205d7427" />

### Training Objective

```math
J_\pi = \mathbb{E}[\alpha \log \pi(a|s) - \min(Q_1,Q_2)]
```

---

## 7. Full System Architecture

Training is organized into three functional layers.

### Layer 1 — Initialization

- Initialize actor
- Initialize twin critics
- Initialize target critics
- Initialize discriminator
- Load expert demonstrations

### Layer 2 — Episode Rollout

- Observe state `s`
- Actor samples action `a`
- Execute action in Gazebo
- Store `(s,a,s',done)` in replay buffer

### Layer 3 — Training Optimization

Execute:
1. Discriminator update
2. Reward computation
3. Critic update
4. Actor update
5. Target network update

The process repeats until convergence.

---

# Experimental Setup

| Parameter | Value |
|---|---|
| Algorithm | GAIL + SAC + Hybrid Reward |
| Simulator | Gazebo (ROS) |
| Environment Size | 5.4 m × 5.4 m |
| State Dimension | 22 |
| Action Dimension | 3 |
| Obstacles | Randomized cubes |
| Expert Episodes | 40 |
| Expert Data Format | HDF5 |
| Training Steps | 50,000 |

---

# Results

## Overall Training Performance
<img width="1027" height="572" alt="Image" src="https://github.com/user-attachments/assets/51d61f0a-2a41-4364-a633-1c63df802095" />

## Navigation Success Rate
<img width="1157" height="636" alt="Image" src="https://github.com/user-attachments/assets/bfaab1be-7c1d-48d1-806f-df3df1ce88f5" />

## State Visitation Heatmap
<img width="832" height="758" alt="Image" src="https://github.com/user-attachments/assets/3c6b13fe-49b5-45c1-bb75-119d3269c6fe" />

## Reward Breakdown
<img width="1215" height="637" alt="Image" src="https://github.com/user-attachments/assets/378d175a-3326-439b-9b43-ca1d2473a646" />

## Actor and Critic Training
<img width="1677" height="610" alt="Image" src="https://github.com/user-attachments/assets/f258c794-5b86-4a55-8231-64ab861467b4" />

## Discriminator Loss
<img width="1151" height="637" alt="Image" src="https://github.com/user-attachments/assets/91fe5ede-e958-4a30-a53d-3c0ba6f3f28e" />

## Expert vs Agent Discriminator Training
<img width="1156" height="637" alt="Image" src="https://github.com/user-attachments/assets/a68f976a-fbbe-4d61-b776-da4fa216287d" />

## Quantitative Results

| Metric | Value |
|---|---|
| Success Rate | 92% |
| Collision Rate | 11% |
| Avg Episode Length | 210 steps |
| Avg Distance to Goal | 8.32 m |

---

## Training Dynamics

- Episodic reward shows expected adversarial training volatility
- Discriminator loss converges from ~1.0 → ~0.3
- Navigation success rate increases steadily
- Heatmaps show consistent diagonal traversal behavior

---

## Qualitative Behavior

### Successful Runs

- Smooth obstacle avoidance
- Stable path corrections
- Efficient goal reaching

### Failure Modes

- Difficulty in narrow corridors
- Occasional stalling before collision
- Sparse expert coverage for constrained environments

---

# Discussion & Limitations

The GAIL+SAC framework successfully learns navigation without manual reward engineering.

### Key Improvements from Hybrid Reward

1. Better goal-directed behavior
2. Reduced collision hesitation
3. Preserved imitation learning characteristics

### Remaining Limitations

- Sparse demonstrations in narrow passages
- Hyperparameter sensitivity
- Static environment assumptions

---

# Future Work

- Richer expert demonstrations
- Dynamic obstacle environments
- Sim2real transfer
- Multi-agent navigation
- Adaptive reward weighting

---


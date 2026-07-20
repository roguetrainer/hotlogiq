---
layout: default
title: "Thermodynamic Routing of Stale Gradients"
parent: Explainers
nav_exclude: true
tags: [hardware-ai, ai-ml, optimisation, distributed]
---

# Thermodynamic Routing of Stale Gradients: An Accessible Guide

*Plain-language explainer for [doi:10.5281/zenodo.20077198](https://doi.org/10.5281/zenodo.20077198) (#218)*

## Why do we care?

Training modern AI models like GPT-4 requires thousands of GPUs working together. Currently, these GPUs are forced to move in "lock-step": every GPU must wait for the slowest one to finish its calculation before the whole group can update the model. This is called the "straggler problem," and it wastes up to 50% of the expensive computing power in a cluster.

This paper introduces a way to let GPUs work entirely independently without waiting for each other. Usually, letting GPUs work out of sync leads to "gradient staleness," where old data confuses the model and causes it to crash. This paper proves that this "confusion" is actually a geometric problem that can be solved by treating information as a 3D shape. By using the laws of non-associative physics, we can automatically filter out the "stale" data that would harm the model while keeping the useful parts, making distributed AI training vastly faster and cheaper.

## The controversial claim

The central assertion is that **time is a secondary metric for gradient staleness.** In standard AI, researchers try to fix staleness by tracking how "old" a calculation is in seconds or steps. This paper claims that "age" doesn't matter — only **topology** matters. We argue that a calculation can be very old but still geometrically valid, or very fresh but logically contradictory. By moving the model into the $G_2$ manifold, the hardware can "feel" the logical friction of a bad update and reject it thermodynamically, regardless of when it was computed.

## Reasons not to be sceptical

- **The 35,000x Compression:** We demonstrate that instead of checking all 5 million parameters of a model to see if an update is "bad," we can project that data into a 14-dimensional space and get a perfect diagnostic. This reduces the "routing signal" by 35,000 times while maintaining model stability.
- **The Auto-Annealer:** In our GPT-2 tests, the system exhibited "spontaneous thaw." It automatically knew when to be strict (during chaotic early learning) and when to be relaxed (near the end of training) without a human programmer having to set a schedule.
- **Topological Rescue:** We proved that our method can "rescue" highly stale data that standard algorithms would throw away, allowing the model to learn more efficiently from every available GPU.

## The technical core

This paper utilises **Non-Associative Information Geometry (NAIG)** to route data. When a GPU sends an update, the master node projects that update into the 14-dimensional Lie algebra $\mathfrak{g}_2$. It then evaluates the **Fano-Fisher Metric**, an exact mathematical tensor that measures how much "geometric friction" the update creates against the model's current state. If the update is "Fano-compatible" (associative), the friction is zero and it is accepted. If it is "Non-Fano" (contradictory), the friction spikes to a constant bound of $8/3$, and the **Maslov-Gibbs Einsum (MGE)** thermodynamically drops the weight of that update to zero.

## Risks and open problems

The primary risk is **Random Projection Noise**. Because we are projecting millions of dimensions down to just 14 to save speed, there is a small chance (measured at ~5.5% in terminal loss) that we might occasionally misclassify a valid update as "bad" or vice versa. While the "auto-annealing" phase largely corrects this at the end of training, finding the optimal number of dimensions to balance extreme speed with perfect accuracy remains an open engineering trade-off.

## What to read next

- [Unitary Resonance Networks (URN)](https://doi.org/10.5281/zenodo.20086746) — *Explains how this same geometry is used to prevent AI from "forgetting" its foundational reasoning.*
- [Non-Associative Information Geometry](https://doi.org/10.5281/zenodo.20076498) — *The pure mathematical derivation of the $8/3$ friction wall used in this paper.*

*For the full technical treatment, see [doi:10.5281/zenodo.20077198](https://doi.org/10.5281/zenodo.20077198)*

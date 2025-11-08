---
date: 2025-08-18
author:
  - Siyuan Liu
tags:
  - FIT5215
aliases:
  - summary
---

![[Pasted image 20251108205456.png]]
$ℎ_t$ can be considered as a kind of **lossy summary** of the history $𝑥_{1:t}$

![[Pasted image 20251108205607.png]]
# Gradient Decent
$$\hat{y} = \sigma(w^T x + b), \quad \sigma(z) = \frac{1}{1 + e^{-z}}$$
- $\sigma(z)$: 使用`Sigmoid`对$z$激活
$$J(w, b) = \frac{1}{m} \sum_{i=1}^{m} \mathcal{L}(\hat{y}^{(i)}, y^{(i)}) = -\frac{1}{m} \sum_{i=1}^{m} \left[ y^{(i)} \log \hat{y}^{(i)} + (1 - y^{(i)}) \log(1 - \hat{y}^{(i)}) \right]$$
- `J(w, b)`: 关于参数 `w` 和 `b` 的成本函数
- $y^{(i)}$: 第 `i` 个训练样本的真实标签


# Mathematical Foundations of Control and Machine Learning

**Friedrich-Alexander-Universität Erlangen-Nürnberg — Department of Mathematics**
Master's level course, Winter semester 2026.

| | |
|---|---|
| **Lecturer** | Prof. Dr. Enrique Zuazua |
| **Teaching Assistant** | Daniel López Montero |
| **Evaluation** | Oral presentation (100%); attendance is taken into account |
| **Contact** | [cml.fau@gmail.com](mailto:cml.fau@gmail.com) | 
| **Website** | [cml-fau.github.io](https://cml-fau.github.io/) |
| **StudOn** | [studon.fau.de/campo/course/579004](https://www.studon.fau.de/campo/course/579004) |

This repository holds the lecture notebooks and the slides for the students. The notebooks, with
their outputs, are published as a website at **https://cml-fau.github.io/**.

## Contents

- [About the course](#about-the-course)
- [Learning objectives](#learning-objectives)
- [Evaluation](#evaluation)
- [Prerequisites](#prerequisites)
- [Course material](#course-material)
- [Installation and running the notebooks](#installation-and-running-the-notebooks)
- [Website](#website)
- [Bibliography](#bibliography)

## About the course

The course provides a unified mathematical perspective on control theory and machine learning. It
introduces key concepts from the analysis of dynamical systems governed by ordinary and partial
differential equations (ODEs and PDEs) — controllability, observability and stability — and builds
on them to show how control-theoretic and optimization-based methods explain the dynamics of
state-of-the-art machine learning systems: deep neural networks, federated learning frameworks,
reinforcement learning and large language models (LLMs).

## Learning objectives

By the end of the course students will have developed a solid understanding of the mathematical and
dynamical foundations underlying control and learning systems. They will be able to

- analyse the optimization and stability properties of deep learning algorithms,
- explain how control-theoretic principles extend to large-scale models such as LLMs,
- deliver clear and rigorous scientific presentations of technical concepts and research results.

## Evaluation

Assessment takes into account attendance and active participation and a group presentation in the final sessions of the course.

- **Groups** of at least three students choose any topic related to the course, provided it has
  substantial mathematical content.
- **Registration:** before 1 November 2026, email [cml.fau@gmail.com](mailto:cml.fau@gmail.com) the
  names of all group members, the topic and your preferred presentation dates.
- **Slides** (PDF) are sent to the same address before the day of the presentation.
- **Format:** 15 minutes of presentation and 15 minutes of questions; every member takes part in both.
- **Attendance** at all presentation sessions is required, also after your own group has presented.

| | |
|---|---|
| **Lectures** | 12 Oct – 7 Dec 2026 |
| **Presentations** | 14 & 21 Dec 2026 · 11, 18, 25 Jan & 1 Feb 2027 |

## Prerequisites

Strongly recommended: basic knowledge of calculus, linear algebra, ODEs and PDEs. The code is
written in Python with PyTorch, but no prior exposure to either is assumed — the notebooks keep the
code to the shortest fragment that illustrates the mathematics.

## Course material

Each notebook in [`notebooks/`](notebooks/) is self-contained: the mathematics is developed in the
text and the code is the smallest runnable confirmation of it.

| # | Notebook | Topics |
|---|---|---|
| 01 | [Introduction to Machine Learning & Deep Learning](notebooks/01_intro_to_ml.ipynb) | Risk minimization, representations, models (linear regression, neural networks, softmax classifiers), training (gradient descent, backpropagation, mini-batch SGD), generalization, a zoo of architectures |
| 02 | [Control Theory](notebooks/02_control_theory.ipynb) | Kalman rank condition, controllability Gramian, pole placement, LQR and the Riccati equation, model predictive control |
| 03 | [Optimization and gradient descent](notebooks/03_optimization.ipynb) | Descent lemma, convergence in the convex and non-convex case, momentum, noisy gradients and the Gibbs measure |
| 04 | [Neural ODEs](notebooks/04_neuralodes.ipynb) | Residual networks as Euler steps, numerical ODE solvers, learning dynamics and representations |
| 05 | [Diffusion models](notebooks/05_diffusion_models.ipynb) | The heat equation as noising, Feynman–Kac, Ornstein–Uhlenbeck forward process, reverse-time SDE and probability-flow ODE, score matching |
| 06 | [Transformers](notebooks/06_transformers.ipynb) | Self-attention, multi-head attention, positional encoding, the transformer block, masked language modelling |
| 07 | [Reinforcement Learning](notebooks/07_reinforcement_learning.ipynb) | Bellman equation and value iteration, Q-learning, exploration vs. exploitation, Pontryagin's maximum principle, Hamilton–Jacobi–Bellman (appendix) |

Lecture slides go in [`lectures/`](lectures/), one folder per lecture (`01_introduction_control_theory/`
holds the `.tex`, the compiled `.pdf` and its `images/`). Presentations from previous years are in
[`presentations/`](presentations/).

## Installation and Running the notebooks

The python environment is managed with [uv](https://docs.astral.sh/uv/). 

```bash
git clone https://github.com/cml-fau/cml-fau.github.io.git mfcml
cd mfcml
uv sync # This creates a `.venv/` with all python dependencies installed
```



To run the notebooks, open one in VS Code and select `.venv/bin/python` as the kernel.

<details>
<summary>Without uv</summary>

```bash
python3 -m venv .venv
.venv/bin/pip install --index-url https://download.pytorch.org/whl/cpu torch
.venv/bin/pip install numpy matplotlib jupyter ipykernel
```
</details>



<details>
<summary>In JupyterLab</summary>

```bash
uv run jupyter lab notebooks/
```
</details>

<!-- 
## Website

The website is built with [Quarto](https://quarto.org) from `_quarto.yml`, `index.qmd` and the
notebooks, and is deployed to GitHub Pages by
[`.github/workflows/publish.yml`](.github/workflows/publish.yml) on every push to `main`. Notebooks
are **not re-executed**: the site shows the outputs saved in them, so run a notebook and save it
before pushing. Code cells are folded by default. To hide a cell on the site, put one of these
comments on its first line: `#| include: false` (drop the cell), `#| echo: false` (hide the code,
keep the output) or `#| output: false` (keep the code, hide the output).

To preview locally (requires the [Quarto CLI](https://quarto.org/docs/get-started/)):

```bash
quarto preview
``` -->

## Bibliography

1. I. Goodfellow, Y. Bengio, and A. Courville, *Deep Learning*. MIT Press, 2016.
2. R. S. Sutton and A. G. Barto, *Reinforcement Learning: An Introduction*, 2nd ed. MIT Press, 2018.
3. C. F. Higham and D. J. Higham, "Deep learning: An introduction for applied mathematicians," *SIAM Review*, 61(4) (2019), 860–891.
4. L. Bottou, F. E. Curtis, and J. Nocedal, "Optimization methods for large-scale machine learning," *SIAM Review*, 60(2) (2018), 223–311.
5. J. Nocedal and S. J. Wright, *Numerical Optimization*, 2nd ed. Springer, 2006.
6. J.-M. Coron, *Control and Nonlinearity*, Mathematical Surveys and Monographs, Vol. 136. American Mathematical Society, 2007.
7. D. Ruiz-Balet and E. Zuazua, "Neural ODE control for classification, approximation and transport," *arXiv preprint* arXiv:2104.05278, 2021.
8. E. Zuazua, "Propagation, observation, and control of waves approximated by finite difference methods," *SIAM Review*, 47(2) (2005), 197–243.
9. E. Zuazua, "Controllability and observability of partial differential equations: Some results and open problems," in *Handbook of Differential Equations: Evolutionary Equations*, Vol. 3, North-Holland, 2006, pp. 527–621.

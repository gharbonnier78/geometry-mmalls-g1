\documentclass[10pt]{article}
\usepackage[a4paper,margin=1.8cm]{geometry}
\usepackage{amsmath,amssymb,booktabs,tabularx,microtype,hyperref,lmodern}
\usepackage[T1]{fontenc}
\hypersetup{colorlinks=true,linkcolor=blue,urlcolor=blue}
\title{Geometry-MMALS G1 v1.0.9\\Stationary Route Geometry Qualification Pilot}
\author{Guillaume Harbonnier}
\date{June 2026}
\begin{document}
\maketitle
\begin{abstract}
Version 1.0.9 is a focused replication protocol derived from the executed v1.0.8 result. v1.0.8 produced strong single-seed d4 candidate evidence for context order, route order, cross-source fiber consistency, held-out factor decoding, effective rank, and source-disjoint causal specificity. A post-run audit identified a nonstationary route target: the same angular relation received different targets as the visible continual-learning span expanded. v1.0.9 replaces that target with a fixed chord-compatible topology, keeps the d4 context bottleneck and global-alignment design, adds a legacy comparator, evaluates five model seeds on a fixed source and sensory boundary, introduces a dense angle grid, and exports both within-seed source-bootstrap and across-seed confidence intervals. The protocol remains non-claiming until execution.
\end{abstract}

\section{Motivation from v1.0.8}
The v1.0.8 d4 full-alignment treatment improved trained context Spearman order by 0.240 with a source-bootstrap interval $[0.199,0.285]$, route order by 0.165 with interval $[0.114,0.216]$, held-out factor decoding from $R^2=-0.009$ to $R^2=0.301$, effective rank from 2.64 to 3.49, and mean nonzero-scale causal specificity to approximately 1.79. Prediction and forgetting changed only slightly. These are promising but single-seed results.

The legacy route loss normalized factor gaps by the maximum gap visible in the current stage. Consequently, a fixed pair such as $(-60^\circ,-30^\circ)$ was first assigned a maximal target and later a quarter-span target. The protocol cannot be qualified while its topology changes during learning.

\section{Stationary route geometry}
For route probabilities $r_{s,a}\in\Delta^{H-1}$, define square-root coordinates $q_{s,a}=\sqrt{r_{s,a}}$. The normalized route chord is
\begin{equation}
 d_R(r_{s,a},r_{s,b})=\sqrt{1-\langle q_{s,a},q_{s,b}\rangle}.
\end{equation}
The factor target is frozen over the declared $120^\circ$ experimental span:
\begin{equation}
 \tau(u_a,u_b)=\sin\left[\frac{\pi}{2}\min\left(\frac{|u_a-u_b|}{120^\circ},1\right)\right].
\end{equation}
The stationary route objective is
\begin{equation}
 \mathcal L_{R,\mathrm{stat}}=
 \mathbb E_{s,a<b}\left[d_R(r_{s,a},r_{s,b})-\tau(u_a,u_b)\right]^2
 +\lambda_{\mathrm{far}}\mathcal L_{\mathrm{far}}.
\end{equation}
The target is invariant to stage, curriculum order, and the number of angles currently visible.

\section{Methods}
The primary context dimension is fixed at four. The frozen sensory grove, source identities, tangent-fit split, tangent-evaluation split, curriculum, anchor weight, optimizer, and compute budget remain identical across methods within every model seed.

\begin{center}
\begin{tabularx}{\linewidth}{@{}lXX@{}}
\toprule
Method & Route objective & Context/global objectives \\
\midrule
\texttt{d4\_no\_geo} & None & None \\
\texttt{d4\_full\_legacy\_route} & v1.0.8 nonstationary target & Context, spread, fiber, centroid \\
\texttt{d4\_full\_stationary\_route} & Fixed chord target & Context, spread, fiber, centroid \\
\bottomrule
\end{tabularx}
\end{center}

The pilot uses model seeds $\{0,1,2,3,4\}$ with a fixed source split and a common frozen sensory representation. This isolates MMALS initialization and training-order variability. A later final qualification should also vary source and sensory seeds.

\section{Evaluation}
The dense final evaluation grid is
\[
-75,-60,-45,-30,-15,0,15,30,45,60,75\;\text{degrees}.
\]
Training uses only $-60,-30,0,60,30$ degrees. Held-out angles never enter training or checkpoint selection.

The notebook exports:
\begin{itemize}
\item source-level context, route, and synthesis order and stress;
\item dense held-out factor decoding;
\item final trained and held-out accuracy, NLL, and forgetting;
\item paired treatment-control source-bootstrap intervals by angle;
\item source-disjoint causal effects and source-bootstrap CSR intervals;
\item class-log-probability change and prediction-identity preservation;
\item per-seed summaries and seed-level Student-$t$ confidence intervals;
\item complete compute, source, sensory, state-hash, and release manifests.
\end{itemize}

\section{Statistical hierarchy}
Two uncertainty levels are kept distinct. Within a model seed, source identities are the bootstrap unit. Across the pilot, the five model seeds are the replication unit. A favorable source interval in a single seed is not considered replication. Candidate promotion requires a positive model-seed interval and at least 80\% positive seeds for the primary paired effect.

\section{Pilot decision gates}
The pilot is considered a candidate C1 success only if:
\begin{enumerate}
\item the stationary treatment has positive seed-level confidence intervals for trained route and context order relative to no geometry;
\item the stationary treatment does not lose its effect on the dense held-out grid;
\item the stationary target performs at least as well as the legacy target;
\item held-out context decoding remains positive and noncollapsed;
\item source-bootstrap causal CSR lower bounds exceed one in at least 80\% of seeds;
\item prediction-identity lower bounds exceed 0.95 in at least 80\% of seeds;
\item equal-compute and release-integrity gates pass for every seed.
\end{enumerate}

Passing these gates does not establish predictive superiority, host specialization, memory transport, or operational utility.

\section{Research history and tracked changes}
The notebook records fourteen changes, including the stationary route loss, the legacy diagnostic comparator, the d4-only focus, five-seed pilot, dense grid, paired prediction intervals, causal confidence intervals, identity preservation, seed-level aggregation, and archival integration of the v1.0.8 result report.

\section{Expected interpretation}
Three outcomes are anticipated. First, if stationary geometry replicates the d4 result and improves upon the legacy target, the next step is a larger qualification run with varied source splits. Second, if the full-alignment result replicates but stationary and legacy targets are equivalent, the v1.0.8 effect is robust but route-target correction is not the main driver. Third, if the effect disappears across seeds, v1.0.8 remains a useful single-seed diagnostic but cannot support C1 promotion.

\section{Non-claims}
This protocol makes no claim of final C1 qualification, predictive advantage, backward transfer, replay-free continual learning, quantum advantage, domain-general geometry, reproducible host specialization, dual-memory transport, or regulated-system readiness.

\section{Archive layout}
The GitHub release contains the v1.0.9 notebook and config, the complete v1.0.8 seed-0 evidence bundle, the v1.0.8 Results and Interpretation report with LaTeX sources, the reviewer Status and Perspective report v1.1 with sources, package tests, release checklists, and a clean source tree without datasets or runtime caches.

\end{document}

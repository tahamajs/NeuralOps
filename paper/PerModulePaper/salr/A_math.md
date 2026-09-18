# Appendix A. Mathematical Formulations

## A.1 Layer Transformation Details
For an incoming tensor $x \in \mathbb{R}^{B \times T \times d_{\text{in}}}$, `SALRLayer` executes:
$$\tilde{y} = x \tilde{W}^\top + b$$
where $\tilde{W}$ incorporates the pruning mask, quantization levels, or factorized low-rank matrix decomposition.

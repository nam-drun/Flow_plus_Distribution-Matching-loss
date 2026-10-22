# Why care?
Current SOTA in image generation is MDP + post-train with RLHF. For example, see [Qwen Image 2.0 technical reports](https://arxiv.org/pdf/2606.27608v1). Previous SOTA in image generation was Flow Matching and modern Diffusion. It looked like the time for Flow Matching has passed. Except that recently, people have figured out that you can post-train flow models with various distribution matching losses such as:
- Fréchet distance, see [FD loss paper](https://arxiv.org/abs/2604.28190).
- Adversarial GAN on Fréchet distance, see [AdvFD loss paper](https://arxiv.org/abs/2608.11205).
- KL, see [TDM paper](https://arxiv.org/abs/2503.06674) and [Mgflow paper](https://arxiv.org/abs/2609.35763).
With only 1 sampling step, these post-trained Flow Matching models could generate better quality images than pretrained Flow Matching with 50 sampling steps. For this reason, it's likely that 2027 will be the renaissance of Flow Matching. But even then, the big question remains: Given the following common senses:
- Pretrained Flow Matching is much more compute efficient than pretrained MDP.
- Post-trained Flow is more compute efficient than pretrained Flow by an order of magnitude.
- MDP and Flow Matching are only remotely related (in theory) via Hamilton-Bellman-Jacobi <-> Hamilton-Jacobi <-> Wasserstein, where only MDP is compatible with RLHF in image generation (see [DDPO paper](https://arxiv.org/abs/2305.13301)).
  
The questions are:
- Can post-trained Flow be even further optimised?
- Can MDP + RLHF (e.g., [Flow-GRPO paper](https://arxiv.org/abs/2505.05470)) be more compute efficient than post-trained Flow?
- Can a practical common feat between MDP and Flow Matching be founded?

We think that all these questions tie back to how post-trained Flow models leverage discretisation error to get better quality image (see left panel in the picture below). 


# Flow Matching recap
If you try to sample any distribution in practice, you will see a point cloud. Suppose you transport all samples of this distribution to some other positions in space after $T$ time, then you will get another distribution $P_t$ (unless somehow $X_0 = X_T$). In physics, you learn about *displacement = velocity x time*, i.e., $X_{t_{k+1}} = X_{t_k} + \Delta t v(t_k, X_{t_k})$. Same idea applies for here. During sampling, given $X_0 \sim \mathcal{N}(0, I_d)$, you "transport" that sample to $X_1$ using *next position = current position + velocity x time*, which is literally the case if you use Euler integration solver, but still holds true for more accurate solvers like Heun and Dormand-Prince 5(4). Now, set $T = 1$, $P_0 = \mathcal{N}(0, I_d)$ and $P_1=$ *data distribution*, then you have discovered Flow Matching. Side note, also from Physics, $X_{t_{k+1}} = X_{t_k} + \Delta t v(t_k, X_{t_k})$ leads to the expression below that links start point $X_0$ to the sampled end point $\hat{X}_1$. This expression has the following worth noting property: As number of sampling steps increase to extremely high, the discretisation error is reduced to 0, thus the sampled end point $\hat{X}_1$ becomes true end point $X_1$.
```math
\begin{align*}
& \hat{X}_1 = X_0 + \Delta t \sum_{k=0}^{N-1} v(t, X_{t_k}), \\
& \text{where } \Delta t = \frac1N, N \text{ is number of sampling steps} \\
& N \to \infty \implies \Delta t \to 0 \implies \Delta t \sum_{k=0}^{N-1} v(t, X_{t_k}) \to \int_0^1 v(s, X_s) ds \\
& \implies \text{discretisation error} \to 0 \implies \hat{X}_1 \to X_1
\end{align*}
```

The next step in Flow Matching is to find out how to train the neural network on velocity. So where is velocity coming from during training? Again in physics, you learn that velocity = derivative of current position $X_t$. Same idea applies here. First, you sample a random pair of "start point, end point": $`\left\{X_0,X_1\right\}`$ with $X_0 \sim \mathcal{N}(0, I_d)$ being pure noise and end point $X_1$ being accessible image during training. Then you compute $X_t$ using noise schedule $\alpha_t$ and $\beta_t$. E.g., if you use VP schedule from DDPM diffusion, then $X_t = \sqrt{1 - t^2}X_0 + tX_1$; if you use linear schedule from [JiT paper](https://arxiv.org/abs/2511.13720v1) then $X_t = (1-t)X_0 + tX_1$. From $X_t$, you take its derivative $\dot{X}_t$ to acquire velocity $v(t, X_t)$. Now, if multiple trajectories intersect at some random point $X_t = x$, you can't really feed multiple "velocities" to the neural network. So the compromise is to take their averages $v(t, x) = \mathbb{E}[\dot{X}_t \mid X_t = x]$. Note, this is also why people use the term "velocity field" $v(t, x)$ instead of "velocity" $v(t, X_t)$ or $\dot{X}_t$ in Flow Matching. But, if the ambient space $\mathbb{R}^d$ has high number of dimensions, which is always true in image generation), then $\mathbb{E}[\dot{X}_t \mid X_t = x] \approx \dot{X}_t$. So it's fine to treat "velocity field" as if it is "velocity". In the picture below, we show how Flow Matching works using Base Continuous $X_t$ and Base Euler, where Base Euler $\hat{X}_t$ is what $X_t$ would look like if we reconstruct it use Euler with 4 sampling steps. Lastly, for modern diffusion, you add-on random noise during sampling, whether this is practically useful or not is questionable. Side note, modern diffusion are distinguished from classical diffusion by using score or denoiser term to derive velocity field to treat the entirety of sampling process as transport (recall the *next position = current position + velocity x time*). Whereas if you look at diffusion in the early days, either they use MCMC (Langevin dynamics) during sampling, see page 4 in ([Yang Song-Kingma 2021 paper](https://arxiv.org/abs/2101.03288)); or they use mean and covariance to treat sampling as a sequence of Gaussian transitions.


# How to leverage discretisation error, instead of fighting it
Given some pretrained velocity field $v_B(t, x)$, it is not a surprise that during post-training, distribution matching loss perturbs $v_B(t, x)$. This means that for the same start point $X_0$, $v_P(t, x)$ will transport $X_0$ along some different trajectory (Perturbed Continuous) to arrive a different endpoint. Assume that $v_B(t, x)$ and $v_P(t, x)$ are perfectly learned, respectively. 
> You can learn a perturbed velocity field that belongs to some ***specific*** Perturbed Continuous trajectory, such that its Perturbed Euler can recover $X_1$ exactly (see the left panel in the picture below).

In other words, you intentionally learn a different velocity field that Flow Matching considers "wrong" (i.e., not arriving $X_1$ with Base Continuous), but still arriving $X_1$ with Perturbed Euler during sampling by leveraging discretisation error (see the left panel in the picture below). This brings us 2 questions: 
- Given $X_0$, where is its corresponding Perturbed Continuous?
- And how can distribution matching loss during training find Perturbed Continuous? 

![the picture below](https://github.com/nam-drun/Flow_plus_Distribution-Matching-loss/blob/main/plots/discretisation-error.png)

For the first question, define discretisation error of Base Continuous as $e_B^{disc} = X_1 - \hat{X}_1$. Now, because $`\left\{X_0,X_1\right\}`$ is drawn randomly. Having access to $X_1$ is easy if you have pretrained the Flow Matching/Diffusion model from scratch. But if you have the access to the pretrained checkpoint, then you'll need to continue pretraining the model to have access to $X_1$. Here, so long as high $\mathbb{R}_d \implies \mathbb{E}[\dot{X}_t \mid X_t = x] \approx \dot{X}_t$ (which is always the case in image generation), then Base Euler's end point $\hat{X}_1$ ***solely** tied to ***that specific*** pair $`\left\{X_0,X_1\right\}`$, not any other pair $`\left\{X_0,X_1\right\}`$ (as visually suggested by the picture above). Now, if you want Perturbed Euler's endpoint to be $X_1$ like in the left panel above, then Perturbed Continuous' end point need to be $X_1 + e_B^{disc}$. By comparison, Base Euler's end point is $X_1 - e_B^{disc}$. As $X_1 + e_B^{disc}$ and $X_1 - e_B^{disc}$ are 2 opposite points in space centred at $X_1$. This concludes the first question.

For the second question. We'll first explore [IMDE paper](https://arxiv.org/abs/2206.07335) with in [left-panel-to-IMDE.md](https://github.com/nam-drun/Flow_plus_Distribution-Matching-loss/blob/main/left-panel-to-IMDE.md), then use its framework to match experiment results for each distribution matching loss. Enjoy reading.

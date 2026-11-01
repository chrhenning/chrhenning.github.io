---
layout: distill
title: An Introduction to Uncertainty in Machine Learning
date: 2026-10-31 10:00:00
description: Every model makes an assumption about uncertainty, often without saying so. Where data is rare, that assumption decides the answer. This introduction explains where uncertainty comes from and how to judge when it needs to be faithful to be useful.
tags: uncertainty bayesian statistics
categories: machine-learning
og_image: https://chrhenning.com/assets/img/posts/introduction-to-uncertainty/lane-split-og.jpg
giscus_comments: true
related_posts: true
related_publications: false
citation: false
bibliography: 2026-10-31-introduction-to-uncertainty.bib
thumbnail: assets/img/posts/introduction-to-uncertainty/lane-split-thumb.jpg

authors:
  - name: Christian Henning
    affiliations:
      name: Personal Blog

toc:
  - name: What Uncertainty Is
  - name: Why It Matters
  - name: Modelling Uncertainty
  - name: Keeping Every Plausible Fit
  - name: Getting a Guarantee
  - name: From Uncertainty to Decisions
  - name: Useful, Not Necessarily Faithful
---

<blockquote>
  <p style="font-size: 1.3rem;">Essentially, all models are wrong, but some are useful.</p>
  <p style="text-align: right; font-style: normal; font-size: 0.9rem; margin-top: 0.5em;">George E. P. Box <d-cite key="box1987empirical"></d-cite></p>
</blockquote>

Most of machine learning is based on probabilistic modelling, even if it does not always seem like it. So most models carry some uncertainty, whether we chose it or not, and in many decisions it pays to take that uncertainty into account, as the examples in this post show.

In my experience, uncertainty in machine learning is a confusing topic to get into, so I wrote this introduction to give an intuitive overview. It is not comprehensive, but it should give you a good enough mental model to choose assumptions that make your uncertainty estimates useful for decision making, even though, as Box put it, the model itself will always be wrong.<d-footnote>This post is based on a talk I gave at the University of Alicante. The <a href="/assets/pdf/uncertainty_talk_alicante_2026.pdf">slides</a> are online. For a more thorough introduction, see Chapters 2 and 3 of my PhD thesis <d-cite key="henning2022phdthesis"></d-cite>.</d-footnote>

## What Uncertainty Is

Generally speaking, [uncertainty](https://en.wikipedia.org/wiki/Uncertainty) is incomplete knowledge, and probability is how we describe it: a distribution over the possible outcomes says how plausible each one is, given what we know.

It helps to separate two kinds of uncertainty:

- **Epistemic uncertainty** comes from what we have not learned yet, such as the true relationship between inputs and outputs. More data can reduce it.
- **Aleatoric uncertainty** comes from what we cannot observe: the inputs do not determine the outcome, so more data of the same kind will not remove it.

<div class="row mt-3 justify-content-center">
    <div class="col-md-6 col-sm-10 mt-3 mt-md-0">
        {% include figure.liquid loading="eager" path="assets/img/posts/introduction-to-uncertainty/08_two_uncertainties.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>Two kinds of uncertainty.</b> A Gaussian process fit to noisy data. The shaded band is where the model expects the output. Where the aleatoric arrow points, the outputs scatter widely even for similar inputs, so the band stays wide no matter how many points we add. Where the epistemic arrow points, there is no data, so the band is wide because the model does not know the function there, and data there would narrow it.
</div>

The line between the two depends on what we measure. A coin flip follows classical mechanics. If we do not measure how the coin is thrown, the best we can say is 50/50, and the uncertainty is aleatoric. If we do measure it, physics tells us how it will land, and the uncertainty becomes epistemic: now we have to learn the physics, which takes data. Richer inputs can reduce aleatoric uncertainty, but they give the model more to learn, and whether that pays off depends on how much data and prior knowledge we have.<d-footnote>Some inputs are out of reach. For example, weather is chaotic, so tiny differences, as small as the flap of a butterfly's wings, can grow into different weather a few weeks later. Since we cannot observe every butterfly, part of the uncertainty in a forecast stays aleatoric, however much we measure.</d-footnote>

## Why It Matters

A prediction is not a decision. When we decide, we often weigh the possible outcomes by how likely they are and what they would cost us, including rare outcomes that could hurt us badly. A single number hides this picture. It also cannot tell us when to hand a case to a human or to collect more data before we decide. The examples below show where modelling uncertainty matters.

<div class="row mt-3 justify-content-center">
    <div class="col-12 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/why-care.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>Five reasons to care about uncertainty.</b> Images in panels 1 and 3 generated with Gemini. The fork in panel 2 is by the United States Department of Agriculture, public domain, <a href="https://commons.wikimedia.org/w/index.php?curid=15699275">via Wikimedia Commons</a>.
</div>

1. **A human decides.** The model does not know what is at stake. A 20% chance of rain means one thing for a wedding and another for a walk. The model should therefore tell us how likely rain is, so that each of us can decide what that means for our own plans.
2. **A point estimate is not enough.** When several outcomes are plausible, a single prediction cannot represent them all. And when rare outcomes are costly, the tail risk can matter more than the typical case, yet a single prediction hides it.
3. **We can choose not to decide yet.** Selective automation hands unsure cases to a human. This works even for aleatoric uncertainty. If dust and an impurity look the same from the camera's angle, more labels will not help the model, but a person can turn the part and look again.
4. **We can ask for the right data.** [Active learning](<https://en.wikipedia.org/wiki/Active_learning_(machine_learning)>) and [Bayesian optimization](https://en.wikipedia.org/wiki/Bayesian_optimization) use uncertainty to ask for new data where it is most useful.
5. **It feeds further computation.** [Sensor fusion](https://en.wikipedia.org/wiki/Sensor_fusion) and [Kalman filters](https://en.wikipedia.org/wiki/Kalman_filter) weigh each input by its uncertainty. A camera is precise in direction but poor in depth, a radar the opposite, and combining them gives an estimate better than either.

All of these need the uncertainty to be useful. To see when it is, it makes sense to look at where it comes from.

## Modelling Uncertainty

As a running example, we look at steering angle prediction. The input is the image from a car's front camera, and the output $y$ is the steering angle. Such datasets can be recorded cheaply from human drivers. Take a car approaching a point where the road splits. In the left lane, drivers mostly go left. In the right lane, they mostly go right. In the middle lane, which points straight at the divider, about half go left and half go right.

<div class="row mt-3 justify-content-center">
    <div class="col-md-4 col-sm-6 mt-3 mt-md-0">
        {% include figure.liquid loading="eager" path="assets/img/posts/introduction-to-uncertainty/lane-split.jpg" class="img-fluid rounded z-depth-1" %}
    </div>
    <div class="col-md-4 col-sm-6 mt-3 mt-md-0">
        {% include figure.liquid loading="eager" path="assets/img/posts/introduction-to-uncertainty/00_lane_split_sketch.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>A lane split.</b> Left: from the middle lane, both directions are valid, but going straight is not (photo adapted from Fig. 3 in <d-cite key="cervera2021uncertainty"></d-cite>). Right: a sketch of the same split, seen from the top. The car's position along the cross section $x$ is important for predicting the steering angle.
</div>

The car's position across the lanes is implicit in the camera image. To keep the figures simple, we use it directly as a one-dimensional input $x$ in the figures below.<d-footnote>The rest of the image, such as where the road goes, matters just as much for the prediction. We implicitly assume that the model knows it, since it cannot be compressed into a simple one-dimensional variable that keeps the explanations easy to follow.</d-footnote>

What we want to learn is the conditional distribution $p^\*(y \mid x)$: for each position, how likely each steering angle is. As is common in [statistical learning theory](https://en.wikipedia.org/wiki/Statistical_learning_theory), we assume that the data come from a fixed joint distribution $p^\*(x, y)$, and the recordings from human drivers are samples from it.

The ground truth $p^\*(y \mid x)$ is just one of many possible conditional distributions.<d-footnote>Strictly speaking, the truth is only defined where $p^*(x) > 0$. Many hypotheses agree with it on the road but differ off the road, where no data can tell them apart.</d-footnote> We call each conditional distribution of $y$ given $x$ a hypothesis, and together they form a space. As we will see, learning amounts to searching a subset of this space.

<div class="row mt-3 justify-content-center">
    <div class="col-md-8 col-sm-12 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/01_space_and_truth.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>The truth is one point in a space of hypotheses.</b> Left: every point in the space is a conditional distribution $p(y \mid x)$, a full description of which steering angles are plausible at each lane position. A few are drawn as small images. The orange star is the truth $p^*(y \mid x)$. Right: the truth for the lane split, with samples from it, and below the distribution of lane positions $p(x)$.
</div>

That subset is the **model**, a family of hypotheses indexed by parameters $\theta$. A common choice for regression is a Gaussian whose mean is a neural network $f_\theta(x)$ and whose variance $\sigma^2$ is fixed:

$$
p_\theta(y \mid x) = \mathcal{N}\big(y;\, f_\theta(x),\, \sigma^2\big).
$$

The truth need not lie inside the model. For the lane split, it does not: a single Gaussian has one peak, but in the middle lane the truth has two.

<div class="row mt-3 justify-content-center">
    <div class="col-md-8 col-sm-12 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/02_model_set.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>A model is a subset of hypotheses.</b> Left: the model (blue region) does not contain the truth. Training starts from some hypothesis $p_{\theta_0}$. Right: that starting hypothesis, a Gaussian with fixed variance around a straight line.
</div>

Training picks the hypothesis that best explains the data. It minimizes the **negative log-likelihood** (NLL), the average of $-\log p_\theta(y_i \mid x_i)$ over the training examples. For the Gaussian with fixed variance, this is the familiar **mean squared error**<d-footnote>I walked through this connection, from the KL divergence to the mean squared error, in an <a href="/blog/2025/when-mse-loss-leads-to-mis-steering/">earlier post</a>.</d-footnote>:

$$
\text{NLL} = \frac{1}{2\sigma^2}\,\text{MSE} + \text{const}.
$$

So a network trained with mean squared error already has an uncertainty model, even if nobody chose it on purpose.

<div class="row mt-3 justify-content-center">
    <div class="col-md-8 col-sm-12 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/03_training.gif" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>Training moves the model closer to the truth.</b> Left: training moves the hypothesis from its starting point $p_{\theta_0}$ toward the truth. It stops at the edge of the model, because the truth lies outside it. Right: the fitted mean and its fixed band.
</div>

How far is the trained model from the truth? The expected NLL splits into two terms:

$$
\mathbb{E}_{x,y}[\text{NLL}] = \mathbb{E}_x\Big[\mathrm{KL}\big(p^* \,\|\, p_\theta\big)\Big] + \mathbb{E}_x\big[H(p^*)\big],
$$

where both expectations are over the true data distribution. The first term is the [KL divergence](https://en.wikipedia.org/wiki/Kullback%E2%80%93Leibler_divergence), which measures how far the model is from the truth and is zero only if they match. The second is the [entropy](<https://en.wikipedia.org/wiki/Entropy_(information_theory)>) of the truth, its aleatoric uncertainty, which does not depend on the model. Minimizing the NLL therefore moves the model toward the truth. But we never know the entropy of the truth, so the NLL alone cannot tell us how far away we still are.<d-footnote>This is why we are usually blind to model misspecification: a low NLL does not tell us whether the truth lies inside the model. I will get back to this later. Moreover, even the KL divergence would not be enough, since it is an average over all inputs. In real driving data, lane splits are rare, so a model can be close to the truth on average and still steer into the divider. Knowing which inputs matter takes domain expertise, which is ultimately the modeller's responsibility.</d-footnote>

<div class="row mt-3 justify-content-center">
    <div class="col-md-6 col-sm-12 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/04_middle_lane.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>The best fit steers into the divider.</b> In the middle lane, drivers take the left or the right lane (orange). The best Gaussian with fixed variance (blue) sits between them.
</div>

Back in the middle lane, the single peak has a dangerous consequence. The mean squared error is minimized by the average steering angle, and the average of left and right is straight ahead, into the divider. No choice of parameters avoids this, because every hypothesis in the model has a single peak. In an [earlier post](/blog/2025/when-mse-loss-leads-to-mis-steering/), I looked at this example in more detail, and we studied it in a paper on misspecification, the case where the truth lies outside the model <d-cite key="cervera2021uncertainty"></d-cite>.

The fix is a model that contains the truth. For this example, a mixture of two Gaussians, whose weights, means and variances are all outputs of the network, is enough to contain the truth.

<div class="row mt-3 justify-content-center">
    <div class="col-md-10 col-sm-12 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/05_model_boxes.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>Two models of the same problem.</b> Left: the network predicts only the mean of a Gaussian with fixed variance (mean squared error regression). Right: it predicts a mixture of two Gaussians, with a weight, two means and two standard deviations.
</div>

Understanding the problem well enough to make this choice is the modeller's job. But a richer model is not free: it contains more hypotheses, so the data has to do more work to single out the right one.<d-footnote>This is the familiar <a href="https://en.wikipedia.org/wiki/Bias%E2%80%93variance_tradeoff">bias–variance tradeoff</a>. For example, a fully connected network can represent everything a convolutional network can. Yet for images we use convolutional networks, because they leave out hypotheses that do not fit images and so need much less data. Their assumptions seem stronger than necessary, though: with enough data, vision transformers, which assume less, do better.</d-footnote>

<div class="row mt-3 justify-content-center">
    <div class="col-md-10 col-sm-12 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/06_more_data.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>A richer model contains the truth, but needs data.</b> With 20 training points, the mixture model (blue region) overfits and finds the wrong hypothesis. With 2,000 points, it comes close to the truth. Each mode fades where its weight, $\pi$ or $1 - \pi$, is small.
</div>

Since the mixture contains the truth, enough data brings it close, including in the middle lane. Only then is its spread the aleatoric uncertainty: with the given information, even a perfect model cannot say which lane a particular driver will take.<d-footnote>As with the coin flip, what counts as aleatoric depends on what the input contains. If $x$ were random noise, it would carry no information, and the best fit would ignore it and learn the distribution of steering angles independent of the input, $p(y)$. A rear camera image is more deceptive. Steering changes slowly (it is strongly <a href="https://en.wikipedia.org/wiki/Autocorrelation">autocorrelated</a>), so the view behind the car shows how the driver steered a moment ago, and repeating that is usually a good guess. The validation error decreases as expected during training, yet the model can never anticipate a turn, because the road ahead is not in the input. I discuss this gap between predicting and forecasting in an <a href="/blog/2026/good-predictor-not-good-forecaster/">earlier post</a>.</d-footnote>

<div class="row mt-3 justify-content-center">
    <div class="col-md-10 col-sm-12 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/12_aleatoric.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>A good fit captures aleatoric uncertainty.</b> Left: the mixture model after 2,000 points. Right: its prediction in the middle lane (dashed blue) against the truth (orange).
</div>

But in practice we do not know the truth, so we cannot check the fit like this. How do we know how much we still do not know?

## Keeping Every Plausible Fit

So far, training gave us a single hypothesis. But with only 20 data points, many hypotheses explain the data about equally well, and by picking one of them, we ignore that the data cannot tell them apart. Bayesian inference instead keeps all of them.<d-footnote>Bayesian inference is not the only way to capture epistemic uncertainty, but it is a principled one, and the one I know best.</d-footnote>

Before seeing any data, we decide how plausible each hypothesis in the model is. This is the **prior** $p(\theta)$, a soft inductive bias. It captures what we know, or assume, before training, and everything the model does not know is measured relative to it.<d-footnote>Choosing a prior can feel arbitrary, and often it is. Think of a CNN, which rules out hypotheses that do not suit images. A prior does not rule them out, but it makes them less plausible from the start. I discuss how the prior shapes what a model does not know in an <a href="/blog/2026/uncertainty-decomposition/#the-prior-determines-what-a-model-considers-surprising">earlier post</a>.</d-footnote> Data then shifts the weight to the hypotheses that explain it, giving rise to the **posterior**:

$$
\underbrace{p(\theta \mid \mathcal{D})}_{\text{posterior}} = \frac{\overbrace{\textstyle\prod_i p_\theta(y_i \mid x_i)}^{\text{likelihood}} \; \overbrace{p(\theta)}^{\text{prior}}}{p(\mathcal{D})},
$$

where $\mathcal{D} = \\{(x_i, y_i)\\}_{i=1}^n$ is the data. The likelihood, written $p(\mathcal{D} \mid \theta)$ for short, measures how well hypothesis $\theta$ agrees with the data.

<div class="row mt-3 justify-content-center">
    <div class="col-md-4 col-sm-8 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/15_bayes_sets.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>Bayes weighs all hypotheses instead of committing to one.</b> Within the model, the prior spreads its weight widely. The posterior concentrates it on the hypotheses that explain the data.
</div>

<div class="row mt-3 justify-content-center">
    <div class="col-md-10 col-sm-12 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/14_prior_posterior_simple.gif" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>From prior to posterior.</b> A few hypotheses from the mixture model, drawn first from the prior and then from the posterior after observing 20 data points. Each color ties a hypothesis on the right to its point in the space on the left. After the data, the hypotheses agree where there is data and still disagree where there is none, such as in the middle lane.
</div>

To predict, we average all hypotheses, each weighted by its posterior probability. This is the **posterior predictive**:

$$
p(y \mid x, \mathcal{D}) = \int p_\theta(y \mid x) \, p(\theta \mid \mathcal{D}) \, \mathrm{d}\theta.
$$

With more and more data, the posterior concentrates on a single hypothesis: the one in the model that is closest to the truth.<d-footnote>Closest in KL divergence. This holds under regularity conditions, including that the prior puts enough weight near that hypothesis <d-cite key="kleijn2006misspecification"></d-cite>.</d-footnote> If the model contains the truth, that hypothesis is the truth itself. If not, as in the sketch below, it is only the best the model has to offer.

<div class="row mt-3 justify-content-center">
    <div class="col-md-4 col-sm-8 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/16_uncertainty_sources.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>Three sources of uncertainty.</b> Aleatoric: the truth itself is uncertain. In our example, the input $x$ does not contain the information needed to know which of the two directions a driver will take. Approximation: given the data seen so far, we do not know which hypothesis in the model is best. The posterior captures this. Model: the truth may lie outside the model. The posterior cannot capture this, because it only weighs hypotheses inside the model.
</div>

This picture splits uncertainty into three sources, using the terms of Hüllermeier and Waegeman <d-cite key="hullermeier2021aleatoric"></d-cite>. What sets them apart is what reduces them:

- **Aleatoric:** more data of the same kind, camera images paired with steering angles, does not help. Only more information in the input would, for example the driver's route.
- **Epistemic**, what we have not learned, in two parts:
  - **Approximation:** more data reduces it, since the posterior concentrates on the closest hypothesis.
  - **Model:** more data does not fix it within the model. Only a different model does, one that is closer to the truth. Data can still guide the model selection, which is why this uncertainty is epistemic too.

The last point matters in practice. A misspecified model can still have a confident posterior: it is confident about the least wrong hypothesis it contains.

<div class="row mt-3 justify-content-center">
    <div class="col-12 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/17_two_models.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>Bayes shows what the model does not know, not whether the model is wrong.</b> Both models see the same data, and for the sake of illustration, both lack data for the right lane. Top: a single Gaussian. Bottom: the mixture of two Gaussians. In both, the posterior hypotheses spread out where there is no data. Only the mixture can represent the two lanes. The log evidence on the right shows that the data clearly favor the mixture.
</div>

Both models above show more uncertainty where data is missing. That is approximation uncertainty, and both capture it. To also question the model itself, a full probabilistic treatment would weigh models too, but that is hard in practice. What we can do is compare a few candidate models. For this, Bayesian inference offers the [evidence](https://en.wikipedia.org/wiki/Marginal_likelihood), $p(\mathcal{D} \mid \mathcal{M}) = \int p(\mathcal{D} \mid \theta) \, p(\theta \mid \mathcal{M}) \, \mathrm{d}\theta$, the probability of the data under model $\mathcal{M}$, averaged over its prior.<d-footnote>The notation can be misleading, since it suggests that we treat the model as a random variable. We do not have to, so a semicolon, $p(\mathcal{D}; \mathcal{M})$, might be a preferable notation. Note also that $\mathcal{M}$ now includes the prior: the same hypotheses with a different prior form a different model.</d-footnote> Here it clearly prefers the mixture.<d-footnote>The evidence has a built-in Occam's razor <d-cite key="mackay1992bayesian"></d-cite>: a more flexible model spreads its prior over more possible datasets, so it pays a price unless the data need that flexibility. Here, the two lanes do.</d-footnote> But it only ranks the models we try, and if none of them contains the truth, it will not tell us.

Like the KL divergence earlier, the evidence is an average over all data. In real driving data, lane splits are rare, so their effect can vanish in the evidence, and the simpler model may even win. Domain knowledge would tell us otherwise. This is why choosing the model remains the modeller's job, and comparing models is a tool for it, not a replacement.

So far, we have taken the prior as given. But the prior is part of the model. In theory, with enough data, its choice stops mattering, as long as it does not rule out the right hypotheses. In practice, we rarely have that much data, and a poor prior, like any poor inductive bias, can hurt a lot. I discussed this in more detail in earlier posts on [uncertainty](/blog/2026/uncertainty-decomposition/) and on [continual learning](/blog/2025/uncertainty-can-solve-continual-learning/).

In short, the posterior is uncertain where the data and our assumptions leave room for disagreement. Low uncertainty therefore does not mean we have seen data there. Generalization works exactly this way: far from the data, the inductive bias makes the hypotheses agree. If the bias is good, the model is confident and right. If not, it is confident and wrong.

## Getting a Guarantee

Sometimes we want a statistical guarantee, ideally one that does not depend on our modelling choices, since those can be arbitrarily wrong. Conformal prediction gives such a guarantee. Instead of a single prediction, it outputs a prediction set that contains the true output, say, 90% of the time. This is called 90% coverage. It wraps any trained model, and as long as the data are [exchangeable](https://en.wikipedia.org/wiki/Exchangeable_random_variables), the guarantee holds no matter how wrong the model is <d-cite key="angelopoulos2023conformal"></d-cite>.

Conformal prediction comes in many flavors. We look at the simplest and most common one, split conformal prediction. Its recipe has four steps:

1. Hold out a **calibration set** that the model was not trained on.
2. Pick a **score** $s(x, y)$ that measures how wrong the model is on a pair $(x, y)$, for instance the absolute error $\lvert y - f(x) \rvert$.
3. Take the 90% quantile $\hat q$ of the scores on the calibration set.<d-footnote>Strictly, a slightly higher quantile, at level $\lceil (n+1)(1-\alpha) \rceil / n$ for $n$ calibration examples and target coverage $1-\alpha$, to account for the finite calibration set.</d-footnote>
4. For a new input $x$, the **prediction set** contains every $y$ with $s(x, y) \le \hat q$.

<div class="row mt-3 justify-content-center">
    <div class="col-md-6 col-sm-10 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/18_conformal_recipe.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>The conformal threshold.</b> The scores of the calibration examples, here the absolute error of a regressor. The threshold $\hat q$ is their 90% quantile.
</div>

If the calibration and test data are exchangeable, the set has at least 90% coverage. This holds on average over inputs, not for any particular input, such as one at the lane split.

But the guarantee does not say whether the sets are useful. For that, we want low scores in the histogram above, since a small $\hat q$ gives tight sets. A poor model has higher scores and gets wider sets, with the same coverage.

<div class="row mt-3 justify-content-center">
    <div class="col-12 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/19_conformal_sets.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>Three conformal sets, all with 90% coverage.</b> Left: the Gaussian with fixed variance and the absolute error as score. The set has the same width everywhere and includes steering straight into the divider. Middle: the mixture model, with a score from its cumulative distribution <d-cite key="chernozhukov2021distributional"></d-cite>. The set is the model's central 90%, which still includes the divider. Right: the same mixture, with a score from its density. The set contains the two lanes and not the divider.
</div>

- **The model matters.** A model that cannot represent two lanes gives a set that does not show them.
- **The score matters.** The score is a modelling choice too. Even with a good model, a poor score can give a set that includes the divider.

The guarantee only needs a calibration set. Useful sets also need the same modelling work as before. I wrote more about this in a [recent post on conformal prediction](/blog/2026/conformal-prediction/).

## From Uncertainty to Decisions

So far, the goal was a faithful uncertainty: a predictive distribution close to the truth. But uncertainty is meant to be used, and [decision theory](https://en.wikipedia.org/wiki/Decision_theory) says how. The model provides a belief $p(y \mid x)$. Whoever acts provides a loss $L(a, y)$, the cost of action $a$ if the outcome turns out to be $y$. We then pick the action with the lowest expected loss:

$$
a^* = \arg\min_a \; \mathbb{E}_{y \sim p(y \mid x)}\big[L(a, y)\big].
$$

In the lane split, the action is a steering angle. The belief says which angles drivers take: left or right, never straight. The loss says what we want. If our destination is to the left, steering left has a low loss, steering right a higher one, and steering into the divider is worst of all. Under the true belief, the decision follows the left lane. A belief with a single peak in the middle rules out neither lane and picks straight.

How faithful does the belief need to be? It depends on the decision.<d-footnote>Since the belief is approximate anyway, we can fit it with the loss in mind, so that it is useful for the decision <d-cite key="lacostejulien2011approximate"></d-cite>.</d-footnote> In the rest of this section, we walk through two practical examples, visual quality inspection and holding reserve for wind power, where the answers differ.

### Visual quality inspection

Many factories use cameras to check every part that comes off the line. Mistakes are costly here, since a missed defect may reach a customer, lead to a recall or, in the worst case, put people at risk. To keep things simple, we consider a binary classifier in this section.<d-footnote>In practice, a yes or no is rarely enough. We may also want to know where the defect is, its outline, which component it affects and why the model flagged it.</d-footnote> It takes the camera image $x$ and outputs the probability $p(\text{defect} \mid x)$ that the part is defective. With stakes this high, should this probability not be faithful, or even come with a guarantee?

<div class="row mt-3 justify-content-center">
    <div class="col-md-6 col-sm-10 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/vqi_illustration.jpg" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>Visual quality inspection.</b> Image generated with ChatGPT.
</div>

To answer this, we look at how the probability turns into a decision. We reject a part if $p = p(\text{defect} \mid x)$ is above a threshold. If we reject, we pay a cost $c_{FP}$ when the part is good, which happens with probability $1 - p$. If we ship, we pay a cost $c_{FN}$ when it is defective, which happens with probability $p$. Rejecting is cheaper on average when $c_{FP}\,(1 - p) < c_{FN}\,p$, that is, when

$$
p(\text{defect} \mid x) > \frac{c_{FP}}{c_{FP} + c_{FN}}.
$$

What this derivation hides is that it takes $p$ at face value, so it assumes the model is **calibrated**: of all parts scored 0.1, about 10% should be defective. In this example, though, calibration matters less than it seems, for two reasons. First, calibrated against whom? Inspectors disagree on borderline parts, and since labels are expensive, each part is usually labeled by only one of them. So the labels can only tell us whether the model is calibrated against whoever labeled the data, and on borderline parts, another inspector would have labeled differently. Second, $c_{FN}$ includes recalls, lost customers and reputation, so it is rarely known. It is not even a single number, since a customer may never notice a faint scratch, while a deep crack can make the part fail. So the threshold is a guess anyway.

<div class="row mt-3 justify-content-center">
    <div class="col-md-6 col-sm-10 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/annotator_disagreement.jpg" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>Calibrated against whom?</b> Inspectors disagree on borderline parts. Image generated with ChatGPT.
</div>

What about a **guarantee**, such as "at most 5% of defects escape"? The guarantee we got from conformal prediction earlier does not give this. It holds on average over all parts, and since defects are rare, it can be met while missing most of them. We need coverage for defects alone. Conformal prediction can give this too, if we set the threshold using defects only. Then at most a fraction $\alpha$ of defects, here 5%, score below it <d-cite key="vovk2012conditional"></d-cite>.

This guarantee has a price. Labeled defects are rare and expensive to collect, and we need many of them for a stable threshold. Worse, a defect is anything that is not normal. The guarantee holds only for defects that are exchangeable with the ones we collected, and the next one may look like none of them.<d-footnote>Indeed, defects are so rare that practical solutions often teach the model with defect-free images only, an approach I worked on at Ethon (see <a href="https://www.ethon.com/articles/industrial-anomaly-detection-using-only-defect-free-images-to-train-your-inspection-model">here</a> and <a href="https://www.ethon.com/articles/why-your-next-visual-quality-inspection-system-will-be-training-free">here</a>).</d-footnote> Finally, the guarantee fixes the threshold, however many good parts it rejects.

<div class="row mt-3 justify-content-center">
    <div class="col-md-6 col-sm-12 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/23_vqi_threshold.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>The same guarantee, at very different prices.</b> In both panels, the threshold (blue) lets 5% of defects escape. Every good part to the right of it (dark gray) is rejected. Top: a good model rejects 3% of the good parts. Bottom: a weaker model rejects 56%.
</div>

If the model rejects too many good parts and we raise the threshold, we give up the guarantee and are back to costs we cannot measure.

So in this example, we need neither calibration nor a guarantee. Since $c_{FN}$ is unknown, an operator tunes the threshold by hand, and for that, only the order of the scores matters: they should grow with the severity of a flaw. Small scratches are rarely called defects and deep cracks almost always, and in between, inspectors disagree. A model calibrated against a large pool of inspectors would give such a score, but these labels are too expensive. Getting the order right without them is hard modelling work: we have to build the right inductive biases into the model, for instance during pre-training.

<div class="row mt-3 justify-content-center">
    <div class="col-md-8 col-sm-12 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/defect_severity.jpg" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>Not faithful, but useful.</b> A score that grows with the severity of a flaw lets the operator choose where the gray area ends. Image generated with ChatGPT.
</div>

### Holding reserve for wind power

Wind power depends on the weather, so a grid operator never knows exactly how much will arrive. To cover a shortfall, meaning less wind power than planned, the operator keeps backup power on standby, called the [reserve](https://en.wikipedia.org/wiki/Operating_reserve). Unlike inspecting parts, no person could forecast the shortfall by hand, so the model learns it from past data alone. It takes inputs $x$, such as the weather forecast and recent measurements, and outputs a distribution $p(\text{shortfall} \mid x)$ over the shortfall. If the shortfall exceeds the reserve, we have a shortage, and each missing unit costs $c_{\text{short}}$, and each unit of reserve that goes unused costs $c_{\text{idle}}$.<d-footnote>In practice, $c_{\text{short}}$ is much larger. A shortage must be covered within minutes, by fast and expensive plants, by buying power at short notice or, in the worst case, by cutting off customers. Idle reserve only costs what it takes to keep a plant ready. Unlike $c_{FN}$ in visual inspection, both costs can be roughly estimated, for instance from market prices, so for the sake of argument, we take them as known.</d-footnote>

The best reserve is the $\tau$-quantile of the predicted shortfall, with

$$
\tau = \frac{c_{\text{short}}}{c_{\text{short}} + c_{\text{idle}}}.
$$

The costs pick the quantile.<d-footnote>Why the $\tau$-quantile? Say we hold a reserve $r$ and add one more unit. If the shortfall turns out larger than $r$, the unit is used and saves $c_{\text{short}}$. Otherwise, it sits idle and costs $c_{\text{idle}}$. So the unit pays off when $c_{\text{short}}\, P(\text{shortfall} > r) > c_{\text{idle}}\, P(\text{shortfall} \le r)$. As $r$ grows, the left side shrinks and the right side grows, so we add reserve until both are equal. With $P(\text{shortfall} > r) = 1 - P(\text{shortfall} \le r)$, this gives $P(\text{shortfall} \le r) = \tau$, which is the $\tau$-quantile.</d-footnote> Since these costs change by the hour, so does $\tau$.

<div class="row mt-3 justify-content-center">
    <div class="col-md-6 col-sm-10 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/20_reserve.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>The best reserve is a quantile of the predicted shortfall.</b> With the reserve at the $\tau$-quantile, a shortage happens with probability $1 - \tau$.
</div>

To see what this asks of the model, we again take a Gaussian model for simplicity. On most days, the forecast is roughly right, and the shortfall is small. But on rare days, the wind dies down unexpectedly, and the shortfall is large. So in the tail, the truth is not Gaussian. Since shortages are costly, $\tau$ is high, and the reserve sits far out in the tail of the predicted distribution, so the model has to get these rare, large shortfalls right.

<div class="row mt-3 justify-content-center">
    <div class="col-md-6 col-sm-10 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/21_reserve_tail.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>The Gaussian gets the tail wrong.</b> The chance of a shortage for each reserve, under the truth (orange) and under the best-fitting Gaussian (blue). The dots mark the reserve each one sets at 90% and at 99%.
</div>

If we plan for a shortage 1 in 10 times ($\tau = 90\%$), the two dots almost coincide, and the Gaussian works well. Now say we plan for 1 in 100 ($\tau = 99\%$). The Gaussian sets the reserve at the blue dot. But how often this reserve falls short is decided by the truth, and at this reserve, the orange curve lies well above 1 in 100. Shortages come more than twice as often as planned. Unlike in visual inspection, the probabilities are used at face value here,<d-footnote>Why not adjust the reserve by hand, as the operator did with the threshold? In inspection, there is one threshold to tune. Here, $\tau$ changes by the hour, so every quantile would need tuning, and shortages are too rare to notice when one is off.</d-footnote> and since $\tau$ changes by the hour, the whole distribution must be faithful, tail included.

<div class="row mt-3 justify-content-center">
    <div class="col-md-6 col-sm-10 mt-3 mt-md-0">
        {% include figure.liquid loading="lazy" path="assets/img/posts/introduction-to-uncertainty/22_tail_data.png" class="img-fluid rounded z-depth-1" %}
    </div>
</div>
<div class="caption">
    <b>The tail is where data runs out.</b> A year of daily shortfalls drawn from the truth (gray), next to the truth and the Gaussian. Shortfalls rarer than once a year leave no data.
</div>

In a year of daily data, a 1-in-100 shortfall shows up only a few times, and anything rarer than once a year not at all. So where we need the uncertainty most, in the tail, we have the least data, and the assumptions built into the model decide the answer. We have to choose them from what we know about wind and weather.

## Useful, Not Necessarily Faithful

Every model in this post made an assumption about uncertainty, whether we chose it or not. Making it faithful took real work: a likelihood that can represent the truth, enough data to find it, and inductive biases that hold up where the data runs out.

That work is not always needed. Our own uncertainty is not faithful either. We humans misjudge probabilities in well-known ways <d-cite key="tversky1974judgment"></d-cite>, yet we handle most everyday tasks just fine. In this post, too, we saw tasks where uncertainty did not have to be faithful, and others where it counted. So **before investing in faithful uncertainty, ask what you gain from it**. And even when it does not have to be faithful, I believe it helps to know what faithful would mean. Then we know what our uncertainty gets wrong and can judge whether that matters for the decision.

_Feedback is welcome. If you think this introduction misses an important aspect, or you know other examples where making uncertainty useful matters, please leave a comment below._

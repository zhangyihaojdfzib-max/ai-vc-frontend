---
title: Ensemble forecasting with IBM Granite time-series models
title_original: Ensemble forecasting with IBM Granite time-series models
date: '2026-10-22'
source: Hugging Face Blog
source_url: https://huggingface.co/blog/ibm-research/granite-timeseries-ensemble-r1
author: ''
summary: '[翻译失败，原文如下]


  # Ensemble forecasting with IBM Granite time-series models


  Four open Granite models, one extensible forecasting interface, and less

  gues...'
categories:
- 未分类
tags: []
draft: false
translated_at: '2026-10-23T07:13:39.599275'
---

[翻译失败，原文如下]

# Ensemble forecasting with IBM Granite time-series models

Four open Granite models, one extensible forecasting interface, and less
guesswork about which model to use.

Pre-trained time-series models can forecast without training on your dataset, but you still have to choose one. A model that handles smooth industrial signals well may struggle with noisy retail demand or a long seasonal horizon, and the best choice depends on the series and the task.

Granite Timeseries Ensemble reduces that choice to a sensible default. One recipe combines four complementary Granite architectures and returns median and quantile forecasts, with no retraining and no fitted ensemble weights. Start with the Probabilistic Ensemble (uniform probability pooling), compare the adaptive Inter Quartile Range (IQR) Ensemble, and extend the same interface with compatible forecasters. The ensemble recipe and its default Granite members are permissively licensed.

The idea will be familiar from weather forecasting.Ensemble forecastsexplore a range of possible outcomes, and systems such as theNorth American Multi-Model Ensemblecombine different models for seasonal prediction. Time-series forecasting benefits in a similar way: complementary models offer different views of what comes next, and an ensemble merges those views into one forecast.

## Try Granite Timeseries Ensemble

Install Granite TSFM and load the recommended four-model recipe directly from
Hugging Face:

```bash
pip install "granite-tsfm>=0.3.11"

```

```python
import pandas as pd

from tsfm_public.models.ensemble.modeling_ensemble import QuantileEnsembleForecaster

df = pd.read_csv(
    "https://raw.githubusercontent.com/zhouhaoyi/ETDataset/main/ETT-small/ETTh1.csv",
    parse_dates=["date"],
)

ensemble = QuantileEnsembleForecaster.from_pretrained(
    "ibm-granite/granite-timeseries-ensemble-r1",
)

result = ensemble(
    df.tail(1024),
    timestamp_column="date",
    target_columns=["OT"],
    context_length=1024,
    prediction_length=24,
)

print(result.prediction_outputs) 
print(result.quantile_outputs)   

```

The recipe stores the ensemble configuration rather than merged model weights. It downloads the four member checkpoints at runtime, so allow extra time for the first run. For the full configuration, member checkpoints, evaluation details, and limitations, see themodel card.

result.prediction_outputscontains the point forecast, whileresult.quantile_outputscontains the quantile predictions which by default range from  0.1 to 0.9. Applications can use the point value as a central prediction and selected quantiles to express forecast ranges. For example, the 0.1 and 0.9 quantiles define a central forecast interval with nominal 80% coverage.

## The ensemble members

The default recipe combines four pre-trained Granite models with different architectures:

For background, see thePatchTST-FM-r1 paper,PatchTST-FM-r2 architecture overview,FlowState paper, andTiny Time Mixers paper.

These architectures capture trends, seasonality, and local variation in different ways, so their errors need not coincide. A50-year review of forecast
combinationsdescribes how combining forecasts can reduce the risk of picking the wrong single model, while stressing that member quality and diversity still matter.

![Four Granite forecasting models feed a common quantile interface and one of two aggregation methods.](/images/posts/0b5aa8a80d56.jpg)

## Two ways to combine the forecasts

Each member returns quantile forecasts. The two main recipes use different rules to turn those forecasts into one predictive distribution and its median.

### Probabilistic Ensemble: the recommended default

The Probabilistic Ensemble (uniform probability pooling) gives each member equal influence, pools their quantile forecasts in probability space, and extracts the requested quantiles from the combined values. Because the weights are fixed, there is no fitting step and no weighting hyperparameters to tune for a new series.

Theforecast combination puzzleoffers useful motivation: in point forecasting, simple equal-weight combinations
have often held up well against methods with estimated weights. This recipe applies the same equal-influence idea to probabilistic forecasts. It is the default loaded in the example above.

### IQR Ensemble: an adaptive alternative

The IQR Ensemble weights members according to their forecast spread, giving narrower intervals greater influence. It approximates each member’s interquartile range from the closest available quantiles around the 25th and 75th percentiles. Weights vary by sample, target, and horizon step, and like the Probabilistic Ensemble, nothing is fitted from historical forecast errors. Isotonic regression keeps the combined quantiles from crossing.

A narrower interval does not necessarily mean a more accurate or better-calibrated forecast, and IQR weighting can favor an overconfident member. If you want to experiment, the recipe exposes a temperature setting (higher values move the weights toward uniform) and an optional cap on any single member's weight.

Load the evaluated IQR recipe by changing only the subfolder:

```python
ensemble = QuantileEnsembleForecaster.from_pretrained(
    "ibm-granite/granite-timeseries-ensemble-r1",
    subfolder="recipes/granite-iqr",
)

```

## Which method should I use?

Start with the Probabilistic Ensemble. If forecast spread looks informative for your application, compare the IQR Ensemble against it on representative data, since accuracy and calibration depend on the series and the horizon.

## Does the ensemble improve on its members?

We evaluated both recipes on 97 GIFT-Eval dataset configurations. The models
forecast without fine-tuning, and test targets were not used to select or fit
the aggregation method. Here we compare the official ensemble submission results
with the four constituent models, using published leaderboard scores and ranks captured on 20 October 2026.

GIFT-Eval reportsMASEfor point forecasts andCRPS/MWQL(the benchmark'smean_weighted_sum_quantile_lossmetric) for probabilistic forecasts. Scores
are normalized to Seasonal Naive and geometrically averaged across configurations.
Lower is better.

★ Best value among the forecasts shown. Lower is better.

Rank columns average per-configuration ranks against the full GIFT-Eval reference leaderboard, not just these six forecasts, so rank values can shift as entries are added to the leaderboard.

Both ensembles outperform all four individual members on aggregate MASE and average MASE Rank. The Probabilistic Ensemble achieves the lowest MASE among these six forecasts: 0.683 compared with 0.685 for PatchTST-FM-r2. Lower average MASE Rank indicates stronger relative point-forecast performance across GIFT-Eval’s diverse dataset configurations. Together, these results support the ensemble as a practical starting point, without requiring developers to select the strongest individual architecture in advance. The MASE margin over the best single member is small, so the main benefit is robustness: you get comparable or better aggregate accuracy without knowing in advance which architecture will suit your data.

PatchTST-FM-r2 retains the lowest aggregate CRPS/MWQL score. The IQR Ensemble achieves the lowest average CRPS Rank among these six forecasts, while the Probabilistic Ensemble ranks behind PatchTST-FM-r2 on that measure. Aggregate error and average rank therefore favor different choices.

[翻译失败，原文如下]

In the 20 October 2026 comparison, the ensemble approach ranks 3rd among eligible systems on MASE Rank and CRPS Rank. The figure below shows both recipes alongside the ten best eligible reference systems per metric. Some systems, including entries excluded as fine-tuned or non-permissively licensed, score better than either recipe, so the value of the ensemble is not that it tops the leaderboard. It is that a single default delivers strong, consistent results across many series without requiring you to choose a member.

![GIFT-Eval average rank comparison for both Granite ensembles and eligible reference systems. Lower is better.](/images/posts/53132315437b.png)

Figure: GIFT-Eval average-rank standings on 20 October 2026, showing both Granite ensembles alongside the ten best eligible reference systems per metric. Eligible systems have replication code and no declared test-data leakage; fine-tuned entries and systems with known non-permissive licenses or member dependencies are excluded. Rank values are taken directly from the published overall leaderboard snapshot; filtering changes which systems are displayed, not their rank values.

## Extend the recipe to other forecasters

The default recipe uses four Granite models, but the commonForecasterinterface also accepts compatible external models. You can change the member mix or the aggregation method and keep the same downstream forecast format, with no merging or retraining of member checkpoints. That makes it easier to fit the ensemble into an existing forecasting stack, and to add forecasters suited to your domain as your needs evolve.

The repository also includes expanded recipes that add IBM Research checkpoints. These carry separate license terms, including non-commercial and research-use restrictions, so review each member's model card before using them.

For any new combination, check forecast compatibility, accuracy, calibration, latency, and licensing.

## Evaluate the recipe for your application

GIFT-Eval is a broad benchmark, but aggregate gains don’t mean every series benefits, and average ranks don’t establish calibration. The way to find out how the recipes behave for your application is to backtest them on representative data:

- Match your use case. Use historical forecast windows that reflect the data available at each forecast origin, the horizon you need, and the series you expect to serve.
- Compare like with like. Run the Probabilistic Ensemble, the IQR Ensemble, and a strong individual member (such as PatchTST-FM-r2) on the same windows.
- Look beyond point error. Assess quantile loss alongside MASE, and check the empirical coverage of the 0.1 to 0.9 interval against its nominal 80%.
- Measure the cost. Record runtime and memory use to judge whether the benefit of combining four models justifies it for your workload.

Keep two limitations in mind. The current recipe forecasts multivariate channels independently, without using cross-channel information, and it loads four member checkpoints, which increases inference time and memory relative to a single member. Member context limits, horizons, preprocessing, and missing-value handling also differ, and neither aggregation method guarantees calibration or robustness under distribution shift, so keep monitoring forecasts after deployment.

## Try it on your data

The recommended starting point is the default four-model recipe:

- Granite Timeseries Ensemble on Hugging Face
- Getting-started notebook
- Granite TSFM repository
- GIFT-Eval benchmark

Load the default recipe to get median and quantile forecasts from all four Granite architectures in one call, and adapt the recipe as your needs evolve.

## References

- ECMWF: Ensemble weather forecasting
- NOAA: North American Multi-Model Ensemble
- FlowState: Sampling-Rate-Equivariant Time-Series Forecasting
- Tiny Time Mixers (TTMs): Fast Pre-trained Models for Enhanced Zero/Few-Shot Forecasting of Multivariate Time Series
- Revisiting the Generic Transformer: Deconstructing a Strong Baseline for Time Series Foundation Models
- Forecast combinations: an over 50-year review
- Smith and Wallis (2009), A Simple Explanation of the Forecast Combination Puzzle

ECMWF: Ensemble weather forecasting

NOAA: North American Multi-Model Ensemble

FlowState: Sampling-Rate-Equivariant Time-Series Forecasting

Tiny Time Mixers (TTMs): Fast Pre-trained Models for Enhanced Zero/Few-Shot Forecasting of Multivariate Time Series

Revisiting the Generic Transformer: Deconstructing a Strong Baseline for Time Series Foundation Models

Forecast combinations: an over 50-year review

Smith and Wallis (2009), A Simple Explanation of the Forecast Combination Puzzle

---

> 本文由AI自动翻译，原文链接：[Ensemble forecasting with IBM Granite time-series models](https://huggingface.co/blog/ibm-research/granite-timeseries-ensemble-r1)
> 
> 翻译时间：2026-10-23 07:13

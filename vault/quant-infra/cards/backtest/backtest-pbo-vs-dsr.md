---
id: backtest-pbo-vs-dsr
node: backtest.overfitting.pbo
type: qa
---
## Q
A strategy shows DSR = 0.42 (below your 0.95 threshold — fails) and, separately, PBO = 15% (well below the 50% "worthless selection" mark — the selection procedure looks reliable). Are these two results redundant, contradictory, or answering different questions? What could explain low PBO alongside a failing DSR?

## A
**They're not redundant — they test different axes of the same overfitting problem.** DSR/PSR answer "is this specific, already-selected Sharpe number statistically distinguishable from what N searched trials of pure noise would be expected to produce" — a significance test on *one* reported result, parameterized by how many things were compared to find it. PBO answers a different question: "does the *act* of picking the in-sample winner out of this candidate set reliably produce something that holds up out-of-sample" — a test of whether the *selection procedure itself* is trustworthy, independent of any absolute performance bar.

Low PBO (15%) says the selection procedure is working well: whichever configuration looks best in-sample reliably stays in the OOS top half across CSCV splits — so overfitting-by-selection isn't what's wrong here. DSR failing (0.42 < 0.95) can still happen on top of that, because it's judging something else: once you deflate the winning Sharpe for the *raw number* of trials N actually searched, the *absolute* level of that Sharpe just isn't high enough to be distinguished from noise at your confidence bar. Concretely: you might have searched 500 configurations, the procedure reliably finds the genuinely-best one every time (good PBO) — but even the genuinely-best one only carries a modest true edge, and a 500-trial deflation swallows a modest edge whether or not selection was reliable. So low PBO + failing DSR reads as "the selection process is trustworthy, but what it selected isn't strong enough given how hard you searched" — a materially different failure than high PBO would indicate (which would instead say "you got lucky, and the process can't be trusted to have found the genuinely-best thing in the first place").

## Q zh
一个策略 DSR = 0.42（低于你的 0.95 阈值——未通过），同时 PBO = 15%（远低于代表"选择流程毫无价值"的 50% 线——选择流程看起来可靠）。这两个结果是重复的、矛盾的，还是在回答不同的问题？低 PBO 与不通过的 DSR 同时出现，可能是什么原因？

## A zh
**它们不是重复的——它们检验的是同一个过拟合问题的不同维度。** DSR/PSR 回答的是"这个具体的、已经被挑选出来的 Sharpe 数字，在统计上是否能和 N 次搜索出来的纯噪音试验本该产生的水平区分开"——这是对**一个**已报告结果的显著性检验，参数是为了找到它比较了多少个东西。PBO 回答的是另一个问题："从这个候选集合里挑样本内赢家**这个动作本身**，是否可靠地产出一个能在样本外站得住的东西"——这是对**选择流程本身**是否可信的检验，与任何绝对表现门槛无关。

低 PBO（15%）说明选择流程运作良好：无论哪个配置在样本内看起来最好，它在 CSCV 各切分中都可靠地留在样本外的前一半——所以这里的问题不在于"靠选择过拟合"。DSR 未通过（0.42 < 0.95）依然可能同时发生，因为它判断的是另一件事：一旦把赢家的 Sharpe 按实际搜索过的**原始试验数** N 折扣，这个 Sharpe 的**绝对水平**就是不够高，无法在你设定的置信门槛下和噪音区分开。具体来说：你可能搜索了 500 组配置，选择流程每次都可靠地找到那个真正最好的（PBO 良好）——但即便是那个真正最好的，也只带着一个不算大的真实 edge，而 500 次试验的折扣无论选择流程可不可靠，都会把一个不大的 edge 吞掉。所以"低 PBO + DSR 未通过"读作："选择流程是可信的，但按你搜索的力度，它选出来的东西本身还不够强"——这与高 PBO 会指示的失败（"你是走了运，而且这套流程本来就不可信、未必找到了那个真正最好的"）在性质上完全不同。

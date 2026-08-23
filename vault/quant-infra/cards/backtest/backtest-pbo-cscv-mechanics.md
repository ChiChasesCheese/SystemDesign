---
id: backtest-pbo-cscv-mechanics
node: backtest.overfitting.pbo
type: qa
---
## Q
You want to compute the Probability of Backtest Overfitting (PBO) for a strategy where the final configuration was chosen by picking whichever of N candidate parameter sets had the best in-sample Sharpe. Walk through the Combinatorially Symmetric Cross-Validation (CSCV) procedure that produces PBO: how are the train/test splits built, and how many are there if you partition the history into S=10 blocks?

## A
**CSCV builds many train/test splits by combination rather than by a single chronological cut, so that being "in-sample" and "out-of-sample" is systematically rotated across the whole dataset instead of fixed to one arbitrary boundary.** Concretely:

1. Split the full return history into **S equal, contiguous blocks** (e.g. S=10).
2. Enumerate every way to choose **S/2 of those blocks as the training set**, with the remaining S/2 as the test set — this gives C(S, S/2) combinations, e.g. **C(10,5) = 252** distinct train/test partitions. "Combinatorially symmetric" refers to this: every combination and its complement both appear, so each block serves as both in-sample and out-of-sample across the full set of splits, rather than any block being permanently "the holdout."
3. For each of the 252 combinations, concatenate the training blocks into one in-sample (IS) return series and the test blocks into one out-of-sample (OOS) series.
4. Within each IS series, evaluate and **rank all N candidate configurations** by in-sample performance (e.g. Sharpe), and note which configuration ranks best — the one you *would have* selected using only that split's IS data.
5. Look up that same configuration's **rank in the corresponding OOS series**.

Repeating steps 4-5 across all 252 splits produces 252 (IS-best-configuration, its OOS-rank) pairs — this collection of OOS ranks, one per split, for whichever configuration would have been picked in-sample each time, is the raw material PBO is computed from. The point of doing this 252 times instead of once is that a single chronological split gives one fragile OOS point estimate; CSCV instead asks the same question — "does the IS winner also win OOS?" — across every way of dividing the sample, so the answer is a distribution, not a coin flip on one arbitrary boundary.

## Q zh
你想为一个策略计算 Probability of Backtest Overfitting（PBO，回测过拟合概率），该策略的最终配置是从 N 个候选参数组合里，选样本内 Sharpe 最好的那一个。请描述产生 PBO 的 Combinatorially Symmetric Cross-Validation（CSCV，组合对称交叉验证）流程：训练/测试切分是怎么构造的？如果把历史数据分成 S=10 个区块，一共有多少种切分？

## A zh
**CSCV 通过组合的方式构造大量训练/测试切分，而不是用单一的一刀切时间分割，这样"样本内"和"样本外"的身份会在整个数据集里被系统性地轮换，而不是固定在某一个随意的边界上。** 具体步骤：

1. 把完整的收益历史切成 **S 个等长、连续的区块**（例如 S=10）。
2. 枚举**每一种选出 S/2 个区块作为训练集**的方式，其余 S/2 个区块作为测试集——这给出 C(S, S/2) 种组合，例如 **C(10,5) = 252** 种不同的训练/测试划分。"组合对称"指的就是这个：每一种组合和它的补集都会出现，所以每个区块在整套切分里既充当过样本内、也充当过样本外，而不是某个区块永远是"留出集"。
3. 对这 252 种组合中的每一种，把训练区块拼接成一条样本内（IS）收益序列，把测试区块拼接成一条样本外（OOS）收益序列。
4. 在每条 IS 序列内，按样本内表现（例如 Sharpe）对**全部 N 个候选配置排名**，并记下排名最好的那个配置——也就是**如果只用这个切分的 IS 数据，你会选出来的那个**。
5. 查出同一个配置在对应 **OOS 序列里的排名**。

对全部 252 种切分重复步骤 4-5，会得到 252 组（每次样本内最优配置，它对应的样本外排名）数据对——这一组样本外排名，每个切分一个，对应的都是"如果只看那次切分的样本内数据你会挑中的那个配置"，正是 PBO 计算所依据的原始材料。做 252 次而不是一次的意义在于：单一的一刀切时间分割只能给出一个脆弱的样本外点估计；CSCV 则在**每一种**划分方式下都问同一个问题——"样本内的赢家在样本外也赢吗？"——于是答案是一个分布，而不是在某一个随意边界上的一次抛硬币。

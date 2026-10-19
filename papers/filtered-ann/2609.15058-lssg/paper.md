# 2609.15058v1 原始 PDF 文本提取

来源：https://arxiv.org/pdf/2609.15058v1

提取日期：2026-10-18。由 PyMuPDF 提取，未经 MinerU 版式转换；公式和表格需回看 PDF。

## PDF page 1

Fast Label-Filtering Approximate Nearest Neighbor Search via
Progressive Label Set Stratification
Ziqi Wang
State Key Laboratory for Novel Software Technology
Nanjing University, China
ziqiw.nju@gmail.com
Jingzhe Zhang
State Key Laboratory for Novel Software Technology
Nanjing University, China
jzzhang.nju@gmail.com
Shuo Shen
State Key Laboratory for Novel Software Technology
Nanjing University, China
sshen.nju@gmail.com
Wei Hu∗
State Key Laboratory for Novel Software Technology
National Institute of Healthcare Data Science
Nanjing University, China
whu@nju.edu.cn
Abstract
Approximate nearest neighbor search (ANNS) retrieves the most
similar vectors to a query vector in high-dimensional space. Label-
filtering ANNS (LFANNS) extends ANNS with a label filter that
the labels of base vectors must satisfy a set relation (e.g., equality,
containment, or overlap) with the query labels. Existing LFANNS
indices suffer from inconsistent performance across different filter
types and degraded scalability under varying label scale and dis-
tribution. In this paper, we define label-stratified similarity graph
(LSSG), where edges connect neighboring vectors whose label sets
fall within stratified similarity thresholds. To implement LSSG ef-
ficiently, we design an incremental insertion algorithm to prune
redundant edges in both vector and label spaces, and leverage a
MinHash structure to ensure scalability for large-scale labels. We an-
alyze stepwise probabilities under explicit label models and explain
why stricter label tiers reduce ineffective in-filtering expansions.
Benchmark experiments show that LSSG achieves ideal optimality
for equality queries, and 1.06x–92.9x and 1.08x–84.1x faster than
the best competing index for containment and overlap, respectively,
in query speed with identical accuracy and 0.35x index size.
CCS Concepts
• Information systems →Nearest-neighbor search; Special-
ized information retrieval.
Keywords
approximate nearest neighbor search, graph-based index, vector
database, label set similarity
∗Corresponding author
Permission to make digital or hard copies of all or part of this work for personal or
classroom use is granted without fee provided that copies are not made or distributed
for profit or commercial advantage and that copies bear this notice and the full citation
on the first page. Copyrights for components of this work owned by others than the
author(s) must be honored. Abstracting with credit is permitted. To copy otherwise, or
republish, to post on servers or to redistribute to lists, requires prior specific permission
and/or a fee. Request permissions from permissions@acm.org.
SIGMOD ’27, Huntington Beach, CA
© 2026 Copyright held by the owner/author(s). Publication rights licensed to ACM.
ACM ISBN 978-1-4503-XXXX-X/2018/06
https://doi.org/XXXXXXX.XXXXXXX
ACM Reference Format:
Ziqi Wang, Jingzhe Zhang, Shuo Shen, and Wei Hu. 2026. Fast Label-Filtering
Approximate Nearest Neighbor Search via Progressive Label Set Stratifica-
tion. In Proceedings of the ACM SIGMOD/PODS International Conference on
Management of Data (SIGMOD ’27). ACM, New York, NY, USA, 21 pages.
https://doi.org/XXXXXXX.XXXXXXX
1
Introduction
Approximate nearest neighbor search (ANNS) is a fundamental op-
eration for semantic query answering, used in vector database man-
agement systems (VDBMS) [23, 39, 57, 63, 70], search engines [6,
29, 59, 68], retrieval-augmented generation (RAG) applications [8,
9, 15], etc. Enormous high-dimensional vectors are generated from
texts, images, and audios by modern embedding models [43, 46, 56].
Given a query vector, rather than scanning all base vectors to obtain
the exact 𝑘nearest neighbors, ANNS indices enable to retrieve most
of these neighbors with significantly lower latency. Particularly,
graph-based ANNS indices [11, 12, 16, 34, 45, 65] are popular for
their fast query speed and high accuracy.
With growing demands for customized queries, label-filtering
ANNS (LFANNS) has become prominent for semantic-constrained
vector search beyond basic similarity retrieval [40, 58, 59, 66]. Label
set predicates are commonly organized around three canonical
positive semantics [1, 5]. For example, in a medical image retrieval
system [2], a physician may query a CT image labeled “lung” and
“nodule”. An equality filter strictly matches images labeled only
“lung” and “nodule”, excluding cases with additional findings or
comorbidities. This filter is useful for scenarios requiring precise
and controlled subsets [19]. A containment filter retrieves images
whose label sets include both query terms (e.g., also annotated with
“CT”, “solid”, or “cancer”), ensuring a comprehensive coverage of
relevant cases. An overlap filter returns images sharing at least one
query label (e.g., lung-related images without nodules, or nodule
images from other regions), supporting association analysis.
There are three mainstream solutions for LFANNS [30]. (1) Pre–
filtering scans all data objects and only computes vector similarity
between the query vector and the filtered subset. Since no vector
index is constructed for the subset, the linear scan becomes ineffi-
cient when the subset is large (e.g., tens of thousands of vectors).
(2) Post-filtering operates on an ANN index constructed over the
entire vector dataset. It first retrieves the most similar vectors using
arXiv:2609.15058v1  [cs.DB]  14 Sep 2026


## PDF page 2

SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
Ziqi Wang, Jingzhe Zhang, Shuo Shen, and Wei Hu
! = 1: $! ∈0, 1.00
! = 2: $! ∈0, 0.67
! = 3: $! ∈0, 0.33
! = 4:$! ∈0, 0
!!
!"
!#
!$
!%
!&
!'
!(
!!!
!!)
!!"
!!
!"
!#
!$
!%
!*
!&
!'
!(
!!!
!!)
!!"
!" !% !* !& !" !# !%
!% !'
!%
! = 4: 0, 0
!$
Neighbor 
layout !!!
."={1,3,6}
.#={1,3,6,8}
.$={1,8}
.% ={3,4,6,9}
.&={4,6,9}
! = 1: 0, 1.00
! = 2: 0, 0.67
! = 3: 0, 0.33
!*
!!
!"
!#
!$
!%
!*
!&
!'
!(
!!!
!!)
!!"
!!
!"
!#
!$
!%
!*
!&
!'
!(
!!!
!!)
!!"
!+
!+
!+
!+
Figure 1: Label-stratified similarity graph (LSSG)
a retrieval size larger than 𝑘, and then retains 𝑘vectors whose label
sets satisfy the filter. It can be ineffective when the filter is highly
selective and fewer than 𝑘vectors are returned. (3) In-filtering per-
forms filter checks during index scanning. It is commonly adopted
by graph-based indices [12, 16, 34], with filter checks executed
when selecting next-hop candidates. Similar to post-filtering, graph
traversal may become less connected when few neighbors satisfy
the filter and may terminate early at local optima [40]. To over-
come the drawbacks of pre-filtering and post-filtering, as well as
the early termination of in-filtering graph traversal, novel LFANNS
indices [1, 5, 16, 17, 22, 32, 58, 66, 69] are proposed with label parti-
tion or label enhancement to improve query performance. However,
two critical challenges in LFANNS remain largely unsolved.
Challenge 1: Inconsistent support for diverse query semantics. It is
difficult to design a unified index due to fundamentally different
label set relations: equality queries require exact matches, contain-
ment queries require super/sub-sets, and overlap queries require
partial intersections. An LFANNS index that is effective for one
filter type often does not transfer well to others. For example, in-
dices based on set containment [69] can support equality filters
only by maintaining isolated auxiliary structures for each unique
label set, which leads to severe index fragmentation and space
overhead. Likewise, overlap queries are often handled by iterative
containment searches, whose cost grows quickly as the query label
set expands [5, 69]. As far as we know, no existing index provides
a unified solution to ensure consistent efficiency and theoretical
guarantees across all semantics.
Challenge 2: Vulnerable to varying label characteristics. Another
key challenge in multi-label indexing is to remain robust because
the number of distinct label sets grows exponentially as the label
space expands. When this number grows to millions, existing in-
dices often face a critical scalability bottleneck: either index size
increases dramatically [1, 69], or query latency becomes prohib-
itively high [5, 32]. The problem is further aggravated by label
distribution. Many existing indices implicitly assume that labels fol-
low skewed distributions (e.g., power-law) [1, 5, 32, 66, 69], where
a large number of data objects share a small set of common labels.
This assumption enables efficient label sharing and therefore more
compact index structures. However, when the distribution goes
toward uniform, such sharing opportunities diminish. As a result,
indices that rely on label sharing [69] tend to become fragmented
or require extensive duplication to remain effective [5]. This creates
a rigid trade-off between space consumption and query efficiency,
limiting robustness under real-world settings.
We propose Label-Stratified Similarity Graph (LSSG), a multi-tier
proximity graph that supports equality, containment, and overlap
filters within a single index. The key idea is to interpret label set
relations through a distance view: different query semantics corre-
spond to searching among vertices with different degrees of label
set similarity. Accordingly, LSSG organizes all vertices into tiers
stratified by label set distance. Each tier enforces a label distance
bound, and edges are created only between vertices whose label
sets satisfy that bound. Upper tiers use tighter bounds, producing
nested similarity ranges (e.g., (︀0, 1⌋︀⊃(︀0, 0.67⌋︀⊃(︀0, 0.33⌋︀⊃(︀0, 0⌋︀
in Fig. 1). The bottom tier ((︀0, 1⌋︀) is label-agnostic and preserves
global navigability, while the top tier ((︀0, 0⌋︀) connects only identi-
cal label sets for exact matching. Intermediate tiers progressively
tighten label consistency for containment and overlap. Within each
tier, vector similarity picks the final neighbors among label-eligible
candidates, enabling progressive exploration at query.
Let us consider a containment query with label set {3, 6} and
query vector 𝑣𝑞(red star in Fig. 1). Starting from a random valid
entry (e.g., 𝑣4 whose label set {1, 3, 6, 8} contains {3, 6}), a bottom-
tier traversal behaves like a vanilla proximity graph. It greedily
follows vector-similarity edges and may move toward 𝑣5, but later
stalls because the most promising next hops (e.g., 𝑣6,𝑣7,𝑣10) are
label-incompatible and cannot be expanded. The search is therefore
trapped in a local minima over the filtered subset. LSSG mitigates
this by escalating to a stricter tier when progress stalls. Higher tiers
contain more label-consistent edges, which can reveal an in-filter
bridge that is absent (or far less likely) in the label-agnostic tier.
For example, LSSG can take 𝑣5 →𝑣12 at tier 3 and reach the true
nearest neighbor via 𝑣12 →𝑣11. Overall, lower tiers preserve global
reachability, while higher tiers provide label-consistent shortcuts
to escape local minima in selective regions.
In summary, our main contributions are outlined below:
●We propose LSSG, a unified multi-tier proximity graph for equal-
ity, containment, and overlap filters. The progressive label set
stratification unifies the semantics of the three filters in a single
graph through tier-ordered in-filtering traversal.
●We introduce a stepwise metric for in-filtering traversal and an-
alyze filter-valid expansion probabilities. Equality is preserved
exactly at the top tier, while containment and overlap admit lower
bounds under explicit label models. These bounds strengthen
monotonically with label set similarity, explaining why intermedi-
ate tiers improve filtered navigation. We also derive a conditional
logarithmic bound on expected query cost with respect to the
filtered subset size.
●We conduct experiments on eight real-world datasets. LSSG im-
proves index size by 16% and indexing time by 22% over the most
build-efficient baseline [5]. At matched accuracy, it is up to 1.06x–
92.9x (avg. 19.3x) faster for containment and up to 1.08x–84.1x
(avg. 15.5x) faster for overlap than the strongest competitor [69],
while using 0.35x index size and 0.87x indexing time. Evaluation


## PDF page 3

Fast Label-Filtering Approximate Nearest Neighbor Search via Progressive Label Set Stratification
SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
Table 1: Frequently-used notations
Notations
Descriptions
𝒟= {𝒱, ℒ} Hybrid dataset 𝒟consisting of vector dataset 𝒱and label
dataset ℒ, with mapping function 𝑙∶𝒱→ℒ
𝛿𝑣(𝑣1, 𝑣2)
Distance between vectors 𝑣1 and 𝑣2
𝛿𝐿(𝐿1, 𝐿2)
Distance between label sets 𝐿1 and 𝐿2
𝑓
Label filter. 𝑓𝑒: equality; 𝑓𝑐: containment; 𝑓𝑜: overlap
𝑁𝑡
𝑣
Neighbor set of 𝑣at tier 𝑡
𝑐𝑡
𝑖,𝑛𝑡
𝑖
𝑖th candidate (𝑐) and neighbor (𝑛) in tier 𝑡
𝑇
Number of tiers
𝜔𝑐
Index parameter: beam width in insertion
𝑚
Index parameter: maximum out-degree
𝜙
Index parameter: IVF scanning budget
𝜏, 𝛽
Index parameter: MinHash signature length and bands
also validates scalability to hundreds of thousands of labels and
millions of label sets, robustness to label distribution drift, effec-
tive tier utilization, and competitive performance against popular
ANNS systems. Source code, experiment data, and appendix are
available at https://github.com/nju-websoft/LSSG.
2
Preliminaries
2.1
Problem Formulation
Definition 1 (ANNS). Given a 𝑑-dimensional vector dataset 𝒱
measured by a distance function 𝛿𝑣, for a query vector 𝑣𝑞∈R𝑑, ANNS
seeks to find a result set 𝒫⊂𝒱of 𝑘neighbors (𝑘≪⋃︀𝒱⋃︀) to minimize
∑𝑘
𝑖=1 𝛿𝑣(𝑣𝑖,𝑣𝑞), ∀𝑣𝑖∈𝒫.
The main distinction between ANNS and exact 𝑘nearest neigh-
bor search is that non-closest vectors are allowed in trade for higher
efficiency (e.g., queries per second (QPS)). The approximation accu-
racy is usually measured by recall@𝑘, defined by ⋃︀𝒫∩𝒯⋃︀
𝑘
, where 𝒯
denotes the set of 𝑘exact nearest neighbors.
Definition 2 (Label Set and Filter Type). Given a universe
of labels 𝐴= {𝑎1,𝑎2, . . .,𝑎⋃︀𝐴⋃︀}, where 𝑎𝑗is a basic type (e.g., integer,
text), a label set dataset is defined by ℒ= {𝐿1,𝐿2, . . .,𝐿⋃︀ℒ⋃︀}, ∀𝐿𝑖⊆𝐴.
Given a query label set 𝐿𝑞⊆𝐴, there are three label filter (𝑓) types:
●Equality filter: 𝑓𝑒(𝐿𝑖⋃︀𝐿𝑞) = I(𝐿𝑞= 𝐿𝑖),
●Containment filter: 𝑓𝑐(𝐿𝑖⋃︀𝐿𝑞) = I(𝐿𝑞⊆𝐿𝑖),
●Overlap filter: 𝑓𝑜(𝐿𝑖⋃︀𝐿𝑞) = I(𝐿𝑞∩𝐿𝑖≠∅),
where I(⋅) is an indicator that equals 1 if true and 0 otherwise.
Label-filtering ANNS is to find the most similar vectors whose
corresponding label sets satisfy a given label filter.
Definition 3 (LFANNS). Given a hybrid dataset 𝒟= {𝒱, ℒ},
𝑙(⋅) ∶𝒱→ℒdenotes a mapping function for the corresponding label
set of a vector in ℒ. Given a query vector 𝑣𝑞∈R𝑑and a query label
set 𝐿𝑞⊆𝐴, LFANNS aims to find a result set ℛ⊂𝒱of 𝑘neighbors
(𝑘≪⋃︀𝒱⋃︀) to minimize ∑𝑘
𝑖=1 𝛿𝑣(𝑣𝑖,𝑣𝑞), ∀𝑣𝑖∈ℛ∧𝑓(𝑙(𝑣𝑖) ⋃︀𝐿𝑞) = 1,
where 𝑓∈{𝑓𝑒, 𝑓𝑐, 𝑓𝑜}.
Like ANNS, the accuracy of LFANNS is measured by recall@𝑘as
well. The filter ratio is defined as the number of passed items over
the size of the dataset, formally
∑𝑣𝑖∈𝒱𝑓(𝑙(𝑣𝑖) ⋃︀𝐿𝑞)
⋃︀𝒱⋃︀
. Query workloads
with high selectivity typically exhibit a small filter ratio.
Table 2: Comparison of LFANNS indices
Indices
Mech.
Sem.
Robt.
Guar.
Vers.
Fidl.
Cmpl.
NHQ
Part.
𝑓𝑒
×
×
×
×
×
Vamana
Enhc.
𝑓𝑐
×
×
×
×
×
CAPS
Part.
𝑓𝑒
×
×
×
×
✓
UniFilter
Part.
𝑓𝑐, 𝑓𝑜
✓
✓
×
×
✓
Curator
Part.
𝑓𝑐, 𝑓𝑜
✓
×
×
×
✓
Packing
Enhc.
𝑓𝑐
✓
×
✓
×
×
RWalks
Enhc.
𝑓𝑐
×
✓
✓
×
×
UNG
Enhc.
𝑓𝑒, 𝑓𝑐
×
×
✓
✓
✓
ELI
Part.
𝑓𝑐, 𝑓𝑜
×
✓
✓
×
×
LSSG
Enhc.
𝑓𝑒, 𝑓𝑐, 𝑓𝑜
✓
✓
✓
✓
✓
Notes. Mech.: mechanism (Part.: label partition; Enhc.: label enhancement).
Sem.: query semantics supported consistently by design (cf. Challenge 1).
Robt.: robustness (cf. Challenge 2). Guar.: whether theoretical guarantees are
provided. Vers./Fidl./Cmpl.: the three challenges in [5]: Versatility: base and
query label sets contain an arbitrary number of labels; Fidelity: comparisons
are only made to vectors whose label sets pass the filter; Completeness: the
index returns sufficient 𝑘vectors.
Frequently used notations are present in Table 1.
2.2
Related Work
ANNS and Filtering ANNS. There are mainly four categories of
ANNS indices: tree-based [37], LSH-based [27, 54, 55, 64], clustering-
based [13, 14, 24, 33, 35], and graph-based [11, 12, 16, 34, 45, 65].
Graph-based indices are popular for fast and accurate query perfor-
mance [60, 65], and their efficiency mainly relies on the monotonic
search property of relative neighborhood graphs (RNG) [12, 34, 60],
where edge pruning preserves this property by eliminating redun-
dant connections based on neighborhood dominance [28, 41].
Filtering ANNS includes four categories: (1) Vector databases
and some ANNS libraries [23, 31, 36, 57, 70, 71] employ cost esti-
mation to select between pre-filtering and post-filtering strategies.
(2) Predicate-agnostic indices [20, 40, 51] support arbitrary filters
without requiring attribute information during index construction.
(3) Range-filtering ANNS indices [21, 42, 62, 67, 74] are specifically
designed for numerical attributes with filters that denote numeric
ranges. (4) LFANNS indices [1, 5, 16, 17, 22, 32, 58, 66, 69] achieve
high efficiency for filtering data objects whose label sets contain
query-specified labels. Specialized indices for range and label filters
show superiority over the first two categories [67, 69]. This paper
focuses on LFANNS and discusses recent work as follows.
LFANNS indices can be divided into two categories. Label-partition
indices group vectors with identical labels or label sets, and groups
are arranged by a tree or an inverted file (IVF) structure. Represen-
tatives include CAPS [17], ELI [69], UniFilter [66], and Curator [22].
This category is effective when filters are simple and label sets
are small (e.g., base/query label sets contain fewer than five labels
on average), since the index can focus on frequent labels [17, 22]
or manageable label combinations [66, 69]. However, as label sets
grow, the number of possible combinations explodes, which either
limits support for complex queries [17, 22, 66] or incurs substantial
space overhead [69]. Consequently, when a query does not match
any pre-built (shared) index, it must fall back to a less compatible


## PDF page 4

SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
Ziqi Wang, Jingzhe Zhang, Shuo Shen, and Wei Hu
index (typically much larger than the true filtered subset), which
can significantly reduce efficiency.
Label-enhancement indices leverage label-enhanced edges to con-
nect two vertices in a graph index via fused distance or label sharing
relationships. Representatives are NHQ [58], Vamana (filtered and
stitched variants) [16], RWalks [1], Packing [32], and UNG [5]. This
category can handle label sets with many labels, but existing algo-
rithms perform well only at one end of the selectivity spectrum.
NHQ and RWalks are efficient when the filter is non-selective (i.e.,
when many vectors can pass the filter). They combine the vector dis-
tance and the label set distance using a user-defined weight. When
the filter is selective, the graph traversal becomes less connected.
Vamana, Packing, and UNG are powerful on query workloads with
high selectivity. The graph is segmented into groups with identical
labels or label sets, and enhanced by cross-group edges that con-
nect only to a limited number of label sets satisfying overlap or
containment relationships. Consequently, the traversal becomes
less connected for non-selective queries [5, 66].
As summarized in Table 2, LSSG is the only index satisfying all
listed criteria. Its performance consistency across all three seman-
tics is empirically validated in Sec. 6.
3
Label Stratified Similarity Graph
This section follows the LSSG workflow. We first define the index
topology, then construct it through similar label set selection and
multi-tier insertion, and introduce tier-ordered in-filtering search.
3.1
Graph Topology Formalization
Definition 4 (Label-Stratified Similarity Graph, LSSG).
Let 𝐺= (𝑉, 𝐸) be a label-stratified similarity graph, where 𝑉and 𝐸
are sets of vertices and directed edges, respectively. Each vertex in 𝑉
denotes a vector, and 𝐸is partitioned into𝑇subsets. The 𝑡th (1 ≤𝑡≤𝑇)
subset and 𝑉compose a subgraph of 𝐺in tier 𝑡: 𝐺𝑡= (𝑉, 𝐸𝑡). An edge
𝑣𝑖→𝑣𝑗∈𝐸𝑡is subject to the following two constraints:
C1. ∀𝑣𝑘∈𝑉/{𝑣𝑖,𝑣𝑗},𝛿𝑣(𝑣𝑖,𝑣𝑗) < 𝛿𝑣(𝑣𝑖,𝑣𝑘) ∨𝛿𝑣(𝑣𝑖,𝑣𝑗) < 𝛿𝑣(𝑣𝑗,𝑣𝑘);
C2. 𝛿𝐿(𝑙(𝑣𝑖),𝑙(𝑣𝑗)) ≤𝜃𝑡and ∀𝑡∈(1,𝑇), ∀𝑣𝑘∈𝑁𝑡
𝑢/{𝑣𝑖}∧𝛿𝑣(𝑣𝑖,𝑣𝑘)
> 𝛿𝑣(𝑣𝑖,𝑣𝑗),𝛿𝐿(𝑙(𝑣𝑗),𝑙(𝑣𝑘)) ≥𝜃𝑡, where 𝜃𝑡= 1 −𝑡−1
𝑇−1 and 𝑁𝑡
𝑣𝑖
is the neighbor of 𝑣𝑖in 𝐺𝑡.
Unlike traditional ANNS graphs relying solely on vector dis-
tance 𝛿𝑣, LSSG couples vector proximity with label set distance
𝛿𝐿. We use Euclidean distance for 𝛿𝑣and Jaccard distance for 𝛿𝐿,
which are widely adopted in LFANNS [5, 58, 69]. Other choices
can also be incorporated [7, 12, 34, 45]. The triangle inequality of
Jaccard distance can benefit effective label-based pruning. Con-
straint C1 follows the standard RNG-style diversification rule used
in graph-based ANNS indices like NSG [12] and HNSW [34]. Ap-
plied within each tier, it removes redundant neighbors in vector
space and preserves directional diversity. Constraint C2 is the core
of LSSG’s tiered design and has two roles: (1) Stratification: the
condition 𝛿𝐿(𝑙(𝑣𝑖),𝑙(𝑣𝑗)) ≤𝜃𝑡makes upper tiers (larger 𝑡, smaller
𝜃𝑡) increasingly strict, so edges gradually concentrate among ver-
tices with more similar (and ultimately identical) label sets. (2)
Diversification: when multiple candidates appear in a similar di-
rection in vector space, C2 prefers neighbors that are label-wise
diverse. Once a closer neighbor 𝑣𝑗is selected, a farther neighbor 𝑣𝑘
is retained only if it is sufficiently different from 𝑣𝑗in label space
Algorithm 1: SelectSimilarLabelSets
Input: 𝐿𝑥: inserted label set
Output: ℒ𝐶: similar label set dataset
Index parameters:𝜙,𝜏, 𝛽(see Table 1)
1 if using IVF scanning then return IVFUnion(𝐿𝑥,𝜙);
2 else return MinHashProbe(ℒx,𝜏, 𝛽);
3 procedure IVFUnion(𝐿𝑥,𝜙)
4
ℒ𝐶←empty bitmap s.t. ⋃︀ℒ𝐶⋃︀= ⋃︀ℒ𝐼⋃︀;
5
𝐿′
𝑥←sort 𝐿𝑥by ascending label frequency;
6
foreach label 𝑎∈𝐿′
𝑥do
7
if ⋃︀ℒ𝐶⋃︀< 𝜙then ℒ𝐶←ℒ𝐶/ IVF𝑎;
▷/: bitwise OR
8
return ℒ𝐶;
9 procedure MinHashProbe(𝐿𝑥,𝜏, 𝛽)
10
ℒ𝐶←{},𝑟←𝜏
𝛽;
▷calculate MinHash rows per band
11
for band 𝐵𝑖←𝐵1, . . ., 𝐵𝛽do
▷𝐵𝑖: band is a hash table; hash: FNV-1a hashing [10]
12
ℒ𝐶←ℒ𝐶∪𝐵𝑖(hash(𝑆𝑥(︀𝑟× (𝑖−1),𝑟× 𝑖⌋︀));
13
return ℒ𝐶;
(i.e., 𝛿𝐿(𝑙(𝑣𝑗),𝑙(𝑣𝑘)) ≥𝜃𝑡), preventing intermediate tiers from be-
ing dominated by a single label cluster and improving reachability
across different label combinations.
Fig. 1 illustrates the resulting hierarchy. Tier 1 (𝜃1 = 1) serves as
the backbone. Since all label set distances are ≤1, C2 is effectively
relaxed and the graph behaves like a standard RNG-based ANNS
structure, ensuring global navigability. In intermediate tiers (1 <
𝑡< 𝑇), edges are selectively admitted or removed according to 𝜃𝑡,
which steers traversal toward regions that better match a query’s
label requirements. For example, in tier 2 (𝜃2 = 0.67), an edge
𝑣6 →𝑣9 can be kept because 𝛿𝐿(𝐿3,𝐿5) falls in the threshold, while
a spatially close candidate 𝑣5 is excluded if 𝛿𝐿(𝐿3,𝐿4) > 0.67. Tier 𝑇
(𝜃𝑇= 0) connects only vertices with identical label sets, forming
exact-match subgraphs that remain reachable through lower tiers.
3.2
Similar Label Set Selection
To build LSSG, we need to frequently identify candidate label sets
that are likely to fall in a tier-specific threshold (i.e., 𝛿𝐿(⋅, ⋅) ≤𝜃𝑡), af-
ter which we compute 𝛿𝐿to verify and filter them. A naive approach
is to precompute and store 𝛿𝐿for all label set pairs, requiring O(1)
lookup but O(⋃︀ℒ⋃︀2) space and preprocessing. This is infeasible at
scale. We use two candidate-selection strategies to avoid quadratic
storage and compute exact 𝛿𝐿only for a bounded candidate set.
Progressive IVF scanning reduces memory overhead by index-
ing label-to-labelset membership. For each label 𝑎, we maintain a
bitmap (or posting list) IVF𝑎indicating which label sets contain
𝑎. Given an inserted label set 𝐿𝑥, IVFUnion in Alg. 1 initializes an
empty bitmap (Line 4), sorts labels in 𝐿𝑥by ascending label fre-
quency (Line 5), and progressively merges their bitmaps via bitwise
OR (Lines 6–7) until a strict candidate budget 𝜙(in terms of the
number of 1-bits) is reached. Processing low-frequency labels first
improves selectivity by activating fewer label sets, thereby reducing
the candidate space and subsequent 𝛿𝐿computations.


## PDF page 5

Fast Label-Filtering Approximate Nearest Neighbor Search via Progressive Label Set Stratification
SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
(b) Label space: LabelPrune
increase by !!
1
2
3
{1,3,6}{1,3}{6}{1,3,6,8}{3,6,8}
""
# "#
# "$
# "%
#
#&
#'
prune !!
" by "# # !"
" , # !!
"
< &"
(a) Vector space: RNGPrune
1
2
3
'$
(%
"
("
"
(&
"
(!
"
prune ("
" by "' '$, ("
" > "' (%
", ("
"
Figure 2: Dual-space pruning diversification for tier 2
Progressive MinHash probing. While IVF scanning is accurate
and space-efficient, its probing cost can grow with the label uni-
verse size ⋃︀𝐴⋃︀and the number of label sets ⋃︀ℒ⋃︀(especially under
high-frequency labels), and it treats all retrieved candidates uni-
formly, even though candidates with higher Jaccard similarity are
more likely to satisfy 𝛿𝐿≤𝜃𝑡. To address both issues, we use the
standard MinHash LSH banding technique [4] to prioritize label
sets with high Jaccard similarity. MinHash probing is insensitive
to ⋃︀𝐴⋃︀during lookup and tends to retrieve more similar label sets
with higher probability. We target label sets within a tier-specific
distance threshold 𝜃𝑡(equivalently, Jaccard similarity 𝐽≥1 −𝜃𝑡),
with a collision probability characterized by Theorem 3.1.
Theorem 3.1. Let ℋ= {ℎ1,ℎ2, . . .,ℎ𝜏} be 𝜏independent hash
functions used to form MinHash signatures. For a label set 𝐿⊆𝐴, its
signature is 𝑠𝐿= (ℎmin
1
(𝐿),ℎmin
2
(𝐿), . . .,ℎmin
𝜏
(𝐿)), where ℎmin
𝑖
(𝐿) =
min𝑎∈𝐿ℎ𝑖(𝑎). Partition 𝑠𝐿into 𝛽bands, each containing 𝑟= 𝜏
𝛽rows.
For two label sets 𝐿1,𝐿2, if 𝐽(𝐿1,𝐿2) ≥1−𝜃𝑡, the probability that they
match in at least one band satisfies:
𝑃collide ≥1 −(1 −(1 −𝜃𝑡)𝑟)
𝛽.
(1)
Equality holds at the similarity boundary 𝐽(𝐿1,𝐿2) = 1 −𝜃𝑡.
The proof is given in Appendix A. Since 𝑃collide increases with
Jaccard similarity (and thus decreases with 𝜃𝑡), more similar label
sets are more likely to be retrieved. This property aligns with LSSG’s
tiering: higher tiers impose smaller 𝜃𝑡and stricter label constraints,
so candidate selection increasingly prioritizes highly similar label
sets. In practice, (𝜏, 𝛽) controls the recall–efficiency trade-off. A
larger signature improves recall but also increases probing cost.
Based on this guarantee, MinHashProbe (Lines 11–12 in Alg. 1)
gathers candidate label sets ℒ𝐶by probing 𝛽LSH tables using the
band hashes of 𝐿𝑥’s signature. We then compute 𝛿𝐿only on ℒ𝐶for
the later selection of which candidates satisfy 𝛿𝐿≤𝜃𝑡.
3.3
Multi-tiered Insertion
Alg. 2 inserts a vector 𝑣𝑥with label set 𝐿𝑥in four phases.
Phase 1 (label set registration). We first check whether 𝐿𝑥has
appeared before. If 𝐿𝑥is new, we register it in the label-to-labelset
inverted structures (e.g., IVF bitmaps). When MinHash is enabled,
we additionally compute the MinHash signature of 𝐿𝑥and insert it
into the corresponding LSH band tables.
Phase 2 (similar label set selection). We then invoke Alg. 1 to
retrieve a candidate set of label sets likely to be close to 𝐿𝑥. For each
retrieved label set 𝐿, we compute 𝛿𝐿(𝐿𝑥,𝐿) and cache the results in
a map 𝒥. It is later reused to filter candidates by tier thresholds 𝜃𝑡
without recomputing 𝛿𝐿.
Algorithm 2: Insert
Input: 𝑣𝑥: vector to insert; 𝐿𝑥: label set of 𝑣𝑥
Output: 𝐼: index after 𝑣𝑥is inserted
Index parameters:𝑚,𝜔𝑐,𝑇(see Table 1)
▷Phase 1: label set registration
1 if 𝐿𝑥∉inserted label set dataset ℒ𝐼then
2
insert 𝐿𝑥into label IVF bitmaps of ℒ𝐼;
3
calculate signature 𝑆𝑥and insert it into MinHash LSH;
▷Phase 2: similar label set selection
4 ℒ𝐶←SelectSimilarLabelSets(𝐿𝑥);
5 𝒥←{𝛿𝐿(𝐿𝑥,𝐿𝑦) ⋃︀𝐿𝑦∈ℒ𝐶};
6 𝐶←{};
▷pool for cross-tier sharing candidates
7 for tier 𝑡←1, . . .,𝑇do
▷Phase 3: filtered candidate selection
8
ℒ𝑡←{𝐿𝑦⋃︀𝛿𝐿(𝐿𝑥,𝐿𝑦) ∈𝒥∩(︀0,𝜃𝑡⌋︀};
▷𝜃𝑡= 1 −𝑡−1
𝑇−1
9
𝐶←{𝑐⋃︀𝑐∈𝐶∧𝑙(𝑐) ∈ℒ𝑡};
▷retain similar label sets
10
if ⋃︀𝐶⋃︀< 𝑚then 𝐶←𝐶∪BeamSearch(𝑣𝑥, ℒ𝑡,𝜔𝑐);
▷Phase 4: dual-space pruning and edge update
11
𝑁𝑡
𝑣𝑥←RNGPrune(𝐶, 𝑚
2 );
12
foreach vector 𝑣𝑦∈𝑁𝑡
𝑣𝑥do
13
𝑁𝑡
𝑣𝑦←𝑁𝑡
𝑣𝑦∪{𝑣𝑥};
▷skip Line 14 if ⋃︀𝑁𝑡
𝑣𝑦⋃︀≤𝑚
14
𝑁𝑡
𝑣𝑦←RNGPrune(𝑁𝑡
𝑣𝑦,𝑚) ∩LabelPrune(𝑁𝑡
𝑣𝑦,𝜃𝑡);
15 return 𝐼;
Phase 3 (vector-space candidate collection). For each tier 𝑡, we
collect candidate vertices by combining vector proximity with the
tier-specific label constraint. Specifically, we restrict candidates to
vertices whose label sets satisfy 𝛿𝐿(𝐿𝑥,𝑙(𝑣)) ∈(︀0,𝜃𝑡⌋︀, and perform
beam search (Alg. 3) to obtain a vector-close candidate pool. When
the candidate pool from Phase 2 is already sufficiently large, we
optionally skip beam search to accelerate indexing, a common
strategy in hierarchical graph indices [42, 62].
Phase 4 (dual-space pruning and edge update). Finally, we
construct outgoing edges for 𝑣𝑥by enforcing the two constraints in
Def. 4. We select up to 𝑚
2 neighbors from the filtered candidates and
keep the remaining capacity for future insertions [34], following
an RNG-style pruning strategy (RNGPrune). Fig.2(a) iteratively
considers candidates in ascending 𝛿𝑣order (𝑐2
1 →𝑐2
4 →𝑐2
3 →𝑐2
2) and
removes geometrically redundant edges (𝑐2
2 in this example).
For each picked neighbor 𝑣𝑦, we also attempt to insert the back-
edge into 𝑣𝑦’s neighbor list. If 𝑣𝑦’s list is full, we apply RNGPrune
to reduce vector-space redundancy. If the remaining neighbors still
satisfy the RNG constraint, we further apply LabelPrune to increase
label set diversity. This dual-space pruning reserves capacity for
neighbors with more diverse label sets, and reduces local graph
density, which speeds up traversal convergence and, in turn, lowers
the total indexing cost of candidate preparation in Phase 3.
Fig. 2(b) shows LabelPrune in tier 2, where 𝜃2 = 0.67 (rounded
from 𝜃2 = 2
3, hereafter). Consider diversifying the neighbor list of a
selected neighbor 𝑣𝑦with 𝑙(𝑣𝑦) = {1, 3, 6}, and candidate neighbors
𝑛2
1 ∶{1, 3, 6}, 𝑛2
2 ∶{1, 3}, 𝑛2
3 ∶{6}, 𝑛2
4 ∶{1, 3, 6, 8}, as well as the
incoming vertex 𝑣𝑥with 𝑙(𝑣𝑥) = {3, 6, 8}. LabelPrune processes
candidates in ascending 𝛿𝑣order and compares each candidate only


## PDF page 6

SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
Ziqi Wang, Jingzhe Zhang, Shuo Shen, and Wei Hu
Algorithm 3: BeamSearch
Input: 𝑣𝑞: query vector; ℒ𝑞: selected label set dataset; 𝜔:
beam width
Output: 𝑊= {𝑣𝑖⋃︀𝑙(𝑣𝑖) ∈ℒ𝑞}: neighbor set
Index parameters:𝑚,𝑇(see Table 1)
1 𝒱𝑟←selected vectors s.t. ∀𝑣𝑟∈𝒱𝑟,𝑙(𝑣𝑟) ∈ℒ𝑞;
2 𝐶←𝒱𝑟,𝑊←𝒱𝑟;
▷min-heap 𝐶and max-heap 𝑊sorted by 𝛿𝑣
3 while 𝐶≠∅do
4
𝑐←pop the nearest vertex to 𝑣𝑞from 𝐶;
5
if 𝛿𝑣(𝑐,𝑣𝑞) > max𝑤∈𝑊𝛿𝑣(𝑤,𝑣𝑞) then break;
6
for tier 𝑡←1, . . .,𝑇do
7
𝑈←𝑈∪{𝑢⋃︀𝑢∈𝑁𝑡
𝑐∧𝑙(𝑢) ∈ℒ𝑞};
8
if number of unvisited vertices in 𝑈> 𝑚then
9
keep the first 𝑚unvisited vertices and break;
10
foreach unvisited neighbor 𝑢∈𝑈do
11
if ⋃︀𝑊⋃︀< 𝜔or 𝛿𝑣(𝑢,𝑣𝑞) < max𝑤∈𝑊𝛿𝑣(𝑤,𝑣𝑞) then
12
mark 𝑢as visited and push it to 𝐶,𝑊;
13
while ⋃︀𝑊⋃︀> 𝜔do pop 𝑊;
14 return 𝑊;
against the already kept neighbors. A candidate is pruned if (1)
its label set is identical to 𝑙(𝑣𝑦), or (2) its label set distance to any
kept neighbor is smaller than the tier threshold 𝜃2. Specifically,
𝑛2
1 is pruned by (1) due to 𝑙(𝑛2
1) = 𝑙(𝑣𝑦). 𝑛2
2 is kept as the first
accepted neighbor. 𝑛2
3 is also kept since 𝛿𝐿(𝑙(𝑛2
2),𝑙(𝑛2
3)) = 1 ⇑< 0.67.
𝑛2
4 is pruned by (2) because it is label-redundant w.r.t. the kept
neighbor 𝑛2
2 ∶𝛿𝐿(𝑙(𝑛2
2),𝑙(𝑛2
4)) = 1 −2
4 = 0.5 < 0.67. Finally, 𝑣𝑥
is kept since it is sufficiently different from the kept neighbors:
𝛿𝐿(𝑙(𝑛2
2),𝑙(𝑣𝑥)) = 0.75 > 0.67 and 𝛿𝐿(𝑙(𝑛2
3),𝑙(𝑣𝑥)) = 0.67 ⇑< 0.67.
3.4
In-Filtering Traversal and LFANNS Query
Alg. 3 performs beam search on the filtered subgraph induced by
the label set scope ℒ𝑞(i.e., only vertices with 𝑙(𝑣) ∈ℒ𝑞are eligible).
It starts by selecting a small set of entry vertices 𝒱𝑟from the eligible
vertices (Line 1), and initializes both the candidate min-heap 𝐶and
the result max-heap 𝑊with 𝒱𝑟(Line 2). Selecting entry vertices
across label sets helps preserve completeness. Even when cross-
label connectivity is sparse in lower tiers, the search can still start
from multiple valid label set regions rather than being trapped in a
single region. This issue is inevitable if the index is not built on the
fully filtered graph for every possible query, yet such a practice is
impractical for LFANNS as to be discussed in Sec. 4.
The traversal iteratively expands candidates (Lines 3–13). At each
iteration, it pops the current closest vertex 𝑐from 𝐶(Line 4) and
terminates early when 𝑐is already farther than the worst element in
𝑊(Line 5), a standard beam-search stopping criterion. For next-hop
expansion, it scans neighbors of 𝑐tier by tier and only collects those
whose labels satisfy 𝑙(𝑢) ∈ℒ𝑞(Line 7). This in-filtering expansion
enforces fidelity by preventing the search from spending steps on
unqualified vertices. To align the expansion cost with the graph
topology, Lines 8–9 cap the number of newly considered (unvisited)
candidates to at most 𝑚, avoiding excessive 𝛿𝑣evaluations that are
unlikely to improve the current beam. Lines 10–13 maintain the
Algorithm 4: LFANNS
Input: 𝑣𝑞: query vector; 𝐿𝑞: query label set; 𝑓: query filter;
𝜔𝑠: search beam width; 𝑘: number of neighbors
Output: ℛ: 𝑘filtered approximate nearest neighbors
1 if 𝑓= 𝑓𝑒then ℒ𝑞←{𝐿𝑞} ;
2 else if 𝑓= 𝑓𝑐then ℒ𝑞←IVFIntersetion(𝐿𝑞, ⋃︀𝐿𝑞⋃︀) ;
3 else if 𝑓= 𝑓𝑜then ℒ𝑞←IVFUnion(𝐿𝑞, ⋃︀𝐿𝑞⋃︀) ;
4 ℛ←BeamSearch(𝑣𝑞, ℒ𝑞,𝜔𝑠);
5 while ⋃︀ℛ⋃︀> 𝑘do pop 𝑅;
6 return ℛ;
two heaps so that the search continues to prioritize vertices closer
to 𝑣𝑞while bounding 𝑊by the beam width 𝜔.
Alg. 4 shows the end-to-end LFANNS query procedure on LSSG.
It first transforms the query filter 𝑓and query label set 𝐿𝑞into
a label set scope ℒ𝑞(Lines 1–3), which specifies the admissible
label sets for the query. For equality queries (𝑓𝑒), ℒ𝑞is simply {𝐿𝑞}.
For containment (𝑓𝑐) and overlap (𝑓𝑜), ℒ𝑞is obtained via bitmap
intersection or union over the inverted structures induced by the
labels in 𝐿𝑞. This design supports arbitrary query label sets without
assuming a fixed label cardinality, thereby satisfying versatility.
Given ℒ𝑞, the algorithm runs in-filtering beam search (Line 4) and
finally retains the closest 𝑘vectors in ℛ(Line 5).
4
Stepwise Analysis of Filter-Valid Expansion
4.1
Stepwise Oracle Proxy
The key effect of LSSG is to leverage tiered label stratification to
increase the probability that an expansion from a filter-valid ver-
tex reaches another filter-valid vertex. This reduces ineffective in-
filtering expansions compared with a label-agnostic graph, while
avoiding the infeasible cost of building a separate graph for ev-
ery possible query filter. We use the oracle label-filtered RNG as a
conceptual reference for filter-valid navigation.
Definition 5 (Oracle Label-Filtered RNG). Given a query
label set 𝐿𝑞and a label filter 𝑓on a hybrid dataset 𝒟= {𝒱, ℒ}, an
oracle label-filtered RNG, denoted by 𝑂𝑓,𝐿𝑞, is built on 𝒱𝑓,𝐿𝑞⊆𝒱,
where ∀𝑣𝑖∈𝒱𝑓,𝐿𝑞,𝑣𝑗∈𝒱−𝒱𝑓,𝐿𝑞, 𝑓(𝑙(𝑣𝑖) ⋃︀𝐿𝑞) = 1, 𝑓(𝑙(𝑣𝑗) ⋃︀𝐿𝑞) = 0.
Edges in 𝑂𝑓,𝐿𝑞satisfy C1 in Def. 4.
Constructing 𝑂𝑓,𝐿𝑞for all possible (𝑓,𝐿𝑞) is infeasible because
the query label set is not known in advance. LSSG therefore keeps a
single multi-tier graph and approximates the oracle behavior only
at the level of one expansion step. Let 𝑐be the current hop selected
by best-first search (Alg. 3, Line 4), and let 𝑢′ ∈𝑁𝑡
𝑐be a neighbor of
𝑐at tier 𝑡. Denote 𝐿1 = 𝑙(𝑐) and 𝐿2 = 𝑙(𝑢′). By LSSG construction,
an edge in tier 𝑡satisfies 𝛿𝐿(𝐿1,𝐿2) = 1 −𝐽(𝐿1,𝐿2) ≤𝜃𝑡= 1 −𝜖𝑡,
equivalently 𝐽(𝐿1,𝐿2) ≥𝜖𝑡, where 𝐽(𝐿1,𝐿2) = ⋃︀𝐿1∩𝐿2⋃︀
⋃︀𝐿1∪𝐿2⋃︀and 𝜖𝑡∈(︀0, 1⌋︀.
The stepwise filter-valid expansion probability is
Pr(𝑢′ ∈𝑈) = Pr (𝑓(𝐿2 ⋃︀𝐿𝑞) = 1 ⋂︀𝑓(𝐿1 ⋃︀𝐿𝑞) = 1 ∧𝐽(𝐿1,𝐿2) ≥𝜖𝑡), (2)
where 𝐿𝑞is the query label set and 𝑓is the filter in Alg. 4. For
the oracle graph 𝑂𝑓,𝐿𝑞(Def. 5), all vertices satisfy 𝑓(⋅⋃︀𝐿𝑞) = 1 by
construction, hence Pr(𝑢′ ∈𝑈) = 1 trivially. For LSSG, it measures
the local probability of an expansion inside the filtered vertex set,


## PDF page 7

Fast Label-Filtering Approximate Nearest Neighbor Search via Progressive Label Set Stratification
SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
and is also a stepwise proxy for filtered navigation quality. For a
fixed tier 𝑡, we write 𝜖instead of 𝜖𝑡for simplicity. Considering the
three filter types in Def. 2, Pr(𝑢′ ∈𝑈) has corresponding forms:
Definition 6 (Target Probabilities for Three Filters). For
label sets 𝐿1,𝐿2 and query label set 𝐿𝑞, define:
●Equality: 𝑃𝑒= Pr (𝐿𝑞= 𝐿2 ⋃︀𝐿𝑞= 𝐿1 ∧𝐽(𝐿1,𝐿2) ≥𝜖);
●Containment: 𝑃𝑐= Pr (𝐿𝑞⊆𝐿2 ⋃︀𝐿𝑞⊆𝐿1 ∧𝐽(𝐿1,𝐿2) ≥𝜖);
●Overlap: 𝑃𝑜= Pr (𝐿𝑞∩𝐿2 ≠∅⋃︀𝐿𝑞∩𝐿1 ≠∅∧𝐽(𝐿1,𝐿2) ≥𝜖).
For tier 𝑇of LSSG, 𝜃𝑇= 0 and thus 𝐽(𝐿1,𝐿2) ≥𝜖𝑇= 1, which
implies 𝐿1 = 𝐿2. Hence 𝑃𝑒= 1 in tier 𝑇, which means once an
equality-valid vertex is reached, a top-tier expansion preserves
equality validity at the label level. The containment and overlap
cases require additional model assumptions, stated explicitly below.
4.2
Containment Target Probability
We analyze containment under an independent Bernoulli model.
All proofs are in Appendices B and C.
Definition 7 (Independent Bernoulli inclusion model). For
each label 𝑎𝑖∈𝐴, let 𝑝𝑖∈(︀0, 1⌋︀be its inclusion probability, sorted so
that 𝑝𝑖≥𝑝𝑖+1. Labels are included independently in each generated
label set, i.e., Pr(𝑎𝑖∈𝐿) = 𝑝𝑖. We assume 𝐿1, 𝐿2, and 𝐿𝑞are generated
independently from this model unless stated otherwise.
We first give a distribution-agnostic lower bound for 𝑃𝑐.
Theorem 4.1 (Lower Bound of 𝑃𝑐). For ∀𝐿1,𝐿2 ∈ℒthat satisfy
𝐽(𝐿1,𝐿2) ≥𝜖, the worst-case lower bound of 𝑃𝑐is
𝑃𝑐≥(1 −𝑝max)(1−𝜖)⋃︀𝐴⋃︀,
𝑝max = max
𝑎𝑖∈𝐴𝑝𝑖.
(3)
Further, 𝜇= E(︀⋃︀𝐿1⋃︀⌋︀= ∑𝑎𝑖∈𝐴𝑝𝑖,𝜎2 = V(︀⋃︀𝐿1⋃︀⌋︀= ∑𝑝𝑖∈𝐴𝑝𝑖(1 −𝑝𝑖),
𝑃𝑐≥(1 −𝑝max)
(1−𝜖)(𝜇+ 𝜎
⌈︂
𝜉),
with probability 1 −𝜉.
(4)
Theorem 4.1 is most informative for uniform or near-uniform
label distributions. For example, suppose 𝜇= 5 and ⋃︀𝐴⋃︀= 100, i.e.,
each label set contains five labels on average and the universe has
100 labels. Under a uniform distribution, 𝑝𝑖=
𝜇
⋃︀𝐴⋃︀= 0.05. For 𝜖= 0.8,
the worst-case bound in Eq. (3) gives 𝑃𝑐≥0.950.2×100 = 0.358, which
is always valid but conservative. With confidence 1−𝜉= 95%, Eq. (4)
yields 𝑃𝑐≥0.95
0.2×(5+
⌉︂
4.75
0.05 ) = 0.859 > 0.358.
In real-world systems, label distributions are often power-law
(Zipf-like) [5, 44, 69, 73]. A small number of head labels occur fre-
quently, while most tail labels are rare. In such skewed settings,
the distribution-agnostic bound in Theorem 4.1 becomes overly
conservative because 𝑝max is dominated by extreme head labels.
However, this looseness does not reflect actual intersection dynam-
ics. Under a high Jaccard similarity constraint, a frequent head label
is unlikely to appear in the difference set 𝐷= 𝐿1/𝐿2 because miss-
ing a high-frequency label in 𝐿2 would strongly penalize Jaccard
similarity. Thus, the difference set tends to be dominated by labels
with relatively small-to-moderate inclusion probabilities, leading
to the sharper bound below.
Theorem 4.2 (Lower Bound of 𝑃𝑐under Skewed Distribu-
tion). Let label inclusion probabilities follow the Zipf distribution,
250
500
750
|A| (Number of Labels)
1.0
1.5
2.0
2.5
3.0
s (Skewness Factor)
(a) s vs |A| (µ=0.5H|A|,s, ε=0.8)
0.6
0.7
0.8
0.9
1.0
ε (Jaccard Similarity)
1.0
1.5
2.0
2.5
3.0
s (Skewness Factor)
(b) s vs ε (|A|=100, µ=0.5H|A|,s)
1.0
1.5
2.0
2.5
3.0
s (Skewness Factor)
0.25
0.50
0.75
1.00
µ
H|A|,s (Scaling Factor)
(c) µ vs s (|A|=100, ε=0.8)
0.6
0.7
0.8
0.9
1.0
ε (Jaccard Similarity)
0.25
0.50
0.75
1.00
µ
H|A|,s (Scaling Factor)
(d) µ vs ε (|A|=100, s=1.5)
0.40
0.45
0.50
0.55
0.60
0.65
0.70
0.75
0.80
0.85
Lower Bound of Pc
0.16
0.28
0.40
0.52
0.64
0.76
0.88
1.00
Lower Bound of Pc
0.16
0.28
0.40
0.52
0.64
0.76
0.88
1.00
Lower Bound of Pc
0.20
0.32
0.44
0.56
0.68
0.80
0.92
Lower Bound of Pc
Figure 3: Simulation of Theorem 4.2
i.e., 𝑝𝑖=
𝜇𝑖−𝑠
𝐻⋃︀𝐴⋃︀,𝑠for 𝑖= 1, 2, . . ., ⋃︀𝐴⋃︀and 𝑠≥0, where 𝐻⋃︀𝐴⋃︀,𝑠= ∑
⋃︀𝐴⋃︀
𝑗=1 𝑗−𝑠
is the generalized harmonic number and 𝜇= E(︀⋃︀𝐿⋃︀⌋︀∈(0,𝐻⋃︀𝐴⋃︀,𝑠⌋︀is
the expected label set size. Define 𝑟= max(2, arg min𝑖
𝐻𝑖,𝑠
𝐻⋃︀𝐴⋃︀,𝑠≥𝜌)
for some 𝜌∈(0, 1), and let 𝐵=
2𝜇(1−𝜖)
1+𝜖
. For any 𝑞≥0, define
Ψ𝑞(𝑥) ∶=
)︀⌉︀⌉︀⌉︀⌉︀⌋︀⌉︀⌉︀⌉︀⌉︀]︀
(𝑟+ 𝑥−1)1−𝑞−(𝑟−1)1−𝑞
1 −𝑞
,
𝑞≠1,
ln 𝑟+ 𝑥−1
𝑟−1
,
𝑞= 1,
𝑥≥0. Then, the
containment target probability satisfies
𝑃𝑐≥exp ⎛
⎝−
𝜇
𝐻⋃︀𝐴⋃︀,𝑠
Ψ𝑠(𝐵) −
𝜇2
𝐻2
⋃︀𝐴⋃︀,𝑠
Ψ2𝑠(𝐵)⎞
⎠(1 −𝜇𝜌(1 −𝜖)).
(5)
Theorem 4.2 complements the conservative bound in Theorem
4.1 by giving a sharper characterization under skewed label distri-
butions. Fig. 3 shows three consistent trends: the bound improves
with stronger skew and larger Jaccard threshold 𝜖, but decreases
as the expected label set size 𝜇grows. For example, at ⋃︀𝐴⋃︀= 100,
the bound increases from 𝑃𝑐≥0.56 when 𝑠= 1 to 𝑃𝑐≥0.84 when
𝑠= 2, and from 𝑃𝑐≥0.60 at 𝜖= 0.6 to 𝑃𝑐≥0.79 at 𝜖= 0.8. These
trends support the same navigation intuition: stricter tiers shrink
the missing-label set 𝐷= 𝐿1/𝐿2, thereby increasing the probability
of a containment-valid next hop expansion.
4.3
Overlap Target Probability
For overlap queries, the probability of non-overlap is maximized
when the query label set is as small as possible.
Theorem 4.3 (Lower Bound of 𝑃𝑜). Assuming that query label
sets of the same size are equally likely, for any 𝐿1,𝐿2 ∈ℒsatisfying
𝐽(𝐿1,𝐿2) ≥𝜖, the overlap target probability satisfies 𝑃𝑜≥𝜖.
Theorem 4.3 shows that 𝑃𝑜increases with label set similarity.
Summary. The containment and overlap analyses lead to the same
design principle. As the tier threshold becomes stricter, an expan-
sion from a filter-valid vertex is more likely to remain filter-valid.
For containment, stricter tiers reduce the possible missing-label
set 𝐿1/𝐿2. For overlap, the lower bound scales with the shared-
label ratio induced by 𝐽(𝐿1,𝐿2) ≥𝜖𝑡. Thus, lower tiers preserve
global vector-space reachability, while higher tiers provide label-
consistent shortcuts. This is the core mechanism by which LSSG


## PDF page 8

SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
Ziqi Wang, Jingzhe Zhang, Shuo Shen, and Wei Hu
approaches oracle filtered navigation without constructing a sepa-
rate graph for each query filter.
5
Asymptotic Complexity
5.1
Index Size
LSSG is composed of graph topology and auxiliary label selection
structures. Each vertex stores at most 𝑚neighbors per tier, giving
O(𝑚⋃︀𝒱⋃︀𝑇) graph space. This bound is further tightened by the
diversification strategy (Fig. 2), which prunes redundant edges
based on label and vector proximity. IVF bitmaps require O(⋃︀𝐴⋃︀⋃︀ℒ⋃︀)
bits, while MinHash signatures and LSH buckets require O((𝜏+
𝛽)⋃︀ℒ⋃︀) space. Relative to a standard proximity graph, the topology
incurs the tier factor 𝑇and the additional label selection structures.
5.2
Indexing Time
For an inserted vector 𝑣𝑥with label set 𝐿𝑥, let 𝐾𝑥be the number
of label set candidates returned by IVF or MinHash, ¯ℓ𝑥be their
average cardinality, and 𝐵𝑥be the number of processed IVF bitmap
words. The cost of candidate selection and Jaccard verification is
𝐶label(𝑥) = O (𝐾𝑥(⋃︀𝐿𝑥⋃︀+ ¯ℓ𝑥)) +
)︀⌉︀⌉︀⌋︀⌉︀⌉︀]︀
O(𝐵𝑥),
IVF,
O(𝜏⋃︀𝐿𝑥⋃︀+ 𝛽+ 𝐾𝑥),
MinHash.
(6)
Let 𝐻𝑥,𝑡denote the actual number of vertices expanded at tier 𝑡.
Each expansion scans at most 𝑚𝑇neighbors, computes at most 𝑚
vector distances, and performs at most 𝑚queue updates. Including
outgoing and reverse-edge pruning, the deterministic insertion cost
𝐶ins(𝑥) is
𝐶ins(𝑥) = 𝐶label(𝑥) + O (
𝑇
∑
𝑡=1
𝐻𝑥,𝑡(𝑚𝑇+𝑚𝑑+𝑚log𝜔𝑐))
+ O (𝑇(𝑚𝜔𝑐𝑑+𝑚3(𝑑+ ¯ℓ𝑥))) .
(7)
The indexing time mainly depends on the expansion counts
𝐻𝑥,𝑡. For a tier-induced search graph satisfying the monotonicity
conditions of [12], the expected search path length is logarithmic
in the graph size. With fixed beam width, this gives
E(︀𝐻𝑥,𝑡⌋︀= O (log ⋃︀𝒱𝑥,𝑡⋃︀),
𝒱𝑥,𝑡= {𝑣∈𝒱∶𝛿𝐿(𝑙(𝑣),𝐿𝑥) ≤𝜃𝑡}. (8)
Therefore, for fixed parameters and bounded label set selection
cost, LSSG retains the expected O(⋃︀𝒱⋃︀log ⋃︀𝒱⋃︀) construction time
of standard proximity graph indexing, with additional costs from
label selection, pruning, and tiered traversal.
5.3
Query Time
For a query (𝑣𝑞,𝐿𝑞, 𝑓), Alg. 4 first constructs the filtered label set
scope ℒ𝑞. The scope construction cost is
𝐶scope(𝑓,𝐿𝑞) =
)︀⌉︀⌉︀⌋︀⌉︀⌉︀]︀
O(1),
𝑓= 𝑓𝑒,
O(∑𝑎∈𝐿𝑞⋃︀IVF𝑎⋃︀),
𝑓∈{𝑓𝑐, 𝑓𝑜}.
(9)
Let 𝐻𝑓,𝑞be the actual number of expanded vertices and define
𝜂𝑞= 𝑚𝑇+𝑚𝑑+𝑚log𝜔𝑠. The deterministic query cost is
𝐶query(𝑓,𝑞) = 𝐶scope(𝑓,𝐿𝑞) + O(𝐻𝑓,𝑞𝜂𝑞).
(10)
This bound holds for any realized graph and query trace. Here,
𝑚𝑇is the tier-scanning overhead, while stricter tiers increase the
chance that scanned neighbors remain label-qualified.
Let 𝒱𝑓,𝐿𝑞= {𝑣∈𝒱∶𝑙(𝑣) ∈ℒ𝑞} be the filtered vertex scope. By
the monotonic-search result used above, its oracle filtered graph re-
quires O(log ⋃︀𝒱𝑓,𝐿𝑞⋃︀) expected progress steps. Let 𝛼𝑓∈{𝑃𝑒,𝑃𝑐,𝑃𝑜}
be the filter-valid expansion lower bound from Sec. 4. Under the
stepwise proxy in Sec. 4, one filter-valid expansion requires O(𝛼−1
𝑓)
attempted expansions in expectation. Combining this factor with
the oracle progress length gives the conditional estimate E(︀𝐻𝑓,𝑞⌋︀=
O (𝛼−1
𝑓
log ⋃︀𝒱𝑓,𝐿𝑞⋃︀). Therefore,
E(︀𝐶query(𝑓,𝑞)⌋︀= 𝐶scope(𝑓,𝐿𝑞) + O (𝛼−1
𝑓𝜂𝑞log ⋃︀𝒱𝑓,𝐿𝑞⋃︀),
(11)
which serves as the conditional search-effort estimate. For fixed
𝑇,𝑚,𝜔𝑠and 𝛼𝑓= Ω(1), the expected traversal cost is O(log ⋃︀𝒱𝑓,𝐿𝑞⋃︀).
Compared with traversal on a standard proximity graph, LSSG pays
the tier scanning overhead but reduces ineffective expansions.
6
Evaluation
We evaluate LSSG by addressing the following research questions:
RQ1. How does LSSG perform in construction? Can it achieve
smaller index size and faster indexing speed than state-of-
the-art LFANNS indices? Is it robust to variations in vector
volume and label cardinality?
RQ2. How does LSSG perform in LFANNS queries? Does it con-
sistently deliver high recall and low latency across query
semantics, evolving label distributions, and diverse label
characteristics, thereby addressing the two challenges in
Sec. 1?
RQ3. How effective are LSSG’s key design components? What
are the comparative strengths of its label set selection algo-
rithms? How do tier usage and filter-valid expansion explain
the query benefits by stratification? How does LSSG scale
with increasing vector and label scales?
6.1
Experiment Setup
Environment. We use a Ubuntu 20.04 LTS server with an Intel
Xeon Gold 6326 CPU @ 2.90 GHz and 240 GB memory. The CPU
has 16 physical cores, 512 KB L1 cache, 65,536 KB L2 cache, and 16
MB L3 cache. All indices are implemented in C++ and compiled by
g++ 9.4.0 with -Ofast and -avx512f compile options enabled.
Datasets. Table 3 summarizes the statistics of eight real-world
benchmark datasets with Zipf-like label distributions. Datasets
are evaluated under three semantics, each using ⋃︀𝑄⋃︀queries (in
total ⋃︀𝑄⋃︀× 3). For each query semantics, label sets are generated
independently. Equality queries sample existing base label sets.
Containment and overlap queries sample from the dataset label
universe. All queries are retained only if they admit at least 𝑘valid
answers. Query-label statistics are reported in Appendix D.
●SIFT and GIST [3] are two classic vector datasets. Following
[5, 40, 58, 66], we generate synthetic integer labels.
●TripClick [48] encodes click logs from a health web search
engine [47] using the DPR model [26]. Following [5, 40], we use
28 clinical labels, with remaining labels categorized as “others”.
●LAION [50] contains four million image-caption pairs, with
images embedded by the CLIP model [46]. Following [40], we
pick a one-million subset with 30 caption keywords as labels.


## PDF page 9

Fast Label-Filtering Approximate Nearest Neighbor Search via Progressive Label Set Stratification
SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
Table 3: Statistical data of the benchmark datasets
Datasets
Size
Dim
⋃︀𝐴⋃︀
⋃︀ℒ⋃︀Avg/Med/P90
label set size
⋃︀𝑄⋃︀
SIFT
1,000,000
128
12
2,385
2.3 / 2 / 4
10,000
GIST
1,000,000
960
12
2,385
2.3 / 2 / 4
1,000
TripClick
1,055,976
768
29
7,734
1.1 / 1 / 2
1,000
LAION
1,000,448
512
30
62,066
2.9 / 3 / 5
1,000
YTB-Video
1,000,000 1,024
3,862 160,018
3.0 / 3 / 5
200
YTB-Audio 5,000,000
128
3,862 498,335
3.0 / 3 / 5
1,000
Wikipedia
5,000,000
384 237,417 184,298
5.9 / 6 / 8
1,000
YFCC-1M
1,000,000
192 181,931 636,356
8.8 / 6 / 16
1,000
●YTB-Video and YTB-Audio [49] share identical topic labels.
Following [52], feature vectors of one million video frames and
five million audio samples are used for benchmarking.
●Wikipedia [18] has five million English paragraph embeddings,
encoded via all-MiniLM-L6-v2 [61]. Labels are from Wikidata P31
(instance of) and P279 (subclass of) properties.
●YFCC-1M [38] is from an image embedding dataset with 10
million vectors [53]. Following [52], main experiments use the
first one million subset and YFCC-10M serves for scalability test.
We compute Spearman’s 𝜌between label Jaccard distance 𝛿𝐿
and vector L2 distance 𝛿𝑣by label set size quartile. Seven datasets
except Wikipedia have negligible overall correlation (⋃︀𝜌⋃︀≤0.021)
and quartile-wise values < 0.05. Wikipedia shows a modest positive
correlation (𝜌= 0.15 overall, 0.038–0.176 by quartile). So, the eval-
uated workloads generally exhibit weak label–vector correlation,
which LSSG does not assume. Complete results are in Appendix D.
Competitors. We compare LSSG to ten competing LFANNS base-
lines using their official open-source implementations. For each
baseline, we use the recommended building parameters, and sweep
query parameters to obtain Pareto-optimal QPS–recall curves.
●LSSG-IVF and LSSG-MinHash differ in similar label set selec-
tion. Unless stated otherwise, they both use 𝑇= 9, 𝑚= 16,𝜔𝑐=
128, with 𝜙= 50,000 for IVF and (𝜏, 𝛽) = (64, 16) for MinHash.
●ACORN [40] is a predicate-agnostic index. It uses bitmaps to
indicate which vector IDs can pass the filter. As suggested, we
set its index parameters to 𝑀= 16, 𝑀𝛽= 32,𝐿= 256,𝛾= 30.
●Packing is the best strategy in [32]. Following their settings, we
set 𝑀= 96, efCons = 256 for the optimal query performance.
●RWalks [1] uses label vector and hybrid distance to enhance
HNSW indices. We use the recommended parameters in their
paper, 𝑀= 32, efCons = 200,𝜏= 0, and ℎ= 0.1.
●UNG [5] builds separate Vamana indices for all label sets and
adds cross-group edges to ensure connectivity. We follow them
and set 𝑀= 32,𝐿= 100 with 𝛿= 6 cross-group edges.
●ELI [69] builds multiple small indices with identical parameters.
We choose 𝑀= 16, efCons = 200 with elastic factor set to 0.2 as
reported the most competitive in the paper.
●FAISS [23] and VSAG [72] serve as ANNS libraries and Milvus
[57] and PGVector [25] serve as VDBMS with native filtering.
HNSW (𝑀= 32, efCons = 200) and k-means IVF (n_lists = 10,000)
are evaluated.
Table 4: Indexing performance
Index size (MB)
Indices
SIFT GIST Trip LAION
Video
Audio
Wiki YFCC
ACORN
346
346
366
347
346
3,416 3,397
346
Packing
310
306
311
439
497
570 2,447
2,826
RWalks
413
413
578
552
29,785
-
-
-
UNG
228
410
318
271
152
954 1,044
433
ELI
419
440
351
745
21,292 92,693
-
-
LSSG-IVF
311
204
199
271
136
1,069
602
239
⋆-MinHash
296
192
200
277
142
1,065
606
303
Indexing time (s)
Indices
SIFT GIST Trip LAION
Video
Audio
Wiki YFCC
ACORN
223
881
754
500
411
1,313 3,630
277
Packing
176
358
471
574
419
2,828 2,387
145
RWalks
155
631
595
306
760
-
-
-
UNG
76
429
311
189
211
1,422
973
309
ELI
98
364
287
257
253
807
-
-
LSSG-IVF
133
241
270
181
287
946
487
379
⋆-MinHash
122
224
233
179
243
721
426
111
●Pre-filtering only computes distance between the query vector
and filtered vectors to obtain exact nearest neighbors.
Note that UniFilter [66] is excluded due to code unavailability,
and its reported performance is comparable to UNG. Curator [22]
requires filters to be known a priori with at most two labels, con-
flicting with our query-time filter setup for arbitrary labels. Early
LFANNS studies, including Filtered-Vamana [16], Stitched-Vamana
[16], NHQ [58], and CAPS [17], are omitted for inferior performance
to existing baselines like UNG [5] and ELI [69].
6.2
RQ1: Indexing Analysis
Table 4 lists the indexing performance under 16-thread parallelism.
(1) Index size. LSSG-IVF and LSSG-MinHash are the smallest (or
among the most compact) indices across datasets. Averaged over
datasets, compared with the most space-efficient baseline UNG,
LSSG-IVF and LSSG-MinHash use 0.82x and 0.84x of UNG’s size,
respectively. Specifically, MinHash adds signature and LSH-bucket
storage, but it often probes far fewer label sets than IVF scanning,
shrinking the insertion candidate set 𝑈and producing a sparser
final graph that offsets the overhead. So, LSSG-MinHash is smaller
than LSSG-IVF on SIFT, GIST, and YTB-Audio.
(2) Indexing time. LSSG-MinHash achieves the best or near-best
indexing time on all datasets, averaging 0.78x UNG’s and 0.87x
ELI’s time (the two fastest baselines). LSSG-IVF is also comparable
to UNG and ELI. This is consistent with Sec. 3.3, where LSSG com-
bines fast similar label set selection (IVF/MinHash) with dual-space
pruning to reduce extensive vector-distance computations.
(3) Sensitivity to label characteristics. LSSG’s indexing cost re-
mains stable as ⋃︀𝐴⋃︀increases, indicating it is dominated by local
graph operations rather than combinatorial label enumeration.
ACORN and UNG show similar insensitivity, but several baselines
degrade. Packing is fast on YFCC-1M but less competitive when ⋃︀𝐴⋃︀
is small (e.g., LAION). RWalks is highly sensitive to ⋃︀𝐴⋃︀and fails


## PDF page 10

SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
Ziqi Wang, Jingzhe Zhang, Shuo Shen, and Wei Hu
0.6
0.8
1.0
102
103
104
Equality
QPS
SIFT
0.6
0.8
1.0
102
103
104
GIST
0.6
0.8
1.0
102
103
104
TripClick
0.6
0.8
1.0
102
103
104
LAION
0.6
0.8
1.0
101
102
103
104
YTB-Video
0.6
0.8
1.0
101
103
YTB-Audio
0.6
0.8
1.0
102
103
104
105
Wikipedia
0.6
0.8
1.0
103
104
YFCC-1M
0.6
0.8
1.0
102
103
104
Containment
QPS
0.6
0.8
1.0
101
102
103
0.6
0.8
1.0
101
102
103
104
0.6
0.8
1.0
102
103
0.6
0.8
1.0
101
102
103
0.6
0.8
1.0
101
103
0.6
0.8
1.0
102
103
0.6
0.8
1.0
102
103
104
0.6
0.8
1.0
Recall@10
102
103
104
Overlap
QPS
0.6
0.8
1.0
Recall@10
101
102
103
0.6
0.8
1.0
Recall@10
101
102
103
0.6
0.8
1.0
Recall@10
101
102
103
0.6
0.8
1.0
Recall@10
100
101
102
103
0.6
0.8
1.0
Recall@10
100
101
102
103
0.6
0.8
1.0
Recall@10
101
102
103
0.6
0.8
1.0
Recall@10
101
102
103
104
LSSG-IVF
LSSG-MinHash
ACORN
Packing
RWalks
UNG
ELI
Pre-ﬁlter
Figure 4: Queries Per Second (QPS) of LFANNS indices
0.6
0.8
1.0
103
104
Equality
DC
GIST
0.6
0.8
1.0
102
103
104
LAION
0.6
0.8
1.0
103
105
YTB-Audio
0.6
0.8
1.0
3×101
4×101
Wikipedia
0.6
0.8
1.0
103
104
Containment
DC
0.6
0.8
1.0
103
104
0.6
0.8
1.0
104
106
0.6
0.8
1.0
103
104
0.6
0.8
1.0
Recall@10
103
104
Overlap
DC
0.6
0.8
1.0
Recall@10
103
104
0.6
0.8
1.0
Recall@10
104
106
0.6
0.8
1.0
Recall@10
103
104
105
LSSG-IVF
LSSG-MinHash
ACORN
Packing
RWalks
UNG
ELI
Oracle
Figure 5: Distance Computations (DC) of LFANNS indices
on YTB-Audio, Wikipedia, and YFCC-1M due to attribute-vector
enhancement overhead. ELI is fast on small-to-medium label spaces
but spends large space overhead to meet the elastic factor (about
twice LSSG on the first four datasets, ∼20x on YTB-Video, and ∼90x
on YTB-Audio), and fails on Wikipedia and YFCC-1M as index shar-
ing scales exponentially with labels per set (e.g., 40 labels ⇒240
combinations). Overall, LSSG is less affected by label cardinality
than prior LFANNS indices while consistently outperforming them.
6.3
RQ2: LFANNS Query Performance
Overall comparison. Fig. 4 shows QPS–Recall@10 curves in one
thread (below 0.5 recall are omitted), following [5, 32, 40, 69]. ELI
and Packing lack native support for equality. To avoid adding extra
index components, we evaluate them by reducing equality to a
strengthened containment check (i.e., candidates must contain the
query labels and have the same label set cardinality).
(1) Equality. LSSG and UNG show the best performance. UNG
is sometimes slightly more accurate (e.g., on GIST, YTB-Audio, and
Wikipedia) for its denser static Vamana underlay with looser RNG
pruning. This gap reflects the underlay choice (static Vamana vs.
incremental HNSW), rather than the label-filtering mechanism.
10% 30% 50% 70% 90%
103
104
Equality
QPS
GIST
10% 30% 50% 70% 90%
103
104
LAION
10% 30% 50% 70% 90%
102
104
YTB-Audio
10% 30% 50% 70% 90%
105
Wikipedia
10% 30% 50% 70% 90%
102
103
Containment
QPS
10% 30% 50% 70% 90%
103
104
10% 30% 50% 70% 90%
101
102
103
104
10% 30% 50% 70% 90%
102
103
104
105
R=0.85
10% 30% 50% 70% 90%
Percentile
102
Overlap
QPS
10% 30% 50% 70% 90%
Percentile
103
10% 30% 50% 70% 90%
Percentile
102
103
R=0.80
10% 30% 50% 70% 90%
Percentile
102
R=0.85
10% 30% 50% 70% 90%
Percentile
10−4
10−2
1
Avg. Filter Ratio
10% 30% 50% 70% 90%
Percentile
10−4
10−2
1
10% 30% 50% 70% 90%
Percentile
10−5
10−4
10−3
10−2
10−1
10% 30% 50% 70% 90%
Percentile
10−5
10−4
10−3
10−2
10−1
LSSG-IVF
LSSG-MinHash
ACORN
UNG
ELI
Equality
Containment
Overlap
Figure 6: QPS at 0.9 recall across different selectivity per-
centiles. Recall is adjusted and labeled in the top-right corner
when no baseline attains 0.90 recall. The bottom row shows
the average filter ratio for each percentile.
LSSG achieves a comparable QPS–Recall frontier while supporting
native incremental updates through HNSW-style insertion.
(2) Containment. LSSG provides the strongest overall perfor-
mance. Among the baselines, UNG is most competitive, while
LSSG-MinHash achieves 2.95x faster on average at matched re-
call. The second best ELI is strong on SIFT–LAION, where LSSG-
MinHash achieves 1.10x faster on average. However, ELI cannot
reach 0.9 recall on YTB-Video, and on YTB-Audio, LSSG-MinHash
achieves 92.9x faster at 0.9 recall. Furthermore, ELI cannot be built
on Wikipedia or YFCC-1M. Packing is competitive on SIFT, GIST,
YTB-Audio, and YFCC-1M, but is less consistent overall, while
RWalks and ACORN show limited performance.


## PDF page 11

Fast Label-Filtering Approximate Nearest Neighbor Search via Progressive Label Set Stratification
SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
0.6
0.8
1.0
102
104
Equality
QPS
GIST
0.6
0.8
1.0
101
103
LAION
0.6
0.8
1.0
101
103
YTB-Audio
0.6
0.8
1.0
101
104
Wikipedia
0.6
0.8
1.0
101
103
Containment
QPS
0.6
0.8
1.0
101
103
0.6
0.8
1.0
101
103
0.6
0.8
1.0
100
102
104
0.6
0.8
1.0
Recall@10
101
103
Overlap
QPS
0.6
0.8
1.0
Recall@10
101
103
0.6
0.8
1.0
Recall@10
101
103
0.6
0.8
1.0
Recall@10
101
103
LSSG-IVF
LSSG-MinHash
FAISS-IVF
FAISS-HNSW
VSAG-IVF
VSAG-HNSW
Milvus-IVF
Milvus-HNSW
PGVector-IVF
PGVector-HNSW
Figure 7: Comparison with ANNS libraries & vector databases
(3) Overlap. LSSG and ACORN provide the strongest overall per-
formance. On Wikipedia, LSSG-IVF reaches 0.948 recall, exceeding
ACORN’s peak recall of 0.909. ELI is competitive on SIFT–LAION,
where LSSG-MinHash achieves 1.34x faster on average, but de-
grades on larger-label workloads. On YTB-Video, LSSG-MinHash
achieves 84.1x faster at 0.7 recall. UNG is generally weaker. On SIFT–
TripClick, where it reaches 0.9 recall, LSSG-MinHash achieves 7.3x
faster on average, with the gap increasing to 99.8x on YFCC-1M
at matched recall. Packing and RWalks do not reach 0.5 recall for
overlap, with peak recall of only 0.41 and 0.32 on SIFT, respectively.
(4) IVF vs. MinHash in LSSG. LSSG-IVF can be slightly better
on a few workloads (notably containment/overlap on YTB-Audio,
Wikipedia, and YFCC-1M). MinHash probing prioritizes high simi-
larity label sets and may miss low similarity yet admissible ones,
while IVF scanning evaluates more Jaccard distances and thus cov-
ers a broader set of allowed label sets—an effect that matters more
with many labels and for overlap. Despite this trade-off, LSSG-
MinHash builds faster and retains strong overall query throughput.
Approximation to the oracle label-filtered RNG. Fig. 5 com-
pares distance computations (DC) with an oracle label-filtered RNG
(Def. 5), implemented as HNSW on the fully filtered subset. For
equality, LSSG and UNG stay closest to the oracle on GIST, LAION,
and YTB-Audio. On Wikipedia, UNG is within about 10 DC of the
oracle. For containment, LSSG is consistently closest, while Pack-
ing is occasionally competitive and UNG, ACORN, and RWalks
generally require more DC or attain lower recall. ELI degrades on
YTB-Audio and cannot be built on Wikipedia. For overlap, LSSG
remains closest on GIST, LAION, and YTB-Audio, with ACORN
closer only on Wikipedia. Overall, LSSG most consistently approxi-
mates the oracle, empirically supporting the connection between
the stepwise advantage analyzed in Sec. 4 and reduced search effort.
Appendix E reports results on the remaining datasets.
Performance w.r.t. different selectivity. In Fig. 6, we sort queries
by selectivity and split each workload into five equal-sized per-
centiles. LSSG is the most stable method across the entire selectivity
spectrum. Averaged over datasets, for containment, LSSG-MinHash
achieves 3.87x, 0.93x, 1.51x, 3.08x, and 8.48x QPS of UNG and 8.38x,
281x, 43.1x, 57.6x, and 5.29x of ELI at identical recall, grouped by
0.5
0.7
0.9 1.0
102
104
Equality
QPS
|A| = 128
0.5
0.7
0.9 1.0
102
104
|A| = 512
0.5
0.7
0.9 1.0
101
103
|A| = 2,048
0.5
0.7
0.9 1.0
104
|A| = 8,192
0.5
0.7
0.9 1.0
102
103
Containment
QPS
0.5
0.7
0.9 1.0
102
104
0.5
0.7
0.9 1.0
101
102
103
0.5
0.7
0.9 1.0
102
103
0.5
0.7
0.9 1.0
Recall@10
101
102
103
Overlap
QPS
0.5
0.7
0.9 1.0
Recall@10
101
103
0.5
0.7
0.9 1.0
Recall@10
101
103
0.5
0.7
0.9 1.0
Recall@10
102
103
LSSG-IVF
LSSG-MinHash
UNG
ELI
Figure 8: Query performance w.r.t. varying label scale ⋃︀𝐴⋃︀
percentiles from 10%, 30%, 50%, 70% to 90%. For overlap, the im-
provements over UNG are 7.1x, 39.2x, 31.3x, 47.1x, and 52.7x, and
over ELI are 80.2x, 77.3x, 23.5x, 15.7x, and 6.5x. See Appendix E for
results on the remaining datasets.
(1) High selectivity (10%). With small filtered subsets, quickly
restricting search space can be effective. Thus, UNG is competitive
for containment, whose cross-group edges connect a small number
of relevant label sets, explaining the smaller 3.87x average contain-
ment gap. For overlap, ELI is strongly penalized by its multi-round
containment reduction, yielding a large gap (80.2x).
(2) Medium selectivity (30%–70%). UNG is competitive around
30%, where LSSG-MinHash achieves 0.93x QPS on average, but
UNG degrades as selectivity decreases because its per-label set sub-
indices become increasingly fragmented, and cross-group edges
are less effective for traversing across many relevant label sets. ELI
is most unstable for containment in this regime (LSSG/ELI peaks at
281x at 30% and stays at 43.1x–57.6x from 50% to 70%). Its heuristic
may select a shared index that is much larger than the true filtered
subset, so many visited candidates are filtered out. LSSG remains
stable by tiered navigation to keep progress within label-consistent
regions and completing the search with a single in-filter traversal.
(3) Low selectivity (90%). With large filtered subsets (common for
overlap), label-agnostic traversal is less penalized, making ACORN
more competitive, especially on Wikipedia. UNG becomes particu-
larly weak for overlap and the gap grows to 52.7x, reflecting limited
cross-label connectivity. ELI’s overlap gap narrows to 6.5x, suggest-
ing multi-round overhead is less harmful when each round is only
weakly selective. LSSG remains faster due to one-pass traversal.
Comparison with ANNS libraries and vector databases. Fig. 7
compares LSSG with FAISS, VSAG, Milvus, and PGVector on GIST,
LAION, YTB-Audio, and Wikipedia. (1) At the library level, FAISS
cannot reach 0.95 recall for equality or containment on any dataset,
with maximum recalls of 0.002–0.79 and 0.13–0.90, respectively.
VSAG reaches high recall more often, but drops to 0.19 and 0.46 QPS
at 0.95 recall for equality and containment on Wikipedia, and re-
mains below 0.95 for equality on YTB-Audio. For overlap, FAISS
remains below 0.95 recall on Wikipedia and YTB-Audio, whereas
VSAG reaches 0.95 recall at only 27–52 QPS. (2) At the database
level, the best Milvus and PGVector variants reach at least 0.95
recall for containment, but achieve only 16–41 and 0.6–13 QPS,


## PDF page 12

SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
Ziqi Wang, Jingzhe Zhang, Shuo Shen, and Wei Hu
0.6
0.8
1.0
102
103
104
Equality
QPS
Zipf
0.6
0.8
1.0
104
Uniform
0.6
0.8
1.0
103
104
Poisson
0.6
0.8
1.0
104
Multinomial
0.6
0.8
1.0
102
103
Containment
QPS
0.6
0.8
1.0
102
103
0.6
0.8
1.0
102
103
0.6
0.8
1.0
103
0.6
0.8
1.0
Recall@10
102
103
Overlap
QPS
0.6
0.8
1.0
Recall@10
101
102
103
0.6
0.8
1.0
Recall@10
102
103
0.6
0.8
1.0
Recall@10
102
103
LSSG-IVF
LSSG-MinHash
UNG
ELI
Figure 9: Performance w.r.t. different label distributions
.6 .7 .8 .9 1.0
0.99900
0.99925
0.99950
Equality
Recall@10
Unseen Labels
0 .25 .5 .75 1
0.9994
0.9996
Frequency Shift
.6 .7 .8 .9 1.0
0.962
0.964
0.966
Unseen Labels
0 .25 .5 .75 1
0.964
0.966
Frequency Shift
.6 .7 .8 .9 1.0
0.965
0.970
0.975
Containment
Recall@10
0 .25 .5 .75 1
0.972
0.974
.6 .7 .8 .9 1.0
0.9500
0.9525
0.9550
0 .25 .5 .75 1
0.950
0.955
.6 .7 .8 .9 1.0
Fraction of data inserted
0.9825
0.9850
0.9875
Overlap
Recall@10
0 .25 .5 .75 1
Inversion fraction
0.9850
0.9875
.6 .7 .8 .9 1.0
Fraction of data inserted
0.865
0.870
0.875
0 .25 .5 .75 1
Inversion fraction
0.85
0.86
0.87
1600
1800
1900
2000
2500
2750
3000
3000
3200
QPS
400
450
480
500
650
700
750
750
800
QPS
290
300
310
300
310
320
500
550
540
560
580
QPS
LAION
YTB-Audio
LSSG-IVF (Recall@10)
LSSG-MinHash (Recall@10)
LSSG-IVF (Init. Recall)
LSSG-MinHash (Init. Recall)
LSSG-IVF (QPS)
LSSG-MinHash (QPS)
Figure 10: Insertion-drift evaluation on LAION and YTB-
Audio with 𝜔𝑠= 500. Dashed lines mark pre-insertion recall
under the initial index. Dotted lines show QPS.
respectively. LSSG maintains high recall with substantially higher
throughput across all three semantics. Overall, integrating filtering
into graph traversal yields a more consistent LFANNS query than
library-level filtering or database-level query processing. Results
on the remaining datasets and indexing costs are in Appendix E.
Performance w.r.t. varying label scale. Fig. 8 increases the label
space (⋃︀𝐴⋃︀) and unique label sets (422,427 →972,650) of LAION.
LSSG is consistently superior, as tier-wise distance bounds enforce
label constraints without enumerating label combinations. ELI fails
at ⋃︀𝐴⋃︀= 8,192 due to rapidly growing index-sharing search space.
UNG degrades due to massive fragmented groups.
Performance w.r.t. different label distributions. Following [5],
we generate Uniform, Poisson, and Multinomial label distributions
on LAION. Fig. 9 compares the strongest indices LSSG, UNG, and
ELI. (1) LSSG performs best, as tiered traversal depends on label
set distance rather than a particular frequency shape, maintaining
stable navigation under all distributions. (2) For UNG, equality
degrades under Uniform/Multinomial, since more diverse label sets
spread the edge budget over more groups and weaken within-group
connectivity. (3) ELI is competitive for containment/overlap but
10−5
1.3×10−4
8.4×10−4
2.8×10−3
1.6×10−2
0
25
50
75
100
Equality
Usage (%)
Visited
10−5
1.3×10−4
8.4×10−4
2.8×10−3
1.6×10−2
Candidate
2.0×10−6
2.4×10−5
1.4×10−4
6.9×10−4
7.3×10−3
Visited
2.0×10−6
2.4×10−5
1.4×10−4
6.9×10−4
7.3×10−3
Candidate
10−5
9.0×10−4
5.6×10−3
2.8×10−2
0.17
0
25
50
75
100
Containment
Usage (%)
10−5
9.0×10−4
5.6×10−3
2.8×10−2
0.17
2.0×10−6
8.7×10−5
4.5×10−4
2.5×10−3
2.0×10−2
2.0×10−6
8.7×10−5
4.5×10−4
2.5×10−3
2.0×10−2
2.5×10−2
0.43
0.73
0.79
0.84
Filter Ratio
0
25
50
75
100
Overlap
Usage (%)
2.5×10−2
0.43
0.73
0.79
0.84
Filter Ratio
3.6×10−5
7.6×10−3
3.4×10−2
9.7×10−2
0.16
Filter Ratio
3.6×10−5
7.6×10−3
3.4×10−2
9.7×10−2
0.16
Filter Ratio
LAION
YTB-Audio
T1
T2
T3
T4
T5
T6
T7
T8
T9
Figure 11: Tier usage on LAION. Each bar decomposes either
visited vertices or final candidates, grouped by filter ratio.
unstable for equality (0.69 under Zipf and below 0.1 under others),
due to equality-incompatible design and distribution sensitivity.
Performance w.r.t. label insertion drift. Fig. 10 evaluates unseen-
label insertion and frequency inversion after indexing the first 50%
of each dataset. Under unseen-label insertion, containment recall
changes by at most 0.014 on LAION and 0.006 on YTB-Audio, while
equality and overlap recalls decrease by at most 0.017. Under fre-
quency inversion, LSSG-MinHash remains stable, where LSSG-IVF
drops by up to 0.017 on YTB-Audio due to frequency-based tier
assignment. This robustness comes from LSSG’s tiered thresholds.
Each insertion follows the same label similarity constraints and
updates only the affected local neighborhoods. MinHash further
improves stability through frequency-independent candidate selec-
tion. Both variants remain nearly unchanged on LAION. Insertion
throughput reaches 3,010–5,668 vectors/s, with index size growing
from 130–212 MB and 520–841 MB.
6.4
RQ3: Micro Benchmarks
We dissect LSSG’s key components and quantify their impact on
index size, time, and query efficiency: (1) tier-usage decomposition
and parameter sensitivity, (2) filter-valid expansion ratio, (3) label
set diversification (LabelPrune), (4) similar label set selection (IVF
scanning vs. MinHash probing), and (5) scalability to large label
space. Appendix E validates more label set distance sensitivity.
Tier use and sensitivity. Fig. 11 decomposes traversal by tier.
More selective filters shift visits and final candidates toward upper
tiers, confirming the active usage of label-consistent edges. For con-
tainment and overlap, fewer than ten queries per dataset use only
the label-agnostic bottom tier. Fig. 12(a) further shows that 𝑇= 2 is
insufficient at high recall, whereas intermediate tiers substantially
improve accuracy. Larger 𝑚and 𝜔𝑐improve recall but incur higher
indexing costs with diminishing returns.
Fig. 12(b) confirms robust QPS–Recall@𝑘for𝑘∈{1, 10, 50, 100, 500}
and varying threads.


## PDF page 13

Fast Label-Filtering Approximate Nearest Neighbor Search via Progressive Label Set Stratification
SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
0.80
0.85
0.90
0.95
1.00
Recall@k
101
102
103
QPS
Varying T
T=2
T=3
T=6
T=9
T=12
0.80
0.85
0.90
0.95
1.00
Recall@k
102
103
QPS
Varying ωc
ωc=32
ωc=64
ωc=128
ωc=256
ωc=512
0.80
0.85
0.90
0.95
1.00
Recall@k
102
103
QPS
Varying m
m=8
m=16
m=24
m=32
m=40
2
3
6
9
12
T
0
71
142
213
116
233
349 Size (MB)
Time (s)
32
64
128
256
512
ωc
0
135
269
404
105
210
315 Size (MB)
Time (s)
8
16
24
32
40
m
0
102
203
305
151
302
453 Size (MB)
Time (s)
(a) Index parameters
0.80
0.85
0.90
0.95
1.00
Recall@k
102
103
QPS
Varying k
k=1
k=10
k=50
k=100
k=500
0.80
0.85
0.90
0.95
1.00
Recall@10
103
104
QPS
Varying Thread Number
thread=1
thread=2
thread=4
thread=8
thread=16
(b) Output size 𝑘and query threads
Figure 12: Parameter sensitivity on LAION
T1
T2
T3
T4
T5
T6
T7
T8
T9
0.00
0.25
0.50
0.75
1.00
LAION
Valid Ratio
Equality
T1
T2
T3
T4
T5
T6
T7
T8
T9
0.00
0.25
0.50
0.75
1.00
Containment
T1
T2
T3
T4
T5
T6
T7
T8
T9
0.00
0.25
0.50
0.75
1.00
Overlap
T1
T2
T3
T4
T5
T6
T7
T8
T9
Tier
0.00
0.25
0.50
0.75
1.00
YTB-Audio
Valid Ratio
T1
T2
T3
T4
T5
T6
T7
T8
T9
Tier
0.00
0.25
0.50
0.75
1.00
T1
T2
T3
T4
T5
T6
T7
T8
T9
Tier
0.00
0.25
0.50
0.75
1.00
Figure 13: Filter-valid expansion ratio on LAION. Tier be-
comes stricter and higher ratio means fewer ineffective scans.
Filter-valid expansion ratio. Fig. 13 shows the fraction of scanned
tier neighbors satisfying the query filter, empirically reflecting the
stepwise probability analyzed in Sec. 4. The ratio generally increases
with tier strictness, yet tiers 6–7 show minor drops since stricter
tiers connect more similar label sets, which can still differ in a few
labels and fail the exact filter. From tier 1 to tier 9, the ratio rises
on LAION/YTB-Audio from 0.12/0.02 to 1.0/1.0 for containment
and from 0.62/0.08 to 1.0/1.0 for overlap. Equality remains 1.0 since
the search only contains exact matches. Thus, lower tiers support
broad exploration, while stricter tiers increase useful expansions.
Effectiveness of label set diversification. LabelPrune removes
redundant neighbors with highly similar label sets, reducing can-
didate processing and edge storage while preserving cross-label
connectivity. As Fig. 14 shows, the query impact is small. At 0.9
recall, QPS drops by only ∼1% on LAION and < 10% on YTB-Audio,
while building cost decreases substantially. On LAION, LabelPrune
reduces index size by 2% (LSSG-IVF) and 10% (LSSG-MinHash), and
indexing time by 51% and 33%, respectively. This aligns with Alg. 2,
where a sparser intermediate graph shrinks the candidate set 𝑈,
boosting candidate selection that dominates insertion time.
0.80
0.85
0.90
0.95
1.00
Recall@10
102
103
QPS
LAION
0.80
0.85
0.90
0.95
1.00
Recall@10
102
103
QPS
YTB-Audio
0
500
1000
Size (MB)
LAION
YTB-Audio
IVF
IVF w/o
MinHash
MinHash w/o
0
500
1000
Time (s)
LAION
YTB-Audio
Cont-IVF
Cont-IVF w/o
Cont-MinHash
Cont-MinHash w/o
Ovlp-IVF
Ovlp-IVF w/o
Ovlp-MinHash
Ovlp-MinHash w/o
Figure 14: LSSG-IVF/MinHash performance w/o LabelPrune
in the containment (Cont.) and overlap (Ovlp.) semantics
0.80
0.85
0.90
0.95
1.00
Recall@10
103
Containment
QPS
LAION
0.80
0.85
0.90
0.95
1.00
Recall@10
103
QPS
YTB-Audio
0.80
0.85
0.90
0.95
1.00
Recall@10
102
103
Overlap
QPS
LAION
0.80
0.85
0.90
0.95
1.00
Recall@10
103
QPS
YTB-Audio
0
500
1000
Size (MB)
LAION
YTB-Audio
φ=50
φ=500
φ=5,000
φ=50,000
φ=500,000
0
500
1000
1500
Time (s)
LAION
YTB-Audio
φ=50
φ=500
φ=5,000
φ=50,000
φ=500,000
Figure 15: Performance w.r.t. varying IVF scanning budget 𝜙
IVF scanning budget 𝜙. Fig. 15 varies 𝜙, the number of label
bitmaps scanned to form ℒ𝑞in Alg. 3. For reference, ⋃︀ℒ⋃︀= 62,066
on LAION and ⋃︀ℒ⋃︀= 498,445 on YTB-Audio. (1) Increasing 𝜙im-
proves QPS first, and then yields diminishing gains once IVF ap-
proaches a near-full scan. On LAION, at 0.9 recall, QPS increases
from 1,098 →2,008 for containment and 2,049 →2,770 for overlap
with 𝜙= 5,000 →50,000, while 𝜙= 500,000 brings little further
benefit (1,803 and 2,616). On YTB-Audio, QPS similarly saturates:
2,473 →3,170 →3,239 for containment and 268 →802 →838 for
overlap with 𝜙= 5,000 →50,000 →500,000. (2) Larger 𝜙increases
bitmap unions and Jaccard computations during insertion and can
add more out-neighbors. On YTB-Audio, indexing time grows as
𝜙increases (785 →946 →1,613 s), while index size grows mildly
(997 →1,069 →1,071 MB). (3) A practical knee point. For large label
scales, moderate 𝜙can be near-optimal. On YTB-Audio, 𝜙= 50,000
is close to 𝜙= 500,000 in QPS at 0.9 recall (3,170 vs. 3,239; 802 vs.
838) but shortens indexing time by 41% (946 vs. 1,613).
MinHash probing analysis. Fig. 16 shows the analysis on YTB-
Audio for Sec. 3.2 by varying (𝜏, 𝛽) in Eq. (1). (1) Reducing the
probing selectivity by decreasing 𝜏or increasing 𝛽on the diagonal


## PDF page 14

SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
Ziqi Wang, Jingzhe Zhang, Shuo Shen, and Wei Hu
8
16
32
64
128
32
64
128
256
512
τ
.9683
.9770
.9798
NaN
NaN
.9357
.9682
.9797
.9791
NaN
.8666
.9477
.9781
.9815
.9808
.8248
.8872
.9577
.9797
.9787
.8243
.8286
.9027
.9638
.9788
Containment: Recall@10
8
16
32
64
128
32
64
128
256
512
409.16 373.74 394.94 NaN
NaN
457.36 414.61 353.64 388.43 NaN
555.19 439.99 392.49 357.08 368.49
638.01 480.69 428.01 364.09 359.30
625.86 627.00 471.96 377.27 387.83
Containment: QPS
8
16
32
64
128
32
64
128
256
512
τ
.9208
.9547
.9559
NaN
NaN
.8164
.9104
.9577
.9547
NaN
.6711
.8504
.9453
.9542
.9571
.6299
.7049
.8786
.9518
.9557
.6268
.6326
.7209
.8978
.9556
Overlap: Recall@10
8
16
32
64
128
32
64
128
256
512
285.50 269.67 278.01 NaN
NaN
311.74 261.50 269.82 269.64 NaN
336.61 294.32 271.46 266.60 258.26
438.01 343.93 293.94 260.79 267.02
425.80 425.19 319.31 262.55 272.40
Overlap: QPS
8
16
32
64
128
β
32
64
128
256
512
τ
1019
1120
1157
NaN
NaN
917
1065
1162
1225
NaN
840
1023
1152
1241
1361
865
953
1177
1289
1394
933
1015
1178
1481
1534
Index Size (MB)
8
16
32
64
128
β
32
64
128
256
512
750
1469
3851
NaN
NaN
600
728
1915
4162
NaN
522
611
1347
2086
4483
528
530
649
1579
2578
529
503
549
669
1606
Indexing Time (s)
0.98
0.82
638
353
0.96
0.63
438
258
1534
840
4483
503
Figure 16: Performance w.r.t. varying MinHash 𝜏, 𝛽
Table 5: Performance with large-scale labels
Datasets
Indices
Indexing
QPS-Recall@10
Size (MB) Time (s)
0.85
0.90 0.95
YFCC-1M
Packing
2,826
145
1,160
659
313
LSSG-IVF
239
379
8,788 4,120
880
⋆-MinHash
303
111
8,393 3,346
766
YFCC-10M
Packing
2,424
4,409
12
-
-
LSSG-IVF
2,413
7,289
491
246
56
⋆-MinHash
2,935
2,729
414
207
55
from upper left to bottom right to get higher collision probabil-
ity increases recall but often lowers QPS due to longer traversals.
(2) Overly selective probing removes edges between moderately
similar label sets, which are more important for overlap. For exam-
ple, at 𝛽= 8, increasing 𝜏from 32 to 512 reduces recall by 0.14 for
containment and 0.29 for overlap. (3) Index size increases with 𝛽,
and can be non-monotonic in 𝜏when 𝜏≤16 because larger 𝜏sparsi-
fies the graph (smaller) and lengthens signatures (larger). Indexing
time increases with smaller 𝜏and larger 𝛽since more collisions
make larger candidate pools and more 𝛿𝐿computations.
Index scalability. Table 5 tests scalability on YFCC-10M (200,386
labels and ∼4M unique label sets) using released 10,000 containment
queries. (1) MinHash improves index scalability. LSSG-MinHash
reduces indexing time by 62% relative to LSSG-IVF, with a 21%
larger index size. Its QPS remains close (gap < 16% at 0.9 recall).
(2) As dataset size increases, index size scales as 𝑂(⋃︀𝒱⋃︀) and in-
dexing time as 𝑂(⋃︀𝒱⋃︀log ⋃︀𝒱⋃︀). Concretely, LSSG-MinHash shows a
9.6x size increase and a 24.5x indexing-time increase, consistent
with Sec. 5. (3) For other baselines, they hit scalability limits. UNG
reaches only 0.6 peak recall at 0.93 QPS. ELI fails at this label scale
due to exponential index-sharing enumeration. Packing builds in
reasonable time but remains non-competitive in QPS.
7
Conclusion
We propose LSSG, a multi-tier proximity graph that addresses two
key LFANNS challenges: consistency across query semantics and
robustness to diverse label characteristics. LSSG enforces label con-
straints via distribution-agnostic stratification by label set similarity,
and scales to large label space with efficient similar label set selec-
tion and dual-space pruning. We derive lower bounds on filter-valid
next-hop probabilities under explicit label models, explaining how
stricter tiers reduce ineffective expansions. Experiments across
datasets, label scales and distributions, selectivity regimes, and
insertion-drift settings confirm fast query in different semantics
and robust incremental construction. Future work includes extend-
ing from label sets to sparse vectors for dense–sparse hybrid search
and supporting richer filters such as regular expression.
Acknowledgments
We thank all reviewers for their valuable feedback. This work was
supported in part by the National Natural Science Foundation of
China (No. 62676187) and the Postgraduate Research & Practice
Innovation Program of Jiangsu Province (No. 26CXJH0355).
References
[1] Anas Ait Aomar, Karima Echihabi, Marco Arnaboldi, Ioannis Alagiannis, Damien
Hilloulin, and Manal Cherkaoui. 2025. RWalks: Random Walks as Attribute
Diffusers for Filtered Vector Search. Proc. ACM Manag. Data 3, 3 (2025), 26 pages.
[2] Ceyhun Burak Akgül, Daniel L. Rubin, Sandy Napel, Christopher F. Beaulieu,
Hayit Greenspan, and Burak Acar. 2011. Content-Based Image Retrieval in
Radiology: Current Status and Future Directions. Journal of Digital Imaging 24,
2 (2011), 208–222.
[3] Laurent Amsaleg and Hervé Jégou. 2026. Evaluation of Approximate Nearest
Neighbors: Large Datasets. http://corpus-texmex.irisa.fr/.
[4] A.Z. Broder. 1997. On the resemblance and containment of documents. In SE-
QUENCES. IEEE, Positano, Italy, 21–29.
[5] Yuzheng Cai, Jiayang Shi, Yizhuo Chen, and Weiguo Zheng. 2024. Navigating La-
bels and Vectors: A Unified Approach to Filtered Approximate Nearest Neighbor
Search. Proc. ACM Manag. Data 2, 6 (2024), 27 pages.
[6] Qi Chen, Bing Zhao, Haidong Wang, Mingqin Li, Chuanjie Liu, Zengzhong Li,
Mao Yang, and Jingdong Wang. 2021. SPANN: Highly-efficient Billion-scale
Approximate Nearest Neighbor Search. In NeurIPS. Curran Associates Inc., Red
Hook, NY, USA, 14 pages.
[7] Tingyang Chen, Cong Fu, Kun Wang, Xiangyu Ke, Yunjun Gao, Wenchao Zhou,
Yabo Ni, and Anxiang Zeng. 2025. Maximum Inner Product is Query-Scaled
Nearest Neighbor. Proc. VLDB Endow. 18, 6 (2025), 1770–1783.
[8] Yangshen Deng, Zhengxin You, Long Xiang, Qilong Li, Peiqi Yuan, Zhaoyang
Hong, Yitao Zheng, Wanting Li, Runzhong Li, Haotian Liu, Kyriakos Mouratidis,
Man Lung Yiu, Huan Li, Qiaomu Shen, Rui Mao, and Bo Tang. 2025. AlayaDB:
The Data Foundation for Efficient and Effective Long-context LLM Inference. In
SIGMOD-Companion. ACM, Berlin, Germany, 364–377.
[9] Wenqi Fan, Yujuan Ding, Liangbo Ning, Shijie Wang, Hengyun Li, Dawei Yin,
Tat-Seng Chua, and Qing Li. 2024. A Survey on RAG Meeting LLMs: Towards
Retrieval-Augmented Large Language Models. arXiv:2405.06211 [cs.CL]
[10] Glenn Fowler, Landon Curt Noll, Kiem-Phong Vo, Donald E. Eastlake 3rd, and
Tony Hansen. 2026. The FNV Non-Cryptographic Hash Algorithm. RFC 9923.
https://www.rfc-editor.org/info/rfc9923
[11] Cong Fu, Changxu Wang, and Deng Cai. 2022. High Dimensional Similarity
Search With Satellite System Graph: Efficiency, Scalability, and Unindexed Query
Compatibility. IEEE Trans. Pattern Anal. Mach. Intell. 44, 8 (2022), 4139–4150.
[12] Cong Fu, Chao Xiang, Changxu Wang, and Deng Cai. 2019. Fast Approximate
Nearest Neighbor Search with the Navigating Spreading-out Graph. Proc. VLDB
Endow. 12, 5 (2019), 461–474.
[13] Jianyang Gao, Yutong Gou, Yuexuan Xu, Yongyi Yang, Cheng Long, and Raymond
Chi-Wing Wong. 2025. Practical and Asymptotically Optimal Quantization of
High-Dimensional Vectors in Euclidean Space for Approximate Nearest Neighbor
Search. Proc. ACM Manag. Data 3, 3 (2025), 26 pages.
[14] Jianyang Gao and Cheng Long. 2024. RaBitQ: Quantizing High-Dimensional
Vectors with a Theoretical Error Bound for Approximate Nearest Neighbor Search.
Proc. ACM Manag. Data 2, 3 (2024), 27 pages.
[15] Yunfan Gao, Yun Xiong, Xinyu Gao, Kangxiang Jia, Jinliu Pan, Yuxi Bi, Yi Dai, Ji-
awei Sun, Meng Wang, and Haofen Wang. 2024. Retrieval-Augmented Generation


## PDF page 15

Fast Label-Filtering Approximate Nearest Neighbor Search via Progressive Label Set Stratification
SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
for Large Language Models: A Survey. arXiv:2312.10997 [cs.CL]
[16] Siddharth Gollapudi, Neel Karia, Varun Sivashankar, Ravishankar Krishnaswamy,
Nikit Begwani, Swapnil Raz, Yiyong Lin, Yin Zhang, Neelam Mahapatro, Premku-
mar Srinivasan, Amit Singh, and Harsha Vardhan Simhadri. 2023. Filtered-
DiskANN: Graph Algorithms for Approximate Nearest Neighbor Search with
Filters. In WWW. ACM, Austin, TX, USA, 3406–3416.
[17] Gaurav Gupta, Jonah Yi, Benjamin Coleman, Chen Luo, Vihan Lakshman, and
Anshumali Shrivastava. 2023. CAPS: A Practical Partition Index for Filtered
Similarity Search. arXiv:2308.15014 [cs.IR]
[18] Huggingface. 2026.
Wikipedia-22-12-en Embeddings with all-MiniLM-L6-
v2. https://huggingface.co/datasets/maloyan/wikipedia-22-12-en-embeddings-
all-MiniLM-L6-v2.
[19] Kyung Hoon Hwang, Haejun Lee, Geon Koh, Debra Willrett, and Daniel L. Rubin.
2017. Building and Querying RDF/OWL Database of Semantically Annotated
Nuclear Medicine Images. Journal of Digital Imaging 30, 1 (2017), 4–10.
[20] Patrick Iff, Paul Bruegger, Marcin Chrapek, David Kochergin, Maciej Besta,
and Torsten Hoefler. 2026.
Benchmarking Filtered Approximate Near-
est Neighbor Search Algorithms on Transformer-based Embedding Vectors.
arXiv:2507.21989 [cs.DB]
[21] Mengxu Jiang, Zhi Yang, Fangyuan Zhang, Guanhao Hou, Jieming Shi, Wenchao
Zhou, Feifei Li, and Sibo Wang. 2025. DIGRA: A Dynamic Graph Indexing for
Approximate Nearest Neighbor Search with Range Filter. Proc. ACM Manag. Data
3, 3 (2025), 26 pages.
[22] Yicheng Jin, Yongji Wu, Wenjun Hu, Bruce M. Maggs, Jun Yang, Xiao Zhang,
and Danyang Zhuo. 2026. Curator: Efficient Vector Search with Low-Selectivity
Filters. arXiv:2601.01291 [cs.DB]
[23] Jeff Johnson, Matthijs Douze, and Hervé Jégou. 2021. Billion-Scale Similarity
Search with GPUs. IEEE Trans. Big Data 7, 3 (2021), 535–547.
[24] Herve Jégou, Matthijs Douze, and Cordelia Schmid. 2011. Product Quantization
for Nearest Neighbor Search. IEEE Trans. Pattern Anal. Mach. Intell. 33, 1 (2011),
117–128.
[25] Andrew Kane. 2026. pgvector: Open-source vector similarity search for Postgres.
https://github.com/pgvector/pgvector.
[26] Vladimir Karpukhin, Barlas Oğuz, Sewon Min, Patrick Lewis, Ledell Wu, Sergey
Edunov, Danqi Chen, and Wen tau Yih. 2020. Dense Passage Retrieval for Open-
Domain Question Answering. arXiv:2004.04906 [cs.CL]
[27] Yifan Lei, Qiang Huang, Mohan Kankanhalli, and Anthony K. H. Tung. 2020.
Locality-Sensitive Hashing Scheme based on Longest Circular Co-Substring. In
SIGMOD. ACM, Portland, OR, USA, 2589–2599.
[28] Binhong Li, Xiao Yan, and Shangqi Lu. 2026. Fast-Convergent Proximity Graphs
for Approximate Nearest Neighbor Search. arXiv:2510.05975 [cs.DS]
[29] Jie Li, Haifeng Liu, Chuanghua Gui, Jianyu Chen, Zhenyuan Ni, Ning Wang, and
Yuan Chen. 2018. The Design and Implementation of a Real Time Visual Search
System on JD E-commerce Platform. In Middleware. ACM, Rennes, France, 9–16.
[30] Mocheng Li, Xiao Yan, Baotong Lu, Yue Zhang, James Cheng, and Chenhao Ma.
2025. Attribute Filtering in Approximate Nearest Neighbor Search: An In-depth
Experimental Study. Proc. ACM Manag. Data 3, 6 (2025), 26 pages.
[31] Zhaoheng Li, Silu Huang, Wei Ding, Yongjoo Park, and Jianjun Chen. 2025. SIEVE:
Effective Filtered Vector Search with Collection of Indexes. Proc. VLDB Endow.
18, 11 (2025), 4723—-4736.
[32] Jiarui Luo, Miao Qiao, Chaoji Zuo, and Dong Deng. 2025. Tag-Filtered Approxi-
mate Nearest Neighbor Search. In ICDE. IEEE, Hong Kong, China, 3642–3654.
[33] Vasilis Mageirakos, Bowen Wu, and Gustavo Alonso. 2025. Cracking Vector
Search Indexes. Proc. VLDB Endow. 18, 11 (2025), 3951–3964.
[34] Yu A. Malkov and D. A. Yashunin. 2020. Efficient and Robust Approximate
Nearest Neighbor Search Using Hierarchical Navigable Small World Graphs.
IEEE Trans. Pattern Anal. Mach. Intell. 42, 4 (2020), 824–836.
[35] Jason Mohoney, Anil Pacaci, Shihabur Rahman Chowdhury, Umar Farooq Minhas,
Jeffery Pound, Cedric Renggli, Nima Reyhani, Ihab F. Ilyas, Theodoros Rekatsinas,
and Shivaram Venkataraman. 2024. Incremental IVF Index Maintenance for
Streaming Vector Search. arXiv:2411.00970 [cs.DB]
[36] Jason Mohoney, Anil Pacaci, Shihabur Rahman Chowdhury, Ali Mousavi, Ihab F.
Ilyas, Umar Farooq Minhas, Jeffrey Pound, and Theodoros Rekatsinas. 2023. High-
Throughput Vector Similarity Search in Knowledge Graphs. Proc. ACM Manag.
Data 1, 2 (2023), 25 pages.
[37] Marius Muja and David G. Lowe. 2014. Scalable Nearest Neighbor Algorithms
for High Dimensional Data. IEEE Trans. Pattern Anal. Mach. Intell. 36, 11 (2014),
2227–2240.
[38] BigANN Organizers. 2026. NeurIPS’23 Competition Track: Big-ANN. https://big-
ann-benchmarks.com/neurips23.html.
[39] James Jie Pan, Jianguo Wang, and Guoliang Li. 2024. Survey of Vector Database
Management Systems. VLDB J. 33 (2024), 1591–1615.
[40] Liana Patel, Peter Kraft, Carlos Guestrin, and Matei Zaharia. 2024. ACORN: Per-
formant and Predicate-Agnostic Search over Vector Embeddings and Structured
Data. Proc. ACM Manag. Data 2, 3 (2024), 27 pages.
[41] Yun Peng, Byron Choi, Tsz Nam Chan, Jianye Yang, and Jianliang Xu. 2023.
Efficient Approximate Nearest Neighbor Search in Multi-dimensional Databases.
Proc. ACM Manag. Data 1, 1 (2023), 27 pages.
[42] Zhencan Peng, Miao Qiao, Wenchao Zhou, Feifei Li, and Dong Deng. 2025. Dy-
namic Range-Filtering Approximate Nearest Neighbor Search. Proc. VLDB Endow.
18, 10 (2025), 13 pages.
[43] Jeffrey Pennington, Richard Socher, and Christopher Manning. 2014. GloVe:
Global Vectors for Word Representation. In EMNLP. ACM, Doha, Qatar, 1532–
1543.
[44] Steven T. Piantadosi. 2014. Zipf’s Word Frequency Law in Natural Language:
A Critical Review and Future Directions. Psychonomic Bulletin & Review 21, 5
(2014), 1112–1130.
[45] Runwen Qiu and Jing Tang. 2025. Efficient Approximate Nearest Neighbor Search
via Hemi-Sphere Centroids Graph. Proc. ACM Manag. Data 3, 6 (2025), 26 pages.
[46] Alec Radford, Jong Wook Kim, Chris Hallacy, Aditya Ramesh, Gabriel Goh, Sand-
hini Agarwal, Girish Sastry, Amanda Askell, Pamela Mishkin, Jack Clark, et al.
2021. Learning Transferable Visual Models from Natural Language Supervision.
In ICML. PMLR, Virtual, 8748–8763.
[47] Navid Rekabsaz, Oleg Lesota, Markus Schedl, Jon Brassey, and Carsten Eickhoff.
2021. TripClick: The Log Files of a Large Health Web Search Engine. In SIGIR.
ACM, Virtual, 2507–2513.
[48] Navid Rekabsaz, Oleg Lesota, Markus Schedl, Jon Brassey, and Carsten Eickhoff.
2026. TripClick: The Log Files of a Large Health Web Search Engine. https:
//tripdatabase.github.io/tripclick/.
[49] Google Research. 2026. YouTube-8M: A Large and Diverse Labeled Video Dataset
for Video Understanding Research. https://research.google.com/youtube8m/
index.html.
[50] Christoph Schuhmann. 2021. LAION-400-Million Open Dataset. https://laion.ai/
blog/laion-400-open-dataset/.
[51] Gaurav Sehgal and Semih Salihoğlu. 2025. NaviX: A Native Vector Index Design
for Graph DBMSs With Robust Predicate-Agnostic Search Performance. Proc.
VLDB Endow. 18, 11 (2025), 4438–4450.
[52] Jiayang Shi, Yuzheng Cai, and Weiguo Zheng. 2025. Filtered Approximate Nearest
Neighbor Search: A Unified Benchmark and Systematic Experimental Study
[Experiment, Analysis & Benchmark]. arXiv:2509.07789 [cs.DB]
[53] Harsha Vardhan Simhadri, Martin Aumüller, Amir Ingber, Matthijs Douze, George
Williams, Magdalen Dobson Manohar, Dmitry Baranchuk, Edo Liberty, Frank
Liu, Ben Landrum, et al. 2024. Results of the Big ANN: NeurIPS’23 Competition.
arXiv:2409.17424 [cs.IR]
[54] Yufei Tao, Ke Yi, Cheng Sheng, and Panos Kalnis. 2009. Quality and Efficiency in
High Dimensional Nearest Neighbor Search. In SIGMOD. ACM, Providence, RI,
USA, 563–576.
[55] Yao Tian, Xi Zhao, and Xiaofang Zhou. 2024. DB-LSH 2.0: Locality-Sensitive
Hashing With Query-Based Dynamic Bucketing. IEEE Trans. Knowl. Data Eng.
36, 3 (2024), 1000–1015.
[56] Michael Tschannen, Alexey Gritsenko, Xiao Wang, Muhammad Ferjad Naeem,
Ibrahim Alabdulmohsin, Nikhil Parthasarathy, Talfan Evans, Lucas Beyer,
Ye Xia, Basil Mustafa, Olivier Hénaff, Jeremiah Harmsen, Andreas Steiner,
and Xiaohua Zhai. 2025.
SigLIP 2: Multilingual Vision-Language Encoders
with Improved Semantic Understanding, Localization, and Dense Features.
arXiv:2502.14786 [cs.CV]
[57] Jianguo Wang, Xiaomeng Yi, Rentong Guo, Hai Jin, Peng Xu, Shengjun Li, Xi-
angyu Wang, Xiangzhou Guo, Chengming Li, Xiaohai Xu, Kun Yu, Yuxing Yuan,
Yinghao Zou, Jiquan Long, Yudong Cai, Zhenxiang Li, Zhifeng Zhang, Yihua
Mo, Jun Gu, Ruiyi Jiang, Yi Wei, and Charles Xie. 2021. Milvus: A Purpose-Built
Vector Data Management System. In SIGMOD. ACM, Xi’an, China, 2614–2627.
[58] Mengzhao Wang, Lingwei Lv, Xiaoliang Xu, Yuxiang Wang, Qiang Yue, and
Jiongkang Ni. 2023. An Efficient and Robust Framework for Approximate Nearest
Neighbor Search with Attribute Constraint. In NeurIPS, Vol. 36. Curran Associates,
Inc., New Orleans, LA, USA, 15738–15751.
[59] Mengzhao Wang, Boyu Tan, Yunjun Gao, Hai Jin, Yingfeng Zhang, Xiangyu
Ke, Xiaoliang Xu, and Yifan Zhu. 2025. Balancing the Blend: An Experimental
Analysis of Trade-offs in Hybrid Search. arXiv:2508.01405 [cs.DB]
[60] Mengzhao Wang, Xiaoliang Xu, Qiang Yue, and Yuxiang Wang. 2021. A Com-
prehensive Survey and Experimental Comparison of Graph-Based Approximate
Nearest Neighbor Search. Proc. VLDB Endow. 14, 11 (2021), 1964–1978.
[61] Wenhui Wang, Furu Wei, Li Dong, Hangbo Bao, Nan Yang, and Ming Zhou.
2020. MiniLM: Deep Self-Attention Distillation for Task-Agnostic Compression
of Pre-Trained Transformers. arXiv:2002.10957 [cs.CL]
[62] Ziqi Wang, Jingzhe Zhang, and Wei Hu. 2025. WoW: A Window-to-Window
Incremental Index for Range-Filtering Approximate Nearest Neighbor Search.
Proc. ACM Manag. Data 3, 6 (2025), 27 pages.
[63] Chuangxian Wei, Bin Wu, Sheng Wang, Renjie Lou, Chaoqun Zhan, Feifei Li, and
Yuanzhe Cai. 2020. AnalyticDB-V: A Hybrid Analytical Engine Towards Query
Fusion for Structured and Unstructured Data. Proc. VLDB Endow. 13, 12 (2020),
3152–3165.
[64] Jiuqi Wei, Botao Peng, Xiaodong Lee, and Themis Palpanas. 2024. DET-LSH: A
Locality-Sensitive Hashing Scheme with Dynamic Encoding Tree for Approxi-
mate Nearest Neighbor Search. Proc. VLDB Endow. 17, 9 (2024), 2241–2254.
[65] Jiadong Xie, Jeffrey Xu Yu, and Yingfan Liu. 2025. Graph Based K-Nearest
Neighbor Search Revisited. ACM Trans. Database Syst. 50, 4 (2025), 30 pages.


## PDF page 16

SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
Ziqi Wang, Jingzhe Zhang, Shuo Shen, and Wei Hu
[66] Jiadong Xie, Jeffrey Xu Yu, Siyi Teng, and Yingfan Liu. 2025. Beyond Vector
Search: Querying With and Without Predicates. Proc. ACM Manag. Data 3, 6
(2025), 26 pages.
[67] Yuexuan Xu, Jianyang Gao, Yutong Gou, Cheng Long, and Christian S. Jensen.
2024. iRangeGraph: Improvising Range-dedicated Graphs for Range-filtering
Nearest Neighbor Search. Proc. ACM Manag. Data 2, 6 (2024), 26 pages.
[68] Yuming Xu, Hengyu Liang, Jin Li, Shuotao Xu, Qi Chen, Qianxi Zhang, Cheng Li,
Ziyue Yang, Fan Yang, Yuqing Yang, Peng Cheng, and Mao Yang. 2023. SPFresh:
Incremental In-Place Update for Billion-Scale Vector Search. In SOSP. ACM,
Koblenz, Germany, 545–561.
[69] Mingyu Yang, Wenxuan Xia, Wentao Li, Raymond Chi-Wing Wong, and Wei
Wang. 2025. Elastic Index Select for Label-Hybrid Search in Vector Database.
arXiv:2505.03212 [cs.DB]
[70] Wen Yang, Tao Li, Gai Fang, and Hong Wei. 2020. PASE: PostgreSQL Ultra-
High-Dimensional Approximate Nearest Neighbor Search Extension. In SIGMOD.
ACM, Portland, OR, USA, 2241–2253.
[71] Qianxi Zhang, Shuotao Xu, Qi Chen, Guoxin Sui, Jiadong Xie, Zhizhen Cai, Yaoqi
Chen, Yinxuan He, Yuqing Yang, Fan Yang, Mao Yang, and Lidong Zhou. 2023.
VBASE: Unifying Online Vector Similarity Search and Relational Queries via
Relaxed Monotonicity. In OSDI. USENIX Association, Boston, MA, USA, 377–395.
[72] Xiaoyao Zhong, Haotian Li, Jiabao Jin, Mingyu Yang, Deming Chu, Xiangyu
Wang, Zhitao Shen, Wei Jia, George Gu, Yi Xie, Xuemin Lin, Heng Tao Shen,
Jingkuan Song, and Peng Cheng. 2025. VSAG: An Optimized Search Framework
for Graph-Based Approximate Nearest Neighbor Search. Proc. VLDB Endow. 18,
12 (2025), 14 pages.
[73] George Kingsley Zipf. 2016. Human Behavior and the Principle of Least Effort: An
Introduction to Human Ecology. Addison-Wesley Publishing, Boston, MA, USA.
[74] Chaoji Zuo, Miao Qiao, Wenchao Zhou, Feifei Li, and Dong Deng. 2024. SeRF:
Segment Graph for Range-Filtering Approximate Nearest Neighbor Search. Proc.
ACM Manag. Data 2, 1 (2024), 26 pages.
A
Proof of Theorem 3.1
Proof. By the MinHash property, for any random function ℎ𝑖,
Pr (ℎmin
𝑖
(𝐿1) = ℎmin
𝑖
(𝐿2)) = 𝐽(𝐿1,𝐿2) ≥1 −𝜃𝑡. Since the hash
functions are independent, the probability that 𝐿1,𝐿2 match in all 𝜏
𝛽
hash values of a single band is at least (1−𝜃𝑡)
𝜏
𝛽, and the prabability
that they do not match in any of the 𝛽band is at most (1 −(1 −
𝜃𝑡)
𝜏
𝛽)
𝛽. Taking the complementary event gives us the probability
that 𝐿1,𝐿2 match in at least one band in Eq. (1).
□
B
Proofs for Containment Lower Bound
We first derive the containment kernel for fixed 𝐿1 and 𝐿2. With-
out the Jaccard similarity constraint, the containment probability
conditioned on fixed 𝐿1 and 𝐿2 is given by Lemma 1.
Lemma 1. For any fixed non-empty 𝐿1,𝐿2 ∈ℒ,
Pr(𝐿𝑞⊆𝐿2 ⋃︀𝐿𝑞⊆𝐿1,𝐿1,𝐿2) =
∏
𝑎𝑖∈𝐿1/𝐿2
(1 −𝑝𝑖) ∶= 𝐾(𝐿1,𝐿2).
(12)
Proof. By definition of conditional probability:
Pr(𝐿𝑞⊆𝐿2 ⋃︀𝐿𝑞⊆𝐿1,𝐿1,𝐿2) = Pr(𝐿𝑞⊆𝐿1 ∩𝐿2 ⋃︀𝐿1,𝐿2)
Pr(𝐿𝑞⊆𝐿1 ⋃︀𝐿1,𝐿2)
.
(13)
As for two arbitrary sets 𝑆and 𝑇, Pr(𝑆⊆𝑇) = ∏𝑎𝑖∉𝑇Pr(𝑎𝑖∉
𝑆) = ∏𝑎𝑖∉𝑇(1 −𝑝𝑖), we have
Pr(𝐿𝑞⊆𝐿2 ⋃︀𝐿𝑞⊆𝐿1,𝐿1,𝐿2) = ∏𝑎𝑖∉(𝐿1∩𝐿2)(1 −𝑝𝑖)
∏𝑎𝑖∉𝐿1(1 −𝑝𝑖)
.
(14)
With relation between sets 𝐿1/(𝐿1∩𝐿2) = 𝐿1/𝐿2, Pr(𝐿𝑞⊆𝐿2 ⋃︀𝐿𝑞⊆
𝐿1,𝐿1,𝐿2) = ∏𝑎𝑖∈𝐿1/𝐿2(1 −𝑝𝑖), which is defined as 𝐾(𝐿1,𝐿2).
□
Lemma 1 shows that, given any label sets 𝐿1 and 𝐿2, the contain-
ment target fails only when 𝐿𝑞contains a label in 𝐿1 that does not
belong to 𝐿2. Thus, every label in 𝐿1/𝐿2 must be absent from 𝐿𝑞,
giving the product term 𝐾(𝐿1,𝐿2).
The term 𝐾(𝐿1,𝐿2) does not yet incorporate the similarity con-
straint between 𝐿1 and 𝐿2. Under 𝐽(𝐿1,𝐿2) ≥𝜖, the size of the
difference set 𝐿1/𝐿2 is controlled by Lemma 2.
Lemma 2. If 𝐽(𝐿1,𝐿2) ≥𝜖, then ⋃︀𝐿1/𝐿2⋃︀≤(1 −𝜖)⋃︀𝐿1⋃︀.
Proof. As ⋃︀𝐿1 ∪𝐿2⋃︀≥⋃︀𝐿1⋃︀, 𝐽(𝐿1,𝐿2) =
⋃︀𝐿1∩𝐿2⋃︀
⋃︀𝐿1∪𝐿2⋃︀≥𝜖, we have
⋃︀𝐿1 ∩𝐿2⋃︀≥𝜖⋃︀𝐿1⋃︀, and ⋃︀𝐿1/𝐿2⋃︀= ⋃︀𝐿1⋃︀−⋃︀𝐿1 ∩𝐿2⋃︀≤(1 −𝜖)⋃︀𝐿1⋃︀.
□
Lemma 2 formalizes the basic effect of label set similarity: a larger
Jaccard threshold leaves fewer labels in 𝐿1 that may be absent from
𝐿2. This is the combinatorial reason why stricter tiers improve
containment consistency.
B.1
Proof of Theorem 4.1
Proof. Combining Lemma 1 and Lemma 2, we have
𝐾(𝐿1,𝐿2) ≥
∏
𝑎𝑖∈𝐿1/𝐿2
(1 −𝑝max) ≥(1 −𝑝max)(1−𝜖)⋃︀𝐿1⋃︀.
(15)
Since the point-wise lower bound in Eq. (15) holds for all pairs
𝐿1,𝐿2, we can take expectation w.r.t. the conditional distribution of
𝐿1,𝐿2 given 𝐿𝑞⊆𝐿1 and 𝐽(𝐿1,𝐿2) ≥𝜖as follows:
𝑃𝑐= E𝐿1,𝐿2)︀𝐾(𝐿1,𝐿2) ⋃︀𝐽(𝐿1,𝐿2) ≥𝜖⌈︀.
(16)
Replace ⋃︀𝐿1/𝐿2⋃︀with Lemma 2 and use the maximum probability
among all labels, taking the fact that ⋃︀𝐿1⋃︀≤⋃︀𝐴⋃︀:
𝑃𝑐≥E [︀(1 −𝑝max)(1−𝜖)⋃︀𝐿1⋃︀⋃︀𝐽(𝐿1,𝐿2) ≥𝜖⌉︀≥(1 −𝑝max)(1−𝜖)⋃︀𝐴⋃︀.
(17)
By Chebyshev’s inequality, Pr (⋃︀𝐿1⋃︀≤𝜇+
𝜎
⌈︂
𝜉) ≥1 −𝜉, replacing
⋃︀𝐿1⋃︀in Eq. (15) gives us a high-confidence bound in Eq. (4), where
𝜇≪⋃︀𝐴⋃︀in real-world datasets.
□
We next characterize the skewed setting. Let 𝒥∶𝐽(𝐿1,𝐿2) ≥𝜖
and 𝐷= 𝐿1/𝐿2. The following lemma bounds the probability that a
specific label appears in the difference set under the high-Jaccard
constraint.
Lemma 3. Let event 𝒥∶𝐽(𝐿1,𝐿2) ≥𝜖, 𝐷= 𝐿1/𝐿2. ∀𝑎𝑖∈𝐴, Pr(𝑎𝑖∈
𝐷⋃︀𝒥) ≤(1 −𝜖)(1 −𝑝𝑖)𝑝𝑖.
Proof. Pr(𝑎𝑖∈𝐷⋃︀𝒥) = Pr(𝑎𝑖∈𝐿1 ⋃︀𝒥) Pr(𝑎𝑖∉𝐿2 ⋃︀𝑎𝑖∈𝐿1, 𝒥).
Given 𝑎𝑖∈𝐿1 and 𝒥with Lemma 2, ⋃︀𝐿1/𝐿2⋃︀≤(1−𝜖)⋃︀𝐿1⋃︀means that
at most (1 −𝜖) fraction of elements in 𝐿1 can be missing from 𝐿2
with probability 1 −𝑝𝑖, i.e. Pr(𝑎𝑖∉𝐿2 ⋃︀𝑎𝑖∈𝐿1, 𝒥) ≤(1 −𝜖)(1 −𝑝𝑖):
Pr(𝑎𝑖∈𝐷⋃︀𝒥) = Pr(𝑎𝑖∈𝐿1 ⋃︀𝒥) Pr(𝑎𝑖∉𝐿2 ⋃︀𝑎𝑖∈𝐿1, 𝒥)
≤(1 −𝜖)(1 −𝑝𝑖)𝑝𝑖.
(18)
□
Lemma 3 explains the intuition behind the Zipf-skewed bound.
Although head labels have large inclusion probabilities, they are less
likely to dominate 𝐷under a high-Jaccard constraint. Intuitively,
if a frequent label appears in 𝐿1, omitting it from 𝐿2 consumes
part of the limited missing-label budget imposed by 𝐽(𝐿1,𝐿2) ≥
𝜖. Therefore, under skewed marginals, the difference set is more
likely to be formed by lower-probability labels, making 𝐾(𝐿1,𝐿2) =
∏𝑎𝑖∈𝐷(1−𝑝𝑖) larger than what the worst-case 𝑝max bound suggests.


## PDF page 17

Fast Label-Filtering Approximate Nearest Neighbor Search via Progressive Label Set Stratification
SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
B.2
Proof of Theorem 4.2
Proof. Let 𝑝𝑖∶=
𝜇𝑖−𝑠
𝐻⋃︀𝐴⋃︀,𝑠,𝐻⋃︀𝐴⋃︀,𝑠∶= ∑
⋃︀𝐴⋃︀
𝑗=1 𝑗−𝑠,𝑠≥0 and define 𝑟∶=
max(2, arg min𝑖
𝐻𝑖,𝑠
𝐻⋃︀𝐴⋃︀,𝑠≥𝜌). Hence, the prefix {𝑎1, . . .,𝑎𝑟} contains
at least a 𝜌-fraction of the Zipf mass. As in the theorem statement,
let 𝒥∶= {𝐽(𝐿1,𝐿2) ≥𝜖}, 𝒜∶= {𝐷⊆{𝑎𝑟, . . .,𝑎⋃︀𝐴⋃︀}}.
(1) Bound the expected tail mass. For fixed 𝑞≥0 and ∀𝑥≥0,
Ψ𝑞(𝑥) ∶=
)︀⌉︀⌉︀⌉︀⌉︀⌋︀⌉︀⌉︀⌉︀⌉︀]︀
(𝑟+ 𝑥−1)1−𝑞−(𝑟−1)1−𝑞
1 −𝑞
,
𝑞≠1,
ln 𝑟+ 𝑥−1
𝑟−1
,
𝑞= 1.
(19)
Since 𝑡↦𝑡−𝑞is decreasing on (︀1, ∞), for any integer 𝑦≥1,
𝑟+𝑦−1
∑
𝑖=𝑟
𝑖−𝑞≤∫
𝑟+𝑦−1
𝑟−1
𝑡−𝑞𝑑𝑡= Ψ𝑞(𝑦),
(20)
where the equality follows by direct evaluation of the integral (with
the logarithmic form when 𝑞= 1). Therefore, on 𝒜,
∑
𝑎𝑖∈𝐷
𝑝𝑖≤
𝜇
𝐻⋃︀𝐴⋃︀,𝑠
Ψ𝑠(⋃︀𝐷⋃︀),
∑
𝑎𝑖∈𝐷
𝑝2
𝑖≤
𝜇2
𝐻2
⋃︀𝐴⋃︀,𝑠
Ψ2𝑠(⋃︀𝐷⋃︀).
(21)
Using ⋃︀𝐷⋃︀≤⋃︀𝐿1⋃︀+ ⋃︀𝐿2⋃︀−2⋃︀𝐿1 ∩𝐿2⋃︀≤1−𝜖
1+𝜖(⋃︀𝐿1⋃︀+ ⋃︀𝐿2⋃︀), we get
E(︀⋃︀𝐷⋃︀⋃︀𝒥, 𝒜⌋︀≤E(︀⋃︀𝐷⋃︀⋃︀𝒥⌋︀≤2𝜇(1 −𝜖)
1 + 𝜖
∶= 𝐵.
(22)
Moreover, Ψ𝑞is concave on 𝑥≥0 for 𝑞≥0 since Ψ′′
𝑞(𝑥) =
−𝑞(𝑟+ 𝑥−1)−𝑞−1 ≤0. Hence, by Jensen’s inequality,
E
⎨⎝⎝⎝⎝⎪
∑
𝑎𝑖∈𝐷
𝑝𝑖
∫︀∫︀∫︀∫︀∫︀∫︀∫︀∫︀∫︀∫︀∫︀
𝒥, 𝒜
⎬⎠⎠⎠⎠⎮
≤
𝜇
𝐻⋃︀𝐴⋃︀,𝑠
Ψ𝑠(𝐵),
E
⎨⎝⎝⎝⎝⎪
∑
𝑎𝑖∈𝐷
𝑝2
𝑖
∫︀∫︀∫︀∫︀∫︀∫︀∫︀∫︀∫︀∫︀∫︀
𝒥, 𝒜
⎬⎠⎠⎠⎠⎮
≤
𝜇2
𝐻2
⋃︀𝐴⋃︀,𝑠
Ψ2𝑠(𝐵).
(23)
(2) Bound the event kernel and control the complement.
𝐾(𝐿1,𝐿2) = ∏
𝑎𝑖∈𝐷
(1 −𝑝𝑖) = exp ⎛
⎝∑
𝑎𝑖∈𝐷
ln(1 −𝑝𝑖)⎞
⎠.
(24)
Under the standard long-tail condition on 𝒜(i.e., assuming 𝑝𝑖≤
0.6 for all 𝑖≥𝑟), we use ln(1 −𝑥) ≥−𝑥−𝑥2 for 𝑥∈(︀0, 0.6⌋︀and
obtain
E(︀𝐾(𝐿1,𝐿2) ⋃︀𝒥, 𝒜⌋︀≥exp ⎛
⎝−
𝜇
𝐻⋃︀𝐴⋃︀,𝑠
Ψ𝑠(𝐵) −
𝜇2
𝐻2
⋃︀𝐴⋃︀,𝑠
Ψ2𝑠(𝐵)⎞
⎠. (25)
For 𝒜𝑐, by Lemma 3,
Pr(𝒜𝑐⋃︀𝒥) = Pr (⋃
𝑖<𝑟
{𝑎𝑖∈𝐷} ⋁︀𝒥)
≤(1 −𝜖) ∑
𝑖<𝑟
𝑝𝑖(1 −𝑝𝑖) ≤(1 −𝜖) ∑
𝑖<𝑟
𝑝𝑖≤𝜇𝜌(1 −𝜖),
(26)
thus Pr(𝒜⋃︀𝒥) ≥1 −𝜇𝜌(1 −𝜖).
(3) Combine bounds by the Bayes’ theorem.
𝑃𝑐= E(︀𝐾(𝐿1,𝐿2) ⋃︀𝒥⌋︀
≥E(︀𝐾(𝐿1,𝐿2)1(𝒜) ⋃︀𝒥⌋︀≥E(︀𝐾(𝐿1,𝐿2) ⋃︀𝒥, 𝒜⌋︀⋅Pr(𝒜⋃︀𝒥)
≥exp ⎛
⎝−
𝜇
𝐻⋃︀𝐴⋃︀,𝑠
Ψ𝑠(𝐵) −
𝜇2
𝐻2
⋃︀𝐴⋃︀,𝑠
Ψ2𝑠(𝐵)⎞
⎠(1 −𝜇𝜌(1 −𝜖)),
(27)
where 𝐵= 2𝜇(1−𝜖)
1+𝜖
. This establishes the claimed lower bound.
□
C
Proofs for Overlap Lower Bound
For overlap queries, we analyze the complementary event that a
query overlaps 𝐿1 but does not overlap 𝐿2. The following lemma
shows that this non-overlap probability is maximized when the
query label set is as small as possible.
Lemma 4. Pr(𝐿𝑞∩𝐿2 = ∅⋃︀𝐿𝑞∩𝐿1 ≠∅) is maximized at ⋃︀𝐿𝑞⋃︀= 1.
Proof. Define 𝐿𝐴= 𝐿1 ∩𝐿2,𝐿𝐵= 𝐿1/𝐿2,𝐿𝐶= 𝐿2/𝐿1,𝐿𝐷= (𝐿1 ∪
𝐿2)𝑐, and 𝑎= ⋃︀𝐿𝐴⋃︀,𝑏= ⋃︀𝐿𝐵⋃︀,𝑐= ⋃︀𝐿𝐶⋃︀,𝑑= ⋃︀𝐿𝐷⋃︀. Then, ⋃︀𝐿1⋃︀= 𝑎+𝑏, ⋃︀𝐿2⋃︀=
𝑎+ 𝑐, ⋃︀𝐿1 ∪𝐿2⋃︀= ⋃︀𝑎+ 𝑏+ 𝑐⋃︀. Define 𝜅= ⋃︀𝐿𝑞⋃︀,
𝑓(𝜅) = Pr(𝐿𝑞∩𝐿2 = ∅⋃︀𝐿𝑞∩𝐿1 ≠∅) =
Pr(𝐿𝑞∩𝐿2=∅∧𝐿𝑞∩𝐿1≠∅)
Pr(𝐿𝑞∩𝐿1≠∅)
.
(28)
The numerator of 𝑓(𝜅) is the probability of a joint event. 𝐿𝑞∩𝐿2 =
∅iff. 𝐿𝑞cannot contain any elements from 𝐿2 = 𝐿𝐴∪𝐿𝐶, and thus 𝐿𝑞
must be contained in (𝐿𝐴∪𝐿𝐶)𝑐= 𝐿𝐵∪𝐿𝐷. Given 𝐿𝑞⊆𝐿𝐵∪𝐿𝐷, since
𝐿𝐷∩𝐿1 = ∅, 𝐿𝑞∩𝐿1 ≠∅means that there is at least one element
from 𝐵. Thus, (𝐿𝑞⊆𝐿𝐵∪𝐿𝐷) ∧(𝐿𝑞∩𝐿𝐵≠∅). The number of
𝜅-element subsets satisfying the above condition is (𝑏+𝑑
𝜅)−(𝑑
𝜅). The
dominator of 𝑓(𝜅) equals to 1−Pr(𝐿𝑞∩𝐿1 = ∅), and for 𝐿𝑞∩𝐿1 = ∅,
𝐿𝑞must be contained by (𝐿𝐴∪𝐿𝐵)𝑐= 𝐿𝐶∪𝐿𝐷. 𝑓(𝜅) =
(𝑏+𝑑
𝜅)−(𝑑
𝜅)
(⋃︀𝐴⋃︀
𝜅)−(𝑐+𝑑
𝜅),
which is non-increasing in 𝜅because 𝑓(𝜅+1)
𝑓(𝜅)
< 1. Therefore, 𝑓(𝜅) ≤
𝑓(1) =
𝑏
𝑎+𝑏.
□
Lemma 4 reduces the worst case of overlap preservation to sin-
gleton query labels. Thus, to lower-bound 𝑃𝑜, it suffices to minimize
the probability that a singleton label overlapping 𝐿1 also belongs
to 𝐿2 under the Jaccard constraint.
C.1
Proof of Theorem 4.3
Proof. We consider the probability from the complement with-
out the Jaccard constraint:
𝑃′
𝑜= 1 −Pr(𝐿𝑞∩𝐿2 = ∅⋃︀𝐿𝑞∩𝐿1 ≠∅).
(29)
By Lemma 4, 𝑃′
𝑜is minimized at ⋃︀𝐿𝑞⋃︀= 1, thus the lower bound of
𝑃𝑜is to minimize 𝑃′
𝑜subject to ⋃︀𝐿1∩𝐿2⋃︀
⋃︀𝐿1∪𝐿2⋃︀≥𝜖. Using the same notation
in the proof of Lemma 4, the object is to find the lower bound of
𝑎
𝑎+𝑏subject to
𝑎
𝑎+𝑏+𝑐≥𝜖.
𝑎
𝑎+𝑏+𝑐≥𝜖⇔𝑎≥
𝜖
1−𝜖(𝑏+ 𝑐):
𝑎
𝑎+ 𝑏≥
𝜖
1−𝜖(𝑏+ 𝑐)
𝜖
1−𝜖(𝑏+ 𝑐) + 𝑏= 𝜖(𝑏+ 𝑐)
𝑏+ 𝜖𝑐
=∶𝑓(𝑐).
(30)
Taking the derivative, 𝑑𝑓
𝑑𝑐= 𝜖𝑏(1−𝜖)
(𝑏+𝜖𝑐)2 ≥0. So, the worst case lower
bound is taken at 𝑐= 0, i.e. 𝐿2 ⊆𝐿1, which gives us
𝑎
𝑎+𝑏≥𝜖.
□


## PDF page 18

SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
Ziqi Wang, Jingzhe Zhang, Shuo Shen, and Wei Hu
Table 6: Query-set workload statistics
Datasets
Semantics
Labels
Sets
Label set size
Avg Med P90
SIFT
Equality
12
588
2.3
2
4
Containment
12
611
2.3
2
4
Overlap
12
622
2.3
2
4
GIST
Equality
12
589
2.3
2
4
Containment
12
611
2.3
2
4
Overlap
12
622
2.3
2
4
TripClick
Equality
29
249
2.0
2
3
Containment
29
305
2.1
2
3
Overlap
29
503
2.7
3
4
LAION
Equality
30
491
2.5
2
4
Containment
30
504
2.7
3
4
Overlap
30
524
2.8
3
5
YTB-Video
Equality
135
120
2.2
2
4
Containment
177
143
2.2
2
4
Overlap
279
174
3.1
3
5
YTB-Audio
Equality
675
652
2.7
2
5
Containment
731
680
2.7
2
5
Overlap
820
708
3.1
3
5
Wikipedia
Equality
32,780 9,673
5.8
6
7
Containment
1,520 2,689
1.7
2
3
Overlap
5,960 9,756
5.9
6
9
YFCC-1M
Equality
186
450
2.9
3
3
Containment
261
502
3.1
3
3
Overlap
4753
939
9.0
6
16
D
Dataset Details
Label–vector correlation. We compute Spearman’s 𝜌between
label Jaccard distance and vector L2 distance for all datasets. Base
vectors are ranked by their label set size ⋃︀𝐿⋃︀and split into four
equal-count quartile buckets: Q1 contains the smallest 25% of label
sets and Q4 the largest 25%. Fig. 17 shows negligible correlations
on seven datasets and a modest positive correlation on Wikipedia.
Thus, the evaluated workloads generally lack strong global label–
vector correlation, which LSSG does not assume. Instead, label
stratification improves local in-filtering navigation by increasing
the likelihood of label-qualified next-hop candidates.
Query workload statistics. Table 6 reports query-side effective
labels, distinct query label sets, and query label set size distributions
for all filter semantics. Most equality and containment queries are
compact, with median size 2–3 and P90 at most 7. Overlap queries
are broader. YFCC-1M overlap uses 4,753 effective query labels with
average/median/P90 size 9.0/6/16, while Wikipedia overlap uses
5,960 effective query labels with size 5.9/6/9. These statistics com-
plement Table 3 and show that the workloads cover both compact
query labels and large, diverse label spaces.
E
Additional Experiments
Approximation to the oracle on other datasets. Fig. 18 com-
pares distance computations (DC) against the oracle HNSW on the
remaining four datasets. On SIFT and TripClick, the label space
is small and containment filters are highly selective, so all meth-
ods operate on relatively small filtered subsets and exhibit similar
Table 7: Indexing performance of ANNS systems
Index size (MB)
Indices
SIFT GIST
Trip LAION Video Audio
Wiki YFCC
FAISS-IVF
13
41
37
26
47
27
53
12
FAISS-HNSW
138
134
145
136
672
672
688
135
VSAG-IVF
207
137
117
155
148
236
170
138
VSAG-HNSW
177
203
233
246
209
867
810
186
Milvus-IVF
8
11
11
10
12
39
40
8
Milvus-HNSW
488
488
516
488
488
2,441
2,441
488
PGVector-IVF
37
304 1,037
656
3,914
167
493
58
PGVector-HNSW
478 4,016 1,024
638
3,905
2,453
2,793
505
LSSG-IVF
311
204
199
271
136
1,069
602
239
LSSG-MinHash
296
192
200
277
142
1,065
606
303
Indexing time (s)
Indices
SIFT GIST
Trip LAION Video Audio
Wiki YFCC
FAISS-IVF
1,546 9,107 8,043
4,880
9,994
3,507 10,920
1,851
FAISS-HNSW
30
149
129
71
74
192
400
42
VSAG-IVF
94
473
350
253
595
250
457
119
VSAG-HNSW
31
82
79
46
59
163
311
29
Milvus-IVF
84
438
387
269
440
446
968
103
Milvus-HNSW
87
678
350
279
410
483
1,257
132
PGVector-IVF
90
631
583
356
750
447
1,237
180
PGVector-HNSW
238 1,092
923
544
1,128
1,136
2,841
276
LSSG-IVF
133
241
270
181
287
946
487
379
LSSG-MinHash
122
224
233
179
243
721
426
111
DC behavior close to the oracle. In contrast, the gap widens on
YTB-Video and YFCC-1M, whose larger label spaces make cross-
label navigation more difficult. LSSG is the closest approximation
among LFANNS indices, indicating better navigation efficiency
under large-scale label constraints.
Selectivity breakdown on other datasets. Fig. 19 reports QPS
across selectivity percentiles on the remaining four datasets. On
SIFT and TripClick where the label universe is small, ELI, UNG,
and LSSG are broadly comparable across percentiles. On YFCC-1M,
ELI fails to construct and UNG cannot reach 0.9 recall across all
selectivity percentiles in the overlap semantic. ACORN performs
strongly for overlap on low-selectivity percentiles, consistent with
its connectivity advantage when a large fraction of candidates pass
the filter.
Indexing performance of ANNS systems. Table 7 illustrates the
index size and indexing time of the systems compared in Fig. 7.
Across eight datasets, LSSG incurs moderate construction costs,
with median index size and indexing time of 287 MB and 229 s,
respectively. FAISS and VSAG HNSW variants build quickly with
moderate space, whereas IVF variants are compact but substantially
slower to construct (median time: 302–6,462 s). Milvus and PGVec-
tor provide integrated filtering but often incur larger index size
and comparable or higher construction time (median: 380–1,008 s).
The two LSSG variants have similar costs, and offer a balanced con-
struction trade-off while achieving stronger LFANNS performance.
Query performance of ANNS systems on other datasets. Fig. 20
shows the system results on SIFT, TripClick, YTB-Video, and YFCC-
1M. FAISS remains recall-limited, attaining at most 0.13–0.91 for


## PDF page 19

Fast Label-Filtering Approximate Nearest Neighbor Search via Progressive Label Set Stratification
SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
300
450
600
ρ = −0.004
Overall
SIFT
1
2
3
ρ = 0.004
Overall
GIST
8
10
12
ρ = 0.016∗∗∗
Overall
TripClick
0.8
1
1.2
ρ = 0.004
Overall
LAION
15
30
ρ = 0.021∗∗∗
Overall
YTB-Video
5
10
15
ρ = −0.005
Overall
YTB-Audio
1.2
1.4
1.5
ρ = 0.150∗∗∗
Overall
Wikipedia
320
400
480
ρ = 0.010∗
Overall
YFCC-1M
300
450
600
ρ = −0.012
Q1 (0–25%): |L| = 1
1
2
3
ρ = −0.004
Q1 (0–25%): |L| = 1
8
10
12
ρ = 0.008
Q1 (0–25%): |L| = 1
0.8
1
1.2
ρ = −0.001
Q1 (0–25%): |L| ∈[1,2]
15
30
ρ = 0.048∗∗∗
Q1 (0–25%): |L| ∈[1,2]
5
10
15
ρ = 0.001
Q1 (0–25%): |L| ∈[1,2]
1.4
1.5
ρ = 0.038∗∗∗
Q1 (0–25%): |L| ∈[1,6]
150
300
450
ρ = 0.001
Q1 (0–25%): |L| ∈[1,3]
300
450
600
ρ = 0.004
Q2 (25–50%): |L| ∈[1,2]
1
2
3
ρ = 0.011
Q2 (25–50%): |L| ∈[1,2]
8
10
12
ρ = 0.017
Q2 (25–50%): |L| = 1
0.8
1
1.2
ρ = 0.003
Q2 (25–50%): |L| ∈[2,3]
15
30
ρ = 0.014
Q2 (25–50%): |L| ∈[2,3]
5
10
15
ρ = −0.009
Q2 (25–50%): |L| ∈[2,3]
1.2
1.4
1.5
ρ = 0.170∗∗∗
Q2 (25–50%): |L| = 6
320
400
480
ρ = −0.004
Q2 (25–50%): |L| ∈[3,6]
300
450
600
ρ = −0.011
Q3 (50–75%): |L| ∈[2,3]
1
2
3
ρ = 0.008
Q3 (50–75%): |L| ∈[2,3]
8
10
12
ρ = −0.002
Q3 (50–75%): |L| = 1
0.8
1
1.2
ρ = 0.007
Q3 (50–75%): |L| ∈[3,4]
10
20
30
ρ = 0.015
Q3 (50–75%): |L| ∈[3,4]
5
10
15
ρ = −0.014
Q3 (50–75%): |L| ∈[3,4]
1.2
1.4
1.5
ρ = 0.176∗∗∗
Q3 (50–75%): |L| = 6
320
400
480
ρ = 0.005
Q3 (50–75%): |L| ∈[6,10]
0.0
0.5
1.0
300
450
600
ρ = 0.006
Q4 (75–100%): |L| ∈[3,8]
0.0
0.5
1.0
1
2
3
ρ = 0.009
Q4 (75–100%): |L| ∈[3,8]
0.0
0.5
1.0
8
10
ρ = −0.004
Q4 (75–100%): |L| ∈[1,8]
0.0
0.5
1.0
0.8
1
1.2
ρ = 0.005
Q4 (75–100%): |L| ∈[4,12]
0.0
0.5
1.0
10
20
30
ρ = 0.025∗∗
Q4 (75–100%): |L| ∈[4,21]
0.0
0.5
1.0
5
10
15
ρ = 0.006
Q4 (75–100%): |L| ∈[4,23]
0.0
0.5
1.0
1.4
1.5
ρ = 0.100∗∗∗
Q4 (75–100%): |L| ∈[6,17]
0.0
0.5
1.0
320
400
480
ρ = 0.033∗∗∗
Q4 (75–100%): |L| ∈[10,1332]
Jaccard Distance
L2 Distance
Figure 17: Correlation between pairwise Jaccard distance and L2 distance. Darker regions indicate more object pairs. The red
curve shows E(︀𝛿𝑣(𝑣1,𝑣2) ⋃︀𝛿𝐿(𝑙(𝑣1),𝑙(𝑣2))⌋︀, and Spearman’s coefficient 𝜌is marked at the top right corner.
0.6
0.8
1.0
103
104
Equality
DC
SIFT
0.6
0.8
1.0
102
103
104
TripClick
0.6
0.8
1.0
103
104
105
YTB-Video
0.6
0.8
1.0
102
YFCC-1M
0.6
0.8
1.0
103
104
Containment
DC
0.6
0.8
1.0
103
104
0.6
0.8
1.0
103
104
105
0.6
0.8
1.0
103
0.6
0.8
1.0
Recall@10
103
104
Overlap
DC
0.6
0.8
1.0
Recall@10
103
104
0.6
0.8
1.0
Recall@10
104
106
0.6
0.8
1.0
Recall@10
103
104
105
LSSG-IVF
LSSG-MinHash
ACORN
Packing
RWalks
UNG
ELI
Oracle
Figure 18: DC of LFANNS indices on other datasets
equality and 0.60–0.93 for containment across these datasets. On
YTB-Video overlap, it reaches only 0.89 recall. At 0.95 recall for con-
tainment, the best VSAG, Milvus, and PGVector variants achieve 18–
136, 17–122, and 9–44 QPS, respectively, while LSSG remains on the
upper QPS–recall frontier. Although library implementations can
be competitive for overlap on SIFT, TripClick, and YFCC-1M, their
performance varies substantially across workloads and degrades
on YTB-Video. Overall, LSSG provides more consistent high-recall
performance across datasets and filter semantics.
Impact of different label set distances. Fig. 21 compares tiering
on LAION using distances induced by alternative label set simi-
larities, including cosine (
⋃︀𝐿1∩𝐿2⋃︀
⌈︂
⋃︀𝐿1⋃︀×⋃︀𝐿2⋃︀), Dice ( 2⋃︀𝐿1∩𝐿2⋃︀
⋃︀𝐿1⋃︀+⋃︀𝐿2⋃︀), and overlap
(
⋃︀𝐿1∩𝐿2⋃︀
min(⋃︀𝐿1⋃︀,⋃︀𝐿2⋃︀)). (1) Jaccard is the best fit for tiering. Stratification by
overlap distance degrades containment because it provides weaker
granularity for separating tiers, underutilizing higher tiers and
10% 30% 50% 70% 90%
103
104
Equality
QPS
SIFT
10% 30% 50% 70% 90%
103
104
105
TripClick
10% 30% 50% 70% 90%
103
104
R=0.85
YTB-Video
10% 30% 50% 70% 90%
105
YFCC-1M
10% 30% 50% 70% 90%
103
104
Containment
QPS
10% 30% 50% 70% 90%
103
104
10% 30% 50% 70% 90%
101
102
103
104
R=0.80
10% 30% 50% 70% 90%
104
10% 30% 50% 70% 90%
Percentile
103
Overlap
QPS
10% 30% 50% 70% 90%
Percentile
103
10% 30% 50% 70% 90%
Percentile
100
101
102
103
R=0.70
10% 30% 50% 70% 90%
Percentile
103
10% 30% 50% 70% 90%
Percentile
10−4
10−2
1
Avg. Filter Ratio
10% 30% 50% 70% 90%
Percentile
10−5
10−4
10−3
10−2
10−1
10% 30% 50% 70% 90%
Percentile
10−4
10−3
10−2
10−1
10% 30% 50% 70% 90%
Percentile
10−5
10−4
10−3
10−2
10−1
LSSG-IVF
LSSG-MinHash
ACORN
UNG
ELI
Equality
Containment
Overlap
Figure 19: Selectivity breakdown on other datasets
weakening progressive navigation. (2) MinHash benefits from met-
ric alignment. Non-Jaccard distances hurt LSSG-MinHash more
than LSSG-IVF, since MinHash is an unbiased estimator for Jaccard
similarity but not for the other distance measures.
Impact of the Jaccard threshold distribution. In Def. 4, we
use uniformly spaced Jaccard-distance thresholds across tiers. We
additionally evaluate logarithmic (𝜃𝑡= 1−log(𝑡)
log(𝑇)), exponential (𝜃𝑡=
1−
exp( 𝑡−1
𝑇−1 )−1
𝑒−1
), and quadratic (𝜃𝑡= 1−( 𝑡−1
𝑇−1)2) schedules. As shown
in Fig. 22, LSSG-MinHash is robust across all threshold schedules,
suggesting that its probing step tolerates moderate changes in tier


## PDF page 20

SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
Ziqi Wang, Jingzhe Zhang, Shuo Shen, and Wei Hu
0.6
0.8
1.0
102
104
Equality
QPS
SIFT
0.6
0.8
1.0
102
104
TripClick
0.6
0.8
1.0
102
104
YTB-Video
0.6
0.8
1.0
101
103
YFCC
0.6
0.8
1.0
102
104
Containment
QPS
0.6
0.8
1.0
101
102
103
0.6
0.8
1.0
101
102
103
0.6
0.8
1.0
102
104
0.6
0.8
1.0
Recall@10
102
104
Overlap
QPS
0.6
0.8
1.0
Recall@10
101
102
103
0.6
0.8
1.0
Recall@10
101
102
103
0.6
0.8
1.0
Recall@10
102
104
LSSG-IVF
LSSG-MinHash
FAISS-IVF
FAISS-HNSW
VSAG-IVF
VSAG-HNSW
Milvus-IVF
Milvus-HNSW
PGVector-IVF
PGVector-HNSW
Figure 20: Query performance of ANNS systems on other
datasets
0.80
0.85
0.90
0.95
1.00
102
103
Containment
QPS
LSSG-IVF
0.80
0.85
0.90
0.95
1.00
102
103
LSSG-MinHash
0.80
0.85
0.90
0.95
1.00
Recall@10
102
103
Overlap
QPS
LSSG-IVF
0.80
0.85
0.90
0.95
1.00
Recall@10
102
103
LSSG-MinHash
Jaccard
Cosine
Dice
Overlap
Figure 21: Comparison of different label set distances
granularity. LSSG-IVF is more sensitive. Non-uniform schedules
can over-emphasize a narrow similarity range, while the uniform
schedule covers a broader spectrum of label set similarity and yields
better containment and overlap performance in our experiments.
Baseline parameter audit. To ensure fair baseline tuning, we
evaluate all 27 construction configurations of UNG and ELI on
SIFT, LAION, and YTB-Audio. For UNG, we sweep 𝑀∈{16, 32, 64},
𝐿build ∈{50, 100, 200}, and 𝛿∈{3, 6, 12}. For ELI, we sweep 𝑀∈
{8, 16, 32}, efc ∈{128, 200, 256}, and 𝑒∈{0.2, 0.4, 0.6}. Fig. 23 shows
all swept results and highlights the recommended, query-best, and
minimum indexing time settings. Table 8 reports the construction
costs of the recommended and query-best settings.
For containment, tuning UNG improves QPS by 1.23–1.33x, but
the gains are accompanied by construction or cross-semantic penal-
ties. The query-best settings require 1.12–2.25x indexing time of
the recommended setting. Index size increases by 83% on SIFT and
37% on YTB-Audio. They also degrade other semantics: for equal-
ity, QPS drops by 13% on SIFT and 14% on YTB-Audio, while on
LAION the maximum recall decreases from 0.877 to 0.832. For over-
lap, the best settings show the same trade-off. On SIFT, the 1.40x
QPS gain reduces that for equality and containment by 21% and
23%, while increasing index size and indexing time by 55% and
0.80
0.85
0.90
0.95
1.00
102
103
Containment
QPS
LSSG-IVF
LAION
0.80
0.85
0.90
0.95
1.00
102
103
LSSG-IVF
YTB-Audio
0.80
0.85
0.90
0.95
1.00
101
102
103
Overlap
QPS
LSSG-IVF
0.80
0.85
0.90
0.95
1.00
102
103
LSSG-IVF
0.80
0.85
0.90
0.95
1.00
102
103
Containment
QPS
LSSG-MinHash
0.80
0.85
0.90
0.95
1.00
102
103
LSSG-MinHash
0.80
0.85
0.90
0.95
1.00
Recall@10
101
102
103
Overlap
QPS
LSSG-MinHash
0.80
0.85
0.90
0.95
1.00
Recall@10
102
103
LSSG-MinHash
Uniform
Logarithmic
Exponential
Quadratic
Figure 22: Impact of Jaccard distance threshold distribution
80
90
100
103
104
QPS
SIFT
Equality
85
90
95
100
103
104
LAION
60
80
100
103
104
YTB-Audio
50
75
100
103
104
UNG
Containment
QPS
50
75
100
103
40
60
80
100
103
104
50
100
Recall@10
102
103
104
QPS
Overlap
25
50
75
Recall@10
102
103
25
50
75
Recall@10
102
103
All 27 conﬁgs
Recommended
Best per workload
Min indexing time
60
70
80
102
103
104
QPS
SIFT
Equality
60
65
70
102
103
LAION
70
80
90
100
101
YTB-Audio
70
80
90
100
102
103
104
ELI
Containment
QPS
80
90
100
102
103
104
80
90
100
100
101
102
80
100
Recall@10
102
103
104
QPS
Overlap
70
80
90
100
Recall@10
102
103
80
90
100
Recall@10
100
101
102
All 27 conﬁgs
Recommended
Best per workload
Min indexing time
Figure 23: Query-side parameter audits


## PDF page 21

Fast Label-Filtering Approximate Nearest Neighbor Search via Progressive Label Set Stratification
SIGMOD ’27, June 13–19, 2027, Huntington Beach, CA
Table 8: Parameter audits of UNG and ELI. “Rec.” is the index
size and indexing time on the recommended settings. The
recommend settings are (32, 100, 6) for UNG and (16, 200, 0.2)
for ELI. “Query-best” is the setting with the best query per-
formance per workload (blue curves in Fig. 23).
Indices Datasets
Sem.
Rec.
(MB / s)
Query-best
setting
Query-best
(MB / s)
UNG
SIFT
Eq.
228 / 76
(16, 50, 3)
169.6 / 33.7
Cont.
228 / 76
(64, 200, 6)
417.6 / 170.8
Ovlp.
228 / 76
(64, 100, 3)
353.1 / 89.5
LAION
Eq.
271 / 189
(16, 50, 12)
234.7 / 87.9
Cont.
271 / 189
(16, 200, 6)
193.3 / 211.2
Ovlp.
271 / 189
(64, 50, 12)
346.3 / 126.5
YTB-Audio
Eq.
954 / 1,422
(32, 100, 12) 1,220.5 / 1,716.4
Cont.
954 / 1,422
(64, 200, 6)
1,303.5 / 1,870.6
Ovlp.
954 / 1,422
(64, 200, 12) 1,552.8 / 1,843.1
ELI
SIFT
Eq.
419 / 98
(16, 200, 0.2)
419 / 98
Cont.
419 / 98
(16, 128, 0.6)
615.0 / 88.8
Ovlp.
419 / 98
(16, 128, 0.4)
615.0 / 88.8
LAION
Eq.
745 / 257
(32, 256, 0.2)
1,331.2 / 399.1
Cont.
745 / 257
(8, 128, 0.6)
597.0 / 182.7
Ovlp.
745 / 257
(16, 128, 0.4)
968.0 / 245.0
YTB-Audio
Eq.
92,693 / 807 (32, 256, 0.4) 94,141.4 / 912.1
Cont. 92,693 / 807 (32, 256, 0.6) 94,915.3 / 989.3
Ovlp. 92,693 / 807 (32, 256, 0.6) 94,915.3 / 989.3
18%. On LAION and YTB-Audio, the maximum recall for overlap
increases from 0.877/0.778 to 0.903/0.812, but QPS for equality de-
creases by 13%/14% and index size increases by 28%/63%; YTB-Audio
also requires 30% longer indexing. Thus, UNG’s query-best settings
improve the target workloads by trading off construction cost or
performance under other filter semantics, rather than providing a
uniformly stronger replacement.
ELI exhibits a clearer dependence on both dataset and filter se-
mantics. The recommended 𝑒= 0.2 gives the best accuracy for
equality on SIFT and LAION, whereas containment favors 𝑒= 0.6
and overlap favors 𝑒= 0.4 on these datasets. Tuning improves QPS
by 2.08–3.95x for containment and by at most 1.64x for overlap, but
reduces maximum recall for equality by 10.6% on SIFT and 6.3%
on LAION. These settings are therefore not uniformly stronger re-
placements. Even (16, 128, 0.2), which retains 𝑒= 0.2 and improves
several SIFT/LAION workloads, loses on YTB-Audio overlap, where
the recommended setting achieves the best result. The best setting
for containment on YTB-Audio instead increases indexing time
by 23%. Thus, no alternative among the 27 configurations consis-
tently improves the recommended setting across all datasets and
semantics.
In summary, using the query-best audited configurations changes
some point-wise winners but not the overall cross-semantics com-
parison. LSSG-MinHash remains 1.33–5.24x faster than query-best
UNG on all three containment workloads, while no audited UNG
configuration reaches 0.95 recall for overlap on LAION or YTB-
Audio. Query-best ELI is 2.63x and 4.49x faster than LSSG-MinHash
on SIFT and LAION for containment and matches LSSG-MinHash
on SIFT for overlap. Conversely, LSSG-MinHash is 1.20x faster on
LAION for overlap and 32.0x/10.1x faster on YTB-Audio for contain-
ment/overlap. Thus, tuning changes individual winners but yields
no baseline with consistent dominance across the audited datasets
and semantics compared. LSSG retains the advantage of consis-
tently strong performance across all semantics with one index.
Received 17 April 2026; revised 20 August 2026; accepted 12 September 2026



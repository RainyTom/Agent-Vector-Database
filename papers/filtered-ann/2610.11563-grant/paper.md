# 2610.11563v1 原始 PDF 文本提取

来源：https://arxiv.org/pdf/2610.11563v1

提取日期：2026-10-18。由 PyMuPDF 提取，未经 MinerU 版式转换；公式和表格需回看 PDF。

## PDF page 1

Grant: A Framework for Approximate Nearest Neighbor Search with
Multi-Attribute Range Filters
Daichi Amagata
The University of Osaka
amagata.daichi@ist.osaka-u.ac.jp
Abstract
Recently, academia and industry have considered the problem of approximate nearest neighbor search (ANNS) with
filters. In this setting, each object consists of a high-dimensional vector and attribute values. Given a query vector, filters
for attribute values, and 𝑘, this problem retrieves 𝑘vectors approximately nearest to the query vector among a set of objects
passing the filters. This paper considers range filters, i.e., users can specify a range constraint for each attribute. Most
existing works do not consider this setting, and they assume (i) only a single attribute or (ii) matching filters that require
the same attribute values or categories. Existing techniques for these assumptions are not available for our setting or are
trivially not efficient. Although standard solutions, such as pre-filter and post-filter, can handle our problem, they are also
inefficient. Some works tackle the same problem as ours, but their techniques necessitate historical query workloads, which
significantly limit practical use cases. To remove these limitations, this work proposes Grant, a novel framework that solves
this problem efficiently while accepting arbitrary range filters and ANNS data structures. Grant can guarantee a search
time sub-linear to the number of objects, which is not held by existing techniques. We conduct extensive experiments, and
their results demonstrate that Grant outperforms existing techniques.
1
Introduction
Modern search engines increasingly rely on machine learning models that embed many types of objects, such as images and
texts, into high-dimensional vectors. Due to this fact, the problem of similarity search in a high-dimensional space becomes
more important in many fields, such as recommender systems [1, 2], information retrieval [6, 5, 8, 24, 23], databases [35, 44,
54, 45], artificial intelligence [27], and machine learning [3, 4]. For example, computing the exact nearest neighbor on large
data with high dimensionality is computationally expensive, and many applications, such as RAG (Retrieval-Augmented
Generation), allow approximate results [28]. Therefore, approximate nearest neighbor search (ANNS) has been studied
extensively [7].
Nowadays, to enable making use of attribute information associated with objects, ANNS with attribute filters has been
considered both in academia [51, 20, 48, 58, 53, 37] and industry (e.g., Alibaba [50], Apple [34], and Microsoft [57, 19]). As
specified in these industrial works, the problem of ANNS with attribute filters is also important in many real-world Web
applications. A typical example of this problem is that, in e-commerce scenarios, each user finds the products most similar
to a given query vector among a set of objects satisfying attribute filters (e.g., price, rating, and production date). Similarly,
RAG applications receive benefits from ANNS with attribute filters. For example, when a user wants to know health risk,
he/she may write a prompt like “investigate what symptoms tend to appear for people aged from 40 to 50 and with blood
pressure at least 140.” This script is transformed into an ANNS with range filters on age and blood pressure attributes, and
the large language model obtains the answer from the retriever.
1.1
Limitations of Prior Work
The existing works on the problem of ANNS with attribute filters have the following issues.
(1) Single attribute assumption. Many existing works [51, 58, 53, 37, 30, 52, 49, 55] assume that each object has only a single
attribute, and their techniques are available only in this case. (Although some works [53, 58, 15, 30, 55] consider range filters,
they cannot deal with multiple attributes, or they are reduced to the standard technique, Post-filter, which is introduced in
Section 2.) This setting significantly limits applications, and objects generally have multiple attributes, as seen in the above
examples.
(2) Dealing with only matching filters. Most existing works consider attribute “matching” as a filter [26, 51, 20, 19, 48, 37, 13],
i.e., a filter evaluates whether a given object has the same attribute value/category as that of this filter. As the above
1
arXiv:2610.11563v1  [cs.DB]  8 Oct 2026


## PDF page 2

application examples show, users typically specify “range” filters, e.g., they want items whose prices and production dates
fall within certain ranges. Obviously, existing techniques for matching filters are inefficient for range filters on multiple
attributes, as they require running for each filter in multiple continuous ranges, which necessitates an infinite number of
iterations.
(3) Always requiring past queries. Although some works [34, 29] consider range filters on multiple attributes, they necessitate
past queries. They build ANNS indices based on past queries, so they do not function without past queries. This strong
assumption significantly limits practical use cases. A better and practical property is that an ANNS algorithm works well
without past query workloads and its efficiency can be accelerated with past queries. Note that no work devised optimal
algorithms for ANNS with range filters on multiple attributes, without past query workloads.
(4) Vector data management systems are general but inefficient. Some vector data management systems, e.g., [50, 46, 41],
support multiple attributes and range filters. They, however, do not optimize ANNS algorithms for this setting, and their
approaches are essentially Pre-filter or Post-filter.
1.2
Contribution
This paper tackles the problem of ANNS with multi-attribute range filters, a more general and challenging problem than
those with a single attribute and matching filters. An efficient and generally available solution (i) must be a workload-free
structure and (ii) has an option of past query usage for efficiency acceleration. No existing works satisfy efficiency and
generality at the same time for this problem.
This paper proposes Grant (Graph in tree index), an efficient framework for this problem, and it incorporates graph
indices into a tree index. It has three main advantages: (i) It handles multiple attributes and arbitrary ranges, optimized for
practical scenarios. (ii) It can employ arbitrary state-of-the-art multi-dimensional tree index and proximity graph. (iii) It
functions well without any past query workloads, and its efficiency can be enhanced with past query vectors. (iv) It is fast
and accurate in practice. To summarize, our main contributions are as follows.
• We propose Grant, a new and general framework for the problem of ANNS with multi-attribute range filters, and it is
built without any past query workloads.
• We present an efficient range-filtered ANNS algorithm that exploits the Grant structure. If past query vectors are avail-
able, the efficiency of the proposed algorithm can be accelerated.
• When we use a kd-tree [12] as a base structure of Grant, Grant can have a theoretical guarantee that the ANNS time
is sub-linear to 𝑛, where 𝑛is the number of objects. This theoretical result is not achieved by existing algorithms for
ANNS with range filters on multiple attributes.
• We conduct extensive experiments, and their results demonstrate that Grant outperforms state-of-the-art baselines in
most tests.
2
Preliminary
2.1
Problem Definition
Let 𝑋be a set of 𝑛objects. Each object 𝑥𝑖∈𝑋has a 𝑑-dimensional vector 𝐯𝑖and 𝑚attribute values 𝐚𝑖, i.e., 𝑥𝑖= (𝐯𝑖, 𝐚𝑖) where
𝑑is large and 𝑚≥2. Notice that the 𝑚attribute values can be represented as an 𝑚-dimensional vector, so we use 𝑎𝑖[𝑗] to
denote the 𝑗-th attribute value of 𝐚𝑖. Let 𝑑𝑖𝑠𝑡(⋅, ⋅) be the distance between two vectors. The problem of 𝑘nearest neighbor
search with multi-attribute range filters is defined as follows:
Definition 1 (𝑘nearest neighbor search with multi-attribute range filters). Given an object set 𝑋, a query vector
𝐪, query range filters 𝐹= {[𝑙1, 𝑢1], ..., [𝑙𝑚, 𝑢𝑚]}, and a result size 𝑘, this problem retrieves a set 𝑆∗(𝐪, 𝐹) of 𝑘objects such that (i)
𝑆∗(𝐪, 𝐹) ⊆𝑋(𝐹) and (ii) ∀𝑥∈𝑆∗(𝐪, 𝐹) and ∀𝑥′ ∈𝑋(𝐹)\𝑆∗(𝐪, 𝐹), 𝑑𝑖𝑠𝑡(𝐯, 𝐪) ≤𝑑𝑖𝑠𝑡(𝐯′, 𝐪), where
𝑋(𝐹) = {𝑥| 𝑥∈𝑋, ∀𝑗∈[1, 𝑚], 𝑙𝑗≤𝑎[𝑗] ≤𝑢𝑗}.
Ties are broken arbitrarily. If |𝑋(𝐹)| < 𝑘, we return 𝑋(𝐹).
This paper considers an approximation version of the above problem. We search for 𝑆(𝐪, 𝐹) such that 𝑆(𝐪, 𝐹) ⊆𝑋(𝐹),
|𝑆(𝐪, 𝐹)| = 𝑘, but we may have 𝑆(𝐪, 𝐹) ≠𝑆∗(𝐪, 𝐹). To measure the accuracy of 𝑆, we use recall@𝑘, a criterion commonly
used in ANNS studies, and
𝑟𝑒𝑐𝑎𝑙𝑙@𝑘= |𝑆(𝐪, 𝐹) ∩𝑆∗(𝐪, 𝐹)|
𝑘
.
2


## PDF page 3

Table 1: Summary of notations
Notation
Meaning
𝑥
Object
𝐯
𝑑-dimensional vector of 𝑥
𝐪
𝑑-dimensional query vector
𝐚
𝑚attribute values (𝑚-dim. vector) of 𝑥
𝑋
Set of 𝑛objects
𝑑𝑖𝑠𝑡(⋅, ⋅)
Distance between two 𝑑-dimensional vector
𝐹
Query filters
𝑘
Search result size
𝑆∗(𝐪, 𝐹)
Exact 𝑘NN result of 𝐪and 𝐹
This work assumes an in-memory setting, and disk-based approaches [43, 14, 56] are not within the scope of this paper.
The main notations in this paper are summarized in Table 1. When we analyze algorithms, we assume that 𝑑= 𝑂(1)
because our algorithms linearly scale to 𝑑.
2.2
Graph Index for ANNS
In a graph index, each vertex corresponds to a vector, and similar vectors are connected by edges. Edge selection is dependent
on a given graph structure: The most representative graph indices, such as HNSW [33], NSG [17], and Vamana [43], follow
relative neighbor graph or RNG structure. Consider three vectors 𝐯1, 𝐯2, and 𝐯3. If 𝑑𝑖𝑠𝑡(𝐯2, 𝐯3) < 𝑑𝑖𝑠𝑡(𝐯1, 𝐯3), the RNG does
not create an edge between 𝐯1 and 𝐯3.
ANNS on a graph index is done by greedy search. Given a query vector 𝐪, the greedy search traverses the graph index
from its entry vertex. For each unvisited neighbor vertex 𝐯, the greedy search computes 𝑑𝑖𝑠𝑡(𝐯, 𝐪) and pushes 𝐯into a heap,
so that we can next move to the nearest vertex to 𝐪. We iterate this traversal until the heap becomes empty (i.e., no closer
vectors are found).
2.3
Baseline Algorithms
The most straightforward algorithm for our problem is a brute-force one that runs a linear scan of 𝑋(and it computes
𝑑𝑖𝑠𝑡(𝐯𝑖, 𝐪) only when 𝐚𝑖satisfies 𝐹). Clearly, this algorithm incurs inefficient 𝑂(𝑛) distance computations, so existing works
devised the following techniques.
Pre-filter first obtains 𝑋(𝐹) and then runs a linear scan of 𝑋(𝐹). Notice that 𝑋(𝐹) can be efficiently obtained with a data
structure based on attribute values. Although this approach can return the exact answer, its search time is slow. Because
𝑋(𝐹) is query-dependent, Pre-filter cannot use any data structure for ANNS.
Post-filter uses a pre-built ANNS index (e.g., graph index [47]) to accelerate query efficiency. Given a query vector 𝐪and
filters 𝐹, it runs a “vanilla” ANNS algorithm on the index and checks the search result set. If the search result set does not
contain 𝑘objects that satisfy 𝐹, it runs another ANNS by enlarging 𝑘. This is repeated until 𝑘objects that satisfy 𝐹are
returned. Because the search strategy of Post-filter does not care about attribute values, its search space can be large and
requires many search iterations, leading to suboptimal performance.
ACORN [37], a state-of-the-art filter-agnostic index, is available for our problem. Its structure is a variant of HNSW, and
ACORN traverses only neighbors that pass a given query filter. This approach may fail to reach the exact 𝑘NN objects if no
neighbors have the query filter. It is not guaranteed that neighbors have similar attribute values. Therefore, ACORN loses
paths to 𝐪when no neighbors pass 𝐹, resulting in low recall. Our experimental results confirm this observation.
3
Related Work
Since the problem of ANNS in high-dimensional space has been used in many applications, its efficient algorithms have
been extensively devised. Although some approaches exist for ANNS, it is widely known that the graph index shows the
best time-recall trade-off among them [28]. To obtain a better time-recall trade-off, many graph indices were designed so
far, e.g., [32, 22, 16, 17, 18, 9, 38]. HNSW [33] and Vamana [43] are famous graph indices. They are usually used as an
underlying data structure in vector data management systems [36] and have theoretical analysis [40, 25]. Grant allows an
arbitrary graph index to maintain the high-dimensional vectors in 𝑋.
3


## PDF page 4

ANNS with Matching Filter. Many works consider this setting [51, 19, 48, 37, 13, 42]. For example, FilteredVamana
[19] extends Vamana by adding a label for each edge. During ANNS, only edges with the label matching a given filter
are traversed. StitchedVamana is another variant of Vamana, and it is a Vamana of the objects having the same label (or
attribute value). That is, for each distinct label, a StitchedVamana is built. NHQ [48] defines a customized distance function
that considers vector and label similarities. A proximity graph is built based on this customized distance function. They do
not support multi-attribute cases and/or range filters.
ANNS with Range Filter. Recent studies [58, 53] considered how to support a range filter in HNSW. SeRF [58] requires
𝑂(𝑛2) space, and iRangeGraph reduced this space to 𝑂(𝑛log 𝑛). Another work [15] developed a different data structure
based on a segment tree, and it also needs 𝑂(𝑛log 𝑛) space. Literature [30] further reduces the space complexity to 𝑂(𝑛).
These works focus on a single attribute case, and [53] suggests that their approaches are reduced to Post-filter when query
filters specify multiple attributes. WoW [49] achieves an updatable index for ANNS with a single range filter.
HQI [34] and SIEVE [29] can deal with multi-attribute range filters, but they require historical query filters to build the
structures. That is, without this assumption, their structures cannot be built. (Without past filters, SIEVE is reduced to a
standard algorithm, e.g., Post-filter on a graph index.) Furthermore, HQI focuses on batch query processing, and this setting
is different from our objective, i.e., processing each ANN query efficiently while providing a high recall result. Unlike these
works, the Grant structure can be built without any past information.
Vector Data Management Systems. Milvus [46], NaviX [41], and ADBV [50] support multi-attribute range filters. Milvus
can select an ANNS index, e.g., graph index and IVF (inverted file index), whereas ADBV employs IVF. ADBV proposes
two approaches: one is Pre-filter, and the other is the verification of a subset of 𝑋. Specifically, when IVF is used, only
some posting lists similar to a given query vector are verified. This verification is the same as the brute-force algorithm
introduced in Section 2. NaviX also employs Pre-filter but runs an approximate verification. Milvus also employs Pre-filter
and considers Post-filter.
4
Grant
Main idea. Indexing low-dimensional data is a classic problem, and many famous tree-based indices, such as kd-tree [12]
and R-tree [21], are known. These data structures support efficient orthogonal (or axis-parallel) range queries. Because
the attribute values held by the objects in 𝑋are regarded as low-dimensional vectors, we can build a tree index based on
the attribute values. Then, for example, 𝑋(𝐹) can be efficiently obtained with a range query of 𝐹. This approach avoids
accessing many vectors that do not satisfy 𝐹. However, simply applying this idea results in Pre-filter, so we suffer from a
high computational cost when |𝑋(𝐹)| is large. (If 𝑛is large, e.g., tens of millions, |𝑋(𝐹)| = 0.01 ⋅𝑛is still large.)
On the other hand, assume that 𝑋is indexed by a graph index (i.e., based on the 𝑑-dimensional vectors). Although this
approach yields a fast search time for ANNS without filters, our approach is limited to Post-filter when filters are specified.
Post-filter may need to access many objects (vectors) that do not satisfy 𝐹.
Now we have a challenging question: Given a query vector 𝐪and query filters 𝐹, how can we access only objects that satisfy
𝐹and are similar to 𝐪? The above observations of the tree and graph indices actually suggest an idea yielding a positive
answer to this question. If we receive benefits of the tree and graph indices (if we can run graph-based ANNS on the range
query result of 𝐹), we overcome the above challenge. We propose Grant, which achieves this idea.
4.1
Grant Structure
Existing indices do not have the ability to navigate objects that pass a given filter and have vectors similar to 𝐪. The
novelty of Grant is this navigation ability. Grant is a tree structure in which leaf nodes have a capacity of 𝑂(𝑛/𝑐), where
𝑐is a constant and hyper-parameter. This tree structure is constructed based on the attribute values. Each object in 𝑋is
maintained by a leaf node of the Grant, and each leaf node maintains the 𝑂(𝑛/𝑐) objects by using a graph index based on
their 𝑑-dimensional vectors. Note that the number of leaf nodes in Grant is 𝑂(𝑐) = 𝑂(1).
Figure 1 illustrates an example of the Grant structure, assuming that each node can have at most two child nodes. This
combination of tree and graph structures is simple yet effective: The main merits of this structure are as follows. (i) A set of
objects having similar attribute values can be maintained by a graph index, i.e., attribute-based and vector-based navigation
is simultaneously achieved. (ii) No past information is required. These properties are not held by existing techniques for
our problem and are important to positively answer the challenging question mentioned earlier and yield a fast ANNS time
described in Theorem 1.
Grant construction. This construction is done only once, and the Grant is general to any query vectors and range filters.
Let be the base tree structure of Grant. We use a top-down tree-building approach, and the Grant is built based on the
construction algorithm of . We assume that it is a balanced tree.
4


## PDF page 5

Figure 1: Grant structure. Grey nodes represent leaf nodes, each of which maintains a graph index.
Algorithm 1: Build(𝑋, 𝑐)
Input: 𝑋, 𝑐
1 root node of ←Make-Node(𝑋, 𝑐)
2 return 
3 Function Make-Node(𝑌, 𝑐):
4
𝑢←a new node of 
5
if |𝑌| ≤𝑛/𝑐then
6
Build-Graph(𝑌)
7
return 𝑢
8
𝑌𝑙, 𝑌𝑟←Split(𝑌)
9
left child node of 𝑢←Make-Node(𝑌𝑙, 𝑐)
10
right child node of 𝑢←Make-Node(𝑌𝑟, 𝑐)
11
return 𝑢
Algorithm 1 describes the constuction algorithm. Building is performed by Make-Node(⋅, 𝑐). Given 𝑋, we make a
root node of . If |𝑋| ≤𝑛/𝑐, it is a leaf node, and we build a graph index based on the 𝑑-dimensional vectors in 𝑋. (is
an arbitrary graph index.) Otherwise, we equally split 𝑋based on the construction algorithm of (i.e., based on attribute
values) to make balanced. We then create its descendant nodes in a recursive manner.
Proposition 1. Let 𝑓(𝑛) be the time of splitting a given set of 𝑛objects. Also, let 𝑔(𝑛) be the time of building a given proximity
graph of the object set. A Grant is built in 𝑂(𝑛(1 + 𝑓(𝑛))) + 𝑔(𝑛) time1.
Proof. Since is a balanced tree, the height of is at most log 𝑐= 𝑂(1) (recall that each leaf node can manage at most
𝑛/𝑐objects and 𝑐= 𝑂(1)). In addition, the number of nodes of is ≤2𝑐−1 = 𝑂(𝑐) = 𝑂(1). Hence, can be built in
𝑂(𝑛(log 𝑐+ 𝑓(𝑛))) = 𝑂(𝑛(1 + 𝑓(𝑛))) time. The remaining cost we need to consider is that of building a graph index in each
leaf node. When we call Build-Graph(𝑌) in Algorithm 1, |𝑌| ≤𝑛/𝑐. Because the number of leaf nodes is at most 𝑐= 𝑂(1),
the total cost of building the graph indices is 𝑔(𝑛). It is now clear that this proposition holds.
Proposition 2 (Space complexity of a Grant). Let 𝑆(𝑛) be the space of a given proximity graph, and a Grant needs 𝑂(1)+𝑆(𝑛)
space.
Proof. Recall the following three facts. (i) Each object in 𝑋is maintained in a leaf node of . (ii) has 𝑂(𝑐) = 𝑂(1) nodes,
because the Grant has 𝑐= 𝑂(1) leaf nodes. (iii) Each graph has 𝑆(𝑛) space. Given these, this proposition is true.
4.2
ANNS on Grant
Algorithm 2 describes our approach to running ANNS with multi-attribute range filters on the Grant. We first run a range
query of 𝐹on the Grant and obtain a set of leaf nodes 𝑈that overlap with 𝐹. Then, for each 𝑢∈𝑈, we run a graph-based
ANNS algorithm and pick only objects satisfying 𝐹. Note that each leaf node may partially overlap 𝐹, so some objects
maintained in a given leaf node may not satisfy 𝐹. Figure 2 depicts an example.
1As seen in Section 5, Grant is built quickly, e.g., within a few minutes on ten million objects. Hence, as long as 𝑋is not frequently updated, rebuilding
Grant is practical for dynamic 𝑋(e.g., batch updates).
5


## PDF page 6

Algorithm 2: Query(, 𝐪, 𝐹, 𝑘)
Input: (Grant), 𝐪, 𝐹, 𝑘
1 𝑆(𝐪, 𝐹) ←∅
2 𝑈←Range-Search(, 𝐹)
3 foreach 𝑢∈𝑈do
4
𝑆′ ←ANNS(, 𝐪, 𝑘)
5
foreach 𝑥∈𝑆′ such that 𝑥satisfies 𝐹do
6
Update 𝑆(𝐪, 𝐹) if necessary
7 return 𝑆
One of our main results is that this approach theoretically sounds and is practically fast, as analyzed below. Note that̃
𝑂(⋅) hides any polylog factors.
Lemma 1. Let 𝑇(𝑛) be the time of a range search on of 𝑛objects. Our algorithm can run in 𝑇(𝑛) +̃ 𝑂(1) time.
Proof. Line 2 requires 𝑇(𝑛) time. We rely on the recent result [31], and there exists a proximity graph that deals with
ANNS(, 𝐪, 𝑘) iñ 𝑂(1) worst time2. Since the number leaf nodes is at most 𝑐= 𝑂(1), |𝑈| = 𝑂(1). Therefore, lines 3–6 need̃
𝑂(1) time.
Existing works that can deal with this problem have no time bound, but our algorithm can yield a sub-linear query time.
Theorem 1. If we use a kd-tree as the base tree structure of a Grant, our algorithm can run in 𝑂(𝑛1−1/𝑚) time.
Proof. A range search on a kd-tree needs 𝑂(𝑛1−1/𝑚+ OUT) time, where OUT is the result size of the range search [12].
Then, 𝑇(𝑛) = 𝑂(𝑛1−1/𝑚+ |𝑈|) = 𝑂(𝑛1−1/𝑚). Note that 𝑂(𝑛1−1/𝑚) >̃ 𝑂(1). From Lemma 1, this theorem holds.
4.3
Optimizing ANNS on Grant by Heuristic
An interesting observation of the above algorithm is that, although Theorem 1 suggests that the main cost of our algorithm
is the range search theoretically, the main “practical” cost is derived from the graph-based ANNS of each leaf node in 𝑈.
It is important to notice that at most 𝑘leaf nodes have the objects ∈𝑆∗(𝐪, 𝐹), but we may have |𝑈| > 𝑘. In this case, our
algorithm runs graph-based ANNS on at least |𝑈| −𝑘unnecessary leaf nodes. However, it is hard to know which leaf node
has the objects ∈𝑆∗(𝐪, 𝐹) in advance. We therefore propose heuristic approaches that skip leaf nodes in 𝑈that would not
have the objects ∈𝑆∗(𝐪, 𝐹). Note that these heuristics are applied only when |𝑈| > 𝑂(𝑘).
Probabilistic node verification. The idea of our heuristic is to make use of an overlapping ratio between 𝐹and each leaf
node in 𝑈. In Figure 2, although 𝑢8 overlaps 𝐹, the overlapping space is very slight against the partition of 𝑢8 and 𝐹. Hence,
it is intuitive that 𝑢8 would not have the 𝑘NN objects, suggesting that 𝑢8 is skippable. This idea is specific to the Grant
structure. To implement this idea, we define the overlap ratio between 𝐹and a leaf node 𝑢.
Definition 2. Let 𝑉(𝐹) be the volume of the hyper-rectangle defined by the ranges in 𝐹. Also, let 𝑉(𝑢) be the volume of the
hyper-rectangle of a node 𝑢. The overlap ratio between 𝐹and 𝑢, 𝑟(𝐹, 𝑢), is
𝑟(𝐹, 𝑢) = max (
𝑉(𝐹∩𝑢)
𝑉(𝐹)
, 𝑉(𝐹∩𝑢)
𝑉(𝑢)
) ,
where 𝐹∩𝑢is the overlapping space between 𝐹and 𝑢.
Assuming a local uniform distribution of attributes within a leaf node, the number of valid candidates 𝐸[𝑛𝑣𝑎𝑙𝑖𝑑] is esti-
mated as
𝐸[𝑛𝑣𝑎𝑙𝑖𝑑| 𝑢, 𝐹] ∝𝑛
𝑐⋅𝑟(𝐹, 𝑢).
Nodes with higher 𝐸[𝑛𝑣𝑎𝑙𝑖𝑑] can be prioritized to increase the likelihood of retrieving true nearest neighbors.
For 𝑢∈𝑈, we have 𝑟(𝐹, 𝑢) ∈(0, 1], and 𝑟(𝐹, 𝑢) is obtained in 𝑂(1) time. Because it is not guaranteed that 𝑘leaf nodes
with the largest overlap ratio have the 𝑘NN objects, we employ a probabilistic approach. Specifically, for each leaf node 𝑢
in the range search result, if 𝑟(𝐹, 𝑢) is larger than a random real value ∈(0, 1], we run graph-based ANNS in this leaf node.
2In our experiments, we used HNSW as a practical instantiation of [31] because it empirically follows similar efficiency trends [33, 40] while providing
superior scalability and implementation simplicity for real-world deployments [47, 10, 28].
6


## PDF page 7

𝑢1
𝑢2
𝑢3
𝑢4
𝑢5
𝑢6
𝑢7
𝑢8
𝑢9
𝑢10
𝑢11
𝑢12
𝑢13
𝑢14
𝑢15
𝑢16
Figure 2: Black points represent two-dimensional attribute values of the objects in 𝑋, and each partition is maintained by
a leaf node 𝑢𝑖. The grey rectangle shows 𝐹, and it overlaps with 𝑢5, 𝑢6, 𝑢7, and 𝑢8, so we run graph-based ANNS on these
leaf nodes.
4.4
Workload-aware ANNS
If past query vectors are available, we can enhance our proposed approach. Let 𝐩be the nearest vector to a given query
vector 𝐪among a set of past query vectors3. Furthermore, let 𝑑𝑖𝑠𝑡(𝐩, 𝑢𝑖) be the distance between 𝐩and the nearest neighbor
vector in the leaf node 𝑢𝑖of the Grant. For ease of explanation, assume that 𝑑𝑖𝑠𝑡(𝐩, 𝑢1) < 𝑑𝑖𝑠𝑡(𝐩, 𝑢2) < ⋯𝑑𝑖𝑠𝑡(𝐩, 𝑢𝑐).
Assuming that 𝑘= 2 and 𝐹overlaps with 10 leaf nodes, 𝑢1, 𝑢2, ..., and 𝑢10, it is intuitively known that running ANNS of 𝐪
in 𝑢1 and 𝑢2 is sufficient to obtain the objects ∈𝑆∗(𝐪, 𝐹). This is because, if 𝑑𝑖𝑠𝑡(𝐩, 𝐪) is small, 𝐩and 𝐪share similar ANNS
results. This idea also skips ANNS on unnecessary nodes and enables accessing only 𝑂(𝑘) leaf nodes while keeping high
recall.
Additional pre-processing. Let 𝐏be a set of past query vectors, and it is maintained based on a graph index 𝐏. Addi-
tionally, for each past query vector 𝐩∈𝐏, we run ANNS on each leaf node 𝑢of the Grant. Let 𝑥be the object obtained for
the ANNS, and we record 𝑑𝑖𝑠𝑡(𝐩, 𝐯). We use a matrix to maintain such a record:
=
⎛
⎜
⎜
⎝
𝑑𝑖𝑠𝑡(𝐩1, 𝐯𝛼)
⋯
𝑑𝑖𝑠𝑡(𝐩1, 𝐯𝛽)
⋮
⋱
⋮
𝑑𝑖𝑠𝑡(𝐩𝑐, 𝐯𝛾)
⋯
𝑑𝑖𝑠𝑡(𝐩𝑐, 𝐯𝜙)
⎞
⎟
⎟
⎠
where the 𝑖-th row 𝑗-th column is the ANN result of 𝐩𝑖in the leaf node 𝑢𝑗. This is done after running building Grant. Note
that this additional pre-processing is also done only once.
When an HNSW is used as the index of 𝐏such that |𝐏| ≤𝑛, the additional pre-processing time is̃ 𝑂(|𝐏|𝑛). This is because
building an HNSW of 𝐏needs 𝑂(|𝐏| log |𝐏|) time [33] and obtaining requires 𝑂(|𝐏|𝑐) = 𝑂(|𝐏|) time. Similarly, its space
complexity is 𝑂(|𝐏|𝑛). (To reduce the time and space complexities, we can randomly sample past queries.)
Query processing. Algorithm 3 presents our algorithm for ANNS with multi-attribute range filters on Grant with 𝑃and
. Its main difference from Algorithm 2 is to exploit a past query vector that is similar to a given query vector 𝐪. We
obtain a set 𝑈′ of leaf nodes that overlap 𝐹. If |𝑈′| is large, we compute 𝐩𝑖, which is an ANN vector to 𝐪in 𝐏, by running
graph-based ANN on 𝐏. Then, we pick only 𝑂(𝑘) leaf nodes in 𝑈′ such that 𝑑𝑖𝑠𝑡(𝐩𝑖, ⋅) is the smallest. The subsequent
operations are the same as our original query processing algorithm. This is an optional workload-aware optimization that
can be applied on top of Grant when past query vectors are available.
3This is a different assumption from that of [34, 29], since they assume that not past query vectors but past query filters are available. Our assumption
is easier to hold: for example, we can use the vectors in 𝑋as past query vectors.
7


## PDF page 8

Algorithm 3: Query(, 𝐏, , 𝐪, 𝐹, 𝑘)
Input: (Grant), 𝐏, , 𝐪, 𝐹, 𝑘
1 𝑆(𝐪, 𝐹) ←∅
2 𝑈, 𝑈′ ←Range-Search(, 𝐹)
3 if |𝑈′| > 𝑂(𝑘) then
4
𝐩𝑖←ANNS(𝐏, 𝐪, 1)
5
𝑈←𝑂(𝑘) nodes in 𝑈′ such that 𝑑𝑖𝑠𝑡(𝐩𝑖, ⋅) (in [𝑖]) is the smallest
6 Run lines 3–6 of Algorithm 2
7 return 𝑆
5
Experiment
All experiments were conducted on a Ubuntu 22.04 LTS machine with a 2.2GHz Intel Core i9-13950HX processor and 128GB
RAM.
5.1
Setting
Datasets. We used four datasets commonly used in ANNS works: Deep [11], SIFT (http://corpus-texmex.irisa.
fr/), SPACEV [14], and T2 (https://big-ann-benchmarks.com/neurips21.html). They are large-scale
and contain 10 million vectors. Deep is a set of 96-dimensional deep features, and SIFT is a set of 128-dimensional SIFT
features. SPACEV is a set of 100-dimensional learned document vectors, and T2I is a set of 200-dimensional vectors learned
from the Yandex visual search engine results. We followed the existing filtered ANNS works [34, 50, 46, 29] to provide
each object with attribute values, and the attribute values follow a power-law distribution [20], which reflects real-world
scenarios [39]. By default, 𝑚= 2.
Queries. For each dataset, we used 100 random query vectors that can be obtained from the same source of the dataset.
Given a query vector 𝐪, to generate query range filters 𝐹, we first assigned a random value, which also follows the same
power-law distribution of the attribute domain, to 𝑙𝑗for each 𝑗∈[1, 𝑚]. Then, 𝑢𝑗= 𝑙𝑗+ 𝜆× domain size, where 𝜆∈[0.2, 0.8].
By default, 𝜆= 0.2 and 𝑘= 10. In this default setting, the average selectivity (i.e., the ratio of the objects satisfying the
range filter) was 0.15.
Evaluated algorithms. For algorithms that do not require past query workloads, we evaluated the following ones:
• BF: A brute-force exact algorithm.
• Pre-filter: This algorithm employs a kd-tree based on the attribute values of the objects in 𝑋. Given a query, it first
traverses the kd-tree based on the query range filters and obtains a set of objects that satisfy the range filters. Then, it
runs a linear scan of this set to return the 𝑘NN vectors, so this algorithm also returns the exact answer. This algorithm
actually corresponds Milvus [46]. Navix [41] also follows this approach but returns an approximate result. We tested
Navix, but its performance was worse than the exact version of Pre-filter, so we omit its result.
• IVF: An ANNS algorithm that is based on an inverted file structure. This approach is widely employed in the state-of-
the-art ANNS systems [46, 50, 34].
• Post-filter: The baseline algorithm introduced in Section 2. We used HNSW [33] as its ANNS index. This algorithm
actually corresponds to SIEVE [29] without past query filters (see Section 3) and VBase [57].
• ACORN: The baseline algorithm introduced in Section 2. Because ACORN-𝛾[37] could not be built in a reasonable time
(i.e., 1 hour), we used ACORN-1.
• Grant-basic: Our algorithm described in Section 4.2. We used a kd-tree as the base tree structure, and each leaf node
maintains the corresponding objects by HNSW. This setting was applied to the next algorithms. We set 𝑐= 150 (see our
supplementary).
• Grant-pnv: Our algorithm with the probabilistic node verification heuristic.
For algorithms that require past query workloads, we evaluated
• WA-Grant: Our algorithm that exploits past query vectors, see Section 4.4. For each dataset, we randomly sampled 1,000
vectors and added Gaussian noise to them. We used them as past query vectors, and they were also indexed by an HNSW.
8


## PDF page 9

0
200
400
600
800
1000
c (SIFT)
QPS
< 76
150
300
450
(a) SIFT
0
50
100
150
200
250
300
350
c (SPACEV)
QPS
< 76
150
300
450
(b) SPACEV
Figure 3: Impact of 𝑐under recall ≈0.9
• SIEVE [29]: the state-of-the-art algorithm for ANNS with range filter on multiple attributes. To maximize performance,
we used the same query filters as past ones (although it is impractical). Because this algorithm requires a memory budget,
we set it so that its memory usage is almost the same as WA-Grant for fair comparison.
All algorithms were implemented in C++ and compiled by g++ 11.3.0 with -O3 optimization. They enabled SIMD instruc-
tions.
For the algorithms using HNSW, we used the original implementation4. We tuned the inner parameters to obtain a
Pareto-optimal QPS-recall tradeoff. For HNSW, we did a grid search from 𝑀= {8, 16, 32, 64, 128} and 𝑒𝑓𝑐𝑜𝑛𝑠𝑡𝑟𝑢𝑐𝑡𝑖𝑜𝑛=
{32, 64, 100, 200, 300}. As a result, we set 𝑀= 64 and 𝑒𝑓𝑐𝑜𝑛𝑠𝑡𝑟𝑢𝑐𝑡𝑖𝑜𝑛= 200 for the baselines, whereas we set 𝑀= 16 and
𝑒𝑓𝑐𝑜𝑛𝑠𝑡𝑟𝑢𝑐𝑡𝑖𝑜𝑛= 64 for Grant. (Since each leaf node has at most 𝑛/𝑐< 𝑛vectors, each HNSW in Grant has smaller parameter
values.) For IVF, we used 1,000 clusters.
We did not consider works that assume matching filters on multiple attributes [20, 48], as they are not trivial to efficiently
address our problem. A straightforward extension of matching filter techniques to range filters requires discretizing each
continuous range into a very large number of (in principle, infinitely many) equality predicates, which is impractical.
5.2
Result
We first report the performances of the algorithms that do not require past query workloads. For indexing time, memory
usage, impact of 𝑐, impact of 𝑘, impact of 𝑚, and impact of range size, refer to our supplementary.
Impact of 𝑐. We tuned 𝑐for Grant, and Figure 3 shows QPS (queries per second) under recall ≈0.9 on SIFT and SPACEV.
Note that (i) we have similar results on Deep and T2I and (ii) the “< 76” case shows the best result when 𝑐≤75.
Although Grant is not very sensitive to 𝑐, it has an optimal 𝑐. When 𝑐is large, we have many leaf nodes overlapping 𝐹,
so it incurs many ANNSs. On the other hand, when 𝑐is small, we have fewer leaf nodes overlapping 𝐹but have a larger
number of objects that do not satisfy 𝐹. These observations yield the results in Figure 3.
Indexing time. Table 2 shows the indexing time of each algorithm. (Since BF does not employ any data structure, it is
omitted.) This phase used 24 threads. Grant-basic and Grant-pnv share the same data structure, so their indexing time is
represented by Grant. Since Pre-filter employs a single tree structure based only on attributes, it needs a shorter indexing
time than the others.
Although Grant employs tree and graph structures, its indexing time is at most just 1.5 minutes for 10 million high-
dimensional vectors. An interesting observation is that Grant needs shorter indexing time than IVF, Post-filter, and ACORN.
Memory consumption. Table 3 exhibits the memory consumption of the data structure of each algorithm. Because of the
graph-based indices, Post-filter and our algorithm needs more memory than Pre-filter and IVF. Nonetheless, our algorithm
does not consume much memory, and only less than about 10GB is required for 10 million high-dimensional vectors, which
is easy to fit into modern servers. (ACORN employs a graph index that is essentially HNSW, so its memory consumption is
almost the same as Post-filter.)
QPS vs. recall. We compare our algorithms with the baseline ones w.r.t. time and accuracy tradeoff. Figure 4 plots the QPS
vs. recall curve of each algorithm. Note that QPS and recall were the averages of the results of the 100 queries. We used a
single thread for each query.
4https://github.com/nmslib/hnswlib
9


## PDF page 10

Table 2: Indexing time [sec]
Dataset
Deep
SIFT
SPACEV
T2I
Pre-filter
3.04
3.04
3.03
3.06
IVF
98.75
151.92
101.37
202.75
Post-filter
888.26
1109.36
1380.33
1040.26
ACORN
1666.40
2067.56
2044.77
2013.43
Grant
60.20
71.52
78.34
97.14
Table 3: Memory consumption [GB]
Dataset
Deep
SIFT
SPACEV
T2I
Pre-filter
0.89
0.89
0.89
0.89
IVF
0.13
0.12
0.13
0.12
Post-filter
9.82
11.01
9.97
13.70
ACORN
9.82
11.01
9.96
13.69
Grant
6.66
7.85
6.81
10.53
0.65
0.7
0.75
0.8
0.85
0.9
0.95
1
100
101
102
103
104
Recall@10 (Deep)
QPS
(a) Deep
0.65
0.7
0.75
0.8
0.85
0.9
0.95
1
100
101
102
103
104
Recall@10 (SIFT)
QPS
(b) SIFT
0.6
0.65
0.7
0.75
0.8
0.85
0.9
0.95
1
100
101
102
103
104
Recall@10 (SPACEV)
QPS
(c) SPACEV
0.55 0.6 0.65 0.7 0.75 0.8 0.85 0.9 0.95
1
100
101
102
103
104
Recall@10 (T2I)
QPS
(d) T2I
Figure 4: QPS vs. recall@10. “⋄” shows BF, “△” shows Pre-filter, “□” shows IVF, “×” shows Post-filter, “◦” shows ACORN,
“∗” shows Grant-basic, and “+” shows Grant-pnv.
Table 4: Decomposed time [microsec] (recall ≈0.9). RS represents Range-Search in Algorithm 2, whereas Grant-basic and
Grant-pnv show the running time in lines 3–6 of Algorithm 2.
Dataset
Deep
SIFT
SPACEV
T2I
RS
0.60
0.50
0.87
0.88
Grant-basic
949.06
1041.10
3839.24
2718.39
Grant-pnv
700.15
667.52
2486.83
2137.70
Our algorithms generally have better time-recall tradeoffs than the existing state-of-the-art ones on the four datasets.
The exact algorithms (i.e., BF and Pre-filter) are slow. IVF, Post-filter, and ACORN improve the efficiency compared with
the exact algorithms. However, their search spaces are still large and suffer from many unnecessary object accesses. Thanks
to the Grant structure, our algorithms alleviate this issue, yielding superiority against the existing techniques. They obtain
high-recall results (e.g., 0.9) within a few milliseconds, which is also seen in Table 4 and is usually required in real-world
systems [57].
Decomposed time. To justify the motivation in Section 4.3, we show the decomposed time of our algorithms in Table 4.
Note that RS represents Range-Search in Algorithm 2. Grant-basic and Grant-pnv share the same RS. Table 4 confirms
that the practical bottleneck of our algorithms is not RS but graph-based ANNS. Figure 4 and Table 4 describe that Grant-
pnv relieves this bottleneck and is better than Grant-basic. Grant-pnv yields about 1.3–1.5x efficiency improvement against
Grant-basic. This result successfully demonstrates that the heuristic provides efficiency acceleration without recall drop.
QPS vs. recall of WA-Grant and SIEVE. Figure 5 compares WA-Grant and SIEVE under the same memory budget, and
we see that WA-Grant normally shows a better speed-accuracy tradeoff. For example, at recall@10 = 0.9, a reasonable
accuracy, WA-Grant is substantially better than SIEVE. This result demonstrates that our idea of limiting nodes for graph
10


## PDF page 11

0.7
0.75
0.8
0.85
0.9
0.95
1
101
102
103
104
Recall@10 (Deep)
QPS
(a) Deep
0.6
0.65
0.7
0.75
0.8
0.85
0.9
0.95
1
101
102
103
104
Recall@10 (SIFT)
QPS
(b) SIFT
0.65
0.7
0.75
0.8
0.85
0.9
0.95
1
101
102
103
104
Recall@10 (SPACEV)
QPS
(c) SPACEV
0.65
0.7
0.75
0.8
0.85
0.9
0.95
1
101
102
103
104
Recall@10 (T2I)
QPS
(d) T2I
Figure 5: QPS vs. recall@10. “▽” shows SIEVE and “∗” shows WA-Grant.
traversal based on past query vectors is effective. Note that the performance of WA-Grant is better than that of Grant-pnv
(more than 2 times faster at recall@10 = 0.9), confirming that Grant can be accelerated by using past query vectors. (This
observation can be seen by comparing the results in Figures 4 and 5.)
6
Conclusion
This paper addressed the problem of ANNS with multi-attribute range filters and proposed Grant, a new data structure
that solves this problem efficiently. Our theoretical analysis proves the efficiency of Grant. In addition, we proposed two
heuristics that optimized the query processing performance of Grant. Our experiments demonstrate that Grant outperforms
the existing state-of-the-art techniques.
Limitation. This work considers a static dataset, and how to efficiently deal with dynamic data (i.e., vector insertions and
deletions) is an open problem. In addition, this work assumes that 𝑚is small because real-world datasets have this tendency
(e.g., price, rating, and date), and it is highly unlikely that ranges are specified for many attributes. If this assumption does
not hold, the Grant structure may not be efficient because the tree structure is efficient only when 𝑚(or dimensionality) is
small (although, due to the curse of dimensionality, it is common to degrade the performance of a given algorithm for large
𝑚).
Acknowledgment. We thank Dr. Yusuke Matsui for his useful comments, which improved the presentation of this paper.
A
Additional Experiments
Impact of 𝑘. Figure 6 illustrates the result under recall ≈0.9. We omit Grant-basic because Grant-pnv is always better. The
QPS of Grant-pnv decreases as 𝑘increases. Nevertheless, it is much better than the existing algorithms. BF, Pre-filter, and
IVF are not affected by 𝑘because they access all objects in 𝑋, all objects in a result set of the range search, and all objects in
the corresponding posting lists, respectively. As 𝑘becomes larger, the QPS of Post-filter becomes very low (e.g., less than
40 for 𝑘= 50) because Post-filter needs to iterate more ANNS. ACORN failed to obtain nearly 0.9 recall (so it does not have
plots) when 𝑘≥20, because its graph traversal approach loses the path to reach the exact 𝑘NN objects.
Impact of 𝑚. We next study the impact of the number of attributes 𝑚. Figure 7 shows that our algorithm keeps outper-
forming the other ones. Recall the time complexity of our algorithm, and its empirical performance follows the theoretical
result. We see that Post-filter and Pre-filter have the opposite tendency. Post-filter is very sensitive to 𝑚, whereas Pre-filter
improves its efficiency with a larger 𝑚. This is because a larger 𝑚usually yields a smaller range search result set. ACORN
again failed to obtain nearly 0.9 recall when 𝑚≥3. These results demonstrate that ACORN is not appropriate for our
problem.
Impact of range size. To investigate the impact of range size (i.e., |𝑋(𝐹)|), we ran experiments by varying 𝜆. Figure 8
exhibits the robustness of our algorithm against range size. This robustness is attributed to their unnecessary leaf node
skipping heuristics. A larger range size provides a larger 𝑋(𝐹), so the performance of Pre-filter (Post-filter) becomes lower
(higher) as 𝜆becomes larger. The performance of Post-filter did not reach that of our algorithm even when 𝜆is large.
11


## PDF page 12

10
20
30
40
50
100
101
102
103
104
k (Deep)
QPS
(a) Deep
10
20
30
40
50
100
101
102
103
104
k (SIFT)
QPS
(b) SIFT
10
20
30
40
50
100
101
102
103
k (SPACEV)
QPS
(c) SPACEV
10
20
30
40
50
100
101
102
103
k (T2I)
QPS
(d) T2I
Figure 6: Impact of 𝑘under recall ≈0.9. “⋄” shows BF, “△” shows Pre-filter, “□” shows IVF, “×” shows Post-filter, “◦” shows
ACORN, and “+” shows Grant-pnv.
2
3
4
100
101
102
103
104
#attributes (Deep)
QPS
(a) Deep
2
3
4
100
101
102
103
104
#attributes (SIFT)
QPS
(b) SIFT
2
3
4
100
101
102
103
#attributes (SPACEV)
QPS
(c) SPACEV
2
3
4
100
101
102
103
#attributes (T2I)
QPS
(d) T2I
Figure 7: Impact of the number of attributes under recall ≈0.9. “⋄” shows BF, “△” shows Pre-filter, “□” shows IVF, “×”
shows Post-filter, “◦” shows ACORN, and “+” shows Grant-pnv.
0.2
0.4
0.6
0.8
100
101
102
103
104
Range size (Deep)
QPS
(a) Deep
0.2
0.4
0.6
0.8
100
101
102
103
104
Range size (SIFT)
QPS
(b) SIFT
0.2
0.4
0.6
0.8
100
101
102
103
Range size (SPACEV)
QPS
(c) SPACEV
0.2
0.4
0.6
0.8
100
101
102
103
Range size (T2I)
QPS
(d) T2I
Figure 8: Impact of range size under recall ≈0.9. “⋄” shows BF, “△” shows Pre-filter, “□” shows IVF, “×” shows Post-filter,
“◦” shows ACORN, and “+” shows Grant-pnv.
References
[1] D. Amagata and T. Hara. Reverse maximum inner product search: How to efficiently find users who would like to buy
my item? In RecSys, pages 273–281, 2021.
[2] D. Amagata and T. Hara. Reverse maximum inner product search: Formulation, algorithms, and analysis. ACM
Transactions on the Web, 17(4):1–23, 2023.
[3] D. Amagata, M. Onizuka, and T. Hara. Fast and exact outlier detection in metric spaces: a proximity graph-based
approach. In SIGMOD, pages 36–48, 2021.
[4] D. Amagata, M. Onizuka, and T. Hara. Fast, exact, and parallel-friendly outlier detection algorithms with proximity
graph in metric spaces. The VLDB Journal, 31(4):797–821, 2022.
[5] D. Amagata, K. Aoyama, K. Kido, and S. Fujita. Approximate reverse k-ranks queries in high dimensions. In SSDBM,
pages 1–6, 2025.
12


## PDF page 13

[6] D. Amagata, K. Aoyama, K. Kido, and S. Fujita. How to mine potentially popular items? a reverse mips-based approach.
In SSDBM, pages 1–11, 2025.
[7] A. Andoni and P. Indyk. Nearest neighbors in high-dimensional spaces. In Handbook of Discrete and Computational
Geometry, pages 1135–1155. 2017.
[8] K. Aoyama, D. Amagata, S. Fujita, and T. Hara. Simpler is much faster: Fair and independent inner product search. In
SIGIR, pages 2379–2383, 2023.
[9] Y. Arai, D. Amagata, S. Fujita, and T. Hara. Lgtm: A fast and accurate knn search algorithm in high-dimensional spaces.
In DEXA, pages 220–231, 2021.
[10] I. Azizi, K. Echihabi, and T. Palpanas. Graph-based vector search: An experimental evaluation of the state-of-the-art.
Proceedings of the ACM on Management of Data, 3(1):1–31, 2025.
[11] A. Babenko and V. Lempitsky. Efficient indexing of billion-scale datasets of deep descriptors. In CVPR, pages 2055–2063,
2016.
[12] J. L. Bentley. Multidimensional binary search trees used for associative searching. Communications of the ACM, 18(9):
509–517, 1975.
[13] Y. Cai, J. Shi, Y. Chen, and W. Zheng. Navigating labels and vectors: A unified approach to filtered approximate nearest
neighbor search. Proceedings of the ACM on Management of Data, 2(6):1–27, 2024.
[14] Q. Chen, B. Zhao, H. Wang, M. Li, C. Liu, Z. Li, M. Yang, and J. Wang. Spann: Highly-efficient billion-scale approximate
nearest neighborhood search. NeurIPS, 34:5199–5212, 2021.
[15] J. Engels, B. Landrum, S. Yu, L. Dhulipala, and J. Shun. Approximate nearest neighbor search with window filters. In
ICML, 2024.
[16] C. Fu and D. Cai. Efannna: An extremely fast approximate nearest neighbor search algorithm based on knn graph.
arXiv preprint arXiv:1609.07228, 2016.
[17] C. Fu, C. Xiang, C. Wang, and D. Cai. Fast approximate nearest neighbor search with the navigating spreading-out
graph. Proceedings of the VLDB Endowment, 12(5):461–474, 2019.
[18] C. Fu, C. Wang, and D. Cai. High dimensional similarity search with satellite system graph: Efficiency, scalability, and
unindexed query compatibility. IEEE Transactions on Pattern Analysis and Machine Intelligence, 44(8):4139–4150, 2021.
[19] S. Gollapudi, N. Karia, V. Sivashankar, R. Krishnaswamy, N. Begwani, S. Raz, Y. Lin, Y. Zhang, N. Mahapatro, P. Srini-
vasan, et al. Filtered-DiskAnn: Graph algorithms for approximate nearest neighbor search with filters. In Web Con-
ference, pages 3406–3416, 2023.
[20] G. Gupta, J. Yi, B. Coleman, C. Luo, V. Lakshman, and A. Shrivastava. Caps: A practical partition index for filtered
similarity search. arXiv preprint arXiv:2308.15014, 2023.
[21] A. Guttman. R-trees: A dynamic index structure for spatial searching. In SIGMOD, pages 47–57, 1984.
[22] B. Harwood and T. Drummond. Fanng: Fast approximate nearest neighbour graphs. In CVPR, pages 5713–5722, 2016.
[23] K. Hirata, D. Amagata, S. Fujita, and T. Hara. Solving diversity-aware maximum inner product search efficiently and
effectively. In RecSys, pages 198–207, 2022.
[24] K. Hirata, D. Amagata, S. Fujita, and T. Hara. Categorical diversity-aware inner product search. IEEE Access, 11:
2586–2596, 2023.
[25] P. Indyk and H. Xu. Worst-case performance of popular approximate nearest neighbor search implementations: Guar-
antees and limitations. In NeurIPS, pages 66239–66256, 2023.
[26] M. Jiang, Z. Yang, F. Zhang, G. Hou, J. Shi, W. Zhou, F. Li, and S. Wang. Digra: A dynamic graph indexing for
approximate nearest neighbor search with range filter. Proceedings of the ACM on Management of Data, 3(3):1–26,
2025.
13


## PDF page 14

[27] K. Kido, D. Amagata, and T. Hara. Fast approximation algorithm for euclidean minimum spanning tree building in
high dimensions. In Pacific-Asia Conference on Knowledge Discovery and Data Mining, pages 432–443, 2025.
[28] W. Li, Y. Zhang, Y. Sun, W. Wang, M. Li, W. Zhang, and X. Lin. Approximate nearest neighbor search on high dimen-
sional data—experiments, analyses, and improvement. IEEE Transactions on Knowledge and Data Engineering, 32(8):
1475–1488, 2019.
[29] Z. Li, S. Huang, W. Ding, Y. Park, and J. Chen. Sieve: Effective filtered vector search with collection of indexes.
Proceedings of the VLDB Endowment, 18(11):4723–4736, 2025.
[30] A. Liang, P. Zhang, B. Yao, Z. Chen, Y. Song, and G. Cheng. Unify: Unified index for range filtered approximate nearest
neighbors search. Proceedings of the VLDB, 18(4):1118–1130, 2025.
[31] S. Lu and Y. Tao. Proximity graphs for similarity search: Fast construction, lower bounds, and euclidean separation.
Proceedings of the ACM on Management of Data, 2026.
[32] Y. Malkov, A. Ponomarenko, A. Logvinov, and V. Krylov. Approximate nearest neighbor algorithm based on navigable
small world graphs. Information Systems, 45:61–68, 2014.
[33] Y. A. Malkov and D. A. Yashunin. Efficient and robust approximate nearest neighbor search using hierarchical navigable
small world graphs. IEEE Transactions on Pattern Analysis and Machine Intelligence, 42(4):824–836, 2018.
[34] J. Mohoney, A. Pacaci, S. R. Chowdhury, A. Mousavi, I. F. Ilyas, U. F. Minhas, J. Pound, and T. Rekatsinas. High-
throughput vector similarity search in knowledge graphs. Proceedings of the ACM on Management of Data, 1(2):1–25,
2023.
[35] H. Nakama, D. Amagata, and T. Hara. Approximate top-k inner product join with a proximity graph. In IEEE Interna-
tional Conference on Big Data, pages 4468–4471, 2021.
[36] J. J. Pan, J. Wang, and G. Li. Survey of vector database management systems. The VLDB Journal, 33(5):1591–1615, 2024.
[37] L. Patel, P. Kraft, C. Guestrin, and M. Zaharia. Acorn: Performant and predicate-agnostic search over vector embed-
dings and structured data. Proceedings of the ACM on Management of Data, 2(3):1–27, 2024.
[38] Y. Peng, B. Choi, T. N. Chan, J. Yang, and J. Xu. Efficient approximate nearest neighbor search in multi-dimensional
databases. Proceedings of the ACM on Management of Data, 1(1):1–27, 2023.
[39] C. Petersen, J. G. Simonsen, and C. Lioma. Power law distributions in information retrieval. ACM Transactions on
Information Systems, 34(2):1–37, 2016.
[40] L. Prokhorenkova and A. Shekhovtsov. Graph-based nearest neighbor search: From practice to theory. In ICML, pages
7803–7813, 2020.
[41] G. Sehgal and S. Salihoğlu. Navix: A native vector index design for graph dbmss with robust predicate-agnostic search
performance. Proceedings of the VLDB Endowment, 18(11):4438–4450, 2025.
[42] H. V. Simhadri, M. Aumüller, A. Ingber, M. Douze, G. Williams, M. D. Manohar, D. Baranchuk, E. Liberty, F. Liu,
B. Landrum, et al. Results of the big ann: Neurips’23 competition. arXiv preprint arXiv:2409.17424, 2024.
[43] S. J. Subramanya, Devvrit, R. Kadekodi, R. Krishaswamy, and H. V. Simhadri. Diskann: Fast accurate billion-point
nearest neighbor search on a single node. In NeurIPS, pages 13766–13776, 2019.
[44] R. Uemura and D. Amagata. Ivf++: A flexible and efficient algorithm for approximate nearest neighbor search under
attribute constraint. In IEEE International Conference on Big Data, pages 7444–7451, 2025.
[45] R. Uemura, D. Amagata, and T. Hara. An efficient framework for approximate nearest neighbor search on high-
dimensional multi-metric data. In International Conference on Similarity Search and Applications, pages 3–17, 2024.
[46] J. Wang, X. Yi, R. Guo, H. Jin, P. Xu, S. Li, X. Wang, X. Guo, C. Li, X. Xu, et al. Milvus: A purpose-built vector data
management system. In SIGMOD, pages 2614–2627, 2021.
[47] M. Wang, X. Xu, Q. Yue, and Y. Wang. A comprehensive survey and experimental comparison of graph-based approx-
imate nearest neighbor search. Proceedings of the VLDB Endowment, 14(11):1964–1978, 2021.
14


## PDF page 15

[48] M. Wang, L. Lv, X. Xu, Y. Wang, Q. Yue, and J. Ni. An efficient and robust framework for approximate nearest neighbor
search with attribute constraint. In NeuIPS, pages 15738–15751, 2023.
[49] Z. Wang, J. Zhang, and W. Hu. Wow: A window-to-window incremental index for range-filtering approximate nearest
neighbor search. Proceedings of the ACM on Management of Data, 3(6):1–27, 2025.
[50] C. Wei, B. Wu, S. Wang, R. Lou, C. Zhan, F. Li, and Y. Cai. Analyticdb-v: A hybrid analytical engine towards query
fusion for structured and unstructured data. Proceedings of the VLDB Endowment, 13(12):3152–3165, 2020.
[51] W. Wu, J. He, Y. Qiao, G. Fu, L. Liu, and J. Yu. Hqann: Efficient and robust similarity search for hybrid queries with
structured and unstructured constraints. In CIKM, pages 4580–4584, 2022.
[52] J. Xie, J. X. Yu, S. Teng, and Y. Liu. Beyond vector search: Querying with and without predicates. Proceedings of the
ACM on Management of Data, 3(6):1–26, 2025.
[53] Y. Xu, J. Gao, Y. Gou, C. Long, and C. S. Jensen. irangegraph: Improvising range-dedicated graphs for range-filtering
nearest neighbor search. 2(6):1–26, 2024.
[54] T. Yamashita, D. Amagata, and Y. Matsui. How should we evaluate data deletion in graph-based ann indexes? arXiv
preprint arXiv:2512.06200, 2025.
[55] C. Ye, X. Yan, and E. Lo.
Compass: General filtered search across vector and structured data.
arXiv preprint
arXiv:2510.27141, 2025.
[56] C. Zhang, J. Wang, W.-L. Zhao, and S. Xiao. Highly efficient disk-based nearest neighbor search on extended neigh-
borhood graph. In SIGIR, pages 2513–2523, 2025.
[57] Q. Zhang, S. Xu, Q. Chen, G. Sui, J. Xie, Z. Cai, Y. Chen, Y. He, Y. Yang, F. Yang, et al. VBASE: Unifying online vector
similarity search and relational queries via relaxed monotonicity. In OSDI, pages 377–395, 2023.
[58] C. Zuo, M. Qiao, W. Zhou, F. Li, and D. Deng. Serf: Segment graph for range-filtering approximate nearest neighbor
search. Proceedings of the ACM on Management of Data, 2(1):1–26, 2024.
15



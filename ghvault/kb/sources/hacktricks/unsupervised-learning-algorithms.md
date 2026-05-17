---
parsed_by: focuslocust
source: hacktricks
type: generated
---
# Unsupervised Learning Algorithms

[Home](../../../README.md)

## Provenance

| Field | Value |
| --- | --- |
| Source | `hacktricks` |
| Type | `hacktricks-topic` |
| Record ID | `hacktricks-ai-ai-unsupervised-learning-algorithms` |
| Source file | `/home/adams/scorchederf/focuslocust/.cache/hacktricks/src/AI/AI-Unsupervised-Learning-Algorithms.md` |
| Parsed by | `focuslocust` |
| Relationship mode | `explicit / conservative inferred / manual` |

## Generated Concept Page

- [Unsupervised Learning Algorithms](../../topics/ai/unsupervised-learning-algorithms.md)

## Extracted Fields

| Field | Value |
| --- | --- |
| id | hacktricks-ai-ai-unsupervised-learning-algorithms |
| name | Unsupervised Learning Algorithms |
| type | hacktricks-topic |
| source | hacktricks |
| url | https://github.com/HackTricks-wiki/hacktricks/blob/master/src/AI/AI-Unsupervised-Learning-Algorithms.md |

## Preserved Source Material

````yaml
_body: "# Unsupervised Learning Algorithms\n\n{{#include ../banners/hacktricks-training.md}}\n\n## Unsupervised Learning\n\
  \nUnsupervised learning is a type of machine learning where the model is trained on data without labeled responses. The\
  \ goal is to find patterns, structures, or relationships within the data. Unlike supervised learning, where the model learns\
  \ from labeled examples, unsupervised learning algorithms work with unlabeled data.\nUnsupervised learning is often used\
  \ for tasks such as clustering, dimensionality reduction, and anomaly detection. It can help discover hidden patterns in\
  \ data, group similar items together, or reduce the complexity of the data while preserving its essential features.\n\n\n\
  ### K-Means Clustering\n\nK-Means is a centroid-based clustering algorithm that partitions data into K clusters by assigning\
  \ each point to the nearest cluster mean. The algorithm works as follows:\n1. **Initialization**: Choose K initial cluster\
  \ centers (centroids), often randomly or via smarter methods like k-means++\n2. **Assignment**: Assign each data point to\
  \ the nearest centroid based on a distance metric (e.g., Euclidean distance).\n3. **Update**: Recalculate the centroids\
  \ by taking the mean of all data points assigned to each cluster.\n4. **Repeat**: Steps 2–3 are repeated until cluster assignments\
  \ stabilize (centroids no longer move significantly).\n\n> [!TIP]\n> *Use cases in cybersecurity:* K-Means is used for intrusion\
  \ detection by clustering network events. For example, researchers applied K-Means to the KDD Cup 99 intrusion dataset and\
  \ found it effectively partitioned traffic into normal vs. attack clusters. In practice, security analysts might cluster\
  \ log entries or user behavior data to find groups of similar activity; any points that don’t belong to a well-formed cluster\
  \ might indicate anomalies (e.g. a new malware variant forming its own small cluster). K-Means can also help malware family\
  \ classification by grouping binaries based on behavior profiles or feature vectors.\n\n#### Selection of K\nThe number\
  \ of clusters (K) is a hyperparameter that needs to be defined before running the algorithm. Techniques like the Elbow Method\
  \ or Silhouette Score can help determine an appropriate value for K by evaluating the clustering performance:\n\n- **Elbow\
  \ Method**: Plot the sum of squared distances from each point to its assigned cluster centroid as a function of K. Look\
  \ for an \"elbow\" point where the rate of decrease sharply changes, indicating a suitable number of clusters.\n- **Silhouette\
  \ Score**: Calculate the silhouette score for different values of K. A higher silhouette score indicates better-defined\
  \ clusters.\n\n#### Assumptions and Limitations\n\nK-Means assumes that **clusters are spherical and equally sized**, which\
  \ may not hold true for all datasets. It is sensitive to the initial placement of centroids and can converge to local minima.\
  \ Additionally, K-Means is not suitable for datasets with varying densities or non-globular shapes and features with different\
  \ scales. Preprocessing steps like normalization or standardization may be necessary to ensure that all features contribute\
  \ equally to the distance calculations.\n\n<details>\n<summary>Example -- Clustering Network Events\n</summary>\nBelow we\
  \ simulate network traffic data and use K-Means to cluster it. Suppose we have events with features like connection duration\
  \ and byte count. We create 3 clusters of “normal” traffic and 1 small cluster representing an attack pattern. Then we run\
  \ K-Means to see if it separates them.\n\n```python\nimport numpy as np\nfrom sklearn.cluster import KMeans\n\n# Simulate\
  \ synthetic network traffic data (e.g., [duration, bytes]).\n# Three normal clusters and one small attack cluster.\nrng\
  \ = np.random.RandomState(42)\nnormal1 = rng.normal(loc=[50, 500], scale=[10, 100], size=(500, 2))   # Cluster 1\nnormal2\
  \ = rng.normal(loc=[60, 1500], scale=[8, 200], size=(500, 2))   # Cluster 2\nnormal3 = rng.normal(loc=[70, 3000], scale=[5,\
  \ 300], size=(500, 2))   # Cluster 3\nattack = rng.normal(loc=[200, 800], scale=[5, 50], size=(50, 2))      # Small attack\
  \ cluster\n\nX = np.vstack([normal1, normal2, normal3, attack])\n# Run K-Means clustering into 4 clusters (we expect it\
  \ to find the 4 groups)\nkmeans = KMeans(n_clusters=4, random_state=0, n_init=10)\nlabels = kmeans.fit_predict(X)\n\n# Analyze\
  \ resulting clusters\nclusters, counts = np.unique(labels, return_counts=True)\nprint(f\"Cluster labels: {clusters}\")\n\
  print(f\"Cluster sizes: {counts}\")\nprint(\"Cluster centers (duration, bytes):\")\nfor idx, center in enumerate(kmeans.cluster_centers_):\n\
  \    print(f\"  Cluster {idx}: {center}\")\n```\n\nIn this example, K-Means should find 4 clusters. The small attack cluster\
  \ (with unusually high duration ~200) will ideally form its own cluster given its distance from normal clusters. We print\
  \ the cluster sizes and centers to interpret the results. In a real scenario, one could label the cluster with few points\
  \ as potential anomalies or inspect its members for malicious activity.\n</details>\n\n### Hierarchical Clustering\n\nHierarchical\
  \ clustering builds a hierarchy of clusters using either a bottom-up (agglomerative) approach or a top-down (divisive) approach:\n\
  \n1. **Agglomerative (Bottom-Up)**: Start with each data point as a separate cluster and iteratively merge the closest clusters\
  \ until a single cluster remains or a stopping criterion is met.\n2. **Divisive (Top-Down)**: Start with all data points\
  \ in a single cluster and iteratively split the clusters until each data point is its own cluster or a stopping criterion\
  \ is met.\n\nAgglomerative clustering requires a definition of inter-cluster distance and a linkage criterion to decide\
  \ which clusters to merge. Common linkage methods include single linkage (distance of closest points between two clusters),\
  \ complete linkage (distance of farthest points), average linkage, etc., and the distance metric is often Euclidean. The\
  \ choice of linkage affects the shape of clusters produced. There is no need to pre-specify the number of clusters K; you\
  \ can “cut” the dendrogram at a chosen level to get the desired number of clusters.\n\nHierarchical clustering produces\
  \ a dendrogram, a tree-like structure that shows the relationships between clusters at different levels of granularity.\
  \ The dendrogram can be cut at a desired level to obtain a specific number of clusters.\n\n> [!TIP]\n> *Use cases in cybersecurity:*\
  \ Hierarchical clustering can organize events or entities into a tree to spot relationships. For example, in malware analysis,\
  \ agglomerative clustering could group samples by behavioral similarity, revealing a hierarchy of malware families and variants.\
  \ In network security, one might cluster IP traffic flows and use the dendrogram to see subgroupings of traffic (e.g., by\
  \ protocol, then by behavior). Because you don’t need to choose K upfront, it’s useful when exploring new data for which\
  \ the number of attack categories is unknown.\n\n#### Assumptions and Limitations\n\nHierarchical clustering does not assume\
  \ a particular cluster shape and can capture nested clusters. It’s useful for discovering taxonomy or relations among groups\
  \ (e.g., grouping malware by family subgroups). It’s deterministic (no random initialization issues). A key advantage is\
  \ the dendrogram, which provides insight into the data’s clustering structure at all scales – security analysts can decide\
  \ an appropriate cutoff to identify meaningful clusters. However, it is computationally expensive (typically $O(n^2)$ time\
  \ or worse for naive implementations) and not feasible for very large datasets. It’s also a greedy procedure – once a merge\
  \ or split is done, it can’t be undone, which may lead to suboptimal clusters if a mistake happens early. Outliers can also\
  \ affect some linkage strategies (single-link can cause the “chaining” effect where clusters link via outliers).\n\n<details>\n\
  <summary>Example -- Agglomerative Clustering of Events\n</summary>\n\nWe’ll reuse the synthetic data from the K-Means example\
  \ (3 normal clusters + 1 attack cluster) and apply agglomerative clustering. We then illustrate how to obtain a dendrogram\
  \ and cluster labels.\n\n```python\nfrom sklearn.cluster import AgglomerativeClustering\nfrom scipy.cluster.hierarchy import\
  \ linkage, dendrogram\n\n# Perform agglomerative clustering (bottom-up) on the data\nagg = AgglomerativeClustering(n_clusters=None,\
  \ distance_threshold=0, linkage='ward')\n# distance_threshold=0 gives the full tree without cutting (we can cut manually)\n\
  agg.fit(X)\n\nprint(f\"Number of merge steps: {agg.n_clusters_ - 1}\")  # should equal number of points - 1\n# Create a\
  \ dendrogram using SciPy for visualization (optional)\nZ = linkage(X, method='ward')\n# Normally, you would plot the dendrogram.\
  \ Here we'll just compute cluster labels for a chosen cut:\nclusters_3 = AgglomerativeClustering(n_clusters=3, linkage='ward').fit_predict(X)\n\
  print(f\"Labels with 3 clusters: {np.unique(clusters_3)}\")\nprint(f\"Cluster sizes for 3 clusters: {np.bincount(clusters_3)}\"\
  )\n```\n</details>\n\n### DBSCAN (Density-Based Spatial Clustering of Applications with Noise)\n\nDBSCAN is a density-based\
  \ clustering algorithm that groups together points that are closely packed together while marking points in low-density\
  \ regions as outliers. It is particularly useful for datasets with varying densities and non-spherical shapes.\n\nDBSCAN\
  \ works by defining two parameters:\n- **Epsilon (ε)**: The maximum distance between two points to be considered part of\
  \ the same cluster.\n- **MinPts**: The minimum number of points required to form a dense region (core point).\n\nDBSCAN\
  \ identifies core points, border points, and noise points:\n- **Core Point**: A point with at least MinPts neighbors within\
  \ ε distance.\n- **Border Point**: A point that is within ε distance of a core point but has fewer than MinPts neighbors.\n\
  - **Noise Point**: A point that is neither a core point nor a border point.\n\nClustering proceeds by picking an unvisited\
  \ core point, marking it as a new cluster, then recursively adding all points density-reachable from it (core points and\
  \ their neighbors, etc.). Border points get added to the cluster of a nearby core. After expanding all reachable points,\
  \ DBSCAN moves to another unvisited core to start a new cluster. Points not reached by any core remain labeled as noise.\n\
  \n> [!TIP]\n> *Use cases in cybersecurity:* DBSCAN is useful for anomaly detection in network traffic. For instance, normal\
  \ user activity might form one or more dense clusters in feature space, while novel attack behaviors appear as scattered\
  \ points that DBSCAN will label as noise (outliers). It has been used to cluster network flow records, where it can detect\
  \ port scans or denial-of-service traffic as sparse regions of points. Another application is grouping malware variants:\
  \ if most samples cluster by families but a few don’t fit anywhere, those few could be zero-day malware. The ability to\
  \ flag noise means security teams can focus on investigating those outliers.\n\n#### Assumptions and Limitations\n\n**Assumptions\
  \ & Strengths:**: DBSCAN does not assume spherical clusters – it can find arbitrarily shaped clusters (even chain-like or\
  \ adjacent clusters). It automatically determines the number of clusters based on data density and can effectively identify\
  \ outliers as noise. This makes it powerful for real-world data with irregular shapes and noise. It’s robust to outliers\
  \ (unlike K-Means, which forces them into clusters). It works well when clusters have roughly uniform density.\n\n**Limitations**:\
  \ DBSCAN’s performance depends on choosing appropriate ε and MinPts values. It may struggle with data that has varying densities\
  \ – a single ε cannot accommodate both dense and sparse clusters. If ε is too small, it labels most points as noise; too\
  \ large, and clusters may merge incorrectly. Also, DBSCAN can be inefficient on very large datasets (naively $O(n^2)$, though\
  \ spatial indexing can help). In high-dimensional feature spaces, the concept of “distance within ε” may become less meaningful\
  \ (the curse of dimensionality), and DBSCAN may need careful parameter tuning or may fail to find intuitive clusters. Despite\
  \ these, extensions like HDBSCAN address some issues (like varying density).\n\n<details>\n<summary>Example -- Clustering\
  \ with Noise\n</summary>\n\n```python\nfrom sklearn.cluster import DBSCAN\n\n# Generate synthetic data: 2 normal clusters\
  \ and 5 outlier points\ncluster1 = rng.normal(loc=[100, 1000], scale=[5, 100], size=(100, 2))\ncluster2 = rng.normal(loc=[120,\
  \ 2000], scale=[5, 100], size=(100, 2))\noutliers = rng.uniform(low=[50, 50], high=[180, 3000], size=(5, 2))  # scattered\
  \ anomalies\ndata = np.vstack([cluster1, cluster2, outliers])\n\n# Run DBSCAN with chosen eps and MinPts\neps = 15.0   #\
  \ radius for neighborhood\nmin_pts = 5  # minimum neighbors to form a dense region\ndb = DBSCAN(eps=eps, min_samples=min_pts).fit(data)\n\
  labels = db.labels_  # cluster labels (-1 for noise)\n\n# Analyze clusters and noise\nnum_clusters = len(set(labels) - {-1})\n\
  num_noise = np.sum(labels == -1)\nprint(f\"DBSCAN found {num_clusters} clusters and {num_noise} noise points\")\nprint(\"\
  Cluster labels for first 10 points:\", labels[:10])\n```\n\nIn this snippet, we tuned `eps` and `min_samples` to suit our\
  \ data scale (15.0 in feature units, and requiring 5 points to form a cluster). DBSCAN should find 2 clusters (the normal\
  \ traffic clusters) and flag the 5 injected outliers as noise. We output the number of clusters vs. noise points to verify\
  \ this. In a real setting, one might iterate over ε (using a k-distance graph heuristic to choose ε) and MinPts (often set\
  \ to around the data dimensionality + 1 as a rule of thumb) to find stable clustering results. The ability to explicitly\
  \ label noise helps separate potential attack data for further analysis.\n\n</details>\n\n### Principal Component Analysis\
  \ (PCA)\n\nPCA is a technique for **dimensionality reduction** that finds a new set of orthogonal axes (principal components)\
  \ which capture the maximum variance in the data. In simple terms, PCA rotates and projects the data onto a new coordinate\
  \ system such that the first principal component (PC1) explains the largest possible variance, the second PC (PC2) explains\
  \ the largest variance orthogonal to PC1, and so on. Mathematically, PCA computes the eigenvectors of the data’s covariance\
  \ matrix – these eigenvectors are the principal component directions, and the corresponding eigenvalues indicate the amount\
  \ of variance explained by each. It is often used for feature extraction, visualization, and noise reduction.\n\nNote that\
  \ this is useful if the dataset dimensions contains **significant linear dependencies or correlations**.\n\nPCA works by\
  \ identifying the principal components of the data, which are the directions of maximum variance. The steps involved in\
  \ PCA are:\n1. **Standardization**: Center the data by subtracting the mean and scaling it to unit variance.\n2. **Covariance\
  \ Matrix**: Compute the covariance matrix of the standardized data to understand the relationships between features.\n3.\
  \ **Eigenvalue Decomposition**: Perform eigenvalue decomposition on the covariance matrix to obtain the eigenvalues and\
  \ eigenvectors.\n4. **Select Principal Components**: Sort the eigenvalues in descending order and select the top K eigenvectors\
  \ corresponding to the largest eigenvalues. These eigenvectors form the new feature space.\n5. **Transform Data**: Project\
  \ the original data onto the new feature space using the selected principal components.\nPCA is widely used for data visualization,\
  \ noise reduction, and as a preprocessing step for other machine learning algorithms. It helps reduce the dimensionality\
  \ of the data while retaining its essential structure.\n\n#### Eigenvalues and Eigenvectors\n\nAn eigenvalue is a scalar\
  \ that indicates the amount of variance captured by its corresponding eigenvector. An eigenvector represents a direction\
  \ in the feature space along which the data varies the most.\n\nImagine A is a square matrix, and v is a non-zero vector\
  \ such that: `A * v = λ * v`\nwhere:\n- A is a square matrix like [ [1, 2], [2, 1]] (e.g., covariance matrix)\n- v is an\
  \ eigenvector (e.g., [1, 1])\n\nThen, `A * v = [ [1, 2], [2, 1]] * [1, 1] = [3, 3]` which will be the eigenvalue λ multiplied\
  \ by the eigenvector v, making the eigenvalue λ = 3.\n\n#### Eigenvalues and Eigenvectors in PCA\n\nLet's explain this with\
  \ an example. Imagine you have a dataset with a lot of grey scale pictures of faces of 100x100 pixels. Each pixel can be\
  \ considered a feature, so you have 10,000 features per image (or a vector of 10000 components per image). If you want to\
  \ reduce the dimensionality of this dataset using PCA, you would follow these steps:\n\n1. **Standardization**: Center the\
  \ data by subtracting the mean of each feature (pixel) from the dataset.\n2. **Covariance Matrix**: Compute the covariance\
  \ matrix of the standardized data, which captures how features (pixels) vary together.\n  - Note that the covariance between\
  \ two variables (pixels in this case) indicates how much they change together so the idea here is to find out which pixels\
  \ tend to increase or decrease together with a linear relationship.\n  - For example, if pixel 1 and pixel 2 tend to increase\
  \ together, the covariance between them will be positive.\n  - The covariance matrix will be a 10,000x10,000 matrix where\
  \ each entry represents the covariance between two pixels.\n3. **Solve the The eigenvalue equation**: The eigenvalue equation\
  \ to solve is `C * v = λ * v` where C is the covariance matrix, v is the eigenvector, and λ is the eigenvalue. It can be\
  \ solved using methods like:\n  - **Eigenvalue Decomposition**: Perform eigenvalue decomposition on the covariance matrix\
  \ to obtain the eigenvalues and eigenvectors.\n  - **Singular Value Decomposition (SVD)**: Alternatively, you can use SVD\
  \ to decompose the data matrix into singular values and vectors, which can also yield the principal components.\n4. **Select\
  \ Principal Components**: Sort the eigenvalues in descending order and select the top K eigenvectors corresponding to the\
  \ largest eigenvalues. These eigenvectors represent the directions of maximum variance in the data.\n\n> [!TIP]\n> *Use\
  \ cases in cybersecurity:* A common use of PCA in security is feature reduction for anomaly detection. For instance, an\
  \ intrusion detection system with 40+ network metrics (like NSL-KDD features) can use PCA to reduce to a handful of components,\
  \ summarizing the data for visualization or feeding into clustering algorithms. Analysts might plot network traffic in the\
  \ space of the first two principal components to see if attacks separate from normal traffic. PCA can also help eliminate\
  \ redundant features (like bytes sent vs. bytes received if they are correlated) to make detection algorithms more robust\
  \ and faster.\n\n#### Assumptions and Limitations\n\nPCA assumes that **principal axes of variance are meaningful** – it’s\
  \ a linear method, so it captures linear correlations in data. It’s unsupervised since it uses only the feature covariance.\
  \ Advantages of PCA include noise reduction (small-variance components often correspond to noise) and decorrelation of features.\
  \ It is computationally efficient for moderately high dimensions and often a useful preprocessing step for other algorithms\
  \ (to mitigate curse of dimensionality). One limitation is that PCA is limited to linear relationships – it won’t capture\
  \ complex nonlinear structure (whereas autoencoders or t-SNE might). Also, PCA components can be hard to interpret in terms\
  \ of original features (they are combinations of original features). In cybersecurity, one must be cautious: an attack that\
  \ only causes a subtle change in a low-variance feature might not show up in top PCs (since PCA prioritizes variance, not\
  \ necessarily “interestingness”).\n\n<details>\n<summary>Example -- Reducing Dimensions of Network Data\n</summary>\n\n\
  Suppose we have network connection logs with multiple features (e.g., durations, bytes, counts). We will generate a synthetic\
  \ 4-dimensional dataset (with some correlation between features) and use PCA to reduce it to 2 dimensions for visualization\
  \ or further analysis.\n\n```python\nfrom sklearn.decomposition import PCA\n\n# Create synthetic 4D data (3 clusters similar\
  \ to before, but add correlated features)\n# Base features: duration, bytes (as before)\nbase_data = np.vstack([normal1,\
  \ normal2, normal3])  # 1500 points from earlier normal clusters\n# Add two more features correlated with existing ones,\
  \ e.g. packets = bytes/50 + noise, errors = duration/10 + noise\npackets = base_data[:, 1] / 50 + rng.normal(scale=0.5,\
  \ size=len(base_data))\nerrors = base_data[:, 0] / 10 + rng.normal(scale=0.5, size=len(base_data))\ndata_4d = np.column_stack([base_data[:,\
  \ 0], base_data[:, 1], packets, errors])\n\n# Apply PCA to reduce 4D data to 2D\npca = PCA(n_components=2)\ndata_2d = pca.fit_transform(data_4d)\n\
  print(\"Explained variance ratio of 2 components:\", pca.explained_variance_ratio_)\nprint(\"Original shape:\", data_4d.shape,\
  \ \"Reduced shape:\", data_2d.shape)\n# We can examine a few transformed points\nprint(\"First 5 data points in PCA space:\\\
  n\", data_2d[:5])\n```\n\nHere we took the earlier normal traffic clusters and extended each data point with two additional\
  \ features (packets and errors) that correlate with bytes and duration. PCA is then used to compress the 4 features into\
  \ 2 principal components. We print the explained variance ratio, which might show that, say, >95% of variance is captured\
  \ by 2 components (meaning little information loss). The output also shows the data shape reducing from (1500, 4) to (1500,\
  \ 2). The first few points in PCA space are given as an example. In practice, one could plot data_2d to visually check if\
  \ the clusters are distinguishable. If an anomaly was present, one might see it as a point lying away from the main cluster\
  \ in PCA-space. PCA thus helps distill complex data into a manageable form for human interpretation or as input to other\
  \ algorithms.\n\n</details>\n\n\n### Gaussian Mixture Models (GMM)\n\nA Gaussian Mixture Model assumes data is generated\
  \ from a mixture of **several Gaussian (normal) distributions with unknown parameters**. In essence, it is a probabilistic\
  \ clustering model: it tries to softly assign each point to one of K Gaussian components. Each Gaussian component k has\
  \ a mean vector (μ_k), covariance matrix (Σ_k), and a mixing weight (π_k) that represents how prevalent that cluster is.\
  \ Unlike K-Means which does “hard” assignments, GMM gives each point a probability of belonging to each cluster.\n\nGMM\
  \ fitting is typically done via the Expectation-Maximization (EM) algorithm:\n\n- **Initialization**: Start with initial\
  \ guesses for the means, covariances, and mixing coefficients (or use K-Means results as a starting point).\n\n- **E-step\
  \ (Expectation)**: Given current parameters, compute the responsibility of each cluster for each point: essentially `r_nk\
  \ = P(z_k | x_n)` where z_k is the latent variable indicating cluster membership for point x_n. This is done using Bayes'\
  \ theorem, where we compute the posterior probability of each point belonging to each cluster based on the current parameters.\
  \ The responsibilities are computed as:\n  ```math\n  r_{nk} = \\frac{\\pi_k \\mathcal{N}(x_n | \\mu_k, \\Sigma_k)}{\\sum_{j=1}^{K}\
  \ \\pi_j \\mathcal{N}(x_n | \\mu_j, \\Sigma_j)}\n  ```\n  where:\n  - \\( \\pi_k \\) is the mixing coefficient for cluster\
  \ k (prior probability of cluster k),\n  - \\( \\mathcal{N}(x_n | \\mu_k, \\Sigma_k) \\) is the Gaussian probability density\
  \ function for point \\( x_n \\) given mean \\( \\mu_k \\) and covariance \\( \\Sigma_k \\).\n\n- **M-step (Maximization)**:\
  \ Update the parameters using the responsibilities computed in the E-step:\n  - Update each mean μ_k as the weighted average\
  \ of points, where weights are the responsibilities.\n  - Update each covariance Σ_k as the weighted covariance of points\
  \ assigned to cluster k.\n  - Update mixing coefficients π_k as the average responsibility for cluster k.\n\n- **Iterate**\
  \ E and M steps until convergence (parameters stabilize or likelihood improvement is below a threshold).\n\nThe result is\
  \ a set of Gaussian distributions that collectively model the overall data distribution. We can use the fitted GMM to cluster\
  \ by assigning each point to the Gaussian with highest probability, or keep the probabilities for uncertainty. One can also\
  \ evaluate the likelihood of new points to see if they fit the model (useful for anomaly detection).\n\n> [!TIP]\n> *Use\
  \ cases in cybersecurity:* GMM can be used for anomaly detection by modeling the distribution of normal data: any point\
  \ with very low probability under the learned mixture is flagged as anomaly. For example, you could train a GMM on legitimate\
  \ network traffic features; an attack connection that doesn’t resemble any learned cluster would have a low likelihood.\
  \ GMMs are also used to cluster activities where clusters might have different shapes – e.g., grouping users by behavior\
  \ profiles, where each profile’s features might be Gaussian-like but with its own variance structure. Another scenario:\
  \ in phishing detection, legitimate email features might form one Gaussian cluster, known phishing another, and new phishing\
  \ campaigns might show up as either a separate Gaussian or as low likelihood points relative to the existing mixture.\n\n\
  #### Assumptions and Limitations\n\nGMM is a generalization of K-Means that incorporates covariance, so clusters can be\
  \ ellipsoidal (not just spherical). It handles clusters of different sizes and shapes if covariance is full. Soft clustering\
  \ is an advantage when cluster boundaries are fuzzy – e.g., in cybersecurity, an event might have traits of multiple attack\
  \ types; GMM can reflect that uncertainty with probabilities. GMM also provides a probabilistic density estimation of the\
  \ data, useful for detecting outliers (points with low likelihood under all mixture components).\n\nOn the downside, GMM\
  \ requires specifying the number of components K (though one can use criteria like BIC/AIC to select it). EM can sometimes\
  \ converge slowly or to a local optimum, so initialization is important (often run EM multiple times). If the data doesn’t\
  \ actually follow a mixture of Gaussians, the model may be a poor fit. There’s also a risk of one Gaussian shrinking to\
  \ cover just an outlier (though regularization or minimum covariance bounds can mitigate that).\n\n\n<details>\n<summary>Example\
  \ --  Soft Clustering & Anomaly Scores\n</summary>\n\n```python\nfrom sklearn.mixture import GaussianMixture\n\n# Fit a\
  \ GMM with 3 components to the normal traffic data\ngmm = GaussianMixture(n_components=3, covariance_type='full', random_state=0)\n\
  gmm.fit(base_data)  # using the 1500 normal data points from PCA example\n\n# Print the learned Gaussian parameters\nprint(\"\
  GMM means:\\n\", gmm.means_)\nprint(\"GMM covariance matrices:\\n\", gmm.covariances_)\n\n# Take a sample attack-like point\
  \ and evaluate it\nsample_attack = np.array([[200, 800]])  # an outlier similar to earlier attack cluster\nprobs = gmm.predict_proba(sample_attack)\n\
  log_likelihood = gmm.score_samples(sample_attack)\nprint(\"Cluster membership probabilities for sample attack:\", probs)\n\
  print(\"Log-likelihood of sample attack under GMM:\", log_likelihood)\n```\n\nIn this code, we train a GMM with 3 Gaussians\
  \ on the normal traffic (assuming we know 3 profiles of legitimate traffic). The means and covariances printed describe\
  \ these clusters (for instance, one mean might be around [50,500] corresponding to one cluster’s center, etc.). We then\
  \ test a suspicious connection [duration=200, bytes=800]. The predict_proba gives the probability of this point belonging\
  \ to each of the 3 clusters – we’d expect these probabilities to be very low or highly skewed since [200,800] lies far from\
  \ the normal clusters. The overall score_samples (log-likelihood) is printed; a very low value indicates the point doesn’t\
  \ fit the model well, flagging it as an anomaly. In practice, one could set a threshold on the log-likelihood (or on the\
  \ max probability) to decide if a point is sufficiently unlikely to be considered malicious. GMM thus provides a principled\
  \ way to do anomaly detection and also yields soft clusters that acknowledge uncertainty.\n</details>\n\n### Isolation Forest\n\
  \n**Isolation Forest** is an ensemble anomaly detection algorithm based on the idea of randomly isolating points. The principle\
  \ is that anomalies are few and different, so they are easier to isolate than normal points. An Isolation Forest builds\
  \ many binary isolation trees (random decision trees) that partition the data randomly. At each node in a tree, a random\
  \ feature is selected and a random split value is chosen between the min and max of that feature for the data in that node.\
  \ This split divides the data into two branches. The tree is grown until each point is isolated in its own leaf or a max\
  \ tree height is reached.\n\nAnomaly detection is performed by observing the path length of each point in these random trees\
  \ – the number of splits required to isolate the point. Intuitively, anomalies (outliers) tend to be isolated quicker because\
  \ a random split is more likely to separate an outlier (which lies in a sparse region) than it would a normal point in a\
  \ dense cluster. The Isolation Forest computes an anomaly score from the average path length over all trees: shorter average\
  \ path → more anomalous. Scores are usually normalized to [0,1] where 1 means very likely anomaly.\n\n> [!TIP]\n> *Use cases\
  \ in cybersecurity:* Isolation Forests have been successfully used in intrusion detection and fraud detection. For example,\
  \ train an Isolation Forest on network traffic logs mostly containing normal behavior; the forest will produce short paths\
  \ for odd traffic (like an IP that uses an unheard-of port or an unusual packet size pattern), flagging it for inspection.\
  \ Because it doesn’t require labeled attacks, it’s suitable for detecting unknown attack types. It can also be deployed\
  \ on user login data to detect account takeovers (the anomalous login times or locations get isolated quickly). In one use-case,\
  \ an Isolation Forest might protect an enterprise by monitoring system metrics and generating an alert when a combination\
  \ of metrics (CPU, network, file changes) looks very different (short isolation paths) from historical patterns.\n\n####\
  \ Assumptions and Limitations\n\n**Advantages**: Isolation Forest doesn’t require a distribution assumption; it directly\
  \ targets isolation. It’s efficient on high-dimensional data and large datasets (linear complexity $O(n\\log n)$ for building\
  \ the forest) since each tree isolates points with only a subset of features and splits. It tends to handle numerical features\
  \ well and can be faster than distance-based methods which might be $O(n^2)$. It also automatically gives an anomaly score,\
  \ so you can set a threshold for alerts (or use a contamination parameter to automatically decide a cutoff based on an expected\
  \ anomaly fraction). \n\n**Limitations**: Because of its random nature, results can vary slightly between runs (though with\
  \ sufficiently many trees this is minor). If the data has a lot of irrelevant features or if anomalies don’t strongly differentiate\
  \ in any feature, the isolation might not be effective (random splits could isolate normal points by chance – however averaging\
  \ many trees mitigates this). Also, Isolation Forest generally assumes anomalies are a small minority (which is usually\
  \ true in cybersecurity scenarios).\n\n<details>\n<summary>Example --  Detecting Outliers in Network Logs\n</summary>\n\n\
  We’ll use the earlier test dataset (which contains normal and some attack points) and run an Isolation Forest to see if\
  \ it can separate the attacks. We’ll assume we expect ~15% of data to be anomalous (for demonstration).\n\n```python\nfrom\
  \ sklearn.ensemble import IsolationForest\n\n# Combine normal and attack test data from autoencoder example\nX_test_if =\
  \ test_data  # (120 x 2 array with 100 normal and 20 attack points)\n# Train Isolation Forest (unsupervised) on the test\
  \ set itself for demo (in practice train on known normal)\niso_forest = IsolationForest(n_estimators=100, contamination=0.15,\
  \ random_state=0)\niso_forest.fit(X_test_if)\n# Predict anomalies (-1 for anomaly, 1 for normal)\npreds = iso_forest.predict(X_test_if)\n\
  anomaly_scores = iso_forest.decision_function(X_test_if)  # the higher, the more normal\nprint(\"Isolation Forest predicted\
  \ labels (first 20):\", preds[:20])\nprint(\"Number of anomalies detected:\", np.sum(preds == -1))\nprint(\"Example anomaly\
  \ scores (lower means more anomalous):\", anomaly_scores[:5])\n```\n\nIn this code, we instantiate `IsolationForest` with\
  \ 100 trees and set `contamination=0.15` (meaning we expect about 15% anomalies; the model will set its score threshold\
  \ so that ~15% of points are flagged). We fit it on `X_test_if` which contains a mix of normal and attack points (note:\
  \ normally you would fit on training data and then use predict on new data, but here for illustration we fit and predict\
  \ on the same set to directly observe results).\n\nThe output shows the predicted labels for the first 20 points (where\
  \ -1 indicates anomaly). We also print how many anomalies were detected in total and some example anomaly scores. We would\
  \ expect roughly 18 out of 120 points to be labeled -1 (since contamination was 15%). If our 20 attack samples are truly\
  \ the most outlying, most of them should appear in those -1 predictions. The anomaly score (Isolation Forest’s decision\
  \ function) is higher for normal points and lower (more negative) for anomalies – we print a few values to see the separation.\
  \ In practice, one might sort the data by score to see the top outliers and investigate them. Isolation Forest thus provides\
  \ an efficient way to sift through large unlabeled security data and pick out the most irregular instances for human analysis\
  \ or further automated scrutiny.\n</details>\n\n\n### t-SNE (t-Distributed Stochastic Neighbor Embedding)\n\n**t-SNE** is\
  \ a nonlinear dimensionality reduction technique specifically designed for visualizing high-dimensional data in 2 or 3 dimensions.\
  \ It converts similarities between data points to joint probability distributions and tries to preserve the structure of\
  \ local neighborhoods in the lower-dimensional projection. In simpler terms, t-SNE places points in (say) 2D such that similar\
  \ points (in the original space) end up close together and dissimilar points end up far apart with high probability.\n\n\
  The algorithm has two main stages:\n\n1. **Compute pairwise affinities in high-dimensional space:** For each pair of points,\
  \ t-SNE computes a probability that one would pick that pair as neighbors (this is done by centering a Gaussian distribution\
  \ on each point and measuring distances – the perplexity parameter influences the effective number of neighbors considered).\n\
  2. **Compute pairwise affinities in low-dimensional (e.g. 2D) space:** Initially, points are placed randomly in 2D. t-SNE\
  \ defines a similar probability for distances in this map (using a Student t-distribution kernel, which has heavier tails\
  \ than Gaussian to allow distant points more freedom).\n3. **Gradient Descent:** t-SNE then iteratively moves the points\
  \ in 2D to minimize the Kullback–Leibler (KL) divergence between the high-D affinity distribution and the low-D one. This\
  \ causes the 2D arrangement to reflect the high-D structure as much as possible – points that were close in original space\
  \ will attract each other, and those far apart will repel, until a balance is found.\n\nThe result is often a visually meaningful\
  \ scatter plot where clusters in the data become apparent.\n\n> [!TIP]\n> *Use cases in cybersecurity:* t-SNE is often used\
  \ to **visualize high-dimensional security data for human analysis**. For example, in a security operations center, analysts\
  \ could take an event dataset with dozens of features (port numbers, frequencies, byte counts, etc.) and use t-SNE to produce\
  \ a 2D plot. Attacks might form their own clusters or separate from normal data in this plot, making them easier to identify.\
  \ It has been applied to malware datasets to see groupings of malware families or to network intrusion data where different\
  \ attack types cluster distinctly, guiding further investigation. Essentially, t-SNE provides a way to see structure in\
  \ cyber data that would otherwise be inscrutable.\n\n#### Assumptions and Limitations\n\nt-SNE is great for visual discovery\
  \ of patterns. It can reveal clusters, subclusters, and outliers that other linear methods (like PCA) might not. It has\
  \ been used in cybersecurity research to visualize complex data like malware behavior profiles or network traffic patterns.\
  \ Because it preserves local structure, it’s good at showing natural groupings.\n\nHowever, t-SNE is computationally heavier\
  \ (approximately $O(n^2)$) so it may require sampling for very large datasets. It also has hyperparameters (perplexity,\
  \ learning rate, iterations) which can affect the output – e.g., different perplexity values might reveal clusters at different\
  \ scales. t-SNE plots can sometimes be misinterpreted – distances in the map are not directly meaningful globally (it focuses\
  \ on local neighborhood, sometimes clusters can appear artificially well-separated). Also, t-SNE is mainly for visualization;\
  \ it doesn’t provide a straightforward way to project new data points without recomputing, and it’s not meant to be used\
  \ as a preprocessing for predictive modeling (UMAP is an alternative that addresses some of these issues with faster speed).\n\
  \n<details>\n<summary>Example -- Visualizing Network Connections\n</summary>\n\nWe’ll use t-SNE to reduce a multi-feature\
  \ dataset to 2D. For illustration, let’s take the earlier 4D data (which had 3 natural clusters of normal traffic) and add\
  \ a few anomaly points. We then run t-SNE and (conceptually) visualize the results.\n\n```python\n# 1 ─────────────────────────────────────────────────────────────────────\n\
  #    Create synthetic 4-D dataset\n#      • Three clusters of “normal” traffic (duration, bytes)\n#      • Two correlated\
  \ features: packets & errors\n#      • Five outlier points to simulate suspicious traffic\n# ──────────────────────────────────────────────────────────────────────\n\
  import numpy as np\nimport matplotlib.pyplot as plt\nfrom sklearn.manifold import TSNE\nfrom sklearn.preprocessing import\
  \ StandardScaler\n\nrng = np.random.RandomState(42)\n\n# Base (duration, bytes) clusters\nnormal1 = rng.normal(loc=[50,\
  \ 500],  scale=[10, 100], size=(500, 2))\nnormal2 = rng.normal(loc=[60, 1500], scale=[8,  200], size=(500, 2))\nnormal3\
  \ = rng.normal(loc=[70, 3000], scale=[5,  300], size=(500, 2))\n\nbase_data = np.vstack([normal1, normal2, normal3])   \
  \    # (1500, 2)\n\n# Correlated features\npackets = base_data[:, 1] / 50 + rng.normal(scale=0.5, size=len(base_data))\n\
  errors  = base_data[:, 0] / 10 + rng.normal(scale=0.5, size=len(base_data))\n\ndata_4d = np.column_stack([base_data, packets,\
  \ errors])  # (1500, 4)\n\n# Outlier / attack points\noutliers_4d = np.column_stack([\n    rng.normal(250, 1, size=5), \
  \    # extreme duration\n    rng.normal(1000, 1, size=5),    # moderate bytes\n    rng.normal(5, 1, size=5),       # very\
  \ low packets\n    rng.normal(25, 1, size=5)       # high errors\n])\n\ndata_viz = np.vstack([data_4d, outliers_4d])   \
  \          # (1505, 4)\n\n# 2 ─────────────────────────────────────────────────────────────────────\n#    Standardize features\
  \ (recommended for t-SNE)\n# ──────────────────────────────────────────────────────────────────────\nscaler = StandardScaler()\n\
  data_scaled = scaler.fit_transform(data_viz)\n\n# 3 ─────────────────────────────────────────────────────────────────────\n\
  #    Run t-SNE to project 4-D → 2-D\n# ──────────────────────────────────────────────────────────────────────\ntsne = TSNE(\n\
  \    n_components=2,\n    perplexity=30,\n    learning_rate='auto',\n    init='pca',\n    random_state=0\n)\ndata_2d = tsne.fit_transform(data_scaled)\n\
  print(\"t-SNE output shape:\", data_2d.shape)  # (1505, 2)\n\n# 4 ─────────────────────────────────────────────────────────────────────\n\
  #    Visualize: normal traffic vs. outliers\n# ──────────────────────────────────────────────────────────────────────\n\
  plt.figure(figsize=(8, 6))\nplt.scatter(\n    data_2d[:-5, 0], data_2d[:-5, 1],\n    label=\"Normal traffic\",\n    alpha=0.6,\n\
  \    s=10\n)\nplt.scatter(\n    data_2d[-5:, 0], data_2d[-5:, 1],\n    label=\"Outliers / attacks\",\n    alpha=0.9,\n \
  \   s=40,\n    marker=\"X\",\n    edgecolor='k'\n)\n\nplt.title(\"t-SNE Projection of Synthetic Network Traffic\")\nplt.xlabel(\"\
  t-SNE component 1\")\nplt.ylabel(\"t-SNE component 2\")\nplt.legend()\nplt.tight_layout()\nplt.show()\n```\n\nHere we combined\
  \ our previous 4D normal dataset with a handful of extreme outliers (the outliers have one feature (“duration”) set very\
  \ high, etc., to simulate an odd pattern). We run t-SNE with a typical perplexity of 30. The output data_2d has shape (1505,\
  \ 2). We won’t actually plot in this text, but if we did, we’d expect to see perhaps three tight clusters corresponding\
  \ to the 3 normal clusters, and the 5 outliers appearing as isolated points far from those clusters. In an interactive workflow,\
  \ we could color the points by their label (normal or which cluster, vs anomaly) to verify this structure. Even without\
  \ labels, an analyst might notice those 5 points sitting in empty space on the 2D plot and flag them. This shows how t-SNE\
  \ can be a powerful aid to visual anomaly detection and cluster inspection in cybersecurity data, complementing the automated\
  \ algorithms above.\n\n</details>\n\n\n### HDBSCAN (Hierarchical Density-Based Spatial Clustering of Applications with Noise)\n\
  \n**HDBSCAN** is an extension of DBSCAN that removes the need to pick a single global `eps` value and is able to recover\
  \ clusters of **different density** by building a hierarchy of density-connected components and then condensing it.  Compared\
  \ with vanilla DBSCAN it usually\n\n* extracts more intuitive clusters when some clusters are dense and others are sparse,\n\
  * has only one real hyper-parameter (`min_cluster_size`) and a sensible default,\n* gives every point a cluster‐membership\
  \ *probability* and an **outlier score** (`outlier_scores_`), which is extremely handy for threat-hunting dashboards.\n\n\
  > [!TIP]\n> *Use cases in cybersecurity:* HDBSCAN is very popular in modern threat-hunting pipelines – you will often see\
  \ it inside notebook-based hunting playbooks shipped with commercial XDR suites.  One practical recipe is to cluster HTTP\
  \ beaconing traffic during IR: user-agent, interval and URI length often form several tight groups of legitimate software\
  \ updaters while C2 beacons remain as tiny low-density clusters or as pure noise.\n\n<details>\n<summary>Example – Finding\
  \ beaconing C2 channels</summary>\n\n```python\nimport pandas as pd\nfrom hdbscan import HDBSCAN\nfrom sklearn.preprocessing\
  \ import StandardScaler\n\n# df has features extracted from proxy logs\nfeatures = [\n    \"avg_interval\",      # seconds\
  \ between requests\n    \"uri_length_mean\",   # average URI length\n    \"user_agent_entropy\" # Shannon entropy of UA\
  \ string\n]\nX = StandardScaler().fit_transform(df[features])\n\nhdb = HDBSCAN(min_cluster_size=15,  # at least 15 similar\
  \ beacons to be a group\n              metric=\"euclidean\",\n              prediction_data=True)\nlabels = hdb.fit_predict(X)\n\
  \ndf[\"cluster\"] = labels\n# Anything with label == -1 is noise → inspect as potential C2\nsuspects = df[df[\"cluster\"\
  ] == -1]\nprint(\"Suspect beacon count:\", len(suspects))\n```\n\n</details>\n\n---\n\n### Robustness and Security Considerations\
  \ – Poisoning & Adversarial Attacks (2023-2025)\n\nRecent work has shown that **unsupervised learners are *not* immune to\
  \ active attackers**:\n\n* **Data-poisoning against anomaly detectors.**  Chen *et al.* (IEEE S&P 2024) demonstrated that\
  \ adding as little as 3 % crafted traffic can shift the decision boundary of Isolation Forest and ECOD so that real attacks\
  \ look normal.  The authors released an open-source PoC (`udo-poison`) that automatically synthesises poison points.\n*\
  \ **Backdooring clustering models.**  The *BadCME* technique (BlackHat EU 2023) implants a tiny trigger pattern; whenever\
  \ that trigger appears, a K-Means-based detector quietly places the event inside a “benign” cluster.\n* **Evasion of DBSCAN/HDBSCAN.**\
  \  A 2025 academic pre-print from KU Leuven showed that an attacker can craft beaconing patterns that purposely fall into\
  \ density gaps, effectively hiding inside *noise* labels.\n\nMitigations that are gaining traction:\n\n1. **Model sanitisation\
  \ / TRIM.**  Before every retraining epoch, discard the 1–2 % highest-loss points (trimmed maximum likelihood) to make poisoning\
  \ dramatically harder.\n2. **Consensus ensembling.**  Combine several heterogeneous detectors (e.g., Isolation Forest +\
  \ GMM + ECOD) and raise an alert if *any* model flags a point. Research indicates this raises the attacker’s cost by >10×.\n\
  3. **Distance-based defence for clustering.**  Re-compute clusters with `k` different random seeds and ignore points that\
  \ constantly hop clusters.\n\n---\n\n### Modern Open-Source Tooling (2024-2025)\n\n* **PyOD 2.x** (released May 2024) added\
  \ *ECOD*, *COPOD* and GPU-accelerated *AutoFormer* detectors.  It now ships a `benchmark` sub-command that lets you compare\
  \ 30+ algorithms on your dataset with **one line of code**:\n  ```bash\n  pyod benchmark --input logs.csv --label attack\
  \ --n_jobs 8\n  ```\n* **Anomalib v1.5** (Feb 2025) focuses on vision but also contains a generic **PatchCore** implementation\
  \ – handy for screenshot-based phishing page detection.\n* **scikit-learn 1.5** (Nov 2024) finally exposes `score_samples`\
  \ for *HDBSCAN* via the new `cluster.HDBSCAN` wrapper, so you do not need the external contrib package when on Python 3.12.\n\
  \n<details>\n<summary>Quick PyOD example – ECOD + Isolation Forest ensemble</summary>\n\n```python\nfrom pyod.models import\
  \ ECOD, IForest\nfrom pyod.utils.data import generate_data, evaluate_print\nfrom pyod.utils.example import visualize\n\n\
  X_train, y_train, X_test, y_test = generate_data(\n    n_train=5000, n_test=1000, n_features=16,\n    contamination=0.02,\
  \ random_state=42)\n\nmodels = [ECOD(), IForest()]\n\n# majority vote – flag if any model thinks it is anomalous\nanomaly_scores\
  \ = sum(m.fit(X_train).decision_function(X_test) for m in models) / len(models)\n\nevaluate_print(\"Ensemble\", y_test,\
  \ anomaly_scores)\n```\n\n</details>\n\n## References\n\n- [HDBSCAN – Hierarchical density-based clustering](https://github.com/scikit-learn-contrib/hdbscan)\n\
  - Chen, X. *et al.* “On the Vulnerability of Unsupervised Anomaly Detection to Data Poisoning.” *IEEE Symposium on Security\
  \ and Privacy*, 2024.\n\n\n\n{{#include ../banners/hacktricks-training.md}}"
_relative_path: AI/AI-Unsupervised-Learning-Algorithms.md
_source_path: /home/adams/scorchederf/focuslocust/.cache/hacktricks/src/AI/AI-Unsupervised-Learning-Algorithms.md
````

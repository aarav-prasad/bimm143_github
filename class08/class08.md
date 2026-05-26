# Class 08: Breast Cancer Mini Project
Aarav Prasad (PID: A17440940)

- [Background](#background)
- [Data Import](#data-import)
- [Exploratory Data Analysis](#exploratory-data-analysis)
- [Principal Component Analysis
  (PCA)](#principal-component-analysis-pca)
- [Interpreting PCA Results](#interpreting-pca-results)
- [Variance Explained](#variance-explained)
  - [Communicating PCA Results](#communicating-pca-results)
  - [Hierarchical clustering](#hierarchical-clustering)
  - [Combining Methods](#combining-methods)

## Background

The goal of this mini-project is for you to explore a complete analysis
using the unsupervised learning techniques covered in class

Today we will analyze a biopsy data-set from fine needle aspiration
(FNA) of a breast mass.

## Data Import

The data is made available as a CSV file for download.

``` r
wisc.df <- read.csv("WisconsinCancer.csv", row.names=1)
```

``` r
head(wisc.df, 3)
```

             diagnosis radius_mean texture_mean perimeter_mean area_mean
    842302           M       17.99        10.38          122.8      1001
    842517           M       20.57        17.77          132.9      1326
    84300903         M       19.69        21.25          130.0      1203
             smoothness_mean compactness_mean concavity_mean concave.points_mean
    842302           0.11840          0.27760         0.3001             0.14710
    842517           0.08474          0.07864         0.0869             0.07017
    84300903         0.10960          0.15990         0.1974             0.12790
             symmetry_mean fractal_dimension_mean radius_se texture_se perimeter_se
    842302          0.2419                0.07871    1.0950     0.9053        8.589
    842517          0.1812                0.05667    0.5435     0.7339        3.398
    84300903        0.2069                0.05999    0.7456     0.7869        4.585
             area_se smoothness_se compactness_se concavity_se concave.points_se
    842302    153.40      0.006399        0.04904      0.05373           0.01587
    842517     74.08      0.005225        0.01308      0.01860           0.01340
    84300903   94.03      0.006150        0.04006      0.03832           0.02058
             symmetry_se fractal_dimension_se radius_worst texture_worst
    842302       0.03003             0.006193        25.38         17.33
    842517       0.01389             0.003532        24.99         23.41
    84300903     0.02250             0.004571        23.57         25.53
             perimeter_worst area_worst smoothness_worst compactness_worst
    842302             184.6       2019           0.1622            0.6656
    842517             158.8       1956           0.1238            0.1866
    84300903           152.5       1709           0.1444            0.4245
             concavity_worst concave.points_worst symmetry_worst
    842302            0.7119               0.2654         0.4601
    842517            0.2416               0.1860         0.2750
    84300903          0.4504               0.2430         0.3613
             fractal_dimension_worst
    842302                   0.11890
    842517                   0.08902
    84300903                 0.08758

Make sure we remove or exclude the `diagnosis` column from the data-set
that we use for further analysis - this is the expert diagnosis as
either M or B:

``` r
wisc.data <- wisc.df[,-1]
diagnosis <- as.factor(wisc.df$diagnosis)
```

## Exploratory Data Analysis

> Q1: How many observations are in this dataset?

``` r
nrow(wisc.data)
```

    [1] 569

569 patients (observations)

> Q2: How many of the observations have a malignant diagnosis?

``` r
table(wisc.df$diagnosis)
```


      B   M 
    357 212 

212 malignant

> Q3:How many variables/features in the data are suffixed with `_mean`?

We can use the `grep()` function to help us

``` r
length(grep("_mean", colnames(wisc.data)))
```

    [1] 10

## Principal Component Analysis (PCA)

We need to scale our data before PCA with the `scale=TRUE` argument to
`prcomp()`.

``` r
wisc.pr <- prcomp(wisc.data, scale = TRUE)
summary(wisc.pr)
```

    Importance of components:
                              PC1    PC2     PC3     PC4     PC5     PC6     PC7
    Standard deviation     3.6444 2.3857 1.67867 1.40735 1.28403 1.09880 0.82172
    Proportion of Variance 0.4427 0.1897 0.09393 0.06602 0.05496 0.04025 0.02251
    Cumulative Proportion  0.4427 0.6324 0.72636 0.79239 0.84734 0.88759 0.91010
                               PC8    PC9    PC10   PC11    PC12    PC13    PC14
    Standard deviation     0.69037 0.6457 0.59219 0.5421 0.51104 0.49128 0.39624
    Proportion of Variance 0.01589 0.0139 0.01169 0.0098 0.00871 0.00805 0.00523
    Cumulative Proportion  0.92598 0.9399 0.95157 0.9614 0.97007 0.97812 0.98335
                              PC15    PC16    PC17    PC18    PC19    PC20   PC21
    Standard deviation     0.30681 0.28260 0.24372 0.22939 0.22244 0.17652 0.1731
    Proportion of Variance 0.00314 0.00266 0.00198 0.00175 0.00165 0.00104 0.0010
    Cumulative Proportion  0.98649 0.98915 0.99113 0.99288 0.99453 0.99557 0.9966
                              PC22    PC23   PC24    PC25    PC26    PC27    PC28
    Standard deviation     0.16565 0.15602 0.1344 0.12442 0.09043 0.08307 0.03987
    Proportion of Variance 0.00091 0.00081 0.0006 0.00052 0.00027 0.00023 0.00005
    Cumulative Proportion  0.99749 0.99830 0.9989 0.99942 0.99969 0.99992 0.99997
                              PC29    PC30
    Standard deviation     0.02736 0.01153
    Proportion of Variance 0.00002 0.00000
    Cumulative Proportion  1.00000 1.00000

> Q4: From your results, what proportion of the original variance is
> captured by the first principal component (PC1)?

0.4427 (44.27%)

> Q5: How many principal components (PCs) are required to describe at
> least 70% of the original variance in the data?

At least 3 PCs

> Q6: How many principal components (PCs) are required to describe at
> least 90% of the original variance in the data?

At least 7 PCs

# Interpreting PCA Results

Now you will use some visualizations to better understand your PCA
model. A common visualization for PCA results is the so-called biplot.

``` r
biplot(wisc.pr)
```

![](class08_files/figure-commonmark/unnamed-chunk-8-1.png)

> Q7: What stands out to you about this plot? Is it easy or difficult to
> understand? Why?

This plot is very difficult to understand because there are way too many
data points/values to visualize on the graph, everything just blends
together. The column names are red, but the rest of the numerical values
all blend together.

Lets see the “PC score plot”

``` r
library(ggplot2)

ggplot(wisc.pr$x) +
  aes(PC1,PC2, col = diagnosis) +
  geom_point()
```

![](class08_files/figure-commonmark/unnamed-chunk-9-1.png)

> Q8: Generate a similar plot for principal components 1 and 3. What do
> you notice about these plots?

Both these plots show that PC1 captures a separation of malignant and
benign samples.

``` r
ggplot(wisc.pr$x) +
  aes(PC1, PC3, col=diagnosis) +
  geom_point()
```

![](class08_files/figure-commonmark/unnamed-chunk-10-1.png)

# Variance Explained

A scree plot shows how much variance each PC captures. We typically look
for an “elbow” — a point where adding more PCs gives diminishing
returns.

Calculate the variance of each principal component by squaring the
`sdev` component of `wisc.pr` (i.e. `wisc.pr$sdev^2`). Save the result
as an object called `pr.var`.

``` r
# Calculate variance of each component
pr.var <- wisc.pr$sdev^2
head(pr.var)
```

    [1] 13.281608  5.691355  2.817949  1.980640  1.648731  1.207357

Calculate the variance explained by each principal component by dividing
by the total variance explained of all principal components.

``` r
# Variance explained by each principal component: pve
pve <- pr.var / sum(pr.var)

# Plot variance explained for each principal component
plot(c(1,pve), xlab = "Principal Component", 
     ylab = "Proportion of Variance Explained", 
     ylim = c(0, 1), type = "o")
```

![](class08_files/figure-commonmark/unnamed-chunk-12-1.png)

``` r
# Alternative scree plot of the same data, note data driven y-axis
barplot(pve, ylab = "Percent of Variance Explained",
     names.arg=paste0("PC",1:length(pve)), las=2, axes = FALSE)
axis(2, at=pve, labels=round(pve,2)*100 )
```

![](class08_files/figure-commonmark/unnamed-chunk-13-1.png)

## Communicating PCA Results

The loading vector (`wisc.pr$rotation`) tells us which original
measurements contribute most to each PC.

> Q9: For the first principal component, what is the component of the
> loading vector (i.e. wisc.pr\$rotation\[,1\]) for the feature
> concave.points_mean? This tells us how much this original feature
> contributes to the first PC. Are there any features with larger
> contributions than this one?

``` r
wisc.pr$rotation["concave.points_mean", 1]
```

    [1] -0.2608538

``` r
sort(abs(wisc.pr$rotation[,1]))
```

              smoothness_se              texture_se             symmetry_se 
                 0.01453145              0.01742803              0.04249842 
     fractal_dimension_mean    fractal_dimension_se            texture_mean 
                 0.06436335              0.10256832              0.10372458 
              texture_worst          symmetry_worst        smoothness_worst 
                 0.10446933              0.12290456              0.12795256 
    fractal_dimension_worst           symmetry_mean         smoothness_mean 
                 0.13178394              0.13816696              0.14258969 
               concavity_se          compactness_se       concave.points_se 
                 0.15358979              0.17039345              0.18341740 
                    area_se               radius_se       compactness_worst 
                 0.20286964              0.20597878              0.21009588 
               perimeter_se             radius_mean               area_mean 
                 0.21132592              0.21890244              0.22099499 
                 area_worst          perimeter_mean            radius_worst 
                 0.22487053              0.22753729              0.22799663 
            concavity_worst         perimeter_worst        compactness_mean 
                 0.22876753              0.23663968              0.23928535 
       concave.points_worst          concavity_mean     concave.points_mean 
                 0.25088597              0.25840048              0.26085376 

The component of the loading vector is -2.608538, there aren’t any
features with larger contributions

## Hierarchical clustering

As part of the preparation for hierarchical clustering, the distance
between all pairs of observations needs to be calculated. This “distance
matrix” will be the input for the `hclust()` function.

First scale the `wisc.data` data and assign the result to `data.scaled`.

``` r
wisc.hclust <- hclust(dist(scale(wisc.data)))
plot(wisc.hclust)
```

![](class08_files/figure-commonmark/unnamed-chunk-15-1.png)

> Q10: Using the plot() and abline() functions, what is the height at
> which the clustering model has 4 clusters?

``` r
plot(wisc.hclust)
abline(h = 19, col = "red", lty = 2)
```

![](class08_files/figure-commonmark/unnamed-chunk-16-1.png)

The clutstering model has 4 clusters at h = 19.

Use `cutree()` to cut the tree so that it has 4 clusters. Assign the
output to the variable `wisc.hclust.clusters`.

``` r
wisc.hclust.clusters <- cutree(wisc.hclust, h = 19)
```

``` r
table(wisc.hclust.clusters, diagnosis)
```

                        diagnosis
    wisc.hclust.clusters   B   M
                       1  12 165
                       2   2   5
                       3 343  40
                       4   0   2

As we discussed in our last class videos there are number of different
“methods” we can use to combine points during the hierarchical
clustering procedure. These include “single”, “complete”, “average” and
(my favorite) “ward.D2”

> Q12: Which method gives your favorite results for the same data.dist
> dataset? Explain your reasoning.

I prefer **ward.D2** because it produces more compact and well-separated
clusters by minimizing within-cluster variance. This makes the
dendrogram easier to interpret compared to methods like single linkage,
which can create chain-like clusters.

## Combining Methods

``` r
d <- dist(wisc.pr$x[,1:4])
wisc.pr.hclust <-hclust(d, method = "ward.D2")
plot(wisc.pr.hclust)
abline(h=70, col = "red")
```

![](class08_files/figure-commonmark/unnamed-chunk-19-1.png)

``` r
grps <- cutree(wisc.pr.hclust, h=70)
table(grps)
```

    grps
      1   2 
    171 398 

How does this clustering `grps` correspond to the expert `diagnosis`?

``` r
table(diagnosis)
```

    diagnosis
      B   M 
    357 212 

``` r
table(diagnosis, grps)
```

             grps
    diagnosis   1   2
            B   6 351
            M 165  47

``` r
ggplot(wisc.pr$x) +
  aes(PC1, PC2) +
  geom_point(col=grps)
```

![](class08_files/figure-commonmark/unnamed-chunk-23-1.png)

``` r
wisc.pr.hclust.clusters <- cutree(wisc.pr.hclust, k = 2)
```

Using `table()`, compare the results from your new hierarchical
clustering model with the actual diagnoses.

> Q13: How well does the newly created hclust model with two clusters
> separate out the two “M” and “B” diagnoses?

``` r
table(wisc.pr.hclust.clusters, diagnosis)
```

                           diagnosis
    wisc.pr.hclust.clusters   B   M
                          1   6 165
                          2 351  47

The 2-cluster model separates the data fairly well: one cluster is
mostly malignant (165 M vs 6 B), and the other is mostly benign (351 B
vs 47 M), though some misclassification remains.

> Q14: How well do the hierarchical clustering models you created in the
> previous sections (i.e. without first doing PCA) do in terms of
> separating the diagnoses? Again, use the table() function to compare
> the output of each model (wisc.hclust.clusters and
> wisc.pr.hclust.clusters) with the vector containing the actual
> diagnoses.

``` r
table(wisc.hclust.clusters, diagnosis)
```

                        diagnosis
    wisc.hclust.clusters   B   M
                       1  12 165
                       2   2   5
                       3 343  40
                       4   0   2

Without PCA, the clustering is less clean because the diagnoses are
spread across multiple clusters instead of being clearly separated into
two groups. Even if one cluster has fewer errors (e.g., 40 M), the
overall separation is worse than the PCA-based 2-cluster model

\##Prediction

``` r
#url <- "new_samples.csv"
url <- "https://tinyurl.com/new-samples-CSV"
new <- read.csv(url)
npc <- predict(wisc.pr, newdata=new)
npc
```

               PC1       PC2        PC3        PC4       PC5        PC6        PC7
    [1,]  2.576616 -3.135913  1.3990492 -0.7631950  2.781648 -0.8150185 -0.3959098
    [2,] -4.754928 -3.009033 -0.1660946 -0.6052952 -1.140698 -1.2189945  0.8193031
                PC8       PC9       PC10      PC11      PC12      PC13     PC14
    [1,] -0.2307350 0.1029569 -0.9272861 0.3411457  0.375921 0.1610764 1.187882
    [2,] -0.3307423 0.5281896 -0.4855301 0.7173233 -1.185917 0.5893856 0.303029
              PC15       PC16        PC17        PC18        PC19       PC20
    [1,] 0.3216974 -0.1743616 -0.07875393 -0.11207028 -0.08802955 -0.2495216
    [2,] 0.1299153  0.1448061 -0.40509706  0.06565549  0.25591230 -0.4289500
               PC21       PC22       PC23       PC24        PC25         PC26
    [1,]  0.1228233 0.09358453 0.08347651  0.1223396  0.02124121  0.078884581
    [2,] -0.1224776 0.01732146 0.06316631 -0.2338618 -0.20755948 -0.009833238
                 PC27        PC28         PC29         PC30
    [1,]  0.220199544 -0.02946023 -0.015620933  0.005269029
    [2,] -0.001134152  0.09638361  0.002795349 -0.019015820

``` r
plot(wisc.pr$x[,1:2], col=grps)
points(npc[,1], npc[,2], col="blue", pch=16, cex=3)
text(npc[,1], npc[,2], c(1,2), col="white")
```

![](class08_files/figure-commonmark/unnamed-chunk-28-1.png)

> Q16: Which of these new patients should we prioritize for follow up
> based on your results?

Patient 2, they are in the “malignant” group.

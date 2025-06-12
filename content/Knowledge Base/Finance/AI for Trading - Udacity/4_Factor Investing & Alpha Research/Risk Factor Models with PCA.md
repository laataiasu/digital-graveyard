## 1. Vectors: Two Perspectives

#### **Vector as a Collection of Numbers**
- **Definition**: A vector can be seen as a list of numbers. This is the most straightforward way to think of vectors in many applied contexts, like statistics or data science.
- **Example**: Imagine you have a spreadsheet column with daily returns for different stocks. Each entry in that column is part of a vector representing those returns.
  
#### **Vector as a Direction in Space**
- **Definition**: A vector can also be thought of as a direction and magnitude in space. In this view, a vector is an arrow pointing from the origin to a point in space.
- **Example**: In 3D space, a vector can be an arrow from the origin \((0,0,0)\) to a point \((x, y, z)\).
  
#### **Transition Between Views**
- **Importance**: In various applications, especially in analysis methods, you might need to switch between these two perspectives of vectors. Being comfortable with both interpretations is crucial for deeper understanding.

## 2. Bases: Understanding Through 2D Plane

#### **Basis Vectors and the 2D Plane**
- **Definition**: In a 2D plane, you can represent any point using coordinates that tell you how far to move along each axis starting from the origin. These movements are guided by **basis vectors**.
- **Standard Basis**: Typically, the vectors \(\mathbf{i}\) and \(\mathbf{j}\), denoted as \(\mathbf{i} = (1,0)\) and \(\mathbf{j} = (0,1)\), form the standard basis. This means:
  - \(\mathbf{i}\) represents a move of 1 unit to the right.
  - \(\mathbf{j}\) represents a move of 1 unit upward.
- **Example**: The vector \((1,2)\) means moving 1 unit right and 2 units up. It can be written as a linear combination of the basis vectors:
  \[
  (1, 2) = 1 \cdot (1, 0) + 2 \cdot (0, 1)
  \]
  
#### **General Basis and PCA**
- **Different Bases**: The standard basis (\(\mathbf{i}\) and \(\mathbf{j}\)) is not the only possible basis for the 2D plane. You can choose different vectors as basis vectors.
- **Effect on Coordinates**: Choosing different basis vectors changes how you describe the location of points in the plane. For example, using a new set of basis vectors (e.g., vectors in red and blue), the grid would change from squares to parallelograms.
- **PCA (Principal Component Analysis)**: PCA essentially involves finding a new basis for your data that best represents the variation in the data. This is done by transforming the data to a new coordinate system where the axes (new basis vectors) are aligned with the directions of maximum variance in the data.
  
#### **Matrix Representation**
- **Linear Combination**: In matrix terms, any vector in the 2D plane can be expressed as a product of a matrix (composed of the basis vectors) and a vector representing the coefficients:
  \[
  \begin{pmatrix} x \\ y \end{pmatrix} = \textbf{B} \cdot \begin{pmatrix} a \\ b \end{pmatrix}
  \]
  Where \(\textbf{B}\) is the matrix whose columns are the basis vectors and \(\begin{pmatrix} a \\ b \end{pmatrix}\) are the coefficients.
  
#### **Translation Between Bases**
- **Changing Language**: When you change the basis, you're essentially translating the coordinates from one system (language) to another. This is akin to converting between different coordinate grids.

### **Summary**
- **Vectors**: Can be seen both as lists of numbers and as directions in space.
- **Bases**: Provide the framework (a set of vectors) for describing any vector in space, with PCA being a method that finds an optimal basis for data representation.

Understanding these concepts deeply is crucial as they form the foundation for many advanced topics in linear algebra and data science, including dimensionality reduction techniques like PCA.

## 3. Translation Between Bases

#### **Original and New Basis**
- **Original Basis (\(\mathbf{i}\) and \(\mathbf{j}\))**: In the standard coordinate system, we usually work with the basis vectors \(\mathbf{i} = (1, 0)\) and \(\mathbf{j} = (0, 1)\).
- **New Basis (Red and Blue Vectors)**: Suppose we have a new set of basis vectors:
  - The **Red Vector** can be written in the original basis as \((1, 0.5)\), meaning 1 unit of \(\mathbf{i}\) and 0.5 units of \(\mathbf{j}\).
  - The **Blue Vector** can be written in the original basis as \((-1, 1)\), meaning -1 unit of \(\mathbf{i}\) and 1 unit of \(\mathbf{j}\).

#### **Expressing the New Basis in Terms of the Original Basis**
- When we express the red and blue vectors in the original basis, we are essentially translating the new basis into the "language" of the old basis. This means understanding how the new vectors are composed of the original basis vectors \(\mathbf{i}\) and \(\mathbf{j}\).

  Mathematically, if we have the red vector as \(\mathbf{r} = (1, 0.5)\) and the blue vector as \(\mathbf{b} = (-1, 1)\), then any vector in the new basis can be expressed as a linear combination of \(\mathbf{r}\) and \(\mathbf{b}\).

#### **Translating a Vector Between Bases**
- Suppose we have a vector \(\mathbf{v}\) that we know how to express in the new basis (using the red and blue vectors). If \(\mathbf{v}\) is written as:
  \[
  \mathbf{v} = 2\mathbf{b} + 1\mathbf{r}
  \]
  To translate this into the original basis, we substitute the expressions for \(\mathbf{r}\) and \(\mathbf{b}\) in terms of \(\mathbf{i}\) and \(\mathbf{j}\):
  \[
  \mathbf{v} = 2(-1, 1) + 1(1, 0.5)
  \]
  Simplifying this:
  \[
  \mathbf{v} = (-2, 2) + (1, 0.5) = (-1, 2.5)
  \]
  This gives us the vector \(\mathbf{v}\) in the original \(\mathbf{i}, \mathbf{j}\) basis.

#### **Translating Between Old and New Basis Using Matrices**
- **Matrix Representation**: To systematically translate between bases, we can use matrices. Suppose the matrix \(\mathbf{M}\) has columns representing the new basis vectors expressed in the old basis:
  \[
  \mathbf{M} = \begin{pmatrix} 1 & -1 \\ 0.5 & 1 \end{pmatrix}
  \]
  If we want to express a vector \(\mathbf{v}\) from the new basis back in the old basis, we multiply the coefficients of the vector in the new basis by \(\mathbf{M}\):
  \[
  \mathbf{v}_{\text{old}} = \mathbf{M} \cdot \mathbf{v}_{\text{new}}
  \]
- **Inverse Matrix**: To translate a vector from the old basis to the new basis, we use the inverse of the matrix \(\mathbf{M}\). The inverse matrix \(\mathbf{M}^{-1}\) will allow us to go back from the original basis to the new basis.

  The concept here is that if you translate from the old basis to the new basis and then back again, you should end up with the original vector. Mathematically:
  \[
  \mathbf{M} \cdot \mathbf{M}^{-1} = \mathbf{I}
  \]
  where \(\mathbf{I}\) is the identity matrix, meaning you get back what you started with.

### **Key Takeaways**
- **Basis Translation**: Translating a vector between different bases involves understanding how the new basis vectors are expressed in the old basis and vice versa.
- **Matrix Inverse**: The matrix that converts from the old basis to the new one has an inverse that converts back from the new basis to the old one.
- **Verification**: You can verify that translating from one basis to another and back again leaves the vector unchanged, which is a good exercise to deepen understanding.

This process of translating between bases is fundamental in linear algebra and helps in various applications like PCA, where finding the right basis is key to simplifying and understanding the data.

## 4. Principal Component Analysis (PCA): The Core Idea

Let's delve into the core idea behind Principal Component Analysis (PCA) and understand it step by step.

#### What is PCA?

In simple terms, PCA is a mathematical technique used to transform our data into a new coordinate system. This new coordinate system (or basis) is special because it aligns the axes (or dimensions) in such a way that the data points are spread out as much as possible along these new axes.

#### Why is This New Basis Special?

- **Maximizing Variance**: The first new axis (or principal component) is chosen such that the data points have the greatest variance along this axis. In other words, this axis captures the direction in which the data varies the most.
- **Projection**: To understand this, imagine you have data points on a 2D plane. If you draw a line (a potential new axis) through the origin, each data point can be projected onto this line. The projection is done by drawing a perpendicular from the point to the line, and the location where it intersects the line is the projected point.

#### The Goal of PCA

The goal of PCA is to choose this line (axis) in such a way that:

1. **Maximizes the Spread of Projected Points (Maximizing Variance)**: The coordinates of the points along this new axis should be as spread out as possible. This spread is the variance, and PCA seeks to maximize it.
2. **Minimizes Reconstruction Error**: The perpendicular distance from each original data point to the line (new axis) should be minimized. This distance represents the error when we try to reconstruct the original data point using only the information from the new axis.

#### Relationship Between Variance and Reconstruction Error

PCA finds the optimal line by balancing two key aspects:

- **Maximizing the Squared Distance Along the Line**: This means the variance of the projected points along the line is maximized.
- **Minimizing the Squared Perpendicular Distance to the Line**: This minimizes the reconstruction error.

The key mathematical concept here is the Pythagorean theorem, which tells us that for any data point:

\[
\text{(Distance from origin to the point)}^2 = \text{(Distance from origin to projection)}^2 + \text{(Perpendicular distance from projection to the point)}^2
\]

When we change the orientation of the line (axis), one of these distances increases while the other decreases. PCA finds the orientation that strikes the best balance, maximizing variance along the axis while minimizing the perpendicular distances (reconstruction error).

#### Finding the Principal Components

- **First Component**: The first principal component (first new axis) is the direction where the data has the most variance.
- **Subsequent Components**: Each subsequent axis (principal component) must be:
  - **Orthogonal (Perpendicular)** to the previous ones.
  - **Maximizes Variance** in its direction, given the orthogonality constraint.

In a 2D space, there's only one possible direction for the second axis—perpendicular to the first. In higher-dimensional spaces, PCA continues to find orthogonal axes that maximize variance until it has the same number of axes (components) as the original data dimensions.

For example, if you start with data in a 4D space, PCA would give you four new axes (principal components).

### Summary

PCA transforms data into a new coordinate system where:
- The first axis captures the maximum variance.
- Each subsequent axis captures the maximum variance possible while being orthogonal to the previous ones.
- This process helps in reducing the dimensions of the data while preserving as much of the data's variability as possible.

## 5. Starting with Mean Centering

Before performing PCA, the first step is **mean centering** the data. Let's explore what this means:

1. **Original Data Points**: Imagine you have a set of data points in a 2D space. Each point has coordinates \((x_i, y_i)\). 
   
2. **Calculate the Mean**:
   - \( \bar{x} \) = Mean of all the \(x\) coordinates
   - \( \bar{y} \) = Mean of all the \(y\) coordinates
   
   These means represent the average position of all data points along the x-axis and y-axis, respectively.

3. **Centering the Data**:
   - To center the data, subtract the mean from each coordinate:
     \[
     x'_i = x_i - \bar{x}
     \]
     \[
     y'_i = y_i - \bar{y}
     \]
   - This results in new coordinates \((x'_i, y'_i)\) for each data point.

4. **Centered Data**:
   - After centering, the new dataset has a mean of zero in both dimensions. This means the data is "centered around zero," which is crucial for PCA to work correctly.

#### Why Centering is Important

Centering the data ensures that:
- The new coordinate system (the principal components) is aligned with the data in a way that accurately reflects the directions of maximum variance.
- PCA can focus on the true structure of the data, rather than being influenced by the arbitrary position of the original data points in the coordinate system.

#### Visualizing the Process

To help visualize, imagine a 2D plane where your data points form a cluster off to one side. If you don’t center the data, your principal components might be skewed. By centering, you shift the entire cluster so that it’s centered around the origin \((0, 0)\). This adjustment allows PCA to accurately determine the direction where the data varies the most.

### Summary

- **Mean Centering**: The first step in PCA is to subtract the mean of each dimension from the data points, centering them around zero.
- **Purpose**: This step is essential to ensure that the PCA calculation focuses on the data’s internal structure, not its position in space.
- **Mathematical Notation**: The centered data points \((x'_i, y'_i)\) are computed by subtracting the mean from each original data point’s coordinates.

This sets the stage for the next steps in PCA, where we will mathematically determine the directions (principal components) that capture the most variance in the data.

## 6. Finding Coordinates in the New Basis

Let's continue with our exploration of Principal Component Analysis (PCA) by understanding how to express data points in terms of the new basis that PCA provides. This involves some key mathematical concepts, such as dot products and projections.

#### Recap: New Basis Vectors

After performing PCA, you obtain a set of new basis vectors, known as Principal Components (PCs). These components:
- **Are Orthogonal**: The vectors are perpendicular to each other.
- **Have Unit Length**: Each vector has a length of 1.

These vectors form the new coordinate system in which we will describe our original data points.

#### Representing a Data Point in the New Basis

Let's focus on one mean-centered data point, which we'll call \( \mathbf{X} \).

1. **Original Vector \( \mathbf{X} \)**:
   - This vector points from the origin to our data point in the original coordinate system.

2. **New Basis Vector \( \mathbf{W} \)**:
   - This is one of the Principal Components (PCs) we obtained from PCA.

3. **Right Triangle Formation**:
   - Imagine a right triangle where:
     - \( \mathbf{X} \) is the hypotenuse.
     - The projection of \( \mathbf{X} \) onto \( \mathbf{W} \) forms one of the legs.
     - The angle between \( \mathbf{X} \) and \( \mathbf{W} \) is \( \theta \).

4. **Finding the New Coordinate**:
   - We want to express the data point \( \mathbf{X} \) in terms of the new basis. Specifically, we want to find the coordinate of \( \mathbf{X} \) along the direction of \( \mathbf{W} \).
   - **Projection Formula**: The projection of \( \mathbf{X} \) onto \( \mathbf{W} \) gives us the coordinate of \( \mathbf{X} \) along the direction of \( \mathbf{W} \). This is given by:
     \[
     \text{Projection of } \mathbf{X} \text{ onto } \mathbf{W} = \mathbf{X} \cdot \mathbf{W}
     \]
     Where \( \mathbf{X} \cdot \mathbf{W} \) is the dot product of \( \mathbf{X} \) and \( \mathbf{W} \).

#### Understanding the Dot Product and Projection

The dot product \( \mathbf{X} \cdot \mathbf{W} \) is defined as:
\[
\mathbf{X} \cdot \mathbf{W} = \|\mathbf{X}\| \cdot \|\mathbf{W}\| \cdot \cos(\theta)
\]
Where:
- \( \|\mathbf{X}\| \) is the magnitude (length) of vector \( \mathbf{X} \).
- \( \|\mathbf{W}\| \) is the magnitude (length) of vector \( \mathbf{W} \). Since \( \mathbf{W} \) is a unit vector, \( \|\mathbf{W}\| = 1 \).
- \( \theta \) is the angle between \( \mathbf{X} \) and \( \mathbf{W} \).

Given that \( \|\mathbf{W}\| = 1 \), the projection simplifies to:
\[
\text{Projection} = \|\mathbf{X}\| \cdot \cos(\theta)
\]

This projection represents how far along the direction of \( \mathbf{W} \) the point \( \mathbf{X} \) lies.

#### Maximizing the Variance

In PCA, the direction of the new basis (i.e., the direction of \( \mathbf{W} \)) is chosen to maximize the variance of these projections for all data points.

- **Variance Maximization**: For each data point, we calculate the projection of its vector \( \mathbf{X} \) onto \( \mathbf{W} \). The goal of PCA is to maximize the variance of these projections across all data points.
- **Why Maximize Variance?**: By maximizing the variance, PCA ensures that the first principal component captures the most significant trend or pattern in the data.

#### Summary

- **New Coordinates**: The coordinates of a data point in the new basis are found by projecting the original vector onto the new basis vectors.
- **Dot Product**: The projection is calculated using the dot product, which gives the magnitude of the data point along the direction of the basis vector.
- **Maximizing Variance**: PCA selects the basis vectors (principal components) by maximizing the variance of these projections across all data points, ensuring that the most important features of the data are captured.

## 7. Maximizing Variance in PCA

Let's continue exploring PCA by understanding how to mathematically express the goal of maximizing variance. We'll start with the familiar formula for variance and then move on to how this relates to the PCA process.

#### Variance Formula Recap

The variance of a set of data points is given by:
\[
\text{Variance} = \frac{1}{n-1} \sum_{i=1}^{n} (x_i - \mu)^2
\]
Where:
- \( n \) is the number of data points.
- \( x_i \) represents each data point.
- \( \mu \) is the mean of the data points.

However, in PCA, we work with mean-centered data, so \( \mu = 0 \). This simplifies the variance formula to:
\[
\text{Variance} = \frac{1}{n-1} \sum_{i=1}^{n} x_i^2
\]

#### Connecting Variance to PCA

In PCA, the goal is to maximize the variance of the projections of the data points onto the new basis vector \( \mathbf{w} \). This means we want to maximize the expression:
\[
\frac{1}{n-1} \sum_{i=1}^{n} (\mathbf{x}_i \cdot \mathbf{w})^2
\]
Where:
- \( \mathbf{x}_i \) is the vector representing the \( i \)th data point.
- \( \mathbf{w} \) is the new basis vector (Principal Component).

Since \( n-1 \) is a constant, maximizing the variance is equivalent to maximizing:
\[
\sum_{i=1}^{n} (\mathbf{x}_i \cdot \mathbf{w})^2
\]

#### Condensed Matrix Notation

To write this in a more compact form, consider the following:

1. **Data Matrix \( \mathbf{X} \)**:
   - \( \mathbf{X} \) is an \( n \times d \) matrix where:
     - \( n \) is the number of data points.
     - \( d \) is the number of dimensions (features).
     - Each row \( \mathbf{x}_i \) of \( \mathbf{X} \) represents a data point.

2. **Vector \( \mathbf{w} \)**:
   - \( \mathbf{w} \) is a \( d \)-dimensional vector representing the direction of the new basis (Principal Component).

3. **Projection as a Matrix Multiplication**:
   - The projection of all data points onto \( \mathbf{w} \) can be written as \( \mathbf{X} \mathbf{w} \).
   - The variance we want to maximize is then:
     \[
     \|\mathbf{X} \mathbf{w}\|^2 = (\mathbf{X} \mathbf{w})^T (\mathbf{X} \mathbf{w})
     \]

4. **Simplified Expression**:
   - This can be further simplified using matrix algebra to:
     \[
     \|\mathbf{X} \mathbf{w}\|^2 = \mathbf{w}^T (\mathbf{X}^T \mathbf{X}) \mathbf{w}
     \]

#### Rayleigh Quotient

The expression \( \mathbf{w}^T (\mathbf{X}^T \mathbf{X}) \mathbf{w} \) is known as the **Rayleigh quotient**. In PCA, we aim to maximize this Rayleigh quotient to determine the direction \( \mathbf{w} \) of the first principal component.

- **Rayleigh Quotient**: This quantity represents the variance of the data along the direction \( \mathbf{w} \). By maximizing it, we find the direction where the data has the most spread (variance).

### Summary

- **Variance and PCA**: In PCA, we maximize the variance of the projections of data points onto a new basis vector \( \mathbf{w} \).
- **Matrix Form**: The problem of maximizing variance can be expressed as maximizing a Rayleigh quotient, \( \mathbf{w}^T (\mathbf{X}^T \mathbf{X}) \mathbf{w} \).
- **Rayleigh Quotient**: This quotient is the key mathematical expression that PCA seeks to maximize to determine the principal components. It encapsulates the idea of finding the direction \( \mathbf{w} \) that captures the maximum variance in the data.

By understanding this, you're well-equipped to follow and interpret the more detailed mathematical treatments of PCA that you might encounter in advanced texts or research papers.

## 8. Summary of PCA: Maximizing Variance and Finding Principal Components

Let's summarize the process of Principal Component Analysis (PCA) and how it relates to the mathematical steps we've discussed.

#### Goal of PCA: Maximizing Variance

- **Objective**: The main goal of PCA is to find the directions (called Principal Components) that maximize the variance of the data. The first principal component is the direction along which the data has the highest variance.
  
- **Mathematical Expression**: The variance of the projections of data points onto a new direction \( \mathbf{w} \) (the first principal component) can be written as:
  \[
  \mathbf{w}^T (\mathbf{X}^T \mathbf{X}) \mathbf{w}
  \]
  This expression represents the variance up to a constant factor, and \( \mathbf{w} \) is chosen to maximize this variance.

#### Finding the First Principal Component

1. **Maximize Variance**: We find the direction \( \mathbf{w} \) that maximizes the variance of the data projections. This direction is the first principal component.
  
2. **Projection and Orthogonality**: Once the first principal component is identified, each data vector \( \mathbf{x}_i \) can be decomposed into:
   - A component along the direction of the first principal component.
   - A residual component that is orthogonal to this direction.

#### Finding Subsequent Principal Components

1. **Subtract the First Component**: After finding the first principal component, we subtract the component of each data vector along this direction. This leaves us with new data vectors that lie in a space orthogonal to the first principal component.

   - **2D Example**: In a 2D space, the remaining data points after subtraction lie on a line perpendicular to the first principal component.
   - **3D Example**: In a 3D space, the data points after subtraction lie in a 2D plane perpendicular to the first principal component.

2. **Repeat the Process**: The same process is applied to this new set of data vectors to find the next principal component. This process continues until we have found a principal component for each original dimension of the data.

#### Visualizing the Process

- **First Component**: Imagine starting with a set of points in 3D space. The first principal component is the line along which the points are most spread out (have the most variance).
  
- **Subtracting and Finding the Next**: Once this line is identified, we effectively "flatten" the data by subtracting the component along this line, leaving us with a 2D plane. The next principal component is the direction within this plane that has the most variance.

- **Continuing in Higher Dimensions**: This process continues until we have identified a principal component for every dimension in the original data.

### Summary

- **Maximizing Variance**: The first principal component is chosen to maximize the variance of the data projections onto that direction.
- **Subsequent Components**: After identifying each principal component, we subtract its effect from the data and find the next component in the orthogonal space.
- **Iterative Process**: This continues until all dimensions are accounted for by a principal component, fully capturing the structure of the data in a new basis.

This approach allows PCA to reduce the dimensionality of the data while preserving as much variance (information) as possible, making it a powerful tool for data analysis and visualization.

## 9. Interpreting Principal Components in PCA

Now that we've found our principal components (PCs), it's essential to understand what they represent and how we interpret them in the context of a dataset.

#### What Are Principal Components?

- **Principal Components as New Dimensions**: After performing PCA, we obtain a new set of basis vectors called principal components. These vectors represent directions in the geometric space of the data.
  
- **Geometric Interpretation**: Geometrically, each principal component is a direction in space along which the data points have the most variance. The first principal component captures the most variance, the second captures the next most variance (while being orthogonal to the first), and so on.

#### Interpretation in the Context of a Dataset

- **Original Dimensions**: In a dataset, each dimension corresponds to a specific feature or measurement. For example, if you're analyzing stock returns, one dimension might represent the returns of Company A, another the returns of Company B, and so forth.

- **Principal Components as Combinations**: The principal components are linear combinations of the original dimensions. This means each principal component is formed by taking a weighted sum of the original features. Mathematically, each PC can be expressed as:
  \[
  \text{PC}_i = w_{i1} \times \text{Feature}_1 + w_{i2} \times \text{Feature}_2 + \ldots + w_{id} \times \text{Feature}_d
  \]
  Where \( w_{ij} \) are the weights that indicate how much each original feature contributes to the principal component.

#### Significance of Principal Components

- **Variance Explained**: The principal components are ordered by the amount of variance they explain. The first PC explains the most variance, the second PC explains the second most, and so on. This means that if you only keep the first few PCs, you retain the most critical information in the dataset.

- **Interpretability**: 
  - **Combinations of Features**: The PCs are combinations of the original features, so their "units" are mixed. For instance, in the stock returns example, a PC might represent a combination of returns from multiple companies.
  - **Real-World Meaning**: The PCs may not correspond to any real-world quantity that is directly interpretable. For example, the first PC might be a mix of returns from multiple companies, and this mix may not have a straightforward economic interpretation.

- **Importance of Context**: 
  - **Depends on the Problem**: Whether or not the PCs have a meaningful interpretation depends on the specific problem you're trying to solve.
  - **Dimensionality Reduction**: Often, the primary goal of PCA is to reduce dimensionality while preserving as much variance as possible, rather than ensuring the new dimensions have a clear real-world meaning.

### Summary

- **Principal Components**: These are new dimensions that are combinations of the original features, capturing the most variance in the data.
- **Interpretation**: The PCs might not always correspond to interpretable real-world quantities, and their significance depends on the problem context.
- **Dimensionality Reduction**: PCA is powerful for reducing the number of dimensions in the data while retaining the most critical information, even if the new dimensions are not directly interpretable.

Understanding the role and interpretation of principal components helps in applying PCA effectively, whether for simplifying complex data, visualizing high-dimensional datasets, or identifying the most important patterns in your data.

## 10. Explained Variance in PCA: Deciding How Many Principal Components to Use

Now that you understand what principal components (PCs) are, let’s explore an important concept: **explained variance**. This concept helps us decide how many principal components we should use in practice.

#### Key Concepts

1. **Explained Variance**: 
   - The explained variance refers to the amount of variance in the data that is captured by each principal component.
   - The first principal component (PC1) captures the most variance, the second PC captures the next most, and so on.
  
2. **Total Variance**: 
   - The total variance of a dataset is the sum of the variances along all dimensions (features). This total variance is preserved when you transform the data into the principal component space.
   - Mathematically, this is the sum of the squared distances of all data points from the origin.

3. **PCA as a Dimensionality Reduction Tool**:
   - Often, we don’t need to use all the PCs. Instead, we can reduce the dimensionality of our data by selecting a subset of the PCs that capture most of the variance.
   - For example, if you have a 2D dataset, you might choose to keep just the first PC if it captures most of the variance. This results in a lower-dimensional representation of the data.

#### Deciding How Many PCs to Keep

- **Cumulative Explained Variance**:
  - When deciding how many PCs to keep, one approach is to calculate the cumulative explained variance. This is the cumulative sum of the variance captured by each PC as you add them one by one.
  - For instance, if PC1 explains 70% of the variance and PC2 explains 20%, then together they explain 90% of the variance.

- **Threshold for Explained Variance**:
  - A common approach is to set a threshold, such as 95% of the total variance, and keep enough PCs to reach this threshold. This way, you retain most of the information while reducing the dimensionality.

#### Visual Example: 2D Dataset

- **Original Data**: 
  - Imagine a 2D dataset where each point has an x-coordinate and a y-coordinate.
  - After applying PCA, you obtain two PCs. The first PC might represent a line along which most data points lie, and the second PC represents the direction orthogonal to this line.

- **Using Just the First PC**:
  - If you decide to only use the first PC, each data point is now represented by its projection onto this line.
  - This simplifies the data to one dimension (a single coordinate) but loses the information about how far each point was along the second (y) direction.
  - If the data points were mostly aligned along the first PC to begin with, you lose very little information by ignoring the second PC.

#### Mathematical Perspective

- **Total Variance Preservation**:
  - The sum of variances along the original dimensions (e.g., x and y) equals the sum of variances along the new PC dimensions.
  - This equality is a direct consequence of the Pythagorean theorem, applied in the new PC space.

- **Variance of Each PC**:
  - Each PC is associated with a specific fraction of the total variance. By examining these fractions, you can decide which PCs to keep.
  - PCs associated with lower variance may be dropped if they don’t contribute significantly to the total variance.

### Conclusion

- **Dimensionality Reduction**: PCA allows us to reduce the dimensionality of a dataset by selecting only the principal components that capture the most variance. This reduction simplifies the dataset while retaining most of its information.
  
- **Explained Variance as a Guide**: The explained variance for each PC guides us in deciding how many components to keep. By focusing on the PCs that explain the majority of the variance, we can efficiently reduce the complexity of the dataset without losing much information.

## 11. Practical Application of PCA for Dimensionality Reduction

#### Introduction
In this session, we'll explore how to apply Principal Component Analysis (PCA) for dimensionality reduction using a small dataset. Dimensionality reduction is one of the primary applications of PCA, helping to simplify complex datasets by reducing the number of variables while retaining most of the original data's variance.

#### Dimensionality Reduction Explained
Consider a 2D dataset where most data points lie close to a straight line. This scenario suggests that the majority of the variation in the data occurs along this line, while the variation along the perpendicular direction is minimal. By projecting the data onto this line, we can reduce the 2D data to 1D without losing much information. This projection allows us to describe the data using fewer variables, simplifying the dataset while still capturing its essential characteristics.

#### Steps to Perform PCA

1. **Creating Correlated Data:**
   - We start by generating some random 2D data with a specified range and correlation. For example, data points might range between 10 and 80 on both the x and y axes, and we can adjust the correlation between these variables to see its effect on the data distribution.

2. **Centering and Normalizing the Data:**
   - Before applying PCA, we center the data around zero, a process called mean normalization. Centering is essential because PCA assumes that the data is centered. Normalization, though optional, helps distribute the data within a small interval around zero, improving the algorithm's efficiency.
   - After normalization, the data that originally ranged from 10 to 80 might now range between -3 and 3.

3. **Implementing PCA with Scikit-learn:**
   - We use Scikit-learn, a Python machine learning library, to perform PCA. First, we create a PCA object, specifying the number of principal components to retain.
   - Scikit-learn's PCA class automatically centers the data, so you can pass the original or normalized dataset to the `fit` method.
   - After fitting the model, we can access the principal components (eigenvectors) and their corresponding eigenvalues. The `explained_variance_ratio_` attribute shows the percentage of variance explained by each principal component, helping us decide how many components to keep.

4. **Visualizing Principal Components:**
   - Visualizing the data along the principal components reveals that the first principal component (PC1) aligns with the direction of maximum variance. This PC captures the most significant features of the data.

5. **Choosing the Number of Principal Components:**
   - Deciding how many principal components to retain depends on how much of the data's variance you want to keep. For instance, if PC1 explains 94% of the variance, and you want to retain 90%, you might choose to use just PC1.
   - For larger datasets, where you might have many dimensions, you'd sum the explained variances until you reach your desired threshold (e.g., 90%). The number of components you need to sum to reach this threshold determines how many principal components to keep.

6. **Dimensionality Reduction Example:**
   - In our simple 2D example, reducing the data to one dimension involves choosing one principal component. The transformed data, projected onto this component, results in a 1D representation—a straight line in this case.
   - For higher-dimensional datasets, the transformed data would lie on a lower-dimensional surface defined by the selected principal components.

#### Conclusion
PCA is a powerful tool for simplifying data by reducing its dimensions while preserving as much variance as possible. By understanding and applying PCA, you can transform complex datasets into more manageable forms, making them easier to analyze and interpret. Whether working with small datasets or large ones with many dimensions, PCA helps reveal the underlying structure of the data, aiding in more effective data analysis.

## 12. Factor Models of Risk and PCA

#### Overview
The focus of this lesson is on **factor models of risk** and how Principal Component Analysis (PCA) can be applied to create such models. Factor models are used extensively in finance to explain the returns of a large number of assets through a smaller number of factors, which capture the underlying sources of risk.

#### Data and Motivation
We start with a **set of time series** representing stock returns for many companies. The primary motivations for using PCA in this context are:

1. **Dimensionality Reduction:** Reducing the number of variables while retaining as much information as possible.
2. **Variance Capture:** Finding a new representation of the data that captures the maximum variance.

The end goal is to use this representation in an **optimization problem** aimed at minimizing risk.

#### Matrices and Dimensions
We deal with several matrices in this factor model, each with specific dimensions that relate to the companies, time points, and factors:

- **Returns Matrix \( R \):** \( n \times T \)  
  \( n \) = Number of companies  
  \( T \) = Number of time points

- **Factor Exposures Matrix \( F \):** \( n \times k \)  
  \( k \) = Number of factors

- **Factor Returns Matrix \( B \):** \( k \times T \)

- **Specific Risk Matrix \( \epsilon \):** \( n \times T \)

#### Applying PCA
PCA is used to find a new basis for the data. Here's how it works:

1. **New Basis Representation:** PCA transforms the original data into a new coordinate system where the principal components (PCs) are the axes.
  
2. **Reconstruction of Data:**
   - If we retain all the PCs, the data can be perfectly reconstructed by multiplying the transformed data (in the PC basis) by the matrix of PCs.
   - If we discard some PCs (dimensionality reduction), multiplying the transformed data by the matrix of retained PCs approximately reconstructs the original data.

3. **Factor Model Representation:** This approximation aligns closely with the factor model representation of the returns:
   \[
   R \approx F \cdot B + \epsilon
   \]
   Where:
   - \( F \) (Factor Exposures) corresponds to the loadings of the retained PCs.
   - \( B \) (Factor Returns) corresponds to the scores of the retained PCs.
   - \( \epsilon \) (Specific Risk) represents the residual or error term, capturing what’s left after the PCA-based factor model.

#### Conclusion
By using PCA, we convert a high-dimensional set of stock returns into a factor model that simplifies our understanding and management of risk. The factor model essentially uses the principal components to capture the most significant sources of variance (risk), allowing for more efficient portfolio management and risk minimization.

## 13. PCA as a Factor Model

#### Factor Exposures and Factor Returns

In the context of using Principal Component Analysis (PCA) as a factor model, the key matrices involved are:

1. **Factor Exposures Matrix \( F \):**
   - This matrix represents the coordinates of the principal components (PCs) in the original basis.
   - It can be thought of as the loadings of each stock (or asset) on the principal components.
   - Since PCA typically results in an orthonormal basis, the inverse of this matrix is simply its transpose: \( F^{-1} = F^T \).

2. **Factor Returns Matrix \( B \):**
   - This matrix is the data transformed into the new coordinate system (the PCA basis).
   - To calculate the factor returns \( B \), you multiply the original returns matrix \( R \) by the transpose of the factor exposures matrix \( F \):
     \[
     B = F^T \cdot R
     \]

#### Factor Covariance Matrix

Once you have the factor returns, the next step in constructing a risk model is to compute the **factor covariance matrix**. This matrix is crucial for understanding the relationships between the different factors:

- **Orthogonality of Factors:**
  - In PCA, the factors (principal components) are orthogonal, meaning they are uncorrelated with each other.
  - As a result, the factor covariance matrix \( \Sigma_B \) is diagonal, with the diagonal elements representing the variances of each factor:
    \[
    \Sigma_B = \text{diag}(\text{Var}(B_1), \text{Var}(B_2), \dots, \text{Var}(B_k))
    \]

- **Variance and Annualization:**
  - If the factor returns are based on daily returns, the variances computed are daily variances.
  - To annualize these variances, multiply the entire covariance matrix by an annualization factor (typically 252, the approximate number of trading days in a year):
    \[
    \Sigma_B^{\text{annualized}} = 252 \times \Sigma_B
    \]
  - No square root is needed because we are dealing with variances, not standard deviations.

#### Specific (Idiosyncratic) Risk Matrix

The **specific risk matrix** \( \Sigma_{\epsilon} \) captures the risk that is unique to each asset (i.e., not explained by the factors):

- **Residuals Calculation:**
  - The residuals \( \epsilon \) are the differences between the original returns and the returns explained by the principal components:
    \[
    \epsilon = R - F \cdot B
    \]

- **Covariance of Residuals:**
  - The covariance matrix of these residuals gives an estimate of the idiosyncratic risk.
  - However, to simplify the model and focus on the specific risk unique to each asset, we set the off-diagonal elements of this covariance matrix to zero, resulting in a diagonal matrix:
    \[
    \Sigma_{\epsilon} = \text{diag}(\text{Var}(\epsilon_1), \text{Var}(\epsilon_2), \dots, \text{Var}(\epsilon_n))
    \]

#### Interpretation and Limitations

- **Interpretation of Factors:**
  - The factors derived from PCA represent latent drivers of return variance. They do not have a direct physical or economic interpretation but can be thought of as underlying sources of risk.

- **Limitations:**
  - By focusing on the principal components, the model captures most of the correlations in the data, but not all. This simplification is reasonable in practice as it highlights the most significant risk drivers while acknowledging that some information is lost.

### Summary

PCA as a factor model involves deriving factor exposures, factor returns, and the corresponding covariance matrices. The key insights include the orthogonality of factors, the diagonal nature of the factor covariance matrix, and the way specific risk is isolated by zeroing out off-diagonal elements in the residual covariance matrix. This approach allows for a simplified yet powerful way to model and manage risk in a high-dimensional setting.
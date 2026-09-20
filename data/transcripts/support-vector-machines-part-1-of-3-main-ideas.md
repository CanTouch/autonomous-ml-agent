---
title: "Support Vector Machines Part 1 (of 3): Main Ideas!!!"
url: "https://www.youtube.com/watch?v=efR1C6CvhmE"
date: "2019-09-30"
video_id: "efR1C6CvhmE"
uploader: "StatQuest with Josh Starmer"
language: "en"
---

# Support Vector Machines Part 1 (of 3): Main Ideas!!!

Support vector machines have a lot of terminology associated with them. Brace yourself. StatQuest Hello, I'm Josh Starmer and welcome to StatQuest. Today, we're going to talk about support vector machines and they're going to be clearly explained. Note, this StatQuest assumes that you are already familiar with the trade-off that plagues all of machine learning, the bias-variance trade-off.

You should also be familiar with cross-validation. If not, check out the quests. The links are in the description below. Let's start by imagining we measured the mass of a bunch of mice. The red dots represent mice that are not obese. And the green dots represent mice that are obese.

Based on these observations, we can pick a threshold. And when we get a new observation that has less mass than the threshold, we can classify it as not obese. And when we get a new observation with more mass than the threshold, we can classify it as obese. However, what if we get a new observation here?

Because this observation has more mass than the threshold, we classify it as obese. But that doesn't make sense because it is much closer to the observations that are not obese. So, this threshold is pretty lame. Can we do better? Yes. Going back to the original training data set, we can focus on the observations on the edges of each cluster and use the midpoint between them as the threshold.

Now, when a new observation falls on the left side of the threshold, it will be closer to the observations that are not obese than it is to the obese observations. So, it makes sense to classify this new observation as not obese. Bam! Oh, no! It's a terminology alert.

The shortest distance between the observations and the threshold is called the margin. Since we put the threshold halfway between these two observations, the distances between the observations and the threshold are the same and both reflect the margin. When the threshold is halfway between the two observations, the margin is as large as it can be.

For example, if we move the threshold to the left a little bit, then the distance between the threshold and the observation that is not obese would be smaller. And thus, the margin would be smaller than it was before. And if we move the threshold to the right a little bit, then the distance between the obese observation and the threshold would get smaller.

And again, the margin would be smaller. When we use the threshold that gives us the largest margin to make classifications, heads up, terminology alert. We are using a maximal margin classifier. Bam? No. No bam. Maximal margin classifiers seem pretty cool, but what if our training data looked like this?

And we had an outlier observation that was classified as not obese, but was much closer to the obese observations. In this case, the maximum margin classifier would be super close to the obese observations. And really far from the majority of the observations that are not obese. Now, if we got this new observation, we would classify it as not obese, even though most of the not obese observations are much further away than the obese observations.

So, maximum margin classifiers are super sensitive to outliers in the training data, and that makes them pretty lame. Can we do better? Yes. To make a threshold that is not so sensitive to outliers, we must allow misclassifications. For example, if we put the threshold halfway between these two observations, then we will misclassify this observation.

However, now when we get a new observation here, we will classify it as obese. And that makes sense, because it is closer to most of the obese observations. Choosing a threshold that allows misclassifications is an example of the bias-variance tradeoff that plagues all of machine learning. In other words, before we allowed misclassifications, we picked a threshold that was very sensitive to the training data. It had low bias.

And it performed poorly when we got new data. It had high variance. In contrast, when we picked a threshold that was less sensitive to the training data and allowed misclassifications, so it had higher bias, it performed better when we got new data. So, it had low variance. Small bam.

Oh, no. It's another terminology alert. When we allow misclassifications, the distance between the observations and the threshold is called a soft margin. So, the question is, how do we know that this soft margin is better than this soft margin? The answer is simple. We use cross-validation to determine how many misclassifications and observations to allow inside of the soft margin to get the best classification.

For example, if cross-validation determined that this was the best soft margin, then we would allow one misclassification and two observations that are correctly classified to be within the soft margin. Bam. When we use a soft margin to determine the location of a threshold, brace yourself, we have another terminology alert.

Then we are using a soft margin classifier, aka a support vector classifier, to classify observations. The name support vector classifier comes from the fact that the observations on the edge and within the soft margin are called support vectors. Super small bam. Note, if each observation had a mass measurement and a height measurement, then the data would be two-dimensional.

When the data are two-dimensional, a support vector classifier is a line. And in this case, the soft margin is measured from these two points. The blue parallel lines gives us a sense of where all of the other points are in relation to the soft margin. These observations are outside of the soft margin.

And this observation is inside the soft margin and misclassified. Just like before, we used cross-validation to determine that allowing this misclassification results in better classification in the long run. Bam! Now, if each observation has a mass, a height, and an age, then the data would be three-dimensional. Note, the axis that age is on is supposed to represent depth.

And these circles are larger in order to appear closer and thus younger. And these circles are smaller in order to look further away and thus older. When the data are three-dimensional, the support vector classifier forms a plane instead of a line. And we classify new observations by determining which side of the plane they are on.

For example, if this were a new observation, we would classify it as not obese since it is above the support vector classifier. Note, if we measured mass, height, age, and blood pressure, then the data would be in four dimensions. And I don't know how to draw four-dimensional graph.

Wah, wah. But we know that when the data are one-dimensional, the support vector classifier is a single point on a one-dimensional number line. Psst. In mathematical jargon, a point is a flat affine zero-dimensional subspace. And when the data are in two dimensions, the support vector classifier is a one-dimensional line in a two-dimensional space.

Psst. In mathematical jargon, a line is a flat affine one-dimensional subspace. And when the data are three-dimensional, the support vector classifier is a two-dimensional plane in a three-dimensional space. Psst. In mathematical jargon, a plane is a flat affine two-dimensional subspace. And when the data are in four or more dimensions, the support vector classifier is a hyperplane.

Psst. In mathematical jargon, a hyperplane is a flat affine subspace. Note. Technically speaking, all flat affine subspaces are called hyperplanes. So, technically speaking, this one-dimensional line is a hyperplane. But we generally only use the term when we can't draw it on paper. Small bam, because this is just more terminology.

Ugh. Support vector classifiers seem pretty cool because they can handle outliers and because they can allow misclassifications, they can handle overlapping classifications. But what if this was our training data and we had tons of overlap? In this new example with tons of overlap, we are now looking at drug dosages.

And the red dots represent patients that were not cured. And the green dots represent patients that were cured. In other words, the drug doesn't work if the dosage is too small or too large. It only works when the dosage is just right. Now, no matter where we put the classifier, we will make a lot of misclassifications.

So, support vector classifiers are only semi-cool since they don't perform well with this type of data. Can we do better than maximal margin classifiers and support vector classifiers? Yes. Since maximal margin classifiers and support vector classifiers can't handle this data, it's high time we talked about support vector machines.

So, let's start by getting an intuitive sense of the main ideas behind support vector machines. We start by adding a Y axis so we can draw a graph. The X axis coordinates in this graph will be the dosages that we have already observed. And the Y axis coordinates will be the square of the dosages.

So, for this observation with dosage equals 0.5 on the X axis, the Y axis value equals dosage squared, which equals 0.5 squared, which equals 0.25. Now, we use dosage squared for this Y axis coordinate. And then we use dosage squared for the Y axis coordinates for the remaining observations.

Since each observation has X and Y axis coordinates, the data are now two-dimensional. And now that the data are two-dimensional, we can draw a support vector classifier that separates the people who were cured from the people who were not cured. And the support vector classifier can be used to classify new observations.

For example, if a new observation had this dosage, then we could calculate the Y-axis coordinate by squaring the dosage, and classify the observation as not cured because it ended up on this side of the support vector classifier. On the other hand, if we got a new observation with this dosage, then we would square the dosage and get a Y-axis coordinate, and classify this observation as cured because it falls on the other side of the support vector classifier.

Bam! The main ideas behind support vector machines are one, start with data in a relatively low dimension. Psst. In this example, the data started in one dimension. Two, move the data into a higher dimension. Psst. In this example, we moved the data from one dimension to two dimensions.

Three, find a support vector classifier that separates the higher dimensional data into two groups. That's all there is to it. Double bam! Going back to the original one-dimensional data, you may be wondering why we decided to create Y-axis coordinates with dosage squared. Why not dosage cubed? Or pi divided by 4 * the square root of dosage?

In other words, how do we decide how to transform the data? In order to make the mathematics possible, support vector machines use something called kernel functions to systematically find support vector classifiers in higher dimensions. So, let me show you how a kernel function systematically finds support vector classifiers in higher dimensions.

For this example, I use the polynomial kernel, which has a parameter D, which stands for the degree of the polynomial. When D equals 1, the polynomial kernel computes the relationships between each pair of observations in one dimension. And these relationships are used to find a support vector classifier.

When D equals 2, we get a second dimension based on dosages squared. And the polynomial kernel computes the two-dimensional relationships between each pair of observations. And those relationships are used to find a support vector classifier. And when we set D equal 3, then we would get a third dimension based on dosages cubed.

And the polynomial kernel computes the three-dimensional relationships between each pair of observations. And those relationships are used to find a support vector classifier. And when D equals 4 or more, then we get even more dimensions to find a support vector classifier. In summary, the polynomial kernel systematically increases dimensions by setting D, the degree of the polynomial.

And the relationships between each pair of observations are used to find a support vector classifier. Last but not least, we can find a good value for D with cross-validation. Double bam! Another very commonly used kernel is the radio kernel, also known as the radial basis function kernel. Unfortunately, the radio kernel finds support vector classifiers in infinite dimensions. So, I can't give you an example of what it does exactly.

However, when using it on a new observation like this, the radio kernel behaves like a weighted nearest neighbor model. In other words, the closest observations, aka the nearest neighbors, have a lot of influence on how we classify the new observation. And observations that are further away have relatively little influence on the classification.

So, since these observations are the closest to the new observation, the radio kernel uses their classification for the new observation. Bam! Now, for the sake of completeness, let me mention one last detail about kernels. Although the examples I've given show the data being transformed from a relatively low dimension to a relatively high dimension, kernel functions only calculate the relationships between every pair of points as if they are in the higher dimensions. They don't actually do the

transformation. This trick, calculating the high-dimensional relationships without actually transforming the data to the higher dimension, is called the kernel trick. The kernel trick reduces the amount of computation required for support vector machines by avoiding the math that transforms the data from low to high dimensions. And it makes calculating the relationships in the infinite dimensions used by the radial kernel possible.

However, regardless of how the relationships are calculated, the concepts are the same. When we have two categories, but no obvious linear classifier that separates them in a nice way, support vector machines work by moving the data into a relatively high dimensional space and finding a relatively high dimensional support vector classifier that can effectively classify the observations.

Triple bam! Hooray! We made it to the end of another exciting StatQuest. If you like this StatQuest and want to see more, please subscribe. And if you want to support StatQuest, consider contributing to my Patreon campaign, becoming a channel member, buying one or two of my original songs, or a t-shirt, or a hoodie, or just donate. The links are in the description below. All right. Until next time, quest on.

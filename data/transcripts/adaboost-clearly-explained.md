---
title: "AdaBoost, Clearly Explained"
url: "https://www.youtube.com/watch?v=LsK-xG1cLYA"
date: "2019-01-14"
video_id: "LsK-xG1cLYA"
uploader: "StatQuest with Josh Starmer"
language: "en"
---

# AdaBoost, Clearly Explained

Machine learning sounds so complicated, but it's not so complicated. StatQuest. Hello, I'm Josh Starmer, and welcome to StatQuest. Today, we're going to cover AdaBoost, and it's going to be clearly explained. Note, this StatQuest shows how to combine AdaBoost with decision trees, because that is the most common way to use AdaBoost. So, if you're not familiar with decision trees, check out the quest.

We will also mention random forests, so if you don't know about them, check out the quest. We'll start by using decision trees and random forests to explain the three concepts behind AdaBoost. Then, we'll get into the nitty-gritty details of how AdaBoost creates a forest of trees from scratch, and how it's used to make classifications.

So, let's start by using decision trees and random forests to explain the three main concepts behind AdaBoost. In a random forest, each time you make a tree, you make a full-sized tree. Some trees might be bigger than others, but there's no predetermined maximum depth. In contrast, in a forest of trees made with AdaBoost, the trees are usually just a node and two leaves.

Oh, no, it's the dreaded terminology alert. A tree with just one node and two leaves is called a stump. So, this is really a forest of stumps rather than trees. Stumps are not great at making accurate classifications. For example, if we were using this data to determine if someone had heart disease or not, then a full-sized decision tree would take advantage of all four variables that we measured, chest pain, blood circulation, blocked arteries, and weight, to make a decision.

But, a stump can only use one variable to make a decision. Thus, stumps are technically weak learners. However, that's the way AdaBoost likes it, and it's one of the reasons why they are so commonly combined. Now, back to the random forest. In a random forest, each tree has an equal vote on the final classification.

This tree's vote is worth just as much as this tree's vote, or this tree's vote. In contrast, in a forest of stumps made with AdaBoost, some stumps get more say in the final classification than others. In this illustration, the larger stumps get more say in the final classification than the smaller stumps.

Lastly, in a random forest, each decision tree is made independently of the others. In other words, it doesn't matter if this tree was made first, or this one. In contrast, in a forest of stumps made with AdaBoost, order is important. The errors that the first stump makes influence how the second stump is made.

And the errors that the second stump makes influence how the third stump is made. Etcetera, etcetera, etcetera. To review, the three ideas behind AdaBoost are: One, AdaBoost combines a lot of weak learners to make classifications. The weak learners are almost always stumps. Two, some stumps get more say in the classification than others.

Three, each stump is made by taking the previous stumps mistakes into account. Bam! Now, let's dive into the nitty-gritty detail of how to create a forest of stumps using AdaBoost. First, we'll start with some data. We create a forest of stumps with AdaBoost to predict if a patient has heart disease.

We will make these predictions based on a patient's chest pain and blocked artery status and their weight. The first thing we do is give each sample a weight that indicates how important it is to be correctly classified. Note, the sample weight is different from the patient weight, and I'll do the best I can to be clear about which of the two I'm talking about.

At the start, all samples get the same weight. One divided by the total number of samples. In this case, that's one divided by eight. And that makes the samples all equally important. However, after we make the first stump, these weights will change in order to guide how the next stump is created.

In other words, we'll talk more about the sample weights later. Now, we need to make the first stump in the forest. This is done by finding the variable chest pain, blocked arteries, or patient weight that does the best job classifying the samples. Note, because all of the weights are the same, we can ignore them right now.

We start by seeing how well chest pain classifies the samples. Of the five samples with chest pain, three were correctly classified as having heart disease. And two were incorrectly classified. Of the three samples without chest pain, two were correctly classified as not having heart disease. And one was incorrectly classified.

Now we do the same thing for blocked arteries. And for patient weight. Note, we used the techniques described in the decision tree StatQuest to determine that 176 was the best weight to separate the patients. Now we calculate the Gini index for the three stumps. The Gini index for patient weight is the lowest.

So this will be the first stump in the forest. Now we need to determine how much say this stump will have in the final classification. Remember, some stumps get more say in the final classification than others. We determine how much say a stump has in the final classification based on how well it classified the samples.

This stump made one error. This patient, who weighs less than 176, has heart disease, but the stump says they do not. The total error for a stump is the sum of the weights associated with the incorrectly classified samples. Thus, in this case, the total error is 1/8. Note, because all of the sample weights add up to one, total error will always be between zero for a perfect stump and one for a horrible stump.

We use the total error to determine the amount of say this stump has in the final classification with the following formula. Amount of say equals 1/2 times the log of 1 minus the total error divided by the total error. We can draw a graph of the amount of say by plugging in a bunch of numbers between zero and one for total error.

The blue line tells us the amount of say for total error values between zero and one. When a stump does a good job and the total error is small, then the amount of say is a relatively large positive value. When a stump is no better at classification than flipping a coin, i.e. half the stumps are correctly classified and half are incorrectly classified, and the total error equals 0.5, then the amount of say will be zero.

And when a stump does a terrible job and the total error is close to one, in other words, if the stump consistently gives you the opposite classification, then the amount of say will be a large negative value. So if a stump votes for heart disease, the negative amount of say will turn that vote into not heart disease.

Note, if total error is one or zero, then this equation will freak out. In practice, a small error term is added to prevent this from happening. With patient weight greater than 176, the total error is 1/8, so we just plug and chug. And the amount of say that this stump has on the final classification is 0.97.

Bam! Now that we've worked out how much say this stump gets when classifying a sample, let's work out how much say the chest pain stump would have if it had been the best stump. Note, we don't need to do this, but I think it helps illustrate the concepts we've covered so far.

Chest pain made three errors. And the total error equals the sum of the weights for the incorrectly classified samples. So, the total error for chest pain is 3/8. We can get a sense of what the amount of say will be by looking at the graph when total error equals 3/8.

So, we are expecting the amount of say to be between 0 and 0.5. Now, we plug 3/8 into the formula for the amount of say and do the math. And the amount of say that the chest pain stump would have had on the final classification is 0.42. I'll leave the blocked artery stump as an exercise for the viewer.

Now, we know how the sample weights for the incorrectly classified samples are used to determine the amount of say each stump gets. Bam! Now, we need to learn how to modify the weights so that the next stump will take the errors that the current stump made into account.

Let's go back to the first stump that we made. When we created this stump, all of the sample weights were the same. And that meant we did not emphasize the importance of correctly classifying any particular sample. But, since this stump incorrectly classified this sample, we will emphasize the need for the next stump to correctly classify it by increasing its sample weight and decreasing all of the other sample weights.

Let's start by increasing the sample weight for the incorrectly classified sample. This is the formula we will use to increase the sample weight for the sample that was incorrectly classified. We plug in the sample weight from the last stump and we scale 1/8 with this term. To get a better understanding of how this part will scale the previous sample weight, let's draw a graph.

The blue line is equal to e raised to the amount of say. When the amount of say is relatively large, i.e. the last stump did a good job classifying samples, then we will scale the previous sample weight with a large number. This means that the new sample weight will be much larger than the old one.

And when the amount of say is relatively low, i.e. the last stump did not do a very good job classifying samples, then the previous sample weight is scaled by a relatively small number. This means that the new sample weight will only be a little larger than the old one.

In this example, the amount of say was 0.97. And e raised to the 0.97 equals 2.64. That means the new sample weight is 0.33, which is more than the old one. Bam. Now we need to decrease the sample weights for all of the correctly classified samples. This is the formula we will use to decrease the sample weights.

The big difference is the negative sign in front of amount of say. Just like before, we plug in the sample weight. And just like before, we can get a better understanding of how this will scale the sample weight by plotting a graph using different values for amount of say.

The blue line represents e raised to the negative amount of say. When the amount of say is relatively large, then we scale the sample weight by a value close to zero. This will make the new sample weight very small. If the amount of say for the last stump is relatively small, then we will scale the sample weight by a value close to one.

This means that the new sample weight will be just a little smaller than the old one. In this example, the amount of say was 0.97. And e raised to the negative 0.97 equals 0.38. The new sample weight is 0.05, which is less than the old one. Bam. We will keep track of the new sample weights in this column.

We plug in 0.33 for the sample that was incorrectly classified. All of the other samples get 0.05. Now we need to normalize the new sample weights so that they will add up to one. Right now, if you add up the new sample weights, you get 0.68. So we divide each new sample weight by 0.68 to get the normalized values.

Now, when we add up the new sample weights, we get one, plus or minus a little rounding error. Now we just transfer the normalized sample weights to the sample weights column, since those are what we will use for the next stump. Now we can use the modified sample weights to make the second stump in the forest.

Bam! In theory, we could use the sample weights to calculate weighted Gini indexes to determine which variable should split the next stump. The weighted Gini index would put more emphasis on correctly classifying this sample, the one that was misclassified by the last stump, since this sample has the largest sample weight.

Alternatively, instead of using a weighted Gini index, we can make a new collection of samples that contains duplicate copies of the samples with the largest sample weights. So we start by making a new, but empty, data set that is the same size as the original. Then we pick a random number between 0 and 1.

And we see where that number falls when we use the sample weights like a distribution. If the number is between 0 and 0.7, then we would put this sample into the new collection of samples. And if the number is between 0.7 and 0.14, then we would put this sample into the new collection of samples.

And if the number is between 0.14 and 0.21, then we would put this sample into the new collection of samples. And if the number is between 0.21 and 0.70, then we would put this sample into the new collection of samples. Et cetera, et cetera. For example, imagine the first number I picked was 0.72.

Then I would put this sample into my new collection of samples. Then I pick another random number and get 0.42. And I would put this sample into my new collection of samples. Then I pick 0.83. And I would put this sample into my new collection of samples. Then I pick 0.51.

And I would put this sample into my new collection of samples. Note, this is the second time we have added this particular sample to the new collection of samples. We then continue to pick random numbers and add samples to the new collection until the new collection is the same size as the original.

Ultimately, this sample was added to the new collection of samples four times, reflecting its larger sample weight. Now we get rid of the original samples and use the new collection of samples. Lastly, we give all of the samples equal sample weights, just like before. However, that doesn't mean the next stump will not emphasize the need to correctly classify these samples.

Because these samples are all the same, they will be treated as a block, creating a large penalty for being misclassified. Now we go back to the beginning and try to find the stump that does the best job classifying the new collection of samples. So that is how the errors that the first tree makes influence how the second tree is made.

And how the errors that the second tree makes influence how the third tree is made. Etcetera, etcetera, etcetera. Double bam! Now we need to talk about how a forest of stumps created by AdaBoost makes classifications. Imagine that these stumps classified a patient as has heart disease. And these stumps classified the patient as does not have heart disease.

These are the amounts of say for these stumps. And these are the amounts of say for these stumps. Now we add up the amounts of say for this group of stumps and for this group of stumps. Ultimately, the patient is classified as has heart disease because this is the larger sum.

Triple bam! To review, the three ideas behind AdaBoost are one, AdaBoost combines a lot of weak learners to make classifications. The weak learners are almost always stumps. Two, some stumps get more say in the classification than others. And three, each stump is made by taking the previous stumps mistakes into account.

If we have a weighted gini function, then we use it with the sample weights. Otherwise, we use the sample weights to make a new data set that reflects those weights. Hooray! We've made it to the end of another exciting StatQuest. If you like this StatQuest and want to see more, please subscribe.

And if you want to support StatQuest, well, consider buying a t-shirt or a hoodie, or buying one or two of my original songs. The links to do this are in the description below. All right, until next time, quest on.

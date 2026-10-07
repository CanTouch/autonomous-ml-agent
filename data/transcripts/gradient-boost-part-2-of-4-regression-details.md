---
title: "Gradient Boost Part 2 (of 4): Regression Details"
url: "https://www.youtube.com/watch?v=2xudPOBz-vs"
date: "2019-04-01"
video_id: "2xudPOBz-vs"
uploader: "StatQuest with Josh Starmer"
language: "en"
---

# Gradient Boost Part 2 (of 4): Regression Details

gradient boost is awesome gradient boost is cool now we're going to dive into some regression details stack Quest hello I'm Josh starmer and welcome to stack Quest today we're going to continue our series on gradient boost specifically we're going to dive into the algorithmic details of how gradient boost is used for regression note this stat Quest assumes who have already watched the first video in this series gradient boost part one regression main ideas if not check out

the quest also although not required it might be helpful if you understand gradient descent so check out that Quest if you haven't already in this stat Quest we are going to walk through the original gradient boost algorithm step by step in order to keep the example from getting out of hand and we are going to use gradient boost to fit a model to a super simple training data set which contains height measurements from three people their favorite color their gender

and their weight great now that we know all about this super simple training data set let's walk through the original gradient descent algorithm step by step we'll start from the top this line describes in an abstract way the training data set and the method we will use to evaluate how well the model fits the training data set this first part is just a fancy way to say that we have some data the x sub I refer to each row of

measurements that we will use to predict weight and the Y sub eyes refer to the weights measured for each person in the data set this part just says that the I's in x sub I and Y sub by go from 1 to n where n is the number of people in our data set in this case n equal three since we only have three rows of data Al together this means that we will refer to this row of measurements as x

sub one and we will refer to this weight as y sub one this row of measurements is x sub 2 and this weight is y sub 2 this row of measurements is X sub3 and this weight is y sub3 now we need a differentiable loss function in this case a loss function is just something that evaluates how well we can predict weight the loss function that is most commonly used doing regression with gradient boost is 12 time the observed value minus the

predicted value squared now just for a few minutes humor me and ignore the one/ half in front when we remove the 1/2 we end up with the same loss function we use for linear regression for example if we had height and weight measurements from three people then we could fit a line to the data residuals are the differences between the observed weights and the weights that are predicted by the line we can evaluate how well this

greenish line fits the data with the sum of the squared residuals thus the loss function is just a squared residual if we wanted to compare how well this greenish line fit the data to this pink line then we would calculate the residuals the difference between the observed and the predicted values for the greenish line Square them and add them up and get 0.26 for the sum of the squared residuals for the greenish line then we would do the same thing for the

pink line and I would see that 0.26 for the greenish line is smaller than 6.43 for the pink line so the greenish line is a better fit because it's some of the squared residuals is smaller note if I multiplied both sides of the formulas by 1/2 and did the math then we would get smaller numbers but we would still know that the greenish line fits the data better since its number is still relatively smaller in other words it doesn't matter

if the loss function is the observed value minus the predicted value squared or if it's 12 * The observed value minus the predicted value squar red since both will tell us that the greenish line has the best fit the reason why people choose this loss function for gradient boost is that when we differentiate it with respect to predicted and use the chain Rule and bring the square down to the front and multiply it by the derivative

of minus predicted which is -1 then the 2 / 2 cancels out and that leaves you with the observed minus the predicted multiplied by -1 in other words we are left with the negative residual and that makes the math easier since gradient boost uses the derivative a lot okay we've got a loss function the Y sub i's are the observed values and F ofx is a function that gives us the predicted values note we'll talk more about F ofx

later we also know that the loss function is differentiable since we have already taken the derivative bam we figured out what the input is for the gradient boost algorithm we've got data and we've got a differentiable loss function note there are other loss functions to choose from but this is the most popular one for regression hooray now we're ready for step one we start by initializing the model with a constant value and that constant value is determined by this funky

looking thing this funky looking thing is easiest to understand if we start on the right side and work our way left this is just the loss function the Y subi refers to the observed values and that funky looking Sy called gamma refers to the predicted values the summation means that we add up one loss function for each observed value and the ARG Min over gamma means we need to find a predicted value that minimizes this sum in other words if we

plot The observed weights on a number line then we want to find the point on the line that minimizes the sum of the squared residuals / 2 here's a plot of 1/2 of the sum of the squared residuals for potential predicted values note we could use gradient descent to find the optimal value for predicted but we can also just solve for it because the math isn't that hard the first thing we do is take the derivative

of each term with respect to predicted and since we've already shown how to take the derivative of our loss function we can just plug it in then we set the sum of the derivatives equal to zero and solve and we end up with the average of The observed weights so given this loss function the value for gamma that minimizes this sum is the average of The observed weights we have now created the initial predicted value fb0 of x and it equals

73.3 that means that the initial predicted value fb0 of x is just a leaf the leaf predicts that all samples will weigh 73.3 bam we finished step one we initialized the model with a constant value F sub Sub 0 of X = 73.3 in other words we created a leaf that predicts all samples will weigh 73.3 now we can work on step two step two is huge but we'll take it one step at a time step two is a loop

where we make all of the trees in generic terms we will make M trees but in practice most people said M to be 100 and make 100 trees Little M refers to an individual tree so when little m equals 1 then we're talking about the first tree when little m equals Big M then we're talking about the last tree and when Little M is somewhere between one and Big M then we're talking about a tree somewhere between one and

Big M since we are just starting step two we will set Little M equal to 1 part A of step two looks nasty but it's not this part is just the derivative of the loss function with respect to the predicted value and we've already calculated this this big minus sign tells us to multiply the derivative by -1 and that leaves us with the observed value minus the predicted value in other words this nasty looking thing is just a

residual now we plug f subm minus1 of x in for predicted and since m equal 1 that means we plug in F Sub 0 ofx for f submus one of X and since F Sub 0 of X is just the leaf set to 73.3 we plug in 73.3 now we can compute R sub I comma M where R is short for residual I is the sample number and M is the tree that we're trying to build this tells us to calculate

residuals for all three samples in the data set so we'll start with r sub1 comma 1 the residual for the first sample and the first tree so we plug in the observed weight for the first sample and get 14.7 we'll keep track of R sub 1 comma 1 by adding it to the data set now we calculate R sub2 comma 1 and we calculate R sub3 comma 1 hooray we finished part A of step two by calculating a residual for each

sample example note before we move on I just want to point out that this derivative is the gradient that gradient boost is named after little bam I also want to point out that the r subi comma M values are technically called pseudo residuals when we use this loss function we end up calculating normal residuals but if we used another LW function this time we're not multiplying by 1/2 then we would end up with something similar to a residual but not

quite in other words we'd end up with a pseudo residual and that's why the r sub I comma M's are called pseudo residuals okay now let's do Part B all this is saying is that we will build a regression tree to predict the residuals instead of the weights so we will use height favorite color and gender to predict the residuals here's the new tree yes I know this is just a stump and gradient boost almost always uses larger trees however

in order to demonstrate the details of the gradient boost algorithm we need at least one leaf with more than one sample in it and when you only have three samples then you can't have more than two leaves so we're stuck using stumps even though they are not typically used with gradient boost the residual for the third sample X sub3 goes to the leaf on the left and the residual for samples x sub1 and x sub2 go to the leaf on the

right so we have a regression tree fit to the residuals now we need to create terminal regions R subj comma M this part is super easy because the leaves are the terminal regions R subj comma M note this little m is the index for the tree we just made since this is the first tree m equal 1 and this little J is the index for each Leaf in the tree since this tree has two leaves J

subm equals 2 so in this example we'll let this Leaf be R sub 1 comma 1 and this Leaf be R sub 2 comma 1 note it doesn't matter which Leaf gets which label however once we give a leaf a label we need to keep track of it hooray we finished Part B of step two by fitting a regression tree to the residuals and labeling the leaves now let's do part C in this part we determine the output

values for each Leaf specific specifically since two residuals ended up in this Leaf it's unclear what its output value should be so for each Leaf in the new tree we compute an output value gamma subj comma M the output value for each Leaf is the value for gamma that minimizes this summation note this minimization is like what we did in step one one small difference is that now we are taking the previous prediction into account while before since we were just

starting out there was no previous prediction the other difference is that this summation is picky about which samples it includes while before the summation included all of the samples specifically the x sub I in R sub I comma J means that since only one sample X sub3 3 goes to Leaf R sub 1A 1 then only X sub3 is used to calculate the output value for R sub 1 comma 1 and since only two samples x sub 1 and

xub 2 go to Leaf R sub 1 comma 2 then only x sub1 and x sub2 are used to calculate the output value for R sub1a 2 let's start by calculating the output value for the leaf on the left R sub 1A 1 that means Jal 1 since this is the first leaf and m equal 1 since this is the first tree now let's replace the generic loss function with the actual loss function that we decided to use and let's expand

the summation into individual terms since only X sub3 goes to R sub 1 comma 1 expanding means we remove the big Sigma and swap the eyes with threes now we plug in the value for y sub3 The observed value and the most recent predicted value for x sub3 since m equal 1 the most recent prediction was F Sub 0 of X which predicted that all samples weighed 73.3 so we plug in 73.3 for f subm minus1 of x sub3

and simplify what's inside the parentheses now we need to find the value for gamma that minimizes this equation just like step one we can try different values for Gamma or Solve IT analytically since the math is easy we'll solve for it first we take the derivative of the loss function with respect to gamma just like we did at the very start we use the chain R and get this now we set the derivative equal to zero and

solve the value for gamma that minimizes this equation is -7.3 and that means gamma sub 1A 1 = -7.3 and ultimately the leaf R sub 1A 1 has an output value of -7.3 now let's solve for the output value for R sub 2 comma 1 that means J equal 2 since this is the second leaf and M equals 1 since this is still the first tree now plug in the loss function expand the summation plug in the observed

weights and plug in 73.3 for f subm minus1 of x sub 1 and f subn minus1 of x sub 2 now simplify what's inside the parentheses and take the derivative with respect to gamma using the chain Rule and that gives us this derivative which we set equal to zero and then we solveo we end up with the average average of the residuals that ended up in leaf R sub 2 comma 1 and that equals 8.7 so the value for gamma that

minimizes this equation is 8.7 and that means gamma sub 2 comma 1 = 8.7 and ultimately the leaf R sub2 comma 1 has an output value of 8.7 one last little observation before we move on we just saw that the output value for this Leaf R sub2 comma 1 is the average of the residuals that ended up here given our choice of loss function the output values are always the average of the residuals that end up in the same

Leaf even if only one residual ends up in a leaf the output value is still the average since -7.3 / 1 = -7.3 hooray we finished part C of step two by Computing gamma values or output values for each Leaf now let's do Part D in part D we make a new prediction for each sample since this is our first pass through step two and M equals 1 this new prediction will be called f sub1 of

x the new prediction f sub1 of x is based on the last prediction we made F Sub 0 ofx and the tree we just finished making note this summation is there just in case a single sample ends up in multiple leaves the summation says we should add up the output values gamma subj comma M's for all the leaves R subj comma M that a sample X can be found in the last thing in this equation is

this Greek character new new is the learning rate and is a value between 1 and zero a small learning rate reduces the effect each tree has on the final prediction and this improves accuracy in the long run in this example we'll set new to 0.1 hooray we've created f sub1 of x now we will use f sub1 of x to make new predictions for each sample we'll start with the first sample X sub1 the new prediction for X sub1

starts with the last prediction F Sub 0 of X which is 73.3 plus 0.1 times the output value from the new tree which is 8.7 because xub 1's height is greater than 1.55 now just do the math the new prediction for the first sample is 74.2 which is slightly closer to the observed weight 88 than the first prediction 73.3 bam now let's make a new prediction for the second sample x sub 2 the new prediction for X sub2 is also

74.2 which is an improvement over the first prediction 73. 3 now let's make a new prediction for the third sample X sub3 the new prediction is 71.6 which is an improvement over 73.3 double bam hooray we made it through one iteration of step two we started by setting M to one then we we solved for the negative gradient Plugged In The observed values plugged in the latest predictions and that gave us residuals then we fit a regression tree

to the residuals and computed the output values gamma subj comma M for each Leaf lastly we made new predictions for each sample F sub one of X based on the previous prediction f F Sub 0 of X the learning rate new and the output values gamma subj comma M from the new tree now we set m equals 2 and do everything over again a calculate new residuals for the new predictions B create a new tree C calculate output

values and D make new predictions at the end of the second round m equal 2 and the new predictions f sub2 ofx are based on the predictions made by f sub1 of x and the learning rate times the output values from the newest tree now in the interest of time let's assume Big M equals 2 so that we are done with step two note in practice Big M equals 100 or more more now we are ready for gradient

Boost's third and final step if Big M equals 2 then f sub2 of x is the output from the gradient boost algorithm holy smokes we made it through this whole thing that's crazy now if we receive some new data we could use f sub2 of x to predict the weight the predicted weight equals 73.3 + 0.1 * -7.3 plus 0.1 * -15.6 which equals 70 gradient boost predicts this person weighs 70 kg triple bam note before we go I want to remind

you that gradient boost usually uses trees larger than stumps I only use stumps in this tutorial because our training data set was so darn small also be sure to watch part three of this exciting series on gradient boost next time we'll talk about classification hooray we've made it to the end of another exciting stack Quest if you like this stack Quest and want to see more please subscribe and if you want to support stack Quest well

consider getting one or two of my original songs or buying a t-shirt or a hoodie or a onesie or something anyways the links are below all right until next time Quest on

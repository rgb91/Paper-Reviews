# Understanding Deep Image Representations by Inverting Them
*Authors: Aravindh Mahendran & Andrea Vedaldi. Published in : CVPR 2015*

## Summary
This paper tries to reconstruct the original image from these representations (i.e., inverting the transformation). Such reconstruction provides insight into what the algorithm is looking for in an image.  The proposed method is applied to representations obtained from CNN, HOG or DSIFT. It tries to find a reconstructed image xr by minimizing the Euclidean distance between the representation of xr and that of the original image. A regularizer is also added to the loss to be minimized to produce more natural looking images. The paper uses SGD with momentum to perform the minimization.

## Strengths
- **Quality**: The overall quality of the paper is top-notch. The proposed method is novel, tested rigorously and covered many aspects in the experimentations. The paper also has good explanations of the experimentations and also well written.
- **Clarity**: Explanations of the most of the techniques the applied were clearly done in the paper. Inverting representations and use of regularisers, momemntum were comprehensible.
- **Orginality**: In terms of novelty and originality, the paper will get full appreciation. It proposed a general framework for representing information learned by different layers with a regulariser to constraint the reconstructed image so that the reconstructed image remains visually similar to original one. This is the main novelty of the paper. 
- **Significance**: It provides a significant work in term of dismantling the myth that neural nets are completely black box algorithms. Hence, it contributes by helping us understand how the deep nets learn from the images and what properties they hold. For example, we can know that the First layers preserve almost all the information of an image; however, the last layers loses information about the location but retain some discriminative features.

## Weeknesses
- **Quality**: No improvement suggested.
- **Clarity**: I think the use of L6 norm can the more clarified in the regularisation section.
- **Orginality**: No improvement suggested. 
- **Significance**: No improvement suggested. 

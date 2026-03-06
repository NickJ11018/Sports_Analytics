

import math
import pandas as pd
import numpy as np
from operator import itemgetter


import matplotlib.pyplot as plt
import seaborn as sns


from sklearn.model_selection import train_test_split
import sklearn.metrics as metrics


from sklearn import tree
from sklearn.tree import _tree

from sklearn.ensemble import RandomForestRegressor 
from sklearn.ensemble import RandomForestClassifier 

from sklearn.ensemble import GradientBoostingRegressor 
from sklearn.ensemble import GradientBoostingClassifier

from sklearn.linear_model import LinearRegression
from sklearn.linear_model import LogisticRegression
from sklearn.metrics import classification_report, confusion_matrix

from mlxtend.feature_selection import SequentialFeatureSelector as SFS
from mlxtend.plotting import plot_sequential_feature_selection as plot_sfs

import warnings
warnings.filterwarnings("ignore")



sns.set()
pd.set_option('display.max_rows', None)
pd.set_option('display.max_columns', None)
pd.set_option('display.width', None)
pd.set_option('display.max_colwidth', None)


INFILE = "H:\\Personal\\NUSPS\\MSDS_422\\Unit 1\\HMEQ_Loss.csv"

TARGET_F = "TARGET_BAD_FLAG"
TARGET_A = "TARGET_LOSS_AMT"



df = pd.read_csv( INFILE )

dt = df.dtypes
#print( dt )

objList = []
numList = []
for i in dt.index :
    #print(" here is i .....", i , " ..... and here is the type", dt[i] )
    if i in ( [ TARGET_F, TARGET_A ] ) : continue
    if dt[i] in (["object"]) : objList.append( i )
    if dt[i] in (["float64","int64"]) : numList.append( i )


"""
FILL IN MISSING WITH THE CATEGORY "MISSING"
"""
for i in objList :
    if df[i].isna().sum() == 0 : continue
    NAME = "IMP_"+i
    df[NAME] = df[i]
    df[NAME] = df[NAME].fillna("MISSING")
    g = df.groupby( NAME )
    df = df.drop( i, axis=1 )

dt = df.dtypes
objList = []
for i in dt.index :
    #print(" here is i .....", i , " ..... and here is the type", dt[i] )
    if i in ( [ TARGET_F, TARGET_A ] ) : continue
    if dt[i] in (["object"]) : objList.append( i )



##'''
##EXPLORE THE CATEGORICAL / OBJECT VARIABLES
##'''
##df["y_EDU_4"] = (df.EDUCATION.isin( ["a_PhD"] ) + 0 )
##df["y_EDU_3"] = (df.EDUCATION.isin( ["a_PhD","b_Masters"] ) + 0)
##df["y_EDU_2"] = (df.EDUCATION.isin( ["a_PhD","b_Masters","c_Bachelors"] ) + 0)
##df["y_EDU_1"] = (df.EDUCATION.isin( ["a_PhD","b_Masters","c_Bachelors","d_High School"] ) + 0)
##df = df.drop( "EDUCATION", axis=1 )
##   
##
##dt = df.dtypes
##objList = []
##for i in dt.index :
##    #print(" here is i .....", i , " ..... and here is the type", dt[i] )
##    if i in ( [ TARGET_F, TARGET_A ] ) : continue
##    if dt[i] in (["object"]) : objList.append( i )
##
##
##for i in objList :
##    thePrefix = "z_" + i
##    y = pd.get_dummies( df[i], prefix=thePrefix, drop_first=True )   
##    #y = pd.get_dummies( df[i], prefix=thePrefix )   
##    df = pd.concat( [df, y], axis=1 )
##    #df = df.drop( i, axis=1 )
##
##
##i = "INCOME"
##FLAG = "M_" + i
##IMP = "IMP_" + i
###print( i )
###print( FLAG )
###print( IMP )
##df[ FLAG ] = df[i].isna() + 0
##df[ IMP ] = df[ i ]
##df.loc[ df[IMP].isna() & df["IMP_JOB"].isin(["Blue Collar"]), IMP ] = 53694
##df.loc[ df[IMP].isna() & df["IMP_JOB"].isin(["Student"]), IMP ] = 360
##df.loc[ df[IMP].isna() & df["IMP_JOB"].isin(["Clerical"]), IMP ] = 30799
##df.loc[ df[IMP].isna() & df["IMP_JOB"].isin(["Doctor"]), IMP ] = 121398
##df.loc[ df[IMP].isna() & df["IMP_JOB"].isin(["Home Maker"]), IMP ] = 776
##df.loc[ df[IMP].isna() & df["IMP_JOB"].isin(["Lawyer"]), IMP ] = 83230
##df.loc[ df[IMP].isna() & df["IMP_JOB"].isin(["MISSING"]), IMP ] = 109953
##df.loc[ df[IMP].isna() & df["IMP_JOB"].isin(["Manager"]), IMP ] = 78589
##df.loc[ df[IMP].isna() & df["IMP_JOB"].isin(["Professional"]), IMP ] = 71230
##df.loc[ df[IMP].isna(), IMP ] = df[i].median()
##df = df.drop( i, axis=1 )
##numList.remove(i)


for i in numList :
    if df[i].isna().sum() == 0 : continue
    FLAG = "M_" + i
    IMP = "IMP_" + i
    #print(i)
    #print( df[i].isna().sum() )
    #print( FLAG )
    #print( IMP )
    #print(" ------- ")
    df[ FLAG ] = df[i].isna() + 0
    df[ IMP ] = df[ i ]
    df.loc[ df[IMP].isna(), IMP ] = df[i].median()
    df = df.drop( i, axis=1 )




"""
Remove Outliers
"""


dt = df.dtypes
numList = []
for i in dt.index :
    #print(i, dt[i])
    if i in ( [ TARGET_F, TARGET_A ] ) : continue
    if dt[i] in (["float64","int64"]) : numList.append( i )


for i in numList :
    theMean = df[i].mean()
    theSD = df[i].std()
    theMax = df[i].max()
    theCutoff = round( theMean + 3*theSD )
    if theMax < theCutoff : continue
    FLAG = "O_" + i
    TRUNC = "TRUNC_" + i
    df[ FLAG ] = ( df[i] > theCutoff )+ 0
    df[ TRUNC ] = df[ i ]
    df.loc[ df[TRUNC] > theCutoff, TRUNC ] = theCutoff
    df = df.drop( i, axis=1 )






for i in objList:
    df = df.drop( i, axis=1 )

"""
SPLIT DATA
"""

X = df.copy()
X = X.drop( TARGET_F, axis=1 )
X = X.drop( TARGET_A, axis=1 )

Y = df[ [TARGET_F, TARGET_A] ]

X_train, X_test, Y_train, Y_test = train_test_split(X, Y, train_size=0.8, test_size=0.2, random_state=2)
#X_train, X_test, Y_train, Y_test = train_test_split(X, Y, train_size=0.8, test_size=0.2 )

##print( "FLAG DATA" )
##print( "TRAINING = ", X_train.shape )
##print( "TEST = ", X_test.shape )


F = ~ Y_train[ TARGET_A ].isna()
W_train = X_train[F].copy()
Z_train = Y_train[F].copy()

F = ~ Y_test[ TARGET_A ].isna()
W_test = X_test[F].copy()
Z_test = Y_test[F].copy()

#print( Z_train.describe() )
#print( Z_test.describe() )
#print( "\n\n")

F = Z_train[ TARGET_A ] > 25000
Z_train.loc[ F, TARGET_A ] = 25000

F = Z_test[ TARGET_A ] > 25000
Z_test.loc[ F, [TARGET_A] ] = 25000

#print( Z_train.describe() )
#print( Z_test.describe() )
#print( "\n\n")


##print( " ====== ")
##
##print( "AMOUNT DATA" )
##print( "TRAINING = ", W_train.shape )
##print( "TEST = ", Z_test.shape )








"""
MODEL ACCURACY METRICS
"""

def getProbAccuracyScores( NAME, MODEL, X, Y ) :
    pred = MODEL.predict( X )
    probs = MODEL.predict_proba( X )
    acc_score = metrics.accuracy_score(Y, pred)
    p1 = probs[:,1]
    fpr, tpr, threshold = metrics.roc_curve( Y, p1)
    auc = metrics.auc(fpr,tpr)
    return [NAME, acc_score, fpr, tpr, auc]

def print_ROC_Curve( TITLE, LIST ) :
    pass
    fig = plt.figure(figsize=(6,4))
    plt.title( TITLE )
    for theResults in LIST :
        NAME = theResults[0]
        fpr = theResults[2]
        tpr = theResults[3]
        auc = theResults[4]
        theLabel = "AUC " + NAME + ' %0.2f' % auc
        plt.plot(fpr, tpr, label = theLabel )
    plt.legend(loc = 'lower right')
    plt.plot([0, 1], [0, 1],'r--')
    plt.xlim([0, 1])
    plt.ylim([0, 1])
    plt.ylabel('True Positive Rate')
    plt.xlabel('False Positive Rate')
    plt.show()

def print_Accuracy( TITLE, LIST ) :
    print( TITLE )
    print( "======" )
    for theResults in LIST :
        NAME = theResults[0]
        ACC = theResults[1]
        print( NAME, " = ", ACC )
    print( "------\n\n" )

def getAmtAccuracyScores( NAME, MODEL, X, Y ) :
    pred = MODEL.predict( X )
    MEAN = Y.mean()
    RMSE = math.sqrt( metrics.mean_squared_error( Y, pred))
    return [NAME, RMSE, MEAN]
























##"""
##DECISION TREE
##"""

def getTreeVars( TREE, varNames ) :
    tree_ = TREE.tree_
    varName = [ varNames[i] if i != _tree.TREE_UNDEFINED else "undefined!" for i in tree_.feature ]

    nameSet = set()
    for i in tree_.feature :
        if i != _tree.TREE_UNDEFINED :
            nameSet.add( i )
    nameList = list( nameSet )
    parameter_list = list()
    for i in nameList :
        parameter_list.append( varNames[i] )
    return parameter_list



# CRASH PROBABILITY

WHO = "TREE"

CLM = tree.DecisionTreeClassifier( max_depth=4 )
CLM = CLM.fit( X_train, Y_train[ TARGET_F ] )

TRAIN_CLM = getProbAccuracyScores( WHO + "_Train", CLM, X_train, Y_train[ TARGET_F ] )
TEST_CLM = getProbAccuracyScores( WHO, CLM, X_test, Y_test[ TARGET_F ] )

#print_ROC_Curve( WHO, [ TRAIN_CLM, TEST_CLM ] ) 
#print_Accuracy( WHO + " CLASSIFICATION ACCURACY", [ TRAIN_CLM, TEST_CLM ] )

feature_cols = list( X.columns.values )
tree.export_graphviz(CLM,out_file='tree_f.txt',filled=True, rounded=True, feature_names = feature_cols, impurity=False, class_names=["Good","Bad"]  )
vars_tree_flag = getTreeVars( CLM, feature_cols ) 


# DAMAGES

AMT = tree.DecisionTreeRegressor( max_depth= 4 )
AMT = AMT.fit( W_train, Z_train[TARGET_A] )

TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train", AMT, W_train, Z_train[TARGET_A] )
TEST_AMT = getAmtAccuracyScores( WHO, AMT, W_test, Z_test[TARGET_A] )
#print_Accuracy( WHO + " RMSE ACCURACY", [ TRAIN_AMT, TEST_AMT ] )

feature_cols = list( X.columns.values )
vars_tree_amt = getTreeVars( AMT, feature_cols ) 
tree.export_graphviz(AMT,out_file='tree_a.txt',filled=True, rounded=True, feature_names = feature_cols, impurity=False, precision=0  )


TREE_CLM = TEST_CLM.copy()
TREE_AMT = TEST_AMT.copy()


"""
RANDOM FOREST
"""


def getEnsembleTreeVars( ENSTREE, varNames ) :
    importance = ENSTREE.feature_importances_
    index = np.argsort(importance)
    theList = []
    for i in index :
        imp_val = importance[i]
        if imp_val > np.average( ENSTREE.feature_importances_ ) :
            v = int( imp_val / np.max( ENSTREE.feature_importances_ ) * 100 )
            theList.append( ( varNames[i], v ) )
    theList = sorted(theList,key=itemgetter(1),reverse=True)
    return theList

WHO = "RF"

CLM = RandomForestClassifier( n_estimators = 25, random_state=1 )
CLM = CLM.fit( X_train, Y_train[ TARGET_F ] )

TRAIN_CLM = getProbAccuracyScores( WHO + "_Train", CLM, X_train, Y_train[ TARGET_F ] )
TEST_CLM = getProbAccuracyScores( WHO, CLM, X_test, Y_test[ TARGET_F ] )

#print_ROC_Curve( WHO, [ TRAIN_CLM, TEST_CLM ] ) 
#print_Accuracy( WHO + " CLASSIFICATION ACCURACY", [ TRAIN_CLM, TEST_CLM ] )


feature_cols = list( X.columns.values )
vars_RF_flag = getEnsembleTreeVars( CLM, feature_cols )


# DAMAGES

AMT = RandomForestRegressor(n_estimators = 100, random_state=1)
AMT = AMT.fit( W_train, Z_train[TARGET_A] )

TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train", AMT, W_train, Z_train[TARGET_A] )
TEST_AMT = getAmtAccuracyScores( WHO, AMT, W_test, Z_test[TARGET_A] )
#print_Accuracy( WHO + " RMSE ACCURACY", [ TRAIN_AMT, TEST_AMT ] )

feature_cols = list( X.columns.values )
vars_RF_amt = getEnsembleTreeVars( AMT, feature_cols )

##for i in vars_RF_amt :
##    print( i )

RF_CLM = TEST_CLM.copy()
RF_AMT = TEST_AMT.copy()



"""
GRADIENT BOOSTING
"""

WHO = "GB"

CLM = GradientBoostingClassifier( random_state=1 )
CLM = CLM.fit( X_train, Y_train[ TARGET_F ] )

TRAIN_CLM = getProbAccuracyScores( WHO + "_Train", CLM, X_train, Y_train[ TARGET_F ] )
TEST_CLM = getProbAccuracyScores( WHO, CLM, X_test, Y_test[ TARGET_F ] )

#print_ROC_Curve( WHO, [ TRAIN_CLM, TEST_CLM ] ) 
#print_Accuracy( WHO + " CLASSIFICATION ACCURACY", [ TRAIN_CLM, TEST_CLM ] )


feature_cols = list( X.columns.values )
vars_GB_flag = getEnsembleTreeVars( CLM, feature_cols )


# DAMAGES

AMT = GradientBoostingRegressor(random_state=1)
AMT = AMT.fit( W_train, Z_train[TARGET_A] )

TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train", AMT, W_train, Z_train[TARGET_A] )
TEST_AMT = getAmtAccuracyScores( WHO, AMT, W_test, Z_test[TARGET_A] )
#print_Accuracy( WHO + " RMSE ACCURACY", [ TRAIN_AMT, TEST_AMT ] )

feature_cols = list( X.columns.values )
vars_GB_amt = getEnsembleTreeVars( AMT, feature_cols )

##for i in vars_RF_amt :
##    print( i )

GB_CLM = TEST_CLM.copy()
GB_AMT = TEST_AMT.copy()









def getCoefLogit( MODEL, TRAIN_DATA ) :
    varNames = list( TRAIN_DATA.columns.values )
    coef_dict = {}
    coef_dict["INTERCEPT"] = MODEL.intercept_[0]
    for coef, feat in zip(MODEL.coef_[0],varNames):
        coef_dict[feat] = coef
    print("\nCRASH")
    print("---------")
    print("Total Variables: ", len( coef_dict ) )
    for i in coef_dict :
        print( i, " = ", coef_dict[i]  )



def getCoefLinear( MODEL, TRAIN_DATA ) :
    varNames = list( TRAIN_DATA.columns.values )
    coef_dict = {}
    coef_dict["INTERCEPT"] = MODEL.intercept_
    for coef, feat in zip(MODEL.coef_,varNames):
        coef_dict[feat] = coef
    print("\nDAMAGES")
    print("---------")
    print("Total Variables: ", len( coef_dict ) )
    for i in coef_dict :
        print( i, " = ", coef_dict[i]  )






"""
REGRESSION ALL VARIABLES
"""

WHO = "REG_ALL"

CLM = LogisticRegression( solver='newton-cg', max_iter=1000 )
CLM = CLM.fit( X_train, Y_train[ TARGET_F ] )

TRAIN_CLM = getProbAccuracyScores( WHO + "_Train", CLM, X_train, Y_train[ TARGET_F ] )
TEST_CLM = getProbAccuracyScores( WHO, CLM, X_test, Y_test[ TARGET_F ] )

#print_ROC_Curve( WHO, [ TRAIN_CLM, TEST_CLM ] ) 
#print_Accuracy( WHO + " CLASSIFICATION ACCURACY", [ TRAIN_CLM, TEST_CLM ] )


# DAMAGES

AMT = LinearRegression()
AMT = AMT.fit( W_train, Z_train[TARGET_A] )

TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train", AMT, W_train, Z_train[TARGET_A] )
TEST_AMT = getAmtAccuracyScores( WHO, AMT, W_test, Z_test[TARGET_A] )
print_Accuracy( WHO + " RMSE ACCURACY", [ TRAIN_AMT, TEST_AMT ] )


varNames = list( X_train.columns.values )

#REG_ALL_CLM_COEF = getCoefLogit( CLM, X_train )
#REG_ALL_AMT_COEF = getCoefLinear( AMT, X_train )

REG_ALL_CLM = TEST_CLM.copy()
REG_ALL_AMT = TEST_AMT.copy()






"""
REGRESSION DECISION TREE
"""

WHO = "REG_TREE"

CLM = LogisticRegression( solver='newton-cg', max_iter=1000 )
CLM = CLM.fit( X_train[vars_tree_flag], Y_train[ TARGET_F ] )

TRAIN_CLM = getProbAccuracyScores( WHO + "_Train", CLM, X_train[vars_tree_flag], Y_train[ TARGET_F ] )
TEST_CLM = getProbAccuracyScores( WHO, CLM, X_test[vars_tree_flag], Y_test[ TARGET_F ] )

#print_ROC_Curve( WHO, [ TRAIN_CLM, TEST_CLM ] ) 
#print_Accuracy( WHO + " CLASSIFICATION ACCURACY", [ TRAIN_CLM, TEST_CLM ] )


# DAMAGES

AMT = LinearRegression()
AMT = AMT.fit( W_train[vars_tree_amt], Z_train[TARGET_A] )

TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train", AMT, W_train[vars_tree_amt], Z_train[TARGET_A] )
TEST_AMT = getAmtAccuracyScores( WHO, AMT, W_test[vars_tree_amt], Z_test[TARGET_A] )
print_Accuracy( WHO + " RMSE ACCURACY", [ TRAIN_AMT, TEST_AMT ] )


varNames = list( X_train.columns.values )

#REG_TREE_CLM_COEF = getCoefLogit( CLM, X_train[vars_tree_flag] )
#REG_TREE_AMT_COEF = getCoefLinear( AMT, X_train[vars_tree_amt] )

REG_TREE_CLM = TEST_CLM.copy()
REG_TREE_AMT = TEST_AMT.copy()








"""
REGRESSION RANDOM FOREST
"""

WHO = "REG_RF"


print("\n\n")
RF_flag = []
for i in vars_RF_flag :
    print(i)
    theVar = i[0]
    RF_flag.append( theVar )

print("\n\n")
RF_amt = []
for i in vars_RF_amt :
    print(i)
    theVar = i[0]
    RF_amt.append( theVar )


CLM = LogisticRegression( solver='newton-cg', max_iter=1000 )
CLM = CLM.fit( X_train[RF_flag], Y_train[ TARGET_F ] )

TRAIN_CLM = getProbAccuracyScores( WHO + "_Train", CLM, X_train[RF_flag], Y_train[ TARGET_F ] )
TEST_CLM = getProbAccuracyScores( WHO, CLM, X_test[RF_flag], Y_test[ TARGET_F ] )

#print_ROC_Curve( WHO, [ TRAIN_CLM, TEST_CLM ] ) 
#print_Accuracy( WHO + " CLASSIFICATION ACCURACY", [ TRAIN_CLM, TEST_CLM ] )


# DAMAGES

AMT = LinearRegression()
AMT = AMT.fit( W_train[RF_amt], Z_train[TARGET_A] )

TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train", AMT, W_train[RF_amt], Z_train[TARGET_A] )
TEST_AMT = getAmtAccuracyScores( WHO, AMT, W_test[RF_amt], Z_test[TARGET_A] )
print_Accuracy( WHO + " RMSE ACCURACY", [ TRAIN_AMT, TEST_AMT ] )


REG_RF_CLM_COEF = getCoefLogit( CLM, X_train[RF_flag] )
REG_RF_AMT_COEF = getCoefLinear( AMT, X_train[RF_amt] )

REG_RF_CLM = TEST_CLM.copy()
REG_RF_AMT = TEST_AMT.copy()







"""
REGRESSION GRADIENT BOOSTING
"""

WHO = "REG_GB"


print("\n\n")
GB_flag = []
for i in vars_GB_flag :
    print(i)
    theVar = i[0]
    GB_flag.append( theVar )

print("\n\n")
GB_amt = []
for i in vars_GB_amt :
    print(i)
    theVar = i[0]
    GB_amt.append( theVar )


CLM = LogisticRegression( solver='newton-cg', max_iter=1000 )
CLM = CLM.fit( X_train[GB_flag], Y_train[ TARGET_F ] )

TRAIN_CLM = getProbAccuracyScores( WHO + "_Train", CLM, X_train[GB_flag], Y_train[ TARGET_F ] )
TEST_CLM = getProbAccuracyScores( WHO, CLM, X_test[GB_flag], Y_test[ TARGET_F ] )

#print_ROC_Curve( WHO, [ TRAIN_CLM, TEST_CLM ] ) 
#print_Accuracy( WHO + " CLASSIFICATION ACCURACY", [ TRAIN_CLM, TEST_CLM ] )


# DAMAGES

AMT = LinearRegression()
AMT = AMT.fit( W_train[GB_amt], Z_train[TARGET_A] )

TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train", AMT, W_train[GB_amt], Z_train[TARGET_A] )
TEST_AMT = getAmtAccuracyScores( WHO, AMT, W_test[GB_amt], Z_test[TARGET_A] )
print_Accuracy( WHO + " RMSE ACCURACY", [ TRAIN_AMT, TEST_AMT ] )

REG_GB_CLM_COEF = getCoefLogit( CLM, X_train[GB_flag] )
REG_GB_AMT_COEF = getCoefLinear( AMT, X_train[GB_amt] )

REG_GB_CLM = TEST_CLM.copy()
REG_GB_AMT = TEST_AMT.copy()








##"""
##REGRESSION STEPWISE
##"""
##
##U_train = X_train[ vars_tree_flag ]
##stepVarNames = list( U_train.columns.values )
##maxCols = U_train.shape[1]
##
##sfs = SFS( LogisticRegression( solver='newton-cg', max_iter=100 ),
##           k_features=( 1, maxCols ),
##           forward=True,
##           floating=False,
##           cv=3
##           )
##sfs.fit(U_train.values, Y_train[ TARGET_F ].values)
##
##theFigure = plot_sfs(sfs.get_metric_dict(), kind=None )
##plt.title('CRASH PROBABILITY Sequential Forward Selection (w. StdErr)')
##plt.grid()
##plt.show()
##
##dfm = pd.DataFrame.from_dict( sfs.get_metric_dict()).T
##dfm = dfm[ ['feature_names', 'avg_score'] ]
##dfm.avg_score = dfm.avg_score.astype(float)
##
##print(" ................... ")
##maxIndex = dfm.avg_score.argmax()
##print("argmax")
##print( dfm.iloc[ maxIndex, ] )
##print(" ................... ")
##
##stepVars = dfm.iloc[ maxIndex, ]
##stepVars = stepVars.feature_names
##print( stepVars )
##
##finalStepVars = []
##for i in stepVars :
##    index = int(i)
##    try :
##        theName = stepVarNames[ index ]
##        finalStepVars.append( theName )
##    except :
##        pass
##
##for i in finalStepVars :
##    print(i)
##
##U_train = X_train[ finalStepVars ]
##U_test = X_test[ finalStepVars ]
##
##
##
##V_train = W_train[ GB_amt ]
##stepVarNames = list( V_train.columns.values )
##maxCols = V_train.shape[1]
##
##sfs = SFS( LinearRegression(),
##           k_features=( 1, maxCols ),
##           forward=True,
##           floating=False,
##           scoring = 'r2',
##           cv=5
##           )
##sfs.fit(V_train.values, Z_train[ TARGET_A ].values)
##
##theFigure = plot_sfs(sfs.get_metric_dict(), kind=None )
##plt.title('DAMAGES Sequential Forward Selection (w. StdErr)')
##plt.grid()
##plt.show()
##
##dfm = pd.DataFrame.from_dict( sfs.get_metric_dict()).T
##dfm = dfm[ ['feature_names', 'avg_score'] ]
##dfm.avg_score = dfm.avg_score.astype(float)
##
##print(" ................... ")
##maxIndex = dfm.avg_score.argmax()
##print("argmax")
##print( dfm.iloc[ maxIndex, ] )
##print(" ................... ")
##
##stepVars = dfm.iloc[ maxIndex, ]
##stepVars = stepVars.feature_names
##print( stepVars )
##
##finalStepVars = []
##for i in stepVars :
##    index = int(i)
##    try :
##        theName = stepVarNames[ index ]
##        finalStepVars.append( theName )
##    except :
##        pass
##
##for i in finalStepVars :
##    print(i)
##
##V_train = W_train[ finalStepVars ]
##V_test = W_test[ finalStepVars ]
##
##
##
##"""
##REGRESSION 
##"""
##
##WHO = "REG_STEPWISE"
##
##CLM = LogisticRegression( solver='newton-cg', max_iter=1000 )
##CLM = CLM.fit( U_train, Y_train[ TARGET_F ] )
##
##TRAIN_CLM = getProbAccuracyScores( WHO + "_Train", CLM, U_train, Y_train[ TARGET_F ] )
##TEST_CLM = getProbAccuracyScores( WHO, CLM, U_test, Y_test[ TARGET_F ] )
##
##print_ROC_Curve( WHO, [ TRAIN_CLM, TEST_CLM ] ) 
##print_Accuracy( WHO + " CLASSIFICATION ACCURACY", [ TRAIN_CLM, TEST_CLM ] )
##
##
### DAMAGES
##
##AMT = LinearRegression()
##AMT = AMT.fit( V_train, Z_train[TARGET_A] )
##
##TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train", AMT, V_train, Z_train[TARGET_A] )
##TEST_AMT = getAmtAccuracyScores( WHO, AMT, V_test, Z_test[TARGET_A] )
##print_Accuracy( WHO + " RMSE ACCURACY", [ TRAIN_AMT, TEST_AMT ] )
##
##REG_STEP_CLM_COEF = getCoefLogit( CLM, U_train )
##REG_STEP_AMT_COEF = getCoefLinear( AMT, V_train )
##
##REG_STEP_CLM = TEST_CLM.copy()
##REG_STEP_AMT = TEST_AMT.copy()
##
##
##
##
##
##
##
##ALL_CLM = [ TREE_CLM, RF_CLM, GB_CLM, REG_ALL_CLM, REG_TREE_CLM, REG_RF_CLM, REG_GB_CLM, REG_STEP_CLM ]
##
##ALL_CLM = sorted( ALL_CLM, key = lambda x: x[4], reverse=True )
##print_ROC_Curve( WHO, ALL_CLM ) 
##
##ALL_CLM = sorted( ALL_CLM, key = lambda x: x[1], reverse=True )
##print_Accuracy( "ALL CLASSIFICATION ACCURACY", ALL_CLM )
##
##
##ALL_AMT = [ TREE_AMT, RF_AMT, GB_AMT, REG_ALL_AMT, REG_TREE_AMT, REG_RF_AMT, REG_GB_AMT, REG_STEP_AMT ]
##ALL_AMT = sorted( ALL_AMT, key = lambda x: x[1] )
##print_Accuracy( "ALL DAMAGE MODEL ACCURACY", ALL_AMT )





"""
Tensorflow stuff
"""



import tensorflow as tf

from sklearn.preprocessing import MinMaxScaler
theScaler = MinMaxScaler() #MinMax to bring it down to 0-1 range
theScaler.fit( X_train ) #fit the data for the Scaler


#TensorFlow specific probability scores, emptoy list to read in >50% score as choice crash or no crash
def get_TF_ProbAccuracyScores( NAME, MODEL, X, Y ) :
    probs = MODEL.predict( X )
    pred_list = []
    for p in probs :
        pred_list.append( np.argmax( p ) )
    pred = np.array( pred_list )
    acc_score = metrics.accuracy_score(Y, pred)
    p1 = probs[:,1]
    fpr, tpr, threshold = metrics.roc_curve( Y, p1)
    auc = metrics.auc(fpr,tpr)
    return [NAME, acc_score, fpr, tpr, auc]



WHO = "TF" #tensorflow

U_train = theScaler.transform( X_train )
U_test = theScaler.transform( X_test )

U_train = pd.DataFrame( U_train )
U_test = pd.DataFrame( U_test )

U_train.columns = list( X_train.columns.values ) #list of possible columns
U_test.columns = list( X_train.columns.values ) #same for test

#Optional to limit columns
#U_train = U_train[ GB_flag ] #choose subset of columns based on selection criteria (GB not a bad choice for selections)
#U_test = U_test[ GB_flag ] #same thing for test




F_theShapeSize = U_train.shape[1] #input size
F_theActivation = tf.keras.activations.relu #node activation function
#F_theActivation_list = [tf.keras.activations.relu, tf.keras.activations.sigmoid, tf.keras.activations.linear] #node activation function
F_theLossMetric = tf.keras.losses.SparseCategoricalCrossentropy() #training loss metric for Category/Yes/No
F_theOptimizer_0 = tf.keras.optimizers.Adam() #Optimizer is basically always Adam
F_theOptimizer_1 = tf.keras.optimizers.Adam() #Optimizer is basically always Adam
F_theOptimizer_2 = tf.keras.optimizers.Adam() #Optimizer is basically always Adam
F_theOptimizer_3 = tf.keras.optimizers.Adam() #Optimizer is basically always Adam
F_theOptimizer_4 = tf.keras.optimizers.Adam() #Optimizer is basically always Adam
F_theOptimizer_5 = tf.keras.optimizers.Adam() #Optimizer is basically always Adam
F_theEpochs = 100 #how many runs

F_theUnits = int( 2*F_theShapeSize / 3 ) #usually less than double the inputs to avoid overfitting



#Relu AllVar#
F_LAYER_01 = tf.keras.layers.Dense( units=F_theUnits, activation=tf.keras.activations.relu, input_dim=F_theShapeSize )
F_LAYER_DROP = tf.keras.layers.Dropout( 0.2 )
F_LAYER_02 = tf.keras.layers.Dense( units=F_theUnits, activation=tf.keras.activations.relu )
F_LAYER_OUTPUT = tf.keras.layers.Dense( units=2, activation=tf.keras.activations.softmax )


CLM = tf.keras.Sequential()
CLM.add( F_LAYER_01 )
#CLM.add( F_LAYER_DROP ) #Throw away some % of nodes to keep things spicy
CLM.add( F_LAYER_02 )
CLM.add( F_LAYER_OUTPUT )
CLM.compile( loss=F_theLossMetric, optimizer=F_theOptimizer_0)
CLM.fit( U_train, Y_train[TARGET_F], epochs=F_theEpochs, verbose=False )
 
TRAIN_CLM_RELU_AllVar = get_TF_ProbAccuracyScores( WHO + "_Train_ReluAllVar", CLM, U_train, Y_train[ TARGET_F ] )
TEST_CLM_RELU_AllVar = get_TF_ProbAccuracyScores( WHO+"_Test_ReluAllVar", CLM, U_test, Y_test[ TARGET_F ] )

print_ROC_Curve( WHO+"_ReluAllVar", [ TRAIN_CLM_RELU_AllVar, TEST_CLM_RELU_AllVar ] ) 
print_Accuracy( WHO+"_ReluAllVar" + " CLASSIFICATION ACCURACY", [ TRAIN_CLM_RELU_AllVar, TEST_CLM_RELU_AllVar ] )



#Optional to limit columns
U_train = U_train[ GB_flag ] #choose subset of columns based on selection criteria (GB not a bad choice for selections)
U_test = U_test[ GB_flag ] #same thing for test

F_theShapeSize = U_train.shape[1] #input size
F_theUnits = int( 2*F_theShapeSize / 3 ) #usually less than double the inputs to avoid overfitting

#Relu NoDrop#
F_LAYER_01 = tf.keras.layers.Dense( units=F_theUnits, activation=tf.keras.activations.relu, input_dim=F_theShapeSize )
F_LAYER_DROP = tf.keras.layers.Dropout( 0.2 )
F_LAYER_02 = tf.keras.layers.Dense( units=F_theUnits, activation=tf.keras.activations.relu )
F_LAYER_OUTPUT = tf.keras.layers.Dense( units=2, activation=tf.keras.activations.softmax )


CLM = tf.keras.Sequential()
CLM.add( F_LAYER_01 )
#CLM.add( F_LAYER_DROP ) #Throw away some % of nodes to keep things spicy
CLM.add( F_LAYER_02 )
CLM.add( F_LAYER_OUTPUT )
CLM.compile( loss=F_theLossMetric, optimizer=F_theOptimizer_1)
CLM.fit( U_train, Y_train[TARGET_F], epochs=F_theEpochs, verbose=False )
 
TRAIN_CLM_RELU_NoDrop = get_TF_ProbAccuracyScores( WHO + "_Train_ReluNoDrop", CLM, U_train, Y_train[ TARGET_F ] )
TEST_CLM_RELU_NoDrop = get_TF_ProbAccuracyScores( WHO+"_Test_ReluNoDrop", CLM, U_test, Y_test[ TARGET_F ] )

print_ROC_Curve( WHO+"_ReluNoDrop", [ TRAIN_CLM_RELU_NoDrop, TEST_CLM_RELU_NoDrop ] ) 
print_Accuracy( WHO+"_ReluNoDrop" + " CLASSIFICATION ACCURACY", [ TRAIN_CLM_RELU_NoDrop, TEST_CLM_RELU_NoDrop ] )


#Relu Drop#
F_LAYER_01 = tf.keras.layers.Dense( units=F_theUnits, activation=tf.keras.activations.relu, input_dim=F_theShapeSize )
F_LAYER_DROP = tf.keras.layers.Dropout( 0.2 )
F_LAYER_02 = tf.keras.layers.Dense( units=F_theUnits, activation=tf.keras.activations.relu )
F_LAYER_OUTPUT = tf.keras.layers.Dense( units=2, activation=tf.keras.activations.softmax )


CLM = tf.keras.Sequential()
CLM.add( F_LAYER_01 )
CLM.add( F_LAYER_DROP ) #Throw away some % of nodes to keep things spicy
CLM.add( F_LAYER_02 )
CLM.add( F_LAYER_OUTPUT )
CLM.compile( loss=F_theLossMetric, optimizer=F_theOptimizer_2)
CLM.fit( U_train, Y_train[TARGET_F], epochs=F_theEpochs, verbose=False )
 
TRAIN_CLM_RELU_Drop = get_TF_ProbAccuracyScores( WHO + "_Train_ReluDrop", CLM, U_train, Y_train[ TARGET_F ] )
TEST_CLM_RELU_Drop = get_TF_ProbAccuracyScores( WHO+"_Test_ReluDrop", CLM, U_test, Y_test[ TARGET_F ] )

print_ROC_Curve( WHO+"_ReluDrop", [ TRAIN_CLM_RELU_Drop, TEST_CLM_RELU_Drop ] ) 
print_Accuracy( WHO+"_ReluDrop" + " CLASSIFICATION ACCURACY", [ TRAIN_CLM_RELU_Drop, TEST_CLM_RELU_Drop ] )


#Relu 2Hidden#
F_LAYER_01 = tf.keras.layers.Dense( units=F_theUnits, activation=tf.keras.activations.relu, input_dim=F_theShapeSize )
F_LAYER_DROP = tf.keras.layers.Dropout( 0.2 )
F_LAYER_02 = tf.keras.layers.Dense( units=F_theUnits, activation=tf.keras.activations.relu )
F_LAYER_03 = tf.keras.layers.Dense( units=F_theUnits, activation=tf.keras.activations.relu )
F_LAYER_OUTPUT = tf.keras.layers.Dense( units=2, activation=tf.keras.activations.softmax )


CLM = tf.keras.Sequential()
CLM.add( F_LAYER_01 )
CLM.add( F_LAYER_DROP ) #Throw away some % of nodes to keep things spicy
CLM.add( F_LAYER_02 )
CLM.add( F_LAYER_03 )
CLM.add( F_LAYER_OUTPUT )
CLM.compile( loss=F_theLossMetric, optimizer=F_theOptimizer_3)
CLM.fit( U_train, Y_train[TARGET_F], epochs=F_theEpochs, verbose=False )
 
TRAIN_CLM_RELU_2Hidden = get_TF_ProbAccuracyScores( WHO + "_Train_Relu2Hidden", CLM, U_train, Y_train[ TARGET_F ] )
TEST_CLM_RELU_2Hidden = get_TF_ProbAccuracyScores( WHO+"_Test_Relu2Hidden", CLM, U_test, Y_test[ TARGET_F ] )

print_ROC_Curve( WHO+"_Relu2Hidden", [ TRAIN_CLM_RELU_2Hidden, TEST_CLM_RELU_2Hidden ] ) 
print_Accuracy( WHO+"_Relu2Hidden" + " CLASSIFICATION ACCURACY", [ TRAIN_CLM_RELU_2Hidden, TEST_CLM_RELU_2Hidden ] )


#Sigmoid#
F_LAYER_01 = tf.keras.layers.Dense( units=F_theUnits, activation=tf.keras.activations.sigmoid, input_dim=F_theShapeSize )
F_LAYER_DROP = tf.keras.layers.Dropout( 0.2 )
F_LAYER_02 = tf.keras.layers.Dense( units=F_theUnits, activation=tf.keras.activations.sigmoid )
F_LAYER_OUTPUT = tf.keras.layers.Dense( units=2, activation=tf.keras.activations.softmax )


CLM = tf.keras.Sequential()
CLM.add( F_LAYER_01 )
CLM.add( F_LAYER_DROP ) #Throw away some % of nodes to keep things spicy
CLM.add( F_LAYER_02 )
CLM.add( F_LAYER_OUTPUT )
CLM.compile( loss=F_theLossMetric, optimizer=F_theOptimizer_4)
CLM.fit( U_train, Y_train[TARGET_F], epochs=F_theEpochs, verbose=False )
 
TRAIN_CLM_SIG = get_TF_ProbAccuracyScores( WHO + "_Train_Sigmoid", CLM, U_train, Y_train[ TARGET_F ] )
TEST_CLM_SIG = get_TF_ProbAccuracyScores( WHO+"_Test_Sigmoid", CLM, U_test, Y_test[ TARGET_F ] )

print_ROC_Curve( WHO+"_Sigmoid", [ TRAIN_CLM_SIG, TEST_CLM_SIG ] ) 
print_Accuracy( WHO+"_Sigmoid" + " CLASSIFICATION ACCURACY", [ TRAIN_CLM_SIG, TEST_CLM_SIG ] )


#Linear#
F_LAYER_01 = tf.keras.layers.Dense( units=F_theUnits, activation=tf.keras.activations.linear, input_dim=F_theShapeSize )
F_LAYER_DROP = tf.keras.layers.Dropout( 0.2 )
F_LAYER_02 = tf.keras.layers.Dense( units=F_theUnits, activation=tf.keras.activations.linear )
F_LAYER_OUTPUT = tf.keras.layers.Dense( units=2, activation=tf.keras.activations.softmax )


CLM = tf.keras.Sequential()
CLM.add( F_LAYER_01 )
CLM.add( F_LAYER_DROP ) #Throw away some % of nodes to keep things spicy
CLM.add( F_LAYER_02 )
CLM.add( F_LAYER_OUTPUT )
CLM.compile( loss=F_theLossMetric, optimizer=F_theOptimizer_5)
CLM.fit( U_train, Y_train[TARGET_F], epochs=F_theEpochs, verbose=False )
 
TRAIN_CLM_LIN = get_TF_ProbAccuracyScores( WHO + "_Train_Linear", CLM, U_train, Y_train[ TARGET_F ] )
TEST_CLM_LIN = get_TF_ProbAccuracyScores( WHO+"_Test_Linear", CLM, U_test, Y_test[ TARGET_F ] )

print_ROC_Curve( WHO+"_Linear", [ TRAIN_CLM_LIN, TEST_CLM_LIN ] ) 
print_Accuracy( WHO+"_Linear" + " CLASSIFICATION ACCURACY", [ TRAIN_CLM_LIN, TEST_CLM_LIN ] )



#Scaler has already been trained from training set
V_train = theScaler.transform( W_train ) #W was created for Amount/Damages, just the ones that have a value
V_test = theScaler.transform( W_test )

V_train = pd.DataFrame( V_train )
V_test = pd.DataFrame( V_test )

V_train.columns = list( W_train.columns.values )
V_test.columns = list( W_train.columns.values )


#Startover for Amount#


A_theShapeSize = V_train.shape[1] #however many records
A_theUnits = int( 2*A_theShapeSize / 3 )
A_theLossMetric = tf.keras.losses.MeanSquaredError() #This is numeric value so MSE
A_theOptimizer_0 = tf.keras.optimizers.Adam()
A_theOptimizer_1 = tf.keras.optimizers.Adam()
A_theOptimizer_2 = tf.keras.optimizers.Adam()
A_theOptimizer_3 = tf.keras.optimizers.Adam()
A_theOptimizer_4 = tf.keras.optimizers.Adam()
A_theOptimizer_5 = tf.keras.optimizers.Adam()
A_theEpochs = 100



print("A_theShapeSize:", A_theShapeSize)
print("A_theUnits:", A_theUnits)


#Relu AllVar#


A_theActivation = tf.keras.activations.relu

A_LAYER_01 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation, input_dim=A_theShapeSize )
A_LAYER_DROP = tf.keras.layers.Dropout( 0.2 )
A_LAYER_02 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation )
A_LAYER_OUTPUT = tf.keras.layers.Dense( units=1, activation=tf.keras.activations.linear ) #linear regression here

AMT = tf.keras.Sequential()
AMT.add( A_LAYER_01 )
#AMT.add( A_LAYER_DROP )
AMT.add( A_LAYER_02 )
AMT.add( A_LAYER_OUTPUT )
AMT.compile( loss=A_theLossMetric, optimizer=A_theOptimizer_0)
AMT.fit( V_train, Z_train[TARGET_A], epochs=A_theEpochs, verbose=False )

#print(AMT.predict(V_train))

TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train_Relu_AllVar", AMT, V_train, Z_train[TARGET_A] )
TEST_AMT = getAmtAccuracyScores( WHO + "_Test_Relu_AllVar", AMT, V_test, Z_test[TARGET_A] )
print_Accuracy( WHO + " RMSE ACCURACY_AllVar", [ TRAIN_AMT, TEST_AMT ] )

TRAIN_AMT_RELU_AllVar = TRAIN_AMT.copy()
TEST_AMT_RELU_AllVar = TEST_AMT.copy()


#update values for just GB_amt variables
V_train = V_train[ GB_amt ]
V_test = V_test[ GB_amt ]


A_theShapeSize = V_train.shape[1] #however many records
A_theUnits = int( 2*A_theShapeSize / 3 )


#Relu NoDrop#

A_theActivation = tf.keras.activations.relu

A_LAYER_01 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation, input_dim=A_theShapeSize )
A_LAYER_DROP = tf.keras.layers.Dropout( 0.2 )
A_LAYER_02 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation )
A_LAYER_OUTPUT = tf.keras.layers.Dense( units=1, activation=tf.keras.activations.linear ) #linear regression here

AMT = tf.keras.Sequential()
AMT.add( A_LAYER_01 )
#AMT.add( A_LAYER_DROP )
AMT.add( A_LAYER_02 )
AMT.add( A_LAYER_OUTPUT )
AMT.compile( loss=A_theLossMetric, optimizer=A_theOptimizer_1)
AMT.fit( V_train, Z_train[TARGET_A], epochs=A_theEpochs, verbose=False )


print("made it here")

TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train_Relu_NoDrop", AMT, V_train[GB_amt], Z_train[TARGET_A] )
TEST_AMT = getAmtAccuracyScores( WHO + "_Test_Relu_NoDrop", AMT, V_test[GB_amt], Z_test[TARGET_A] )
print_Accuracy( WHO + " RMSE ACCURACY_NoDrop", [ TRAIN_AMT, TEST_AMT ] )

TRAIN_AMT_RELU_NoDrop = TRAIN_AMT.copy()
TEST_AMT_RELU_NoDrop = TEST_AMT.copy()



#Relu Drop#

A_theActivation = tf.keras.activations.relu

A_LAYER_01 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation, input_dim=A_theShapeSize )
A_LAYER_DROP = tf.keras.layers.Dropout( 0.2 )
A_LAYER_02 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation )
A_LAYER_OUTPUT = tf.keras.layers.Dense( units=1, activation=tf.keras.activations.linear ) #linear regression here

AMT = tf.keras.Sequential()
AMT.add( A_LAYER_01 )
AMT.add( A_LAYER_DROP )
AMT.add( A_LAYER_02 )
AMT.add( A_LAYER_OUTPUT )
AMT.compile( loss=A_theLossMetric, optimizer=A_theOptimizer_2)
AMT.fit( V_train, Z_train[TARGET_A], epochs=A_theEpochs, verbose=False )


TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train_Relu_Drop", AMT, V_train[GB_amt], Z_train[TARGET_A] )
TEST_AMT = getAmtAccuracyScores( WHO + "_Test_Relu_Drop", AMT, V_test[GB_amt], Z_test[TARGET_A] )
print_Accuracy( WHO + " RMSE ACCURACY_Drop", [ TRAIN_AMT, TEST_AMT ] )

TRAIN_AMT_RELU_Drop = TRAIN_AMT.copy()
TEST_AMT_RELU_Drop = TEST_AMT.copy()




#Relu 2Hidden#

A_theActivation = tf.keras.activations.relu

A_LAYER_01 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation, input_dim=A_theShapeSize )
A_LAYER_DROP = tf.keras.layers.Dropout( 0.2 )
A_LAYER_02 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation )
A_LAYER_03 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation )
A_LAYER_OUTPUT = tf.keras.layers.Dense( units=1, activation=tf.keras.activations.linear ) #linear regression here

AMT = tf.keras.Sequential()
AMT.add( A_LAYER_01 )
AMT.add( A_LAYER_DROP )
AMT.add( A_LAYER_02 )
AMT.add( A_LAYER_03 )
AMT.add( A_LAYER_OUTPUT )
AMT.compile( loss=A_theLossMetric, optimizer=A_theOptimizer_3)
AMT.fit( V_train, Z_train[TARGET_A], epochs=A_theEpochs, verbose=False )


TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train_Relu2Hidden", AMT, V_train[GB_amt], Z_train[TARGET_A] )
TEST_AMT = getAmtAccuracyScores( WHO + "_Test_Relu2Hidden", AMT, V_test[GB_amt], Z_test[TARGET_A] )
print_Accuracy( WHO + " RMSE ACCURACY_Relu2Hidden", [ TRAIN_AMT, TEST_AMT ] )

TRAIN_AMT_RELU_2Hidden = TRAIN_AMT.copy()
TEST_AMT_RELU_2Hidden = TEST_AMT.copy()




#Sigmoid#
A_theActivation = tf.keras.activations.sigmoid

A_LAYER_01 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation, input_dim=A_theShapeSize )
A_LAYER_DROP = tf.keras.layers.Dropout( 0.2 )
A_LAYER_02 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation )
A_LAYER_03 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation )
A_LAYER_OUTPUT = tf.keras.layers.Dense( units=1, activation=tf.keras.activations.linear ) #linear regression here

AMT = tf.keras.Sequential()
AMT.add( A_LAYER_01 )
AMT.add( A_LAYER_DROP )
AMT.add( A_LAYER_02 )
AMT.add( A_LAYER_03 )
AMT.add( A_LAYER_OUTPUT )
AMT.compile( loss=A_theLossMetric, optimizer=A_theOptimizer_4)
AMT.fit( V_train, Z_train[TARGET_A], epochs=A_theEpochs, verbose=False )


TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train_Sigmoid", AMT, V_train[GB_amt], Z_train[TARGET_A] )
TEST_AMT = getAmtAccuracyScores( WHO + "_Test_Sigmoid", AMT, V_test[GB_amt], Z_test[TARGET_A] )
print_Accuracy( WHO + " RMSE ACCURACY_Sigmoid", [ TRAIN_AMT, TEST_AMT ] )

TRAIN_AMT_SIG = TRAIN_AMT.copy()
TEST_AMT_SIG = TEST_AMT.copy()




#Linear#

A_theActivation = tf.keras.activations.linear

A_LAYER_01 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation, input_dim=A_theShapeSize )
A_LAYER_DROP = tf.keras.layers.Dropout( 0.2 )
A_LAYER_02 = tf.keras.layers.Dense( units=A_theUnits, activation=A_theActivation )
A_LAYER_OUTPUT = tf.keras.layers.Dense( units=1, activation=tf.keras.activations.linear ) #linear regression here

AMT = tf.keras.Sequential()
AMT.add( A_LAYER_01 )
AMT.add( A_LAYER_DROP )
AMT.add( A_LAYER_02 )
AMT.add( A_LAYER_OUTPUT )
AMT.compile( loss=A_theLossMetric, optimizer=A_theOptimizer_5)
AMT.fit( V_train, Z_train[TARGET_A], epochs=A_theEpochs, verbose=False )


TRAIN_AMT = getAmtAccuracyScores( WHO + "_Train_Linear", AMT, V_train[GB_amt], Z_train[TARGET_A] )
TEST_AMT = getAmtAccuracyScores( WHO + "_Test_Linear", AMT, V_test[GB_amt], Z_test[TARGET_A] )
print_Accuracy( WHO + " RMSE ACCURACY_Linear", [ TRAIN_AMT, TEST_AMT ] )

TRAIN_AMT_LIN = TRAIN_AMT.copy()
TEST_AMT_LIN = TEST_AMT.copy()











#ALL_CLM = [ TREE_CLM, RF_CLM, GB_CLM, REG_ALL_CLM, REG_TREE_CLM, REG_RF_CLM, REG_GB_CLM, TF_CLM ]
ALL_CLM = [ TREE_CLM, RF_CLM, GB_CLM, REG_ALL_CLM, REG_TREE_CLM, REG_RF_CLM, REG_GB_CLM, TEST_CLM_RELU_AllVar, TEST_CLM_RELU_NoDrop, TEST_CLM_RELU_Drop, TEST_CLM_RELU_2Hidden, TEST_CLM_SIG, TEST_CLM_LIN ]

ALL_CLM = sorted( ALL_CLM, key = lambda x: x[4], reverse=True )
print_ROC_Curve( WHO, ALL_CLM ) 

ALL_CLM = sorted( ALL_CLM, key = lambda x: x[1], reverse=True )
print_Accuracy( "ALL CLASSIFICATION ACCURACY", ALL_CLM )



ALL_AMT = [ TREE_AMT, RF_AMT, GB_AMT, REG_ALL_AMT, REG_TREE_AMT, REG_RF_AMT, REG_GB_AMT, TEST_AMT_RELU_NoDrop, TEST_AMT_RELU_Drop, TEST_AMT_RELU_2Hidden, TEST_AMT_SIG, TEST_AMT_LIN ]
ALL_AMT = sorted( ALL_AMT, key = lambda x: x[1] )
print_Accuracy( "ALL AMOUNT MODEL ACCURACY", ALL_AMT )







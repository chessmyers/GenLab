<html>
  <head>
    <title>EvoLab</title>
    <link rel="stylesheet" href="https://stackpath.bootstrapcdn.com/bootstrap/4.1.3/css/bootstrap.min.css" integrity="sha384-MCw98/SFnGE8fJT3GXwEOngsV7Zt27NXFoaoApmYm81iuXoPkFOJwJ8ERdknLPMO" crossorigin="anonymous">
  </head>
  <body>
<h1 class="display-4 text-center">GenLab Help</h1>
  <p class="lead text-center">Welcome to GenLab!</p>
  <p class="lead text-center">This program can be used to visualize game-theoretical models such as the Prisoner's Dilemma,
    Hawk-Dove, and more.</p>
  <p class="lead text-center">To use, simply fill out desired options and click <b>Generate Network!</b> to create your
    network.  Once the network has been created, press the <b>Next Generation!</b> button to progress through the generations
    of this network as many times as you wish.  As you can see, many of the options have indicated default values that are used
    when a value is not provided for that element.  If you are happy with the default values, feel free to leave some options blank.
    The only option that <b>must</b> be filled out is the payoff matrix, or the program will not work. More information about each
    option can be found below.</p>
  <h4>Network Type:</h4>
  <p class="lead">There are two options for the network type: 1D and 2D.  A 2D network will be a full lattice of cells which interact
    with those surrounding them, while a 1D network will be a single row of cells that only interact with those on the left and right
    sides of them.</p>
    <p class="lead">Sequential generations for 1D networks will stack on top of one another so you can see how the populations change over
    time, while for 2D networks new generations will replace the previous one. If you don't choose a network type, the program will default to generating
      a 2D network.  It should also be noted that the <b>Neighborhood Type</b> option only applies to 2D networks, so if generating a 1D network it will be ignored.</p>
  <h4>Wrap?</h4>
  <p class="lead">This binary option indicates a preference for cells on the edge of the network interacting with those on the opposite side.  If checked,
    they will exhibit this behavior.  For example, let's say a certain cell is in the top right corner of a 2D network.  If wrapping is turned on,
    this cell will play against the cell in the top left corner, bottom right corner, and (if using a Moore neighborhood--more on that next) bottom
    left corner, bottom right corner second-rightmost cell and top left corner second-highest cell.  If wrapping is not on, it will play against the other three
    cells around it but not the five mentioned.  For 1D networks, cells on the left and right edges will play against the cells on the edge opposite to them if wrapping is on.</p>
    <p class="lead">By default, this option is on, so if you wish to turn it off you will need to check and then uncheck the box.</p>
  <h4>Neighborhood Type</h4>
  <p class="lead">This option (which as mentioned only applies for 2D networks) indicates whether each cell will interact will all 8 cells surrounding it (top left corner,
    top middle, top right corner, right side, bottom right corner, bottom middle, bottom left corner, and left side) or just the cells in its four cardinal directions (above it,
    to the right, below it, and to the left).  The neighborhood type that interacts will all 8 cells around the player cell is a <b>Moore neighborhood</b>,
    while a <b>Von Neumann neighborhood</b> only includes four cells around the player cell.  Note that if you do not touch this, the program will default to using a Moore neighborhood.</p>
  <p class="lead"> Here is a visualization:</p>
  <table style="width:100%;">
    <tr>
      <td align="middle">
  <label>Von Neumann</label>
  <table>
    <tr>
      <td></td>
      <td class="helpCell"></td>
      <td></td>
    </tr>
    <tr>
      <td class="helpCell"></td>
      <td class="helpCellMain"> </td>
      <td class="helpCell"></td>
    </tr>
    <tr>
      <td></td>
      <td class="helpCell"></td>
      <td></td>
    </tr>
  </table>
      </td>
      <td align="middle">

    <label>Moore</label>
    <table>
      <tr>
        <td class="helpCell"></td>
        <td class="helpCell"></td>
        <td class="helpCell"></td>
      </tr>
      <tr>
        <td class="helpCell"></td>
        <td class="helpCellMain"> </td>
        <td class="helpCell"></td>
      </tr>
      <tr>
        <td class="helpCell"></td>
        <td class="helpCell"></td>
        <td class="helpCell"></td>
      </tr>
    </table>

      </td>
    </tr>
  </table>
  <h4>Network Size</h4>
  <p class="lead">The network size determines the number of cells in the entire network.  For 1D networks this is the width, so this
    number is also the total number of cells in the network.  For 2D networks this is both the width and the height, so the total number of
    cells in the network is this number squared.  For example, if you put 50 here and generate a 2D network, that network will have 50^2 = 2,500 cells.
    Be careful when generating very large networks, as doing so may cause the program to slow down.  If you generate an extremely large network that is too slow in updating,
    simply generate a smaller one and the old one will be discarded to speed the program up.  It should be noted that if you leave this field blank, the program
    will default to generating networks of size 20.</p>
  <h4>Cell Size</h4>
  <p class="lead">This option simply allows you to change the size of each cell in the graph (measured in pixels).  So if you put 5 here, each cell will be 5 pixels high and 5 pixels wide.
    This can be useful when generating very large networks that need a smaller cell size to fit on the screen, or very small networks that would be easier to see if each cell were a bit bigger.
    For 2D networks, there will be a button <b>Redraw Game</b> (appears after network is generated) that allows you to update the cell size of the network without generating an entirely new game.
    Note that if this field is left blank, the program will default to 10 pixels in size for each cell.</p>
  <h4>Learning Method</h4>
  <p class="lead">Changing the learning method allows you to alter how adjacent cells interact with one another and adapt.  There are three options: </p>
  <h5>Imitate-the-best</h5>
  <p class="lead">Imitate-the-best, as its name implies, is a learning method that has each cell imitating its most successful neighbor.  In each generation, every cell will play against its immediate neighbors
    (which for 2D networks is influenced by the neighborhood type selected) and tally up the payoffs it receives.  After each cell has played against its neighbors, it will then compare itself against its neighbors
    to see who fared the best.  If a cell received a higher payoff than all of its neighbors, it will keep strategy it has.  If a certain neighbor received a higher payoff than both the cell in question and all of its other neighbors,
    the cell will adopt that neighbor's strategy.  If one or multiple neighbors and the cell in question received the same payoff, a strategy will be randomly chosen among those with the highest payoff.  </p>
  <p class="lead">Note that if no learning method is chosen, this will be the default.</p>
  <h5>Myopic Best Response</h5>
  <p class="lead">Myopic best response is a nearsighted learning method that has cells figuring out, given their current neighbors, which strategy would net the highest payoff and then adopting that strategy in the next round.  This being the case,
    the cell's current strategy is irrelevant for its learning as it is only concerned with which, among the available strategies, would fare best.  If a given cell has strategy S2 and it would have received the highest payoff among those available
    if it were S3, that's what it will switch to.  If it is currently faring better than any other strategy would in its position, the cell will not change.</p>
  <p class="lead">The reason this learning method is nearsighted is because every other cell in the network is going through the same process, so the strategy that would fair best in the given neighborhood is almost irrelevant because that neighborhood will completely change in the next generation.
  However, unlike the other two learning methods, it allows for the emergence of strategies not even present on the board, let alone in the immediate neighborhood of the cell, and so can make for some very interesting models.</p>
  <h5>Probabilistic Imitation</h5>
  <p class="lead">Probabilistic Imitation is similar to <b>imitate-the-best</b> in that has cells looking to copy their successful neighbors; however, method does not guarantee that the neighbor with the highest payoff will be copied or even that a cell with a payoff higher than all neighbors will retain its strategy.
    Rather, the strategies in the neighborhood will be copied with probability proportional to what percentage their payoffs are of the total of payoffs in the neighborhood.  Every cell in the network plays against its neighbors to generate a payoff just like in ITB.  After that, each will take the sum of all the payoffs in its neighborhood,
    and randomly choose a strategy in the neighborhood based on the percentage that strategy's payoffs are of the total.  A cell may very well retain its original strategy through this method.</p>
  <p class="lead">For example, let's say that the sum of all the strategies in a neighborhood is 50, cells with strategy S1 have generated a total payoff of 10, cells with strategy S2 have generated a total payoff of 25, and cells with other strategies have generated the other 15 utils.
    This cell has a 20% chance of adopting strategy S1, a 50% chance of adopting S2, and a 30% chance of adopting one of the other strategies.  With this learning method, even strategies that are less successful than most others have a chance of surviving.</p>
  <h4>Matrix Size</h4>
  <p class="lead">GenLab can model up to sixteen different strategies; by default, inputs for just four will be shown since most will not need more than that.  To show the full 16x16 matrix, select <b>16</b> for <b>Matrix Size</b> and the original 4x4 one, as well as the strategy percentages options, will disappear to be replaced by a button that displays a new panel.
    This panel will have boxes to set up to 16 strategies (256 total payoffs to input), as well as for setting initial generation percentages for each strategy.  The 16x16 matrix functions exactly like the 4x4 one (see below); while you can set all 16 strategies, feel free to use as few as 2 or anywhere in between.  Note that EVERY payoff must be filled out if a strategy is being used,
    otherwise the program will not function correctly.</p>
  <h4>Payoff Matrix</h4>
  <p class="lead">Perhaps the most important element of the program, this matrix allows you to set the payoffs for the games being modeled.  You can have up to sixteen strategies in the game being modeled,
    and as few as two.  Simply fill out the game you wish to model, and the program will figure out which strategies you are using and omit the rest.  For example, if you are modeling the classic Prisoner's Dilemma
    with the two strategies Cooperate and Defect and fill out the matrix as such, the program will know and generate a network with just those two.  If you fill out the matrix incompletely, the network may still generate but you
    will be unable to advance generations and will have to re-generate the network once it is fixed.</p>
  <p class="lead">It should also be noted that the matrix should be filled just with <b>player 1's</b> payoffs, so each cell in the matrix should have just one number in it.  For example, if given the game</p>
  <table>
    <tr>
      <td class="helpTable"></td>
      <td class="helpTable">Cooperate</td>
      <td class="helpTable">Defect</td>
    </tr>
    <tr>
      <td class="helpTable">Cooperate</td>
      <td class="helpTable">2,2</td>
      <td class="helpTable">0,3</td>
    </tr>
    <tr>
      <td class="helpTable">Defect</td>
      <td class="helpTable">3,0</td>
      <td class="helpTable">1,1</td>
    </tr>
  </table>
  <p class="lead">The (4x4) payoff matrix should look like this: </p>
  <table>
    <tr>
      <td class="helpTable"></td>
      <td class="helpTable">S1</td>
      <td class="helpTable">S2</td>
      <td class="helpTable">S3</td>
      <td class="helpTable">S4</td>
    </tr>
    <tr>
      <td class="helpTable">S1</td>
      <td class="helpTable">2</td>
      <td class="helpTable">0</td>
      <td class="helpTable"></td>
      <td class="helpTable"></td>
    </tr>
    <tr>
      <td class="helpTable">S2</td>
      <td class="helpTable">3</td>
      <td class="helpTable">1</td>
      <td class="helpTable"></td>
      <td class="helpTable"></td>
    </tr>
    <tr>
      <td class="helpTable">S3</td>
      <td class="helpTable"></td>
      <td class="helpTable"></td>
      <td class="helpTable"></td>
      <td class="helpTable"></td>
    </tr>
    <tr>
      <td class="helpTable">S4</td>
      <td class="helpTable"></td>
      <td class="helpTable"></td>
      <td class="helpTable"></td>
      <td class="helpTable"></td>
    </tr>
  </table>
  <p class="lead">Also note that this is the only option that <b>cannot</b> be left blank, so be sure to fill this out before generating the network.</p>
  <h4>Strategy Percentages</h4>
  <p class="lead">The boxes represent the preferred percentage of each strategy that will be created during initial generation.  Be sure to only fill out boxes for strategies that are used
    (so if using S1, S2, S3, S4, S5, and S6, leave the rest blank) and to have the given percentages add up to 100%.  For example, if you are using S1, S2, and S3, you might put 10 for S1, 50 for S2, 40 for S3,
    and leave the others blank.  This will generate a network that is comprised of approximately 10% S1, 50% S2, 40% S3, and nothing else.</p>
  <p class="lead">Alternatively, you can leave these boxes blank to generate equal percentages of each strategy used.  So, if using S1 and S2, the network will generate with 50% of each; if using S1,
    S2, and S3, there will be about 33.3% of each; if using four strategies, 25% of each; and so on and so forth.  This may be an easier option if initial strategy proportions do not matter.</p>
  <br>
  <h3 style="text-align: center">Happy Modeling!</h3>
  <br><br>
  <p class="lead text-center">Created by Christopher Myers
    <br>Northeastern University '22
    <br><a href="https://github.com/chessmyers">https://github.com/chessmyers</a></p>
</body>
